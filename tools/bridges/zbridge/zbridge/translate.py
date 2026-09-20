"""Anthropic /v1/messages <-> z.ai GLM /chat/completions translation.

Pure functions: no I/O, no logging setup. Contract per PLAN.md §5.1, §5.2, §5.2.1.
"""
from __future__ import annotations

import base64
import hashlib
import hmac
import json
import secrets
from typing import Any

DEFAULT_MODEL_ALIAS: dict[str, str] = {
    "claude-3-5-sonnet-latest": "glm-5.3",
    "claude-3-5-sonnet-20241022": "glm-5.3",
    "claude-3-opus-latest": "glm-5.3",
    "claude-sonnet-4-5": "glm-5.3",
    "claude-sonnet-4-6": "glm-5.3",
    "claude-opus-4-8": "glm-5.3",
    "claude-opus-4-7": "glm-5.3",
    "claude-haiku-4-5-20251001": "glm-5.3",
}

UNSUPPORTED_FIELDS = ("n", "logprobs", "seed", "service_tier")


class TranslationError(Exception):
    """Raised for request payloads zbridge cannot translate."""

    def __init__(self, message: str, error_type: str = "invalid_request_error"):
        super().__init__(message)
        self.error_type = error_type


# ---------------------------------------------------------------------------
# Request: Anthropic -> GLM
# ---------------------------------------------------------------------------

def anthropic_to_glm_request(
    body: dict[str, Any],
    model_alias: dict[str, str] | None = None,
    preserve_thinking: bool = False,
) -> dict[str, Any]:
    _reject_unsupported(body)

    alias = {**DEFAULT_MODEL_ALIAS, **(model_alias or {})}
    model = alias.get(body["model"], body["model"])

    out: dict[str, Any] = {
        "model": model,
        "messages": _build_messages(body, preserve_thinking),
    }
    if "max_tokens" in body:
        out["max_tokens"] = body["max_tokens"]

    if "stream" in body:
        out["stream"] = bool(body["stream"])
        if out["stream"]:
            # OpenAI-compatible endpoints omit `usage` entirely from a streamed
            # response unless this is asked for. Without it the terminal chunk
            # carries no prompt/cached counts, so every streamed turn reports
            # input_tokens=0 and cache_read_input_tokens=0 downstream.
            out["stream_options"] = {"include_usage": True}
    if "temperature" in body:
        out["temperature"] = body["temperature"]
    if "top_p" in body:
        out["top_p"] = max(0.01, min(1.0, float(body["top_p"])))
    if "stop_sequences" in body and isinstance(body["stop_sequences"], list):
        out["stop"] = list(body["stop_sequences"])[:4]

    # Tools
    if "tools" in body:
        out["tools"] = _translate_tools(body["tools"])
    if "tool_choice" in body:
        out["tool_choice"] = _translate_tool_choice(body["tool_choice"])

    # Thinking
    if isinstance(body.get("thinking"), dict) and body["thinking"].get("type") == "enabled":
        out["thinking"] = {"type": "enabled"}
        budget = body["thinking"].get("budget_tokens", 4096)
        out["reasoning_effort"] = map_reasoning_effort(int(budget), model)
        if preserve_thinking:
            out["clear_thinking"] = False

    # metadata.user_id (length gate)
    md = body.get("metadata") or {}
    uid = md.get("user_id") if isinstance(md, dict) else None
    if isinstance(uid, str) and 6 <= len(uid) <= 128:
        out["user_id"] = uid

    return out


def _reject_unsupported(body: dict[str, Any]) -> None:
    for field in UNSUPPORTED_FIELDS:
        if field in body:
            raise TranslationError(f"unsupported field: {field}")
    rf = body.get("response_format")
    if isinstance(rf, dict) and rf.get("type") == "json_schema":
        raise TranslationError("unsupported field: response_format=json_schema")


def _translate_tools(tools: list[dict[str, Any]]) -> list[dict[str, Any]]:
    out = []
    for t in tools:
        if not isinstance(t, dict):
            continue
        if "input_schema" not in t:
            raise TranslationError(f"tool {t.get('name')!r} missing input_schema")
        out.append({
            "type": "function",
            "function": {
                "name": t["name"],
                "description": t.get("description", ""),
                "parameters": t["input_schema"],
            },
        })
    return out


