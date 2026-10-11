#include "anthropic.h"

#include <algorithm>
#include <cstdlib>
#include <optional>
#include <string>
#include <string_view>
#include <utility>
#include <variant>
#include <vector>

#include <glaze/json.hpp>

#include <lighter/async/async.h>
#include <lighter/async/io/watcher.h>
#include <lighter/codec/json/json.h>

#include <lilia/provider/compact.h>
#include <lilia/provider/detail/anthropic_protocol.h>
#include <lilia/provider/detail/completion_retry.h>

// Anthropic Messages API wire types. Internal: the public surface speaks the
// neutral transcript (provider/history.h); everything here is serialization
// detail behind complete()/compact().
namespace lilia::anthropic::wire {

struct CacheControl {
    std::string type = "ephemeral";
};

struct TextBlock {
    std::string text;
    struct Citation {
        std::string type;
        std::string url;
        std::optional<std::string> title;
    };
    std::optional<std::vector<Citation>> citations;
    /// Requests only: a cache breakpoint after this block.
    std::optional<CacheControl> cache_control;
};

// Neutral ToolCall's fields (id/name/input) already spell the Anthropic wire
// names, so it serializes as the tool_use block directly.
using ToolUseBlock = provider::ToolCall;

/// `tool_use_id` is Anthropic's spelling of the neutral ToolOutcome's
/// `call_id`. Requests only - responses never carry tool_result blocks.
struct ToolResultBlock {
    std::string tool_use_id;
    std::string content;
    bool is_error = false;
};

struct ThinkingBlock {
    std::string thinking;
    std::string signature;
};

struct RedactedThinkingBlock {
    std::string data;
};

struct ServerToolUseBlock {
    std::string id;
    std::string name;
    glz::generic input;
};

struct WebSearchToolResultBlock {
    std::string tool_use_id;
    glz::generic content;
};

struct WebFetchToolResultBlock {
    std::string tool_use_id;
    glz::generic content;
};

/// Requests only: an inline base64 image in a user message.
struct ImageBlock {
    struct Source {
        std::string type = "base64";
        std::string media_type;
        std::string data;
    };
    Source source;
};

using ContentBlock = std::variant<TextBlock, ToolUseBlock, ToolResultBlock, ThinkingBlock, RedactedThinkingBlock, ServerToolUseBlock,
                                  WebSearchToolResultBlock, WebFetchToolResultBlock, ImageBlock>;

/// The block form of `system`, which unlike the plain string can carry a
/// cache breakpoint.
struct SystemBlock {
    std::string type = "text";
    std::string text;
    std::optional<CacheControl> cache_control;
};

struct Tool {
    std::optional<std::string> type;
    std::string name;
    std::optional<std::string> description;
    std::optional<provider::InputSchema> input_schema;
    std::optional<CacheControl> cache_control;
};

struct Message {
    std::string role; // "user" / "assistant"
    std::vector<ContentBlock> content;
};

struct MessageRequest {
    struct Thinking {
        std::string type = "adaptive";
    };

    struct OutputConfig {
        std::string effort;
    };

    struct ToolChoice {
        std::string type;
    };

    std::string model;
    u32 max_tokens = 8192;
    std::optional<std::variant<std::string, std::vector<SystemBlock>>> system;
    std::vector<Message> messages;
    std::optional<std::vector<Tool>> tools; // omitted when nullopt
    bool stream = true;
    std::optional<Thinking> thinking;
    std::optional<OutputConfig> output_config;
    std::optional<ToolChoice> tool_choice;
    std::optional<double> temperature;
    /// Automatic prompt caching: the breakpoint goes on the last cacheable block.
    std::optional<CacheControl> cache_control;
};

struct Model {
    std::string id;
    std::string display_name;
};

struct ModelsResponse {
    std::vector<Model> data;
    bool has_more = false;
    std::optional<std::string> last_id;
};

struct Usage {
    u64 input_tokens = 0;
    u64 output_tokens = 0;
    u64 cache_creation_input_tokens = 0;
    u64 cache_read_input_tokens = 0;
};

struct AssistantMessage {
    std::string id;
    std::string model;
    std::vector<ContentBlock> content;
    std::string stop_reason;
    std::optional<std::string> stop_sequence;
    Usage usage;
    std::string request_id; // request-id response header
};

} // namespace lilia::anthropic::wire

template <>
struct glz::meta<lilia::anthropic::wire::ContentBlock> {
    static constexpr std::string_view tag = "type";
    static constexpr auto ids = std::array{"text",
                                           "tool_use",
                                           "tool_result",
                                           "thinking",
                                           "redacted_thinking",
                                           "server_tool_use",
                                           "web_search_tool_result",
                                           "web_fetch_tool_result",
                                           "image"};
};

