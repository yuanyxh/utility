"""Protocol conversion and request injection layer for token_proxy.

Split out from token_proxy.py (2026-08-30, refactor stage 2): anthropic↔openai
protocol conversion (ProtocolConverter/OpenAIToAnthropicStream), safety classifier
detection and injection, system rule injection (_inject_system_prompt), SSE stream
extraction. The code was moved verbatim without logic changes.
"""

from __future__ import annotations

import json
import os

from config import notes_dir
from log_utils import setup_logging

# The single authoritative implementation of "how to read the Anthropic system
# field" lives in the normalization layer and is reused here, avoiding deriving the
# same fact twice (when the system structure is extended, only one place changes).
# Dependency direction: proxy_protocol → proxy_normalize (the latter depends only on
# the standard library, so no cycle).
from proxy_normalize import system_to_text as _system_to_text

# ---------------------------------------------------------------------------
# Configuration (identical to token_proxy.py before the split)
# ---------------------------------------------------------------------------

NOTES_DIR = notes_dir()
SYSTEM_PROMPTS_FILE = os.path.join(NOTES_DIR, "MCP", "System_Prompts.md")

logger = setup_logging("token_proxy", json_format=True)


#: The start/end markers of the rule-injection block. Defined by the injector (this
#: module); the stripper (usage extraction in proxy_usage) reuses the same constants —
#: avoiding deriving "which marker the injector uses" and "which marker the stripper
#: recognizes" in two places.
RULE_START_MARK = "---rule_start"
RULE_END_MARK = "---rule_end"


def strip_injected_rules(text: str) -> str:
    """Strip the rule block injected by `_inject_system_prompt`, keeping the rest of the user text.

    The injected block is a whole `System_Prompts.md` (up to several thousand
    characters), while the extraction caps for usage records are only 100~500
    characters — without stripping, the three fields `context_summary` /
    `input_preview` / `actual_user_input` would all show the beginning of the rules
    and the real user input would be pushed out entirely.

    Supports stripping multiple blocks; an unclosed block is discarded to the end
    (guarding against a leftover half-block).
    """
    if not text or RULE_START_MARK not in text:
        return text
    out: list[str] = []
    rest = text
    while True:
        i = rest.find(RULE_START_MARK)
        if i < 0:
            out.append(rest)
            break
        out.append(rest[:i])
        j = rest.find(RULE_END_MARK, i + len(RULE_START_MARK))
        if j < 0:
            break  # block unclosed → discard the remainder, do not treat a half rule as user input
        rest = rest[j + len(RULE_END_MARK) :]
    return "".join(out).strip()


def _sse_event(event: str, data: dict) -> str:
    return f"event: {event}\ndata: {json.dumps(data, ensure_ascii=False)}\n\n"


# ---------------------------------------------------------------------------
# Protocol constants
# ---------------------------------------------------------------------------

#: OpenAI `finish_reason` → Anthropic `stop_reason` mapping. **Single authoritative
#: definition**, shared by the streaming conversion / non-streaming conversion / SSE
#: usage extraction.
#:
#: Maintaining it in separate places makes the same upstream response yield different
#: conclusions on different paths: content_filter once had a mapping only in the
#: record layer's table while both conversion layers lacked it, so
#: `mapping.get(finish, "end_turn")` treated "content filtered" as "normal end" — the
#: client saw end_turn and the routing layer also concluded normal termination from
#: it, the anomaly signal was lost entirely, while the database faithfully recorded
#: content_filter.
FINISH_REASON_MAP: dict[str, str] = {
    "stop": "end_turn",
    "tool_calls": "tool_use",
    "length": "max_tokens",
    "content_filter": "content_filter",
}

#: Fallback when the conversion layer meets an unknown finish_reason — must be a legal
#: Anthropic enum value, otherwise the client rejects the entire response for an
#: illegal stop_reason.
FALLBACK_STOP_REASON = "end_turn"