def _translate_tool_choice(choice: Any) -> str:
    if choice == "auto" or choice is None:
        return "auto"
    if isinstance(choice, dict) and choice.get("type") == "auto":
        return "auto"
    # any / tool / {type:tool,name:...} => REJECT (S14)
    raise TranslationError(
        "GLM Coding Plan supports only tool_choice=auto; forced tool selection unavailable in v1."
    )


def _build_messages(body: dict[str, Any], preserve_thinking: bool) -> list[dict[str, Any]]:
    messages: list[dict[str, Any]] = []

    # System
    system = body.get("system")
    if isinstance(system, str) and system.strip():
        messages.append({"role": "system", "content": system})
    elif isinstance(system, list):
        parts = []
        for blk in system:
            if isinstance(blk, dict) and blk.get("type") == "text":
                parts.append(blk.get("text", ""))
        joined = "\n\n".join(p for p in parts if p)
        if joined:
            messages.append({"role": "system", "content": joined})

    # Conversation messages
    for msg in body.get("messages", []):
        if not isinstance(msg, dict):
            continue
        role = msg.get("role")
        content = msg.get("content")
        if role == "user":
            messages.extend(_translate_user_message(content))
        elif role == "assistant":
            messages.append(_translate_assistant_message(content, preserve_thinking))

    return messages


def _translate_user_message(content: Any) -> list[dict[str, Any]]:
    """Return one or more GLM messages for a single Anthropic user message.

    - string -> [{role:user, content:str}]
    - list of blocks where blocks include tool_result:
        * emit one role=tool msg per tool_result (in order)
        * residual text -> one trailing role=user msg
    - list of blocks (text/image only) -> multimodal or joined text
    """
    if isinstance(content, str):
        return [{"role": "user", "content": content}]
    if not isinstance(content, list):
        return [{"role": "user", "content": str(content)}]

    tool_results = [b for b in content if isinstance(b, dict) and b.get("type") == "tool_result"]
    non_tool = [b for b in content if not (isinstance(b, dict) and b.get("type") == "tool_result")]

    out: list[dict[str, Any]] = []
    for tr in tool_results:
        c = tr.get("content", "")
        if isinstance(c, list):
            c = "\n".join(
                (blk.get("text", "") if isinstance(blk, dict) else str(blk)) for blk in c
            )
        elif not isinstance(c, str):
            c = json.dumps(c)
        out.append({"role": "tool", "tool_call_id": tr["tool_use_id"], "content": c})

    if non_tool:
        # If any image blocks -> multimodal array; else join text
        has_image = any(isinstance(b, dict) and b.get("type") == "image" for b in non_tool)
        if has_image:
            arr: list[dict[str, Any]] = []
            for b in non_tool:
                if not isinstance(b, dict):
                    continue
                if b.get("type") == "text":
                    arr.append({"type": "text", "text": b.get("text", "")})
                elif b.get("type") == "image":
                    src = b.get("source") or {}
                    if src.get("type") == "base64":
                        media = src.get("media_type", "image/png")
                        data = src.get("data", "")
                        url = f"data:{media};base64,{data}"
                    elif src.get("type") == "url":
                        url = src.get("url", "")
                    else:
                        continue
                    arr.append({"type": "image_url", "image_url": {"url": url}})
            out.append({"role": "user", "content": arr})
        else:
            text = " ".join(
                b.get("text", "") for b in non_tool if isinstance(b, dict) and b.get("type") == "text"
            )
            if text.strip():
                out.append({"role": "user", "content": text})

    if not out:
        # empty user message; keep placeholder
        out.append({"role": "user", "content": ""})

    return out


