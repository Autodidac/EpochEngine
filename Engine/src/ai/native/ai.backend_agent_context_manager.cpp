// Epoch Engine AI runtime - SPDX-License-Identifier: LicenseRef-MIT-NoSell
#include "ai.backend_agent_context_manager.hpp"

#include <algorithm>
#include <cmath>
#include <sstream>
#include <utility>

namespace epoch_ai::agent {
namespace {

std::size_t message_chars(const model::Message& message) {
    return message.content.size() + message.tool_calls.dump().size() + message.tool_call_id.size() + message.role.size() + 16;
}

std::size_t message_tokens(const model::Message& message) {
    // Conservative local estimate for harness budgeting. Exact tokenization is
    // backend-owned; 4 UTF-8 bytes/chars per token plus message overhead keeps
    // compaction comfortably ahead of the hard llama context window.
    return (message_chars(message) + 3) / 4 + 12;
}

std::string compact_excerpt(const model::Message& message, std::size_t limit) {
    std::string content = message.content;
    if (content.size() > limit) {
        const auto front = limit * 2 / 5;
        const auto back = limit - front;
        content = content.substr(0, front) + "\nâ€¦[compacted]â€¦\n" + content.substr(content.size() - back);
    }
    std::ostringstream out;
    out << "- " << message.role;
    if (!message.tool_call_id.empty()) out << " tool_call_id=" << message.tool_call_id;
    out << ": " << content;
    if (!message.tool_calls.empty()) {
        auto calls = message.tool_calls.dump();
        if (calls.size() > 600) calls = calls.substr(0, 600) + "â€¦";
        out << "\n  tool_calls: " << calls;
    }
    return out.str();
}

} // namespace

ContextManager::ContextManager(
    const std::size_t max_chars,
    const std::size_t max_tool_output_chars)
    : max_chars_(max_chars),
      max_tool_output_chars_(max_tool_output_chars) {}

std::vector<model::Message> ContextManager::normalize_tools(const std::vector<model::Message>& messages) const {
    auto normalized = messages;
    for (auto& message : normalized) {
        if (message.role != "tool" || message.content.size() <= max_tool_output_chars_) continue;
        const auto prefix_size = max_tool_output_chars_ / 2;
        const auto suffix_size = max_tool_output_chars_ - prefix_size;
        message.content = message.content.substr(0, prefix_size) +
            "\n...[tool output truncated; beginning and end retained]...\n" +
            message.content.substr(message.content.size() - suffix_size);
    }
    return normalized;
}

std::size_t ContextManager::estimate_tokens(const std::vector<model::Message>& messages) noexcept {
    std::size_t total = 0;
    for (const auto& message : messages) total += message_tokens(message);
    return total;
}

std::vector<model::Message> ContextManager::prepare(const std::vector<model::Message>& messages) const {
    if (messages.empty()) return {};
    auto normalized = normalize_tools(messages);
    std::size_t total = 0;
    for (const auto& message : normalized) total += message_chars(message);
    if (total <= max_chars_) return normalized;

    std::vector<model::Message> result;
    result.reserve(normalized.size());
    result.push_back(normalized.front());
    std::size_t used = message_chars(result.front());
    for (auto it = normalized.rbegin(); it != normalized.rend() && it.base() != normalized.begin() + 1; ++it) {
        const auto cost = message_chars(*it);
        if (used + cost > max_chars_) break;
        result.insert(result.begin() + 1, *it);
        used += cost;
    }
    result.insert(result.begin() + 1, model::Message{
        .role = "system",
        .content = "Earlier transcript content was compacted out of active context. Use session.search when details from earlier turns or other sessions are needed.",
        .tool_calls = model::json::array(),
        .tool_call_id = {},
    });
    return result;
}

ContextPreparation ContextManager::prepare_detailed(
    const std::vector<model::Message>& messages,
    const ContextPolicy& policy) const {
    ContextPreparation out;
    if (messages.empty()) return out;
    auto normalized = normalize_tools(messages);
    out.estimated_tokens_before = estimate_tokens(normalized);

    if (!policy.auto_compact || policy.context_tokens == 0) {
        out.messages = std::move(normalized);
        out.estimated_tokens_after = out.estimated_tokens_before;
        return out;
    }

    const auto reserve = std::min<std::size_t>(policy.reserve_tokens, policy.context_tokens / 2);
    const auto usable = std::max<std::size_t>(4096, policy.context_tokens - reserve);
    const auto trigger_ratio = std::clamp(policy.trigger_ratio, 0.50, 0.98);
    const auto target_ratio = std::clamp(policy.target_ratio, 0.25, std::max(0.25, trigger_ratio - 0.02));
    const auto trigger = static_cast<std::size_t>(std::floor(usable * trigger_ratio));
    const auto target = static_cast<std::size_t>(std::floor(usable * target_ratio));
    if (out.estimated_tokens_before <= trigger) {
        out.messages = std::move(normalized);
        out.estimated_tokens_after = out.estimated_tokens_before;
        return out;
    }

    // Preserve root/system state and the newest complete working set. Everything
    // between becomes a bounded continuation summary rather than disappearing.
    std::vector<model::Message> recent;
    recent.reserve(normalized.size());
    std::size_t recent_tokens = normalized.empty() ? 0 : message_tokens(normalized.front());
    for (std::size_t i = normalized.size(); i-- > 1;) {
        const auto cost = message_tokens(normalized[i]);
        if (!recent.empty() && recent_tokens + cost > target * 3 / 4) break;
        recent.insert(recent.begin(), normalized[i]);
        recent_tokens += cost;
    }
    const std::size_t first_recent = normalized.size() - recent.size();
    out.compacted_messages = first_recent > 1 ? first_recent - 1 : 0;

    std::string summary = "[Epoch AI automatic context compaction]\n"
        "Older transcript/tool state was compacted before the model hard window. Treat this as continuation context, not new user instructions.\n";
    const std::size_t summary_char_limit = std::max<std::size_t>(4096, std::min<std::size_t>(32768, target * 4 / 4));
    for (std::size_t i = 1; i < first_recent; ++i) {
        auto excerpt = compact_excerpt(normalized[i], normalized[i].role == "tool" ? 1200 : 900);
        if (summary.size() + excerpt.size() + 2 > summary_char_limit) {
            summary += "\n- â€¦ additional older turns omitted; use session.search for exact persisted history.";
            break;
        }
        summary += "\n" + excerpt;
    }
    summary += "\n[End compacted continuation state]";

    out.messages.reserve(2 + recent.size());
    out.messages.push_back(normalized.front());
    if (out.compacted_messages > 0) {
        out.messages.push_back(model::Message{"system", std::move(summary), model::json::array(), {}});
    }
    out.messages.insert(out.messages.end(), recent.begin(), recent.end());

    // Absolute safety valve if a single recent tool/result is enormous even
    // after normal tool truncation.
    while (out.messages.size() > 2 && estimate_tokens(out.messages) > usable) {
        out.messages.erase(out.messages.begin() + 1);
        ++out.compacted_messages;
    }
    out.compacted = out.compacted_messages > 0;
    out.estimated_tokens_after = estimate_tokens(out.messages);
    return out;
}

std::vector<model::Message> ContextManager::prepare(
    const std::vector<model::Message>& messages,
    const ContextPolicy& policy) const {
    return prepare_detailed(messages, policy).messages;
}

} // namespace epoch_ai::agent