def _tool_choice_anthropic_to_openai(choice):
    """Anthropic tool_choice → OpenAI tool_choice.

    Anthropic: {"type": "auto"|"any"|"tool"|"none"[, "name": ...]}
    OpenAI:    "auto"|"required"|"none" | {"type":"function","function":{"name":...}}
    """
    if not isinstance(choice, dict):
        return choice
    ctype = choice.get("type")
    if ctype == "any":
        return "required"
    if ctype == "tool":
        return {"type": "function", "function": {"name": choice.get("name", "")}}
    return ctype or "auto"


def _tool_choice_openai_to_anthropic(choice):
    """OpenAI tool_choice → Anthropic tool_choice (the inverse of the previous function)."""
    if isinstance(choice, str):
        return {"type": {"required": "any", "none": "none"}.get(choice, "auto")}
    if isinstance(choice, dict):
        fn = choice.get("function") or {}
        return {"type": "tool", "name": fn.get("name", "")}
    return choice


class ProtocolConverter:
    """Bidirectional conversion of Anthropic Messages API ↔ OpenAI Chat Completions request bodies."""

    @staticmethod
    def request_anthropic_to_openai(body: dict) -> dict:
        out: dict = {
            "model": body.get("model", ""),
            "stream": body.get("stream", False),
        }
        if body.get("max_tokens"):
            out["max_tokens"] = body["max_tokens"]
        if body.get("temperature") is not None:
            out["temperature"] = body["temperature"]
        if body.get("top_p") is not None:
            out["top_p"] = body["top_p"]
        # Anthropic's stop-sequence field is `stop_sequences` (an array); the OpenAI
        # equivalent is `stop`. This used to read `stop` — Anthropic request bodies
        # have no such key, so the conversion never took effect (silently dropping config).
        if body.get("stop_sequences") is not None:
            out["stop"] = body["stop_sequences"]
        if body.get("tool_choice") is not None:
            out["tool_choice"] = _tool_choice_anthropic_to_openai(body["tool_choice"])

        system_text = _system_to_text(body.get("system"))
        messages: list[dict] = []
        if system_text.strip():
            messages.append({"role": "system", "content": system_text})

        for m in body.get("messages", []):
            role, content = m.get("role"), m.get("content")
            if role == "user":
                if isinstance(content, str):
                    messages.append({"role": "user", "content": content})
                elif isinstance(content, list):
                    text_parts: list[str] = []
                    tool_results: list[dict] = []
                    for b in content:
                        if not isinstance(b, dict):
                            continue
                        bt = b.get("type")
                        if bt == "text":
                            text_parts.append(b.get("text", ""))
                        elif bt == "tool_result":
                            tool_results.append(
                                {
                                    "role": "tool",
                                    "tool_call_id": b.get("tool_use_id", ""),
                                    "content": b.get("content", ""),
                                }
                            )
                        elif bt == "image":
                            src = b.get("source", {})
                            if src.get("type") == "base64":
                                text_parts.append(
                                    "![image](data:{};base64,{})".format(
                                        src.get("media_type", ""), src.get("data", "")
                                    )
                                )
                    if text_parts:
                        messages.append(
                            {"role": "user", "content": "".join(text_parts)}
                        )
                    messages.extend(tool_results)
            elif role == "assistant":
                if isinstance(content, str):
                    messages.append({"role": "assistant", "content": content})
                elif isinstance(content, list):
                    text_parts, tool_calls = [], []
                    for b in content:
                        if not isinstance(b, dict):
                            continue
                        bt = b.get("type")
                        if bt == "text":
                            text_parts.append(b.get("text", ""))
                        elif bt == "tool_use":
                            tool_calls.append(
                                {
                                    "id": b.get("id", ""),
                                    "type": "function",
                                    "function": {
                                        "name": b.get("name", ""),
                                        "arguments": json.dumps(
                                            b.get("input", {}), ensure_ascii=False
                                        ),
                                    },
                                }
                            )
                    msg = {"role": "assistant"}
                    if text_parts:
                        msg["content"] = "".join(text_parts)
                    if tool_calls:
                        msg["tool_calls"] = tool_calls
                    messages.append(msg)

        out["messages"] = messages

        tools = body.get("tools")
        if tools:
            out["tools"] = [
                {
                    "type": "function",
                    "function": {
                        "name": t.get("name", ""),
                        "description": t.get("description", ""),
                        "parameters": t.get(
                            "input_schema", {"type": "object", "properties": {}}
                        ),
                    },
                }
                for t in tools
                if isinstance(t, dict)
            ]
        if body.get("stream"):
            # openai streaming does not return usage by default; explicitly request it be carried at the end
            out["stream_options"] = {"include_usage": True}
        return out

    @staticmethod
    def request_openai_to_anthropic(body: dict) -> dict:
        out: dict = {
            "model": body.get("model", ""),
            "stream": body.get("stream", False),
        }
        if body.get("max_tokens"):
            out["max_tokens"] = body["max_tokens"]
        if body.get("temperature") is not None:
            out["temperature"] = body["temperature"]
        if body.get("top_p") is not None:
            out["top_p"] = body["top_p"]
        # OpenAI `stop` ↔ Anthropic `stop_sequences`: the field names differ on the two sides and must be converted explicitly
        if body.get("stop") is not None:
            out["stop_sequences"] = body["stop"]

        system_text = ""
        messages: list[dict] = []
        for m in body.get("messages", []):
            role = m.get("role")
            if role == "system":
                system_text += (m.get("content") or "") + "\n"
            elif role == "tool":
                messages.append(
                    {
                        "role": "user",
                        "content": [
                            {
                                "type": "tool_result",
                                "tool_use_id": m.get("tool_call_id", ""),
                                "content": m.get("content", ""),
                            }
                        ],
                    }
                )
            elif role == "user":
                content = m.get("content")
                if isinstance(content, str):
                    messages.append({"role": "user", "content": content})
                elif isinstance(content, list):
                    blocks = []
                    for b in content:
                        if isinstance(b, dict) and b.get("type") == "text":
                            blocks.append({"type": "text", "text": b.get("text", "")})
                    messages.append({"role": "user", "content": blocks})
            elif role == "assistant":
                content = m.get("content")
                blocks = []
                if content:
                    text = (
                        content
                        if isinstance(content, str)
                        else json.dumps(content, ensure_ascii=False)
                    )
                    blocks.append({"type": "text", "text": text})
                for tc in m.get("tool_calls") or []:
                    fn = tc.get("function", {})
                    try:
                        inp = json.loads(fn.get("arguments") or "{}")
                    except (json.JSONDecodeError, TypeError):
                        inp = {}
                    blocks.append(
                        {
                            "type": "tool_use",
                            "id": tc.get("id", ""),
                            "name": fn.get("name", ""),
                            "input": inp,
                        }
                    )
                messages.append({"role": "assistant", "content": blocks})

        if system_text.strip():
            out["system"] = [{"type": "text", "text": system_text.strip()}]
        out["messages"] = messages

        tools = body.get("tools")
        if tools:
            out["tools"] = []
            for t in tools:
                if isinstance(t, dict) and t.get("type") == "function":
                    fn = t.get("function", {})
                    out["tools"].append(
                        {
                            "name": fn.get("name", ""),
                            "description": fn.get("description", ""),
                            "input_schema": fn.get(
                                "parameters", {"type": "object", "properties": {}}
                            ),
                        }
                    )
        if body.get("tool_choice") is not None:
            out["tool_choice"] = _tool_choice_openai_to_anthropic(body["tool_choice"])
        return out

    @staticmethod
    def response_openai_to_anthropic(resp: dict) -> dict:
        """OpenAI Chat Completions non-streaming response → Anthropic Messages response."""
        choice = (resp.get("choices") or [{}])[0]
        message = choice.get("message", {}) or {}
        content_blocks = []
        text = message.get("content") or ""
        if text:
            content_blocks.append({"type": "text", "text": text})
        for tc in message.get("tool_calls") or []:
            fn = tc.get("function", {})
            try:
                inp = json.loads(fn.get("arguments") or "{}")
            except (json.JSONDecodeError, TypeError):
                inp = {}
            content_blocks.append(
                {
                    "type": "tool_use",
                    "id": tc.get("id", ""),
                    "name": fn.get("name", ""),
                    "input": inp,
                }
            )
        usage = resp.get("usage", {})
        return {
            "id": resp.get("id", "msg_proxy"),
            "type": "message",
            "role": "assistant",
            "model": resp.get("model", ""),
            "content": content_blocks,
            "stop_reason": FINISH_REASON_MAP.get(
                choice.get("finish_reason"), FALLBACK_STOP_REASON
            ),
            "stop_sequence": None,
            "usage": {
                "input_tokens": usage.get("prompt_tokens", 0),
                "output_tokens": usage.get("completion_tokens", 0),
            },
        }