def _translate_assistant_message(content: Any, preserve_thinking: bool) -> dict[str, Any]:
    if isinstance(content, str):
        return {"role": "assistant", "content": content}
    if not isinstance(content, list):
        return {"role": "assistant", "content": str(content)}

    text_parts: list[str] = []
    thinking_text = ""
    tool_calls: list[dict[str, Any]] = []
    for blk in content:
        if not isinstance(blk, dict):
            continue
        t = blk.get("type")
        if t == "text":
            text_parts.append(blk.get("text", ""))
        elif t == "thinking":
            thinking_text += blk.get("thinking", "")
        elif t == "tool_use":
            tool_calls.append({
                "id": blk["id"],
                "type": "function",
                "function": {
                    "name": blk["name"],
                    "arguments": json.dumps(blk.get("input", {}), ensure_ascii=False),
                },
            })

    msg: dict[str, Any] = {"role": "assistant", "content": " ".join(text_parts).strip()}
    if tool_calls:
        msg["tool_calls"] = tool_calls
    if preserve_thinking and thinking_text:
        msg["reasoning_content"] = thinking_text
    return msg


def map_reasoning_effort(budget_tokens: int, model: str) -> str:
    """Map Anthropic budget_tokens to GLM reasoning_effort, gated by model family.

    GLM-5.x accepts only low/high/max (never medium).
    GLM-4.x accepts the full ladder.
    """
    if model.startswith("glm-5"):
        if budget_tokens < 4096:
            return "low"
        if budget_tokens < 8192:
            return "high"
        return "max"
    # GLM-4.x (and any other): full ladder
    if budget_tokens < 2048:
        return "low"
    if budget_tokens < 4096:
        return "medium"
    if budget_tokens < 8192:
        return "high"
    return "max"


# ---------------------------------------------------------------------------
# Response: GLM non-stream -> Anthropic Message
# ---------------------------------------------------------------------------

FINISH_REASON_MAP: dict[str, str] = {
    "stop": "end_turn",
    "tool_calls": "tool_use",
    "length": "max_tokens",
    "sensitive": "stop_sequence",
    "model_context_window_exceeded": "max_tokens",
    "network_error": "end_turn",  # non-stream never sees this; stream-side handles specially
}

# z.ai writes its prompt cache in fixed-size blocks and never caches the trailing
# partial block. Verified empirically: every `cached_tokens` value observed in a
# 164-turn GLM-5.3 trajectory is divisible by 64 (gcd exactly 64), and
# `floor((prompt_tokens - 1) / 64) * 64` predicts the NEXT turn's `cached_tokens`
# on 156/163 turns. See scripts/probe_usage.py and docs/TRANSLATION.md.
DEFAULT_CACHE_BLOCK_TOKENS = 64

CACHE_WRITE_ATTRIBUTIONS = ("block", "none")


