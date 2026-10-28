"""Answer an Anthropic Messages API request with a Codex model.

The Codex CLI's `codex exec --json` emits agent_message items only -- there is
no raw completion endpoint and no native tool-use channel the bridge can read.
So one request becomes one tool-less Codex call (`complete()`): the system
prompt, the caller's tools and the conversation so far are rendered into a
single prompt, and the reply is parsed back into Messages API content blocks.

Tool use is emulated. The prompt lists the caller's tools and asks the model to
request them in a fixed text form,

    <tool_call>
    {"name": "<tool>", "input": {...}}
    </tool_call>

which is parsed into `tool_use` blocks. Earlier tool calls and their results
are rendered in the same form, so the model sees its own format at work. A
reply that names an unknown tool, carries broken JSON, or skips a tool the
request required is retried once with the problem stated.

Structured output (`output_format` / a forced single tool, which is how
LiteLLM sends `response_format=json_schema` to Anthropic) is asked for as a
bare JSON object and returned in the shape the request expects.
"""

from __future__ import annotations

import json
import re
import secrets
import time
from collections.abc import Mapping
from dataclasses import dataclass, field
from typing import Any

from codex_bridge.config import CodexBridgeError

DEFAULT_REPAIR_ATTEMPTS = 1
STARTUP_RETRIES = 2
STARTUP_RETRY_DELAY_SEC = 3.0
ESTIMATED_BYTES_PER_TOKEN = 4
ESTIMATED_USAGE_SOURCE = "codex_bridge_utf8_bytes_div_4"
_TOOL_CALL = re.compile(r"<tool_call>\s*(.*?)\s*</tool_call>", re.DOTALL)
_FENCE = re.compile(r"^```(?:json)?\s*(.*?)\s*```$", re.DOTALL)
_MODEL_PREFIXES = ("anthropic/", "codex/", "openai/")

FRAME = """You are the language model behind an automated agent framework, answering one turn \
of its conversation. In this exchange you have no tools of your own and must not try to use \
any: the framework runs tools for you.

{tool_rules}

Reply with the assistant's next turn only. Do not describe this framing."""

TOOL_RULES = """To call tools, end your reply with one block per call, exactly in this form:
<tool_call>
{"name": "<tool name>", "input": {<arguments matching that tool's input_schema>}}
</tool_call>
Several blocks run in order. Put any text meant for the user before the blocks. The framework \
runs the calls and shows their results in its next message, inside <tool_result> elements.

If a tool named `finish` is offered, every reply MUST call at least one offered tool. When work \
remains, call the tool needed to continue in this same reply; never stop after merely saying what \
you need or plan to do next. When the task is complete or cannot proceed, call `finish` with the \
final response. A prose-only reply is invalid while `finish` is available. Otherwise, when no \
`finish` tool is offered, a reply with no <tool_call> block ends your turn."""

NO_TOOL_RULES = "No tools are offered in this conversation. Answer in text."

REASONING_SUMMARY_RULES = """Before the visible answer or any <tool_call> blocks, include a concise, useful summary of your reasoning in exactly this form:
<reasoning_summary>
One to three short sentences describing the evidence considered and why the next action or answer follows.
</reasoning_summary>
This is an explicit reasoning summary for the caller, not hidden chain-of-thought. Do not include private scratch work. Always include it when requested, including before a required bare JSON object; the bridge removes the summary block before parsing that object."""
THINKING_SIGNATURE = "codex_bridge_reasoning_summary_v1"


@dataclass
class MessagesReply:
    content: list[dict[str, Any]]
    stop_reason: str
    model: str
    usage: dict[str, Any] = field(default_factory=dict)
    raw_text: str = ""

    def to_body(self) -> dict[str, Any]:
        return {
            "id": f"msg_cb_{secrets.token_hex(12)}",
            "type": "message",
            "role": "assistant",
            "model": self.model,
            "content": self.content,
            "stop_reason": self.stop_reason,
            "stop_sequence": None,
            "usage": self.usage,
        }


def codex_model(requested: str, override: str | None = None) -> str:
    model = (override or requested or "").strip()
    for prefix in _MODEL_PREFIXES:
        if model.startswith(prefix):
            model = model[len(prefix):]
    if not model:
        raise CodexBridgeError("request names no model")
    return model