class OpenAIToAnthropicStream:
    """openai SSE streaming response → anthropic SSE events (incremental conversion).

    State machine: after the first content block has accumulated enough, emit
    content_block_start, then deltas one by one; tool calls are mapped by the openai
    index to independent content blocks; at the end emit message_delta (stop_reason +
    usage) and message_stop. Block order assigns indices by "first appearance".
    """

    def __init__(self):
        self.blocks: list[int] = []
        self.text_block: int | None = None
        self.tool_blocks: dict[int, int] = {}
        self.tool_state: dict[int, dict] = {}
        self.sent_start = False
        self.stop_reason: str | None = None
        self.usage: dict = {}
        self.model = ""

    def feed(self, chunk: dict) -> list[str]:
        events: list[str] = []
        if chunk.get("model"):
            self.model = chunk["model"]

        if not self.sent_start:
            events.append(
                _sse_event(
                    "message_start",
                    {
                        "type": "message_start",
                        "message": {
                            "id": "msg_proxy",
                            "type": "message",
                            "role": "assistant",
                            "content": [],
                            "model": self.model,
                            "stop_reason": None,
                            "stop_sequence": None,
                            "usage": {"input_tokens": 0, "output_tokens": 0},
                        },
                        "usage": {"input_tokens": 0, "output_tokens": 0},
                    },
                )
            )
            self.sent_start = True

        for choice in chunk.get("choices") or []:
            delta = choice.get("delta") or {}
            finish = choice.get("finish_reason")

            text = delta.get("content")
            if text:
                if self.text_block is None:
                    self.text_block = len(self.blocks)
                    self.blocks.append(self.text_block)
                    events.append(
                        _sse_event(
                            "content_block_start",
                            {
                                "type": "content_block_start",
                                "index": self.text_block,
                                "content_block": {"type": "text", "text": ""},
                            },
                        )
                    )
                events.append(
                    _sse_event(
                        "content_block_delta",
                        {
                            "type": "content_block_delta",
                            "index": self.text_block,
                            "delta": {"type": "text_delta", "text": text},
                        },
                    )
                )

            for tc in delta.get("tool_calls") or []:
                t_idx = tc.get("index", 0)
                fn = tc.get("function", {})
                st = self.tool_state.get(t_idx, {"id": "", "name": ""})
                if tc.get("id"):
                    st["id"] = tc["id"]
                if fn.get("name"):
                    st["name"] = fn["name"]
                self.tool_state[t_idx] = st

                if t_idx not in self.tool_blocks:
                    block_idx = len(self.blocks)
                    self.blocks.append(block_idx)
                    self.tool_blocks[t_idx] = block_idx
                    events.append(
                        _sse_event(
                            "content_block_start",
                            {
                                "type": "content_block_start",
                                "index": block_idx,
                                "content_block": {
                                    "type": "tool_use",
                                    "id": st["id"],
                                    "name": st["name"],
                                    "input": {},
                                },
                            },
                        )
                    )
                args = fn.get("arguments") or ""
                if args:
                    events.append(
                        _sse_event(
                            "content_block_delta",
                            {
                                "type": "content_block_delta",
                                "index": self.tool_blocks[t_idx],
                                "delta": {
                                    "type": "input_json_delta",
                                    "partial_json": args,
                                },
                            },
                        )
                    )

            if finish:
                self.stop_reason = FINISH_REASON_MAP.get(finish, FALLBACK_STOP_REASON)

        if chunk.get("usage"):
            u = chunk["usage"]
            self.usage = {
                "input_tokens": u.get("prompt_tokens", 0),
                "output_tokens": u.get("completion_tokens", 0),
            }

        return events

    def finish(self) -> list[str]:
        events: list[str] = []
        for block_idx in self.blocks:
            events.append(
                _sse_event(
                    "content_block_stop",
                    {"type": "content_block_stop", "index": block_idx},
                )
            )
        # input_tokens must be sent here: OpenAI's prompt_tokens only appears in the
        # last chunk of the stream, whereas message_start was sent long ago (which could
        # only write 0). Sending only output_tokens would make the client (Claude Code's
        # statusLine) always show input as 0.
        events.append(
            _sse_event(
                "message_delta",
                {
                    "type": "message_delta",
                    "delta": {
                        "stop_reason": self.stop_reason or FALLBACK_STOP_REASON,
                        "stop_sequence": None,
                    },
                    "usage": {
                        "input_tokens": self.usage.get("input_tokens", 0),
                        "output_tokens": self.usage.get("output_tokens", 0),
                    },
                },
            )
        )
        events.append(_sse_event("message_stop", {"type": "message_stop"}))
        return events