def map_usage(
    usage_in: dict[str, Any] | None,
    attribution: str = "block",
    block_tokens: int = DEFAULT_CACHE_BLOCK_TOKENS,
) -> dict[str, Any]:
    """Translate a z.ai/OpenAI `usage` object into Anthropic usage semantics.

    The two conventions disagree about cached tokens, and getting this wrong
    inflates every downstream token count and cost figure:

        OpenAI / z.ai : prompt_tokens INCLUDES prompt_tokens_details.cached_tokens
        Anthropic     : input_tokens EXCLUDES cache_read_input_tokens

    Confirmed live against api.z.ai by scripts/probe_usage.py: a byte-identical
    prompt reports prompt_tokens=5384 on both a forced cache miss (cached=0) and
    a cache hit (cached=5376). Since the prompt never changed, prompt_tokens must
    include the cached portion. Assigning it straight to `input_tokens` while also
    emitting `cache_read_input_tokens` makes consumers that reconstruct
    `prompt_tokens = input + cache_read + cache_creation` (LiteLLM's Anthropic
    transform does exactly this) count every cached token twice.

    So the invariant this function guarantees is:

        input_tokens + cache_read_input_tokens + cache_creation_input_tokens
            == upstream prompt_tokens

    z.ai reports no cache-WRITE counter at all (the only cache key in its usage
    object is `prompt_tokens_details.cached_tokens`), so cache creation has to be
    modelled. `attribution` selects how the fresh (uncached) remainder is split:

      "block"  Fresh tokens that land in a whole cache block are reported as
               cache creation; the trailing partial block — which z.ai will not
               cache and which therefore gets re-read as fresh input next turn —
               stays in `input_tokens`. Because the cacheable prefix is at most
               `prompt_tokens - 1`, `input_tokens` is always >= 1.
      "none"   No cache-write modelling: the whole fresh remainder is
               `input_tokens` and cache creation is reported as 0.

    Cache fields are only emitted when upstream actually reported `cached_tokens`,
    so a provider that says nothing about caching is never given invented numbers.
    """
    usage_in = usage_in or {}
    prompt = _nonneg_int(usage_in.get("prompt_tokens"))
    completion = _nonneg_int(usage_in.get("completion_tokens"))

    cached, has_cached = _extract_cached(usage_in)
    # Defend against upstream nonsense: cached can never exceed the prompt.
    cached = min(cached, prompt)
    fresh = max(0, prompt - cached)

    creation = 0
    if attribution == "block" and has_cached and fresh > 0 and block_tokens > 0:
        # Tokens that will be resident in cache after this turn, block-aligned.
        cacheable = ((prompt - 1) // block_tokens) * block_tokens
        # Newly written = cacheable prefix minus what was already there. Capped at
        # fresh - 1 so at least one token always remains as real input; cacheable
        # is <= prompt - 1 by construction, so this cap is not usually binding.
        creation = max(0, min(cacheable - cached, fresh - 1))

    usage: dict[str, Any] = {
        "input_tokens": fresh - creation,
        "output_tokens": completion,
    }
    if has_cached:
        usage["cache_read_input_tokens"] = cached
        usage["cache_creation_input_tokens"] = creation
    return usage


def _nonneg_int(v: Any) -> int:
    try:
        return max(0, int(v or 0))
    except (TypeError, ValueError):
        return 0


def _extract_cached(usage_in: dict[str, Any]) -> tuple[int, bool]:
    """Return (cached_tokens, upstream_reported_it). Accepts nested or flat form."""
    ptd = usage_in.get("prompt_tokens_details")
    if isinstance(ptd, dict) and ptd.get("cached_tokens") is not None:
        return _nonneg_int(ptd["cached_tokens"]), True
    if usage_in.get("cached_tokens") is not None:
        return _nonneg_int(usage_in["cached_tokens"]), True
    return 0, False


def glm_to_anthropic_response(
    body: dict[str, Any],
    thinking_sig_key: bytes | None = None,
    cache_write_attribution: str = "block",
    cache_block_tokens: int = DEFAULT_CACHE_BLOCK_TOKENS,
) -> dict[str, Any]:
    raw_id = body.get("id", "") or secrets.token_hex(12)
    msg_id = raw_id if str(raw_id).startswith("msg_") else f"msg_{raw_id}"

    choices = body.get("choices") or []
    msg = choices[0].get("message", {}) if choices else {}
    finish = choices[0].get("finish_reason", "stop") if choices else "stop"

    content_blocks: list[dict[str, Any]] = []

    reasoning = msg.get("reasoning_content")
    if isinstance(reasoning, str) and reasoning:
        sig = ""
        if thinking_sig_key:
            sig = hmac.new(thinking_sig_key, reasoning.encode("utf-8"), hashlib.sha256).hexdigest()[:24]
        content_blocks.append({"type": "thinking", "thinking": reasoning, "signature": sig})

    text = msg.get("content")
    if isinstance(text, str) and text:
        content_blocks.append({"type": "text", "text": text})

    for tc in msg.get("tool_calls") or []:
        fn = tc.get("function", {})
        try:
            args = json.loads(fn.get("arguments", "") or "{}")
            if not isinstance(args, dict):
                args = {}
        except (ValueError, TypeError):
            args = {}
        content_blocks.append({
            "type": "tool_use",
            "id": tc.get("id", ""),
            "name": fn.get("name", ""),
            "input": args,
        })

    usage = map_usage(
        body.get("usage"),
        attribution=cache_write_attribution,
        block_tokens=cache_block_tokens,
    )

    return {
        "id": msg_id,
        "type": "message",
        "role": "assistant",
        "model": body.get("model", ""),
        "content": content_blocks,
        "stop_reason": FINISH_REASON_MAP.get(finish, "end_turn"),
        "stop_sequence": None,
        "usage": usage,
    }


# ---------------------------------------------------------------------------
# Utilities
# ---------------------------------------------------------------------------

def _b64(data: bytes) -> str:
    return base64.b64encode(data).decode("ascii")