def estimate_text_tokens(text: str) -> int:
    """Codex-only fallback estimate: UTF-8 bytes / 4, rounded up.

    `codex exec --json` reports real token counts on `turn.completed`, so this
    only fires on the rare case upstream returns zero (e.g. a run that failed
    before `turn.completed`). Deliberately simple, deterministic, dep-free,
    and labelled as an estimate everywhere it is propagated. Must never
    replace a positive upstream count.
    """
    if not text:
        return 0
    return max(1, (len(text.encode("utf-8")) + ESTIMATED_BYTES_PER_TOKEN - 1)
               // ESTIMATED_BYTES_PER_TOKEN)


def estimate_request_tokens(body: Mapping[str, Any]) -> int:
    return estimate_text_tokens(render_prompt(body))


def _usage_with_estimates(
    usage: Mapping[str, Any] | None,
    prompt: str,
    text: str,
    thinking: str,
) -> dict[str, Any]:
    out: dict[str, Any] = dict(usage or {})
    estimated_fields: list[str] = []

    if _usage_int(out, "input_tokens") <= 0:
        out["input_tokens"] = estimate_text_tokens(prompt)
        estimated_fields.append("input_tokens")

    reasoning_estimate = estimate_text_tokens(thinking)
    if reasoning_estimate and _usage_int(out, "reasoning_tokens") <= 0:
        out["reasoning_tokens"] = reasoning_estimate
        estimated_fields.append("reasoning_tokens")

    if _usage_int(out, "output_tokens") <= 0:
        # Anthropic output usage includes both thinking and visible/tool text.
        out["output_tokens"] = estimate_text_tokens(text) + reasoning_estimate
        estimated_fields.append("output_tokens")

    out["cache_read_tokens"] = _usage_int(out, "cache_read_tokens")
    out["cache_write_tokens"] = _usage_int(out, "cache_write_tokens")
    out["request_count"] = max(1, _usage_int(out, "request_count"))

    if estimated_fields:
        out["usage_estimated"] = True
        out["usage_source"] = ESTIMATED_USAGE_SOURCE
        out["estimated_fields"] = estimated_fields
    return out


def _usage_int(usage: Mapping[str, Any], key: str) -> int:
    try:
        return max(0, int(usage.get(key) or 0))
    except (TypeError, ValueError):
        return 0


def answer(bridge: Any, body: Mapping[str, Any], *, model: str,
           timeout_sec: float | None = None,
           repair_attempts: int = DEFAULT_REPAIR_ATTEMPTS) -> MessagesReply:
    request = _Request(body)
    prompt = render_prompt(body)
    usage: dict[str, Any] = {}
    problem = ""
    text = ""
    thinking = ""
    for _attempt in range(repair_attempts + 1):
        attempt_prompt = prompt if not problem else (
            f"{prompt}\n\n<framework_note>Your previous reply could not be used: {problem} "
            "Write the turn again, following the rules above.</framework_note>"
        )
        text, call_usage, thinking = _complete(
            bridge, attempt_prompt, model, timeout_sec, request.effort
        )
        _add_usage(
            usage,
            _usage_with_estimates(call_usage, attempt_prompt, text, thinking),
        )
        try:
            content, stop = request.parse(text)
        except ValueError as err:
            problem = str(err)
            continue
        exposed_thinking = thinking if request.wants_reasoning else ""
        return MessagesReply(_with_thinking(content, exposed_thinking), stop, model,
                             _anthropic_usage(usage), text)
    # Never turn an invalid response into a successful end_turn after repairs
    # are exhausted. The HTTP layer reports this as an API error, allowing the
    # caller's retry policy to run without fabricating a tool call or a
    # successful final answer.
    raise CodexBridgeError(
        f"model reply remained invalid after {repair_attempts + 1} "
        f"attempt{'s' if repair_attempts else ''}: {problem}"
    )


def _complete(bridge: Any, prompt: str, model: str,
              timeout_sec: float | None, effort: str) -> tuple[str, Mapping[str, Any], str]:
    """`bridge.complete_with_reasoning()`, retried when the run never started.

    A run that started and then failed is not retried, it may have done work.
    """
    for attempt in range(STARTUP_RETRIES + 1):
        try:
            kwargs: dict[str, Any] = {"model": model, "timeout_sec": timeout_sec}
            if effort:
                kwargs["effort"] = effort
            if hasattr(bridge, "complete_with_reasoning"):
                return bridge.complete_with_reasoning("", prompt, **kwargs)
            text, usage = bridge.complete("", prompt, **kwargs)
            return text, usage, ""
        except CodexBridgeError as err:
            if "did not start" not in str(err) or attempt == STARTUP_RETRIES:
                raise
            time.sleep(STARTUP_RETRY_DELAY_SEC * (attempt + 1))
    raise AssertionError("unreachable")


def render_prompt(body: Mapping[str, Any]) -> str:
    request = _Request(body)
    parts = [FRAME.format(tool_rules=TOOL_RULES if request.tools else NO_TOOL_RULES)]
    if request.wants_reasoning:
        parts.append(REASONING_SUMMARY_RULES)
    system = _text_of(body.get("system"))
    if system:
        parts.append(f"<system_prompt>\n{system}\n</system_prompt>")
    if request.tools:
        listed = "\n".join(
            json.dumps({"name": t.get("name"), "description": t.get("description", ""),
                        "input_schema": t.get("input_schema") or {"type": "object"}})
            for t in request.tools
        )
        parts.append(f"<tools>\n{listed}\n</tools>")
    turns = [_render_turn(m) for m in body.get("messages") or [] if isinstance(m, Mapping)]
    parts.append("<conversation>\n" + "\n".join(t for t in turns if t) + "\n</conversation>")
    requirement = request.requirement()
    if requirement:
        parts.append(f"<requirement>{requirement}</requirement>")
    return "\n\n".join(parts)


def _render_turn(message: Mapping[str, Any]) -> str:
    role = "assistant" if message.get("role") == "assistant" else "user"
    content = message.get("content")
    if isinstance(content, str):
        return f'<turn role="{role}">\n{content}\n</turn>'
    pieces = []
    for block in content or []:
        if not isinstance(block, Mapping):
            continue
        kind = block.get("type")
        if kind == "text":
            pieces.append(str(block.get("text", "")))
        elif kind == "tool_use":
            call = {"name": block.get("name"), "input": block.get("input") or {}}
            pieces.append(f"<tool_call>\n{json.dumps(call)}\n</tool_call>")
        elif kind == "tool_result":
            flag = ' is_error="true"' if block.get("is_error") else ""
            pieces.append(f'<tool_result tool_use_id="{block.get("tool_use_id", "")}"{flag}>\n'
                          f"{_text_of(block.get('content'))}\n</tool_result>")
        elif kind in ("image", "document"):
            pieces.append(f"[{kind} omitted]")
    body = "\n".join(p for p in pieces if p)
    return f'<turn role="{role}">\n{body}\n</turn>' if body else ""


def _text_of(value: Any) -> str:
    # Strip NUL bytes before forwarding: raw .docx/.pdf contents sent as tool
    # results carry \x00, and codex's JSON transport will reject them with a
    # parse error that drops the whole conversation.
    if value is None:
        return ""
    if isinstance(value, str):
        return value.replace("\x00", "")
    if isinstance(value, list):
        out = []
        for block in value:
            if isinstance(block, Mapping):
                if block.get("type") == "text":
                    out.append(str(block.get("text", "")))
                elif block.get("type") in ("image", "document"):
                    out.append(f"[{block.get('type')} omitted]")
            elif isinstance(block, str):
                out.append(block)
        return "\n".join(out).replace("\x00", "")
    return str(value).replace("\x00", "")


def _requested_effort(body: Mapping[str, Any]) -> str:
    """Map Anthropic/LiteLLM reasoning controls to a Codex CLI effort level.

    Returns one of the Codex effort values, or "none" for disabled thinking
    (CodexBackend translates "none" -> "minimal" since the Codex CLI has no
    equivalent of "off"), or "" when the request does not ask for reasoning.
    """
    direct = body.get("reasoning_effort")
    if isinstance(direct, str) and direct.strip():
        return direct.strip().lower()
    thinking = body.get("thinking")
    if not isinstance(thinking, Mapping):
        return ""
    kind = str(thinking.get("type") or "").lower()
    if kind == "disabled":
        return "none"
    stated = thinking.get("effort")
    if isinstance(stated, str) and stated.strip():
        return stated.strip().lower()
    try:
        budget = int(thinking.get("budget_tokens") or 0)
    except (TypeError, ValueError):
        budget = 0
    if budget:
        if budget <= 1024:
            return "low"
        if budget <= 4096:
            return "medium"
        if budget <= 16384:
            return "high"
        return "xhigh"
    return "high" if kind in ("enabled", "adaptive") else ""


def _with_thinking(content: list[dict[str, Any]], thinking: str) -> list[dict[str, Any]]:
    text = thinking.strip()
    if not text:
        return content
    return [{"type": "thinking", "thinking": text, "signature": THINKING_SIGNATURE}, *content]


class _Request:
    def __init__(self, body: Mapping[str, Any]) -> None:
        self.effort = _requested_effort(body)
        self.wants_reasoning = bool(self.effort and self.effort != "none")
        choice = body.get("tool_choice") or {}
        self.choice = choice.get("type", "auto") if isinstance(choice, Mapping) else "auto"
        self.forced = str(choice.get("name", "")) if self.choice == "tool" else ""
        tools = [t for t in body.get("tools") or [] if isinstance(t, Mapping) and t.get("name")]
        self.tools = [] if self.choice == "none" else tools
        self.names = {str(t["name"]) for t in self.tools}
        fmt = body.get("output_format") or {}
        self.schema = fmt.get("schema") if isinstance(fmt, Mapping) and fmt.get("type") == "json_schema" else None
        if self.schema is None and self.forced and len(self.tools) == 1:
            self.schema = self.tools[0].get("input_schema")
            self.json_tool = self.forced
        else:
            self.json_tool = ""
        # OpenHands exposes `finish` as an ordinary tool; its conversation loop
        # must receive either a work tool or finish. Prose-only output is not a
        # valid terminal signal there. Keep normal Anthropic auto-tool behavior
        # when no finish tool is present, and do not interfere with schema
        # output. Rubric judges never set this (they call via output_format),
        # so this code path is dormant for the judge use case but harmless.
        self.finish_requires_tool = (
            self.schema is None
            and self.choice == "auto"
            and "finish" in self.names
        )
        self.requires_tool = self.finish_requires_tool or (
            self.choice == "any" and bool(self.tools)
        )

    def requirement(self) -> str:
        if self.schema is not None:
            prefix = ("After the required <reasoning_summary> block, reply with "
                      if self.wants_reasoning else "Reply with ")
            return (f"{prefix}only one JSON object matching this JSON schema, no prose and no "
                    f"<tool_call> block:\n{json.dumps(self.schema)}")
        if self.forced:
            return f"Your reply must call the tool {self.forced!r}, and only it."
        if self.finish_requires_tool:
            return ("Your reply must call at least one offered tool. If work remains, call the "
                    "tool needed to continue now; do not merely describe the next step. If the "
                    "task is complete or cannot proceed, call `finish` with the final response.")
        if self.requires_tool:
            return "Your reply must call at least one tool."
        return ""

    def parse(self, text: str) -> tuple[list[dict[str, Any]], str]:
        if self.schema is not None:
            obj = _json_object(text)
            if self.json_tool:
                return [_tool_use(self.json_tool, obj)], "tool_use"
            return [{"type": "text", "text": json.dumps(obj)}], "end_turn"
        calls = []
        for raw in _TOOL_CALL.findall(text):
            call = _json_object(raw)
            name = str(call.get("name") or "")
            if name not in self.names:
                raise ValueError(f"<tool_call> names {name!r}, which is not one of the offered "
                                 f"tools ({', '.join(sorted(self.names)) or 'none'}).")
            args = call.get("input", call.get("arguments", {}))
            if isinstance(args, str):
                args = _json_object(args)
            if not isinstance(args, dict):
                raise ValueError(f"the input of {name!r} is not a JSON object.")
            schema = next(
                (t.get("input_schema") for t in self.tools if t.get("name") == name),
                None,
            )
            if isinstance(schema, Mapping):
                required = schema.get("required")
                if isinstance(required, list):
                    missing = [k for k in required if k not in args]
                    if missing:
                        raise ValueError(
                            f"the input of {name!r} is missing required keys: {missing}"
                        )
            calls.append(_tool_use(name, args))
        if "<tool_call>" in text and len(calls) != text.count("<tool_call>"):
            raise ValueError("a <tool_call> block is not closed with </tool_call>.")
        if self.forced and not any(c["name"] == self.forced for c in calls):
            raise ValueError(f"the reply must call {self.forced!r}.")
        if self.requires_tool and not calls:
            if self.finish_requires_tool:
                raise ValueError(
                    "a tool call is required while `finish` is available: call a work tool "
                    "to continue, or call `finish` if the task is complete or cannot proceed."
                )
            raise ValueError("the reply must call at least one tool.")
        prose = _TOOL_CALL.sub("", text).strip()
        content: list[dict[str, Any]] = [{"type": "text", "text": prose}] if prose else []
        content += calls
        if not content:
            content = [{"type": "text", "text": ""}]
        return content, ("tool_use" if calls else "end_turn")


def _tool_use(name: str, args: dict[str, Any]) -> dict[str, Any]:
    return {"type": "tool_use", "id": f"toolu_cb_{secrets.token_hex(12)}", "name": name,
            "input": args}


def _json_object(text: str) -> dict[str, Any]:
    raw = text.strip()
    fenced = _FENCE.match(raw)
    if fenced:
        raw = fenced.group(1)
    try:
        obj = json.loads(raw)
    except ValueError:
        start, end = raw.find("{"), raw.rfind("}")
        try:
            obj = json.loads(raw[start:end + 1]) if 0 <= start < end else None
        except ValueError:
            obj = None
        if obj is None:
            raise ValueError(f"this is not valid JSON: {raw[:200]!r}") from None
    if not isinstance(obj, dict):
        raise ValueError("expected a JSON object.")
    return obj


def _add_usage(total: dict[str, Any], usage: Mapping[str, Any]) -> None:
    for key in (
        "input_tokens",
        "output_tokens",
        "cache_read_tokens",
        "cache_write_tokens",
        "reasoning_tokens",
        "request_count",
    ):
        total[key] = _usage_int(total, key) + _usage_int(usage, key)
    if usage.get("usage_estimated"):
        total["usage_estimated"] = True
        total["usage_source"] = str(
            usage.get("usage_source") or ESTIMATED_USAGE_SOURCE
        )
        fields = set(total.get("estimated_fields") or [])
        fields.update(str(field) for field in usage.get("estimated_fields") or [])
        total["estimated_fields"] = sorted(fields)


def _anthropic_usage(usage: Mapping[str, Any]) -> dict[str, Any]:
    out: dict[str, Any] = {
        "input_tokens": _usage_int(usage, "input_tokens"),
        "output_tokens": _usage_int(usage, "output_tokens"),
        "cache_read_input_tokens": _usage_int(usage, "cache_read_tokens"),
        "cache_creation_input_tokens": _usage_int(usage, "cache_write_tokens"),
        "reasoning_tokens": _usage_int(usage, "reasoning_tokens"),
        "request_count": _usage_int(usage, "request_count"),
    }
    if usage.get("usage_estimated"):
        out.update(
            usage_estimated=True,
            usage_source=str(usage.get("usage_source") or ESTIMATED_USAGE_SOURCE),
            estimated_fields=list(usage.get("estimated_fields") or []),
        )
    return out


def sse_events(reply: MessagesReply) -> list[bytes]:
    """The reply as the Messages API's streaming events, after message_start."""
    events: list[dict[str, Any]] = []
    for index, block in enumerate(reply.content):
        if block["type"] == "thinking":
            events.append({"type": "content_block_start", "index": index,
                           "content_block": {"type": "thinking", "thinking": "",
                                             "signature": ""}})
            events.append({"type": "content_block_delta", "index": index,
                           "delta": {"type": "thinking_delta",
                                     "thinking": block["thinking"]}})
            events.append({"type": "content_block_delta", "index": index,
                           "delta": {"type": "signature_delta",
                                     "signature": block.get("signature", THINKING_SIGNATURE)}})
        elif block["type"] == "text":
            events.append({"type": "content_block_start", "index": index,
                           "content_block": {"type": "text", "text": ""}})
            events.append({"type": "content_block_delta", "index": index,
                           "delta": {"type": "text_delta", "text": block["text"]}})
        else:
            events.append({"type": "content_block_start", "index": index,
                           "content_block": {"type": "tool_use", "id": block["id"],
                                             "name": block["name"], "input": {}}})
            events.append({"type": "content_block_delta", "index": index,
                           "delta": {"type": "input_json_delta",
                                     "partial_json": json.dumps(block["input"])}})
        events.append({"type": "content_block_stop", "index": index})
    events.append({"type": "message_delta",
                   "delta": {"stop_reason": reply.stop_reason, "stop_sequence": None},
                   "usage": {"output_tokens": reply.usage.get("output_tokens", 0)}})
    events.append({"type": "message_stop"})
    return [sse(e) for e in events]


def sse(event: Mapping[str, Any]) -> bytes:
    return f"event: {event.get('type', 'message')}\ndata: {json.dumps(event)}\n\n".encode()