def _detect_api_format(body: dict) -> str:
    """Detect the API format from the request body: 'anthropic' or 'openai'."""
    if "system" in body and isinstance(body.get("system"), list):
        return "anthropic"
    messages = body.get("messages", [])
    if messages and messages[0].get("role") == "system":
        return "openai"
    tools = body.get("tools", [])
    if tools and isinstance(tools[0], dict):
        # Anthropic's tool-definition field is `input_schema` (snake_case). This used to
        # be mistakenly written as `inputSchema` (that is the spelling of MCP tools/list,
        # not any API format), making this branch never match and degenerate into dead
        # code, relying only on the trailing anthropic fallback to be "coincidentally correct".
        if "input_schema" in tools[0]:
            return "anthropic"
        if tools[0].get("type") == "function":
            return "openai"
    return "anthropic"


def _is_classifier_candidate(body: dict) -> bool:
    """Structural heuristic for whether this is a classifier candidate: stream != true + empty tools + messages ≤ 2.

    Does not match any hard-coded signature (the signature changes with the Claude Code
    version; generalization avoids silent failure). The v2.1.160+ classifier request
    carries an assistant pre-fill, with messages = 2; a real conversation has dozens to
    hundreds.
    """
    if body.get("stream"):
        return False
    if body.get("tools"):
        return False
    return len(body.get("messages", [])) <= 2