namespace lilia::anthropic {

namespace json = lighter::codec::json;
namespace http = lighter::http;
using lighter::fail;
using lighter::or_fail;
using lighter::outcome_error;
using lighter::Task;

namespace {

// The API adds fields over time; unknown keys must not break decoding.
inline constexpr json::Opts k_wire_opts{{.null_terminated = false, .error_on_unknown_keys = false}};

template <typename T>
Result<T> parse_wire(std::string_view text, std::string_view context) {
    T value{};
    if (auto ctx = glz::read<k_wire_opts>(value, text)) {
        return outcome_error(Error::json({.code = ctx.ec, .detail = glz::format_error(ctx, text)}, std::string(context)));
    }
    return value;
}

std::optional<std::string> citation_markdown(const wire::TextBlock::Citation &citation) {
    if (citation.url.empty()) return std::nullopt;
    const auto label = citation.title && !citation.title->empty() ? *citation.title : citation.url;
    return "[" + label + "](" + citation.url + ")";
}

std::string cited_text(wire::TextBlock text) {
    if (!text.citations || text.citations->empty()) return std::move(text.text);
    std::vector<std::string> citations;
    for (const auto &value : *text.citations) {
        auto citation = citation_markdown(value);
        if (citation && std::ranges::find(citations, *citation) == citations.end()) citations.push_back(*std::move(citation));
    }
    if (!citations.empty()) {
        text.text += "\n\nSources:";
        for (const auto &citation : citations) text.text += "\n- " + citation;
    }
    return std::move(text.text);
}

/// Anthropic envelope types that indicate a transient upstream condition.
bool transient_api_type(std::string_view type) {
    return type == "overloaded_error" || type == "rate_limit_error" || type == "api_error" || type == "timeout_error";
}

// --- neutral <-> wire translation ---------------------------------------

Result<std::string> encode_opaque(wire::ContentBlock block) {
    auto encoded = json::to_string(block);
    if (!encoded) {
        return outcome_error(Error::json(std::move(encoded).error(), "opaque block"));
    }
    return *std::move(encoded);
}

/// History -> wire messages. Opaque parts carrying our tag are replayed
/// verbatim (thinking blocks with their signatures); foreign-tagged parts
/// belong to another provider and are dropped.
struct WireHistory {
    /// One block per instruction text; concatenated they are the system prompt.
    std::vector<wire::SystemBlock> system;
    /// How many leading blocks come from SYSTEM items, the part that stays the
    /// same from call to call (DEVELOPER text carries the time and chat state).
    usize stable_system = 0;
    std::vector<wire::Message> messages;
};

void append_instruction(WireHistory &serialized, provider::Role role, std::string_view text) {
    if (text.empty()) return;
    std::string block;
    if (serialized.system.empty()) {
        block = "Instruction hierarchy: SYSTEM instructions take precedence over DEVELOPER instructions.\n";
    }
    block += role == provider::Role::SYSTEM ? "\n[SYSTEM]\n" : "\n[DEVELOPER]\n";
    block += text;
    serialized.system.push_back({.text = std::move(block)});
    if (role == provider::Role::SYSTEM && serialized.stable_system + 1 == serialized.system.size()) ++serialized.stable_system;
}

/// The plain string, or with prompt caching the blocks with a breakpoint after
/// the stable SYSTEM part, so a new reply reuses it even though the DEVELOPER
/// text and the conversation after it have changed.
std::optional<std::variant<std::string, std::vector<wire::SystemBlock>>> encode_system(WireHistory &serialized, bool prompt_cache) {
    if (serialized.system.empty()) return std::nullopt;
    if (prompt_cache) {
        if (serialized.stable_system > 0) serialized.system[serialized.stable_system - 1].cache_control = wire::CacheControl{};
        return std::move(serialized.system);
    }
    std::string prompt;
    for (const auto &block : serialized.system) prompt += block.text;
    return prompt;
}

std::string_view without_trailing_space(std::string_view text) {
    const auto last = text.find_last_not_of(" \t\r\n");
    return last == std::string_view::npos ? std::string_view{} : text.substr(0, last + 1);
}

/// `prompt_cache` keeps the breakpoints text parts ask for; without it they
/// are dropped.
Result<WireHistory> to_wire(const provider::History &history, bool prompt_cache) {
    WireHistory serialized;
    serialized.messages.reserve(history.size());
    bool conversation_started = false;

    for (const auto &item : history) {
        const bool instruction = provider::is_instruction(item.role);
        if (instruction && conversation_started) {
            return outcome_error(Error::protocol("system and developer instructions must precede conversation messages"));
        }
        if (instruction) {
            for (const auto &part : item.parts) {
                if (const auto *text = std::get_if<provider::TextPart>(&part)) {
                    append_instruction(serialized, item.role, text->text);
                } else {
                    return outcome_error(Error::protocol("instruction messages may contain only text"));
                }
            }
            continue;
        }
        conversation_started = true;

        wire::Message message{.role = item.role == provider::Role::ASSISTANT ? "assistant" : "user"};
        message.content.reserve(item.parts.size());

        for (const auto &part : item.parts) {
            if (const auto *text = std::get_if<provider::TextPart>(&part)) {
                // Trailing whitespace is dropped from a message's last block on
                // the way to the model; sent as is, the same block would differ
                // once later blocks follow it, and a cached prefix ending there
                // would never be read again. (Empty text blocks are refused.)
                const auto trimmed = without_trailing_space(text->text);
                if (trimmed.empty()) continue;
                message.content.push_back(wire::TextBlock{
                    .text = std::string(trimmed),
                    .cache_control = prompt_cache && text->cache ? std::optional(wire::CacheControl{}) : std::nullopt,
                });
            } else if (const auto *call = std::get_if<provider::ToolCall>(&part)) {
                message.content.push_back(*call);
            } else if (const auto *result = std::get_if<ToolOutcome>(&part)) {
                message.content.push_back(wire::ToolResultBlock{
                    .tool_use_id = result->call_id,
                    .content = std::string(without_trailing_space(render_tool_outcome(*result))),
                    .is_error = tool_outcome_is_error(result->kind),
                });
            } else if (const auto *image = std::get_if<provider::ImagePart>(&part)) {
                message.content.push_back(wire::ImageBlock{.source = {.media_type = image->media_type, .data = image->data}});
            } else if (const auto *opaque = std::get_if<provider::OpaquePart>(&part)) {
                if (opaque->provider_tag != k_provider_tag) {
                    continue; // another provider's private state
                }
                auto block = parse_wire<wire::ContentBlock>(opaque->payload, "opaque replay");
                if (!block) {
                    return outcome_error(std::move(block).error());
                }
                message.content.push_back(*std::move(block));
            }
        }

        // An item whose parts were all foreign opaques would serialize as an
        // empty message, which the API rejects; skip it entirely.
        if (!message.content.empty()) {
            if (message.role == "assistant" && !serialized.messages.empty() && serialized.messages.back().role == message.role) {
                auto &content = serialized.messages.back().content;
                content.insert(content.end(), std::make_move_iterator(message.content.begin()),
                               std::make_move_iterator(message.content.end()));
            } else {
                serialized.messages.push_back(std::move(message));
            }
        }
    }
    return serialized;
}

provider::StopKind to_stop_kind(std::string_view stop_reason) {
    if (stop_reason == "end_turn" || stop_reason == "stop_sequence") {
        return provider::StopKind::DONE;
    }
    if (stop_reason == "tool_use") {
        return provider::StopKind::NEEDS_TOOL_RESULTS;
    }
    if (stop_reason == "max_tokens") {
        return provider::StopKind::TRUNCATED;
    }
    if (stop_reason == "refusal") {
        return provider::StopKind::REFUSED;
    }
    if (stop_reason == "model_context_window_exceeded") {
        return provider::StopKind::CONTEXT_EXHAUSTED;
    }
    return provider::StopKind::OTHER;
}

provider::ProviderCallCompletion to_call_completion(wire::AssistantMessage message) {
    const auto context_tokens = message.usage.input_tokens + message.usage.output_tokens + message.usage.cache_read_input_tokens +
                                message.usage.cache_creation_input_tokens;
    return {
        .stop = to_stop_kind(message.stop_reason),
        .stop_detail = std::move(message.stop_reason),
        .usage = {.input_tokens = message.usage.input_tokens,
                  .output_tokens = message.usage.output_tokens,
                  .cache_read_tokens = message.usage.cache_read_input_tokens,
                  .cache_write_tokens = message.usage.cache_creation_input_tokens,
                  .context_tokens = context_tokens},
        .model = std::move(message.model),
        .request_id = std::move(message.request_id),
    };
}

Result<provider::OutputItem> to_output_item(wire::ContentBlock block, provider::OutputItemId id) {
    if (auto *text = std::get_if<wire::TextBlock>(&block)) {
        return provider::OutputItem(provider::AssistantMessageItem{
            .id = std::move(id),
            .parts = {{.text = cited_text(std::move(*text))}},
        });
    }
    if (auto *call = std::get_if<wire::ToolUseBlock>(&block)) {
        return provider::OutputItem(provider::ToolCallItem{.id = std::move(id), .call = std::move(*call)});
    }
    if (std::holds_alternative<wire::ThinkingBlock>(block) || std::holds_alternative<wire::RedactedThinkingBlock>(block) ||
        std::holds_alternative<wire::ServerToolUseBlock>(block) || std::holds_alternative<wire::WebSearchToolResultBlock>(block) ||
        std::holds_alternative<wire::WebFetchToolResultBlock>(block)) {
        auto payload = encode_opaque(std::move(block));
        if (!payload) return outcome_error(std::move(payload).error());
        return provider::OutputItem(provider::ProviderOpaqueItem{
            .id = std::move(id),
            .part = {.provider_tag = std::string(k_provider_tag), .payload = *std::move(payload)},
        });
    }
    return outcome_error(Error::protocol("unexpected tool_result block in assistant response"));
}

// --- SSE wire event payloads (probe shapes, all fields optional-ish) ----

struct WireUsage {
    std::optional<u64> input_tokens;
    std::optional<u64> output_tokens;
    std::optional<u64> cache_creation_input_tokens;
    std::optional<u64> cache_read_input_tokens;
};

struct WireMessageStart {
    std::string id;
    std::string model;
    std::optional<WireUsage> usage;
};

struct MessageStartEvent {
    WireMessageStart message;
};

struct WireBlockProbe {
    std::string type;
    std::optional<std::string> text;
    std::optional<std::string> id;
    std::optional<std::string> name;
    std::optional<std::string> thinking;
    std::optional<std::string> signature;
    std::optional<std::string> data;
    std::optional<std::string> tool_use_id;
    std::optional<glz::generic> content;
    std::optional<std::vector<wire::TextBlock::Citation>> citations;
};

struct ContentBlockStartEvent {
    u64 index = 0;
    WireBlockProbe content_block;
};

struct WireDeltaProbe {
    std::string type;
    std::optional<std::string> text;
    std::optional<std::string> partial_json;
    std::optional<std::string> thinking;
    std::optional<std::string> signature;
    std::optional<wire::TextBlock::Citation> citation;
};

struct ContentBlockDeltaEvent {
    u64 index = 0;
    WireDeltaProbe delta;
};

struct ContentBlockStopEvent {
    u64 index = 0;
};

struct WireMessageDelta {
    std::optional<std::string> stop_reason;
    std::optional<std::string> stop_sequence;
};

struct MessageDeltaEvent {
    WireMessageDelta delta;
    std::optional<WireUsage> usage;
};

struct WireApiError {
    std::string type;
    std::string message;
};

struct ErrorEvent {
    WireApiError error;
};

struct ApiErrorEnvelope {
    std::string type;
    WireApiError error;
    std::optional<std::string> request_id;
};

/// Classifies a context-window rejection whichever way it arrives, as an
/// HTTP status or as a streamed error event: Anthropic reports an oversized
/// prompt as an invalid_request_error whose message reads
/// "prompt is too long: N tokens > M maximum".
Error classify_context_exhaustion(Error error) {
    if (error.detail.contains("prompt is too long")) {
        error.code = ErrorCode::CONTEXT_EXHAUSTED;
    }
    return error;
}

// --- stream accumulator -------------------------------------------------

struct PendingText {
    std::string text;
    std::vector<wire::TextBlock::Citation> citations;
};

struct PendingToolUse {
    std::string id;
    std::string name;
    std::string input_json;
};

struct PendingThinking {
    std::string thinking;
    std::string signature;
};

struct PendingServerToolUse {
    std::string id;
    std::string name;
    std::string input_json;
};

struct PendingServerResult {
    std::string type;
    std::string tool_use_id;
    glz::generic content;
};

using PendingBlock =
    std::variant<PendingText, PendingToolUse, PendingThinking, wire::RedactedThinkingBlock, PendingServerToolUse, PendingServerResult>;

struct StreamAccumulator {
    wire::AssistantMessage message;
    std::vector<std::optional<PendingBlock>> pending;
    std::vector<std::optional<wire::ContentBlock>> completed;