def _inject_classifier_disabled(body: dict, api_format: str) -> None:
    """Inject thinking disabled (deepseek compatibility layer) into the request body and remove the old-version parameters."""
    if api_format == "anthropic":
        body["thinking"] = {"type": "disabled"}
        for k in ("reasoning_effort", "output_config"):
            body.pop(k, None)
    else:
        # openai format: no thinking parameter, removing reasoning_effort suffices
        body.pop("reasoning_effort", None)


_sys_prompt_content: str | None = None

_sys_prompt_mtime: float = 0


def _inject_system_prompt(body: dict) -> tuple[bytes | None, int]:
    """Read System_Prompts.md and inject it into **every** real user input.

    The injection point must not follow "the last real user input": it shifts each time
    the user speaks, the rule block vanishes from its old message, and the upstream
    prompt cache breaks from there on (measured on a real session: 2 breaks per 247
    requests with the moving target, 0 with this one). Injecting everywhere is
    deterministic per message, so the prefix stays byte-identical across turns, and the
    newest turn — the one that drives model adherence — is still covered. A real user
    input has content as a string or an array containing a text block; a pure
    tool_result message contains no text and is skipped — when such a message also
    carries text (the user interjected while a tool was executing), the rule goes after
    the last tool_result, which must always remain first. Returns (body_bytes, injected
    count), the count being 0 when the file is missing / read fails / no match. Skips
    disk reads when mtime is unchanged.
    """
    global _sys_prompt_content, _sys_prompt_mtime

    try:
        current_mtime = os.path.getmtime(SYSTEM_PROMPTS_FILE)
    except OSError:
        _sys_prompt_content = None
        return None, -1

    if current_mtime != _sys_prompt_mtime:
        try:
            with open(SYSTEM_PROMPTS_FILE, "r", encoding="utf-8") as f:
                content = f.read().strip()
            _sys_prompt_content = content if content else None
            _sys_prompt_mtime = current_mtime
        except Exception as e:
            _sys_prompt_content = None
            logger.warning(
                json.dumps({"msg": "system_prompt_read_failed", "error": str(e)})
            )
            return None, -1

    if _sys_prompt_content is None:
        return None, -1

    # Every real user input gets its own copy: a moving injection point drops the rule block
    # from its old message each turn, breaking the upstream prompt cache from there on.
    messages = body.get("messages", [])
    rule_block = f"{RULE_START_MARK}\n" + _sys_prompt_content + f"\n{RULE_END_MARK}\n\n"
    injected = 0
    for msg in messages:
        if msg.get("role") != "user":
            continue
        content = msg.get("content", "")
        # Determine whether it is the real user input: a string type, or an array containing a text-type block
        is_real_user_input = False
        if isinstance(content, str):
            is_real_user_input = True
        elif isinstance(content, list):
            is_real_user_input = any(
                b.get("type") == "text" for b in content if isinstance(b, dict)
            )
        if not is_real_user_input:
            continue
        if isinstance(content, str):
            msg["content"] = rule_block + content
        elif isinstance(content, list):
            # Anthropic hard constraint: in a message responding to tool_use,
            # tool_result must be the first block (officially listed under
            # Troubleshooting as a cause of this error). Inserting it first would push
            # tool_result back and the upstream would directly return 400 for "tool_use
            # not immediately followed by tool_result", so insert **after** the last
            # tool_result; with no tool_result it degenerates to the first position,
            # behavior unchanged.
            last_tool_result = -1
            for idx, block in enumerate(content):
                if isinstance(block, dict) and block.get("type") == "tool_result":
                    last_tool_result = idx
            content.insert(last_tool_result + 1, {"type": "text", "text": rule_block})
        injected += 1

    # File exists but no real user input found (e.g. all user messages are tool_result) → log a warning to guard against silent failure
    if injected == 0:
        logger.warning(
            json.dumps(
                {
                    "msg": "rule_inject_no_target",
                    "user_messages": sum(
                        1 for m in messages if m.get("role") == "user"
                    ),
                }
            )
        )

    return json.dumps(body).encode(), injected


def _extract_usage_from_sse(
    sse_data: bytes, api_format: str = "anthropic"
) -> dict | None:
    """Extract the last chunk containing usage from the SSE stream.

    When api_format="openai":
      - the usage fields use prompt_tokens/completion_tokens
      - finish_reason is mapped to stop_reason
      - normalized to the input_tokens/output_tokens/cache_read_input_tokens field names
    """
    last_usage = None
    detected_model = ""
    detected_stop_reason = ""

    for line in sse_data.decode("utf-8", errors="replace").split("\n"):
        if not line.startswith("data: "):
            continue
        data_str = line[6:].strip()
        if data_str == "[DONE]":
            break
        try:
            chunk = json.loads(data_str)

            if "model" in chunk:
                detected_model = chunk["model"]

            if api_format == "anthropic":
                sr = chunk.get("stop_reason") or (chunk.get("delta") or {}).get(
                    "stop_reason"
                )
                if sr:
                    detected_stop_reason = sr
            else:
                # OpenAI: finish_reason is in choices[0]
                choices = chunk.get("choices", [])
                if choices:
                    fr = choices[0].get("finish_reason")
                    if fr:
                        # Unified mapping table (see FINISH_REASON_MAP). Unknown values
                        # are kept as-is: the record layer must faithfully persist, and
                        # must not disguise an unknown reason as end_turn.
                        detected_stop_reason = FINISH_REASON_MAP.get(fr, fr)

            if "usage" in chunk:
                last_usage = chunk
        except json.JSONDecodeError:
            continue

    if last_usage:
        if detected_model:
            last_usage["model"] = detected_model
        if detected_stop_reason:
            last_usage["stop_reason"] = detected_stop_reason

        if api_format == "openai":
            # Normalize the OpenAI usage field names to the unified format
            u = last_usage.get("usage", {})
            if "prompt_tokens" in u:
                u["input_tokens"] = u["prompt_tokens"]
            if "completion_tokens" in u:
                u["output_tokens"] = u["completion_tokens"]
            details = u.get("prompt_tokens_details", {})
            if isinstance(details, dict) and "cached_tokens" in details:
                u["cache_read_input_tokens"] = details["cached_tokens"]

    return last_usage