    bool saw_message_start = false;
    bool saw_message_stop = false;
    bool output_emitted = false;

    Result<void> consume(const http::sse::Event &event, const provider::StreamCallbacks &callbacks);
    Result<wire::AssistantMessage> finish() &&;

private:
    void apply_usage(const WireUsage &usage);
    provider::OutputItemId block_id(u64 index) const;
    Result<void> on_block_start(const ContentBlockStartEvent &event, const provider::StreamCallbacks &callbacks);
    Result<void> on_block_delta(const ContentBlockDeltaEvent &event, const provider::StreamCallbacks &callbacks);
    Result<void> on_block_stop(const ContentBlockStopEvent &event, const provider::StreamCallbacks &callbacks);
};

provider::OutputItemId StreamAccumulator::block_id(u64 index) const { return {.value = message.id + ":" + std::to_string(index)}; }

void StreamAccumulator::apply_usage(const WireUsage &usage) {
    // Streaming usage is cumulative: later events overwrite, never add.
    if (usage.input_tokens) message.usage.input_tokens = *usage.input_tokens;
    if (usage.output_tokens) message.usage.output_tokens = *usage.output_tokens;
    if (usage.cache_creation_input_tokens) {
        message.usage.cache_creation_input_tokens = *usage.cache_creation_input_tokens;
    }
    if (usage.cache_read_input_tokens) {
        message.usage.cache_read_input_tokens = *usage.cache_read_input_tokens;
    }
}

Result<void> StreamAccumulator::on_block_start(const ContentBlockStartEvent &event, const provider::StreamCallbacks &callbacks) {
    auto index = static_cast<usize>(event.index);
    if (pending.size() <= index) {
        pending.resize(index + 1);
        completed.resize(index + 1);
    }
    if (pending[index] || completed[index]) {
        return outcome_error(Error::protocol("content_block_start for an already-started index"));
    }

    const auto &probe = event.content_block;
    if (probe.type == "text") {
        pending[index] =
            PendingText{.text = probe.text.value_or(""), .citations = probe.citations.value_or(std::vector<wire::TextBlock::Citation>{})};
    } else if (probe.type == "tool_use") {
        pending[index] = PendingToolUse{.id = probe.id.value_or(""), .name = probe.name.value_or("")};
    } else if (probe.type == "server_tool_use") {
        pending[index] = PendingServerToolUse{.id = probe.id.value_or(""), .name = probe.name.value_or("")};
    } else if (probe.type == "web_search_tool_result" || probe.type == "web_fetch_tool_result") {
        pending[index] = PendingServerResult{
            .type = probe.type,
            .tool_use_id = probe.tool_use_id.value_or(""),
            .content = probe.content.value_or(glz::generic{}),
        };
    } else if (probe.type == "thinking") {
        pending[index] = PendingThinking{.thinking = probe.thinking.value_or(""), .signature = probe.signature.value_or("")};
    } else if (probe.type == "redacted_thinking") {
        pending[index] = wire::RedactedThinkingBlock{.data = probe.data.value_or("")};
    } else {
        return outcome_error(Error::protocol("unknown content block type: " + probe.type));
    }
    output_emitted = true;
    if (callbacks.on_item_started) {
        const auto kind = probe.type == "text"     ? provider::OutputItemKind::ASSISTANT_MESSAGE :
                          probe.type == "tool_use" ? provider::OutputItemKind::TOOL_CALL :
                                                     provider::OutputItemKind::PROVIDER_OPAQUE;
        callbacks.on_item_started({.id = block_id(event.index), .kind = kind});
    }
    return {};
}

Result<void> StreamAccumulator::on_block_delta(const ContentBlockDeltaEvent &event, const provider::StreamCallbacks &callbacks) {
    auto index = static_cast<usize>(event.index);
    if (index >= pending.size() || !pending[index]) {
        return outcome_error(Error::protocol("content_block_delta without an active block"));
    }
    auto &block = *pending[index];
    const auto &delta = event.delta;

    if (delta.type == "text_delta") {
        auto *text = std::get_if<PendingText>(&block);
        if (!text) {
            return outcome_error(Error::protocol("text_delta for a non-text block"));
        }
        auto piece = delta.text.value_or("");
        text->text += piece;
        output_emitted = true;
        if (callbacks.on_assistant_text_delta && !piece.empty()) {
            callbacks.on_assistant_text_delta(block_id(event.index), piece);
        }
    } else if (delta.type == "input_json_delta") {
        if (auto *tool = std::get_if<PendingToolUse>(&block)) {
            tool->input_json += delta.partial_json.value_or("");
        } else if (auto *tool = std::get_if<PendingServerToolUse>(&block)) {
            tool->input_json += delta.partial_json.value_or("");
        } else {
            return outcome_error(Error::protocol("input_json_delta for a non-tool_use block"));
        }
    } else if (delta.type == "citations_delta") {
        auto *text = std::get_if<PendingText>(&block);
        if (!text || !delta.citation) return outcome_error(Error::protocol("citations_delta for a non-text block"));
        text->citations.push_back(*delta.citation);
        auto citation = citation_markdown(*delta.citation);
        if (citation && callbacks.on_assistant_text_delta) {
            callbacks.on_assistant_text_delta(block_id(event.index), "\n\nSource: " + *citation);
        }
    } else if (delta.type == "thinking_delta") {
        auto *thinking = std::get_if<PendingThinking>(&block);
        if (!thinking) {
            return outcome_error(Error::protocol("thinking_delta for a non-thinking block"));
        }
        thinking->thinking += delta.thinking.value_or("");
    } else if (delta.type == "signature_delta") {
        auto *thinking = std::get_if<PendingThinking>(&block);
        if (!thinking) {
            return outcome_error(Error::protocol("signature_delta for a non-thinking block"));
        }
        thinking->signature += delta.signature.value_or("");
    } else {
        return outcome_error(Error::protocol("unknown delta type: " + delta.type));
    }
    return {};
}

Result<void> StreamAccumulator::on_block_stop(const ContentBlockStopEvent &event, const provider::StreamCallbacks &callbacks) {
    auto index = static_cast<usize>(event.index);
    if (index >= pending.size() || !pending[index]) {
        return outcome_error(Error::protocol("content_block_stop without an active block"));
    }

    auto block = *std::move(pending[index]);
    pending[index].reset();

    if (auto *text = std::get_if<PendingText>(&block)) {
        completed[index] = wire::TextBlock{
            .text = std::move(text->text),
            .citations = text->citations.empty() ? std::nullopt : std::optional(std::move(text->citations)),
        };
    } else if (auto *tool = std::get_if<PendingToolUse>(&block)) {
        std::string_view input_json = tool->input_json.empty() ? std::string_view("{}") : tool->input_json;
        auto input = parse_wire<glz::generic>(input_json, "tool_use input");
        if (!input) {
            return outcome_error(std::move(input).error());
        }
        if (!input->is_object()) {
            return outcome_error(Error::protocol("tool_use input is not a JSON object"));
        }
        completed[index] = wire::ToolUseBlock{
            .id = std::move(tool->id),
            .name = std::move(tool->name),
            .input = *std::move(input),
        };
    } else if (auto *thinking = std::get_if<PendingThinking>(&block)) {
        completed[index] = wire::ThinkingBlock{
            .thinking = std::move(thinking->thinking),
            .signature = std::move(thinking->signature),
        };
    } else if (auto *redacted = std::get_if<wire::RedactedThinkingBlock>(&block)) {
        completed[index] = std::move(*redacted);
    } else if (auto *tool = std::get_if<PendingServerToolUse>(&block)) {
        std::string_view input_json = tool->input_json.empty() ? std::string_view("{}") : tool->input_json;
        auto input = parse_wire<glz::generic>(input_json, "server_tool_use input");
        if (!input) return outcome_error(std::move(input).error());
        if (!input->is_object()) return outcome_error(Error::protocol("server_tool_use input is not a JSON object"));
        completed[index] = wire::ServerToolUseBlock{
            .id = std::move(tool->id),
            .name = std::move(tool->name),
            .input = *std::move(input),
        };
    } else if (auto *result = std::get_if<PendingServerResult>(&block)) {
        if (result->type == "web_search_tool_result") {
            completed[index] =
                wire::WebSearchToolResultBlock{.tool_use_id = std::move(result->tool_use_id), .content = std::move(result->content)};
        } else {
            completed[index] =
                wire::WebFetchToolResultBlock{.tool_use_id = std::move(result->tool_use_id), .content = std::move(result->content)};
        }
    }
    auto output = to_output_item(*completed[index], block_id(event.index));
    if (!output) return outcome_error(std::move(output).error());
    if (callbacks.on_item_completed) callbacks.on_item_completed(*output);
    return {};
}

Result<void> StreamAccumulator::consume(const http::sse::Event &event, const provider::StreamCallbacks &callbacks) {
    const auto &name = event.event;

    if (name == "ping") {
        return {};
    }
    if (name == "message_start") {
        if (saw_message_start) {
            return outcome_error(Error::protocol("duplicate message_start"));
        }
        auto parsed = parse_wire<MessageStartEvent>(event.data, "message_start");
        if (!parsed) {
            return outcome_error(std::move(parsed).error());
        }
        saw_message_start = true;
        message.id = std::move(parsed->message.id);
        message.model = std::move(parsed->message.model);
        if (parsed->message.usage) {
            apply_usage(*parsed->message.usage);
        }
        return {};
    }
    if (name == "error") {
        auto parsed = parse_wire<ErrorEvent>(event.data, "error event");
        if (!parsed) {
            return outcome_error(std::move(parsed).error());
        }
        bool transient = transient_api_type(parsed->error.type);
        return outcome_error(classify_context_exhaustion(
            Error::api(std::move(parsed->error.type), std::move(parsed->error.message), message.request_id, transient)));
    }
    if (!saw_message_start) {
        return outcome_error(Error::protocol("event before message_start: " + name));
    }
    if (name == "content_block_start") {
        auto parsed = parse_wire<ContentBlockStartEvent>(event.data, "content_block_start");
        if (!parsed) {
            return outcome_error(std::move(parsed).error());
        }
        return on_block_start(*parsed, callbacks);
    }
    if (name == "content_block_delta") {
        auto parsed = parse_wire<ContentBlockDeltaEvent>(event.data, "content_block_delta");
        if (!parsed) {
            return outcome_error(std::move(parsed).error());
        }
        return on_block_delta(*parsed, callbacks);
    }
    if (name == "content_block_stop") {
        auto parsed = parse_wire<ContentBlockStopEvent>(event.data, "content_block_stop");
        if (!parsed) {
            return outcome_error(std::move(parsed).error());
        }
        return on_block_stop(*parsed, callbacks);
    }
    if (name == "message_delta") {
        auto parsed = parse_wire<MessageDeltaEvent>(event.data, "message_delta");
        if (!parsed) {
            return outcome_error(std::move(parsed).error());
        }
        if (parsed->delta.stop_reason) {
            message.stop_reason = std::move(*parsed->delta.stop_reason);
        }
        if (parsed->delta.stop_sequence) {
            message.stop_sequence = std::move(*parsed->delta.stop_sequence);
        }
        if (parsed->usage) {
            apply_usage(*parsed->usage);
        }
        return {};
    }
    if (name == "message_stop") {
        for (const auto &entry : pending) {
            if (entry) {
                return outcome_error(Error::protocol("message_stop with unfinished content block"));
            }
        }
        if (message.stop_reason.empty()) {
            return outcome_error(Error::protocol("message_stop without a stop_reason"));
        }
        saw_message_stop = true;
        return {};
    }
    // Unknown event types are ignored per Anthropic versioning policy.
    return {};
}

Result<wire::AssistantMessage> StreamAccumulator::finish() && {
    if (!saw_message_stop) {
        return outcome_error(Error::protocol("stream ended before message_stop"));
    }
    message.content.reserve(completed.size());
    for (auto &entry : completed) {
        if (!entry) {
            return outcome_error(Error::protocol("content block index gap in stream"));
        }
        message.content.push_back(*std::move(entry));
    }
    return std::move(message);
}

// --- request helpers ----------------------------------------------------

/// Drain up to `limit` bytes of an (error) response body; transport failures
/// just truncate what we report - we are already on an error path.
Task<std::string> read_bounded_body(http::StreamingResponse &response, usize limit) {
    std::string body;
    while (body.size() < limit) {
        auto chunk = co_await response.read_chunk();
        if (!chunk || chunk->empty()) {
            break;
        }
        auto take = std::min(chunk->size(), limit - body.size());
        body.append(chunk->data(), take);
        response.consume(chunk->size());
    }
    co_return body;
}

std::optional<std::chrono::milliseconds> parse_retry_after(const http::StreamingResponse &response) {
    auto value = response.header_value("retry-after");
    if (!value) {
        return std::nullopt;
    }
    char *end = nullptr;
    std::string text(*value);
    auto seconds = std::strtol(text.c_str(), &end, 10);
    if (end == text.c_str() || seconds < 0) {
        return std::nullopt;
    }
    return std::chrono::seconds(seconds);
}

Task<provider::ProviderCallCompletion, Error> attempt_stream(http::Client &http_client, const ClientOptions &options,
                                                             const std::string &body, const provider::StreamCallbacks &callbacks,
                                                             bool &output_emitted) {
    auto request = http_client.on().post(options.base_url + "/v1/messages");
    request.header("anthropic-version", "2023-06-01").header("accept", "text/event-stream").json_text(body);
    if (!options.auth) {
        co_await fail(Error::config("provider has no authentication resolver"));
    }
    auto auth = co_await options.auth().or_fail();
    if (!auth.api_key.empty()) {
        request.header("x-api-key", auth.api_key);
    }
    if (!auth.bearer_token.empty()) {
        request.bearer_auth(auth.bearer_token);
    }
    for (const auto &header : auth.headers) {
        request.header(header.name, header.value);
    }

    auto streamed = co_await std::move(request).stream();
    if (!streamed) {
        co_await fail(Error::http(std::move(streamed).error()));
    }
    auto response = *std::move(streamed);
    std::string request_id(response.header_value("request-id").value_or(""));

    if (!response.ok()) {
        auto error_body = co_await read_bounded_body(response, 64 * 1024);
        co_await fail(protocol::decode_status_error(response.status, error_body, std::move(request_id), parse_retry_after(response)));
    }

    auto content_type = response.header_value("content-type").value_or("");
    if (content_type.find("text/event-stream") == std::string_view::npos) {
        co_await fail(Error::protocol("expected text/event-stream response, got: " + std::string(content_type)));
    }

    http::sse::EventStream events(std::move(response));
    StreamAccumulator accumulator;
    accumulator.message.request_id = std::move(request_id);

    while (!accumulator.saw_message_stop) {
        auto event = co_await events.next();
        if (!event) {
            output_emitted = accumulator.output_emitted;
            co_await fail(Error::http(std::move(event).error()));
        }
        if (!*event) {
            break; // clean EOF; finish() rejects it if message_stop never came
        }
        auto consumed = accumulator.consume(**event, callbacks);
        output_emitted = accumulator.output_emitted;
        if (!consumed) {
            co_await fail(std::move(consumed).error());
        }
    }

    auto message = co_await or_fail(std::move(accumulator).finish());
    co_return to_call_completion(std::move(message));
}

} // namespace

namespace protocol {

Error decode_status_error(int status, std::string_view body, std::string request_id, std::optional<std::chrono::milliseconds> retry_after) {
    std::string api_type;
    std::string detail(body);
    if (auto envelope = parse_wire<ApiErrorEnvelope>(body, "error body")) {
        api_type = std::move(envelope->error.type);
        detail = std::move(envelope->error.message);
        if (request_id.empty() && envelope->request_id) {
            request_id = std::move(*envelope->request_id);
        }
    }
    return classify_context_exhaustion(
        Error::http_status(status, std::move(api_type), std::move(detail), std::move(request_id), retry_after));
}

Result<std::string> encode_complete_request(const provider::History &history, const std::vector<provider::ToolDefinition> &tools,
                                            const ClientOptions &options) {
    auto wire_history = to_wire(history, options.prompt_cache);
    if (!wire_history) {
        return outcome_error(std::move(wire_history).error());
    }
    wire::MessageRequest request{
        .model = options.model,
        .max_tokens = options.max_tokens,
        .system = encode_system(*wire_history, options.prompt_cache),
        .messages = std::move(wire_history->messages),
    };
    if (!tools.empty()) {
        std::vector<wire::Tool> encoded_tools;
        encoded_tools.reserve(tools.size());
        for (const auto &tool : tools) {
            switch (tool.kind) {
                case provider::ToolKind::FUNCTION:
                    encoded_tools.push_back({
                        .name = tool.name,
                        .description = tool.description,
                        .input_schema = tool.input_schema,
                    });
                    break;
                case provider::ToolKind::WEB_SEARCH: encoded_tools.push_back({.type = "web_search_20250305", .name = "web_search"}); break;
                case provider::ToolKind::WEB_FETCH: encoded_tools.push_back({.type = "web_fetch_20250910", .name = "web_fetch"}); break;
            }
        }
        // Every call offers the same tools: cache them on their own too, unless
        // a system breakpoint (after them in the prefix) already covers them;
        // breakpoints are limited to four, and relays may add their own.
        const bool system_cached = request.system && std::holds_alternative<std::vector<wire::SystemBlock>>(*request.system) &&
                                   std::ranges::any_of(std::get<std::vector<wire::SystemBlock>>(*request.system),
                                                       [](const wire::SystemBlock &block) { return block.cache_control.has_value(); });
        if (options.prompt_cache && !system_cached) encoded_tools.back().cache_control = wire::CacheControl{};
        request.tools = std::move(encoded_tools);
        if (options.require_tool) request.tool_choice = wire::MessageRequest::ToolChoice{.type = "any"};
    }
    if (options.prompt_cache) request.cache_control = wire::CacheControl{};
    request.temperature = options.temperature;
    if (options.reasoning_effort) {
        request.thinking = wire::MessageRequest::Thinking{};
        request.output_config = wire::MessageRequest::OutputConfig{.effort = *options.reasoning_effort};
    } else if (options.disable_thinking) {
        request.thinking = wire::MessageRequest::Thinking{.type = options.thinking_off};
    }

    auto encoded = json::to_string(request);
    if (!encoded) {
        return outcome_error(Error::json(std::move(encoded).error(), "request body"));
    }
    return *std::move(encoded);
}

Result<provider::ProviderCallCompletion> decode_stream(std::span<const http::sse::Event> events, const provider::StreamCallbacks &callbacks,
                                                       std::string request_id) {
    StreamAccumulator accumulator;
    accumulator.message.request_id = std::move(request_id);
    for (const auto &event : events) {
        auto consumed = accumulator.consume(event, callbacks);
        if (!consumed) {
            return outcome_error(std::move(consumed).error());
        }
    }
    auto message = std::move(accumulator).finish();
    if (!message) {
        return outcome_error(std::move(message).error());
    }
    return to_call_completion(*std::move(message));
}

} // namespace protocol

Client::Client(ClientOptions options) : options(std::move(options)) {
    while (!this->options.base_url.empty() && this->options.base_url.back() == '/') {
        this->options.base_url.pop_back();
    }
}

Task<provider::ProviderCallCompletion, Error> Client::complete(const provider::History &history,
                                                               const std::vector<provider::ToolDefinition> &tools,
                                                               const provider::StreamCallbacks &callbacks) {
    const std::string body = co_await or_fail(protocol::encode_complete_request(history, tools, options));
    provider::detail::CompletionAttempts attempts{
        .stream = [this](const std::string &request_body, const provider::StreamCallbacks &stream_callbacks,
                         bool &output_emitted) -> Task<provider::ProviderCallCompletion, Error> {
            return attempt_stream(http_client, options, request_body, stream_callbacks, output_emitted);
        },
        .sleep = [](std::chrono::milliseconds delay) { return lighter::sleep(delay); },
    };
    co_return co_await provider::detail::complete_with_retry(attempts, body, callbacks, options.max_retries, options.initial_retry_delay)
        .or_fail();
}

Task<void, Error> Client::compact(provider::History &history, provider::CompactRequest request) {
    // No native compaction endpoint; summarize through our own complete().
    co_return co_await provider::local_compact(this, history, std::move(request)).or_fail();
}

Task<std::vector<provider::DiscoveredModel>, Error> list_models(ClientOptions options) {
    while (!options.base_url.empty() && options.base_url.back() == '/') {
        options.base_url.pop_back();
    }

    http::Client client;
    std::vector<provider::DiscoveredModel> models;
    std::optional<std::string> after_id;
    do {
        auto request = client.on().get(options.base_url + "/v1/models");
        request.header("anthropic-version", "2023-06-01").query("limit", "1000");
        if (after_id) {
            request.query("after_id", *after_id);
        }
        if (!options.auth) {
            co_await fail(Error::config("provider has no authentication resolver"));
        }
        auto auth = co_await options.auth().or_fail();
        if (!auth.api_key.empty()) {
            request.header("x-api-key", auth.api_key);
        }
        if (!auth.bearer_token.empty()) {
            request.bearer_auth(auth.bearer_token);
        }
        for (const auto &header : auth.headers) {
            request.header(header.name, header.value);
        }

        auto sent = co_await std::move(request).send();
        if (!sent) {
            co_await fail(Error::http(std::move(sent).error()));
        }
        if (!sent->ok()) {
            auto request_id = std::string(sent->header_value("request-id").value_or(""));
            co_await fail(Error::http_status(sent->status, {}, sent->text_copy(), std::move(request_id)));
        }
        auto response = parse_wire<wire::ModelsResponse>(sent->text(), "models response");
        if (!response) {
            co_await fail(std::move(response).error());
        }
        for (auto &entry : response->data) {
            if (!entry.id.empty()) {
                models.push_back({.id = std::move(entry.id), .name = std::move(entry.display_name)});
            }
        }
        if (!response->has_more) {
            break;
        }
        if (!response->last_id || response->last_id->empty() || response->last_id == after_id) {
            co_await fail(Error::protocol("models response pagination did not advance"));
        }
        after_id = std::move(response->last_id);
    } while (true);

    co_return models;
}

} // namespace lilia::anthropic