def _extract_output_from_sse(sse_data: bytes, api_format: str = "anthropic") -> str:
    """Extract the output text content from the SSE stream (first 2000 chars)."""
    output_text = []
    for line in sse_data.decode("utf-8", errors="replace").split("\n"):
        if not line.startswith("data: "):
            continue
        data_str = line[6:].strip()
        if data_str == "[DONE]":
            break
        try:
            chunk = json.loads(data_str)

            if api_format == "anthropic":
                # extract text from content_delta
                delta = chunk.get("delta", {})
                if "text" in delta:
                    output_text.append(delta["text"])
                # extract text from the content array
                content = chunk.get("content", [])
                if isinstance(content, list):
                    for block in content:
                        if isinstance(block, dict) and block.get("type") == "text":
                            output_text.append(block.get("text", ""))
            else:
                # OpenAI: choices[0].delta.content
                choices = chunk.get("choices", [])
                if choices:
                    delta = choices[0].get("delta", {})
                    content = delta.get("content")
                    if content is not None:
                        output_text.append(content)
        except json.JSONDecodeError:
            continue
    # take the first 2000 chars
    full_text = "".join(output_text)
    return full_text[:2000] if full_text else ""


def _extract_tool_name_from_sse(sse_data: bytes, api_format: str = "anthropic") -> str:
    """Extract the tool name of tool_use/tool_calls from the SSE stream."""
    if api_format == "anthropic":
        # Anthropic: content_block_start → content_block.name
        for line in sse_data.decode("utf-8", errors="replace").split("\n"):
            if not line.startswith("data: "):
                continue
            data_str = line[6:].strip()
            if data_str == "[DONE]":
                break
            try:
                chunk = json.loads(data_str)
                if chunk.get("type") == "content_block_start":
                    block = chunk.get("content_block", {})
                    if isinstance(block, dict) and block.get("type") == "tool_use":
                        name = block.get("name", "")
                        if name:
                            return name
            except json.JSONDecodeError:
                continue
    else:
        # OpenAI: choices[0].delta.tool_calls[0].function.name
        for line in sse_data.decode("utf-8", errors="replace").split("\n"):
            if not line.startswith("data: "):
                continue
            data_str = line[6:].strip()
            if data_str == "[DONE]":
                break
            try:
                chunk = json.loads(data_str)
                choices = chunk.get("choices", [])
                if choices:
                    delta = choices[0].get("delta", {})
                    tool_calls = delta.get("tool_calls", [])
                    if tool_calls:
                        for tc in tool_calls:
                            fn = tc.get("function", {})
                            name = fn.get("name", "")
                            if name:
                                return name
            except json.JSONDecodeError:
                continue
    return ""
