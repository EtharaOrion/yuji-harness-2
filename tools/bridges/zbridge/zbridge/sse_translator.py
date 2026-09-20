"""GLM SSE -> Anthropic SSE translator (stateful, per-request).

Contract per PLAN.md §5.3 including rule 5.5 ([DONE]-without-terminal recovery),
mixed-scalar / multi-tool state machine, and per-instance isolation.

The class is stateful and NOT reentrant. `bridge.py` allocates one per incoming
`/v1/messages` stream request. No shared state across instances.
"""
from __future__ import annotations

import hashlib
import hmac
import json
import secrets
from collections.abc import Callable, Iterator
from typing import Any

# Same map as translate.py, duplicated intentionally so this module stays leaf.
_FINISH_REASON_MAP: dict[str, str] = {
    "stop": "end_turn",
    "tool_calls": "tool_use",
    "length": "max_tokens",
    "sensitive": "stop_sequence",
    "model_context_window_exceeded": "max_tokens",
    # network_error: passthrough closes with event: error (handled specially below)
}


def _event(event_name: str, data: dict[str, Any]) -> bytes:
    """Encode one SSE frame: event: X\\ndata: {...}\\n\\n."""
    return (
        f"event: {event_name}\ndata: "
        + json.dumps(data, ensure_ascii=False)
        + "\n\n"
    ).encode("utf-8")


class SseTranslator:
    """Consume GLM SSE bytes; yield Anthropic SSE event bytes.

    Usage:
        t = SseTranslator(model="glm-5.3")
        for out_chunk in t.feed(input_bytes):
            client.send(out_chunk)
        # after upstream EOF:
        for out_chunk in t.close():
            client.send(out_chunk)
    """

    def __init__(
        self,
        model: str = "glm-5.3",
        thinking_sig_key: bytes | None = None,
        usage_mapper: Callable[[dict[str, Any]], dict[str, Any]] | None = None,
    ):
        self.model = model
        self.thinking_sig_key = thinking_sig_key
        # Injected rather than imported so this module stays a leaf (see the
        # duplicated _FINISH_REASON_MAP above). bridge.py hands in
        # translate.map_usage bound to the configured cache attribution, which
        # is what converts z.ai's prompt/cached counts into Anthropic's
        # input/cache_read/cache_creation split.
        self.usage_mapper = usage_mapper

        self._carry = b""

        self._started = False
        self._terminal_emitted = False
        self._errored = False

        # Scalar block (thinking XOR text — mutually exclusive)
        self._current_scalar: str | None = None  # "thinking" | "text" | None
        self._current_scalar_index: int = -1
        # Reasoning text of the open thinking block, kept so the block can be
        # signed at close (the signature covers the whole block, and the text
        # is not known until the last delta has arrived).
        self._thinking_buf: list[str] = []

        # Tool blocks — may be multiple open concurrently, keyed by GLM index
        self._open_tools: dict[int, tuple[int, str, str]] = {}
        # ordering of opens for deterministic close order at terminal
        self._open_tools_order: list[int] = []

        self._next_index = 0
        self._output_tokens_estimate = 0
        self._pending_usage: dict[str, Any] | None = None
        self._pending_finish: str | None = None

        self._msg_id = f"msg_{secrets.token_hex(12)}"

    # -----------------------------------------------------------------
    # Public API
    # -----------------------------------------------------------------

    def feed(self, chunk: bytes) -> Iterator[bytes]:
        if not isinstance(chunk, (bytes, bytearray)):
            return
        self._carry += bytes(chunk)
        # Parse every complete SSE frame (delimited by blank line \n\n)
        while b"\n\n" in self._carry:
            frame, self._carry = self._carry.split(b"\n\n", 1)
            yield from self._process_frame(frame)

    def close(self) -> Iterator[bytes]:
        """Called when upstream reaches EOF or is aborted.

        - If terminal already emitted: nothing to do.
        - If we saw ANY frames but no terminal: emit error (passthrough drop).
        - If we saw no frames at all: no output (never opened the stream).
        """
        if self._terminal_emitted or self._errored:
            return
        if self._pending_finish is not None:
            # Upstream EOF'd after finish_reason but before [DONE]. The turn is
            # complete; emit its real terminal rather than the drop error.
            yield from self._flush_terminal()
            return
        if not self._started:
            return
        yield from self._close_all_open_blocks()
        self._errored = True
        yield _event("error", {
            "type": "error",
            "error": {
                "type": "api_error",
                "message": "zbridge: upstream stream aborted before terminal frame",
            },
        })

    # -----------------------------------------------------------------
    # Frame processing
    # -----------------------------------------------------------------

    def _process_frame(self, frame_bytes: bytes) -> Iterator[bytes]:
        for raw_line in frame_bytes.split(b"\n"):
            line = raw_line.strip()
            if not line.startswith(b"data:"):
                continue
            payload = line[len(b"data:"):].strip()
            if payload == b"[DONE]":
                if not self._terminal_emitted:
                    yield from self._flush_terminal()
                return
            try:
                data = json.loads(payload)
            except (json.JSONDecodeError, UnicodeDecodeError):
                continue
            if not isinstance(data, dict):
                continue
            yield from self._process_data(data)

    def _process_data(self, data: dict[str, Any]) -> Iterator[bytes]:
        if not self._started:
            yield from self._emit_message_start(data)
            self._started = True

        # `stream_options.include_usage` delivers usage in its own trailing
        # chunk with an empty `choices` list, so it has to be picked up here
        # rather than off the finish_reason chunk.
        upstream_usage = data.get("usage")
        if isinstance(upstream_usage, dict):
            self._pending_usage = upstream_usage

        for choice in (data.get("choices") or []):
            if not isinstance(choice, dict):
                continue
            delta = choice.get("delta") or {}
            finish = choice.get("finish_reason")

            # Fixed processing order: reasoning_content -> content -> tool_calls
            r = delta.get("reasoning_content")
            if isinstance(r, str) and r:
                yield from self._delta_thinking(r)

            c = delta.get("content")
            if isinstance(c, str) and c:
                yield from self._delta_text(c)

            tc_list = delta.get("tool_calls")
            if isinstance(tc_list, list) and tc_list:
                yield from self._delta_tool_calls(tc_list)

            if finish:
                # Hold the terminal frame: the usage chunk arrives AFTER this
                # one, and message_delta is the only place those counts can go.
                # [DONE], EOF, or close() flushes it.
                self._pending_finish = finish
                return

    # -----------------------------------------------------------------
    # Block emit helpers
    # -----------------------------------------------------------------

    def _delta_thinking(self, text: str) -> Iterator[bytes]:
        # Any tool blocks close (thinking cannot follow open tool_use in Anthropic protocol)
        yield from self._close_all_open_tools()

        if self._current_scalar != "thinking":
            yield from self._close_current_scalar()
            self._current_scalar_index = self._next_index
            self._next_index += 1
            self._current_scalar = "thinking"
            yield _event("content_block_start", {
                "type": "content_block_start",
                "index": self._current_scalar_index,
                "content_block": {"type": "thinking", "thinking": "", "signature": ""},
            })
        self._thinking_buf.append(text)
        yield _event("content_block_delta", {
            "type": "content_block_delta",
            "index": self._current_scalar_index,
            "delta": {"type": "thinking_delta", "thinking": text},
        })

    def _delta_text(self, text: str) -> Iterator[bytes]:
        yield from self._close_all_open_tools()

        if self._current_scalar != "text":
            yield from self._close_current_scalar()
            self._current_scalar_index = self._next_index
            self._next_index += 1
            self._current_scalar = "text"
            yield _event("content_block_start", {
                "type": "content_block_start",
                "index": self._current_scalar_index,
                "content_block": {"type": "text", "text": ""},
            })
        yield _event("content_block_delta", {
            "type": "content_block_delta",
            "index": self._current_scalar_index,
            "delta": {"type": "text_delta", "text": text},
        })
        self._output_tokens_estimate += max(1, len(text) // 4)

    def _delta_tool_calls(self, calls: list[Any]) -> Iterator[bytes]:
        # Close scalar block before opening any tool block
        yield from self._close_current_scalar()

        for tc in calls:
            if not isinstance(tc, dict):
                continue
            glm_idx = int(tc.get("index", 0))
            fn = tc.get("function") or {}

            if glm_idx not in self._open_tools:
                anth_idx = self._next_index
                self._next_index += 1
                tc_id = tc.get("id") or f"call_{glm_idx}"
                tc_name = fn.get("name", "") if isinstance(fn, dict) else ""
                self._open_tools[glm_idx] = (anth_idx, str(tc_id), str(tc_name))
                self._open_tools_order.append(glm_idx)
                yield _event("content_block_start", {
                    "type": "content_block_start",
                    "index": anth_idx,
                    "content_block": {
                        "type": "tool_use",
                        "id": str(tc_id),
                        "name": str(tc_name),
                        "input": {},
                    },
                })

            args = fn.get("arguments", "") if isinstance(fn, dict) else ""
            if isinstance(args, str) and args:
                anth_idx, _, _ = self._open_tools[glm_idx]
                yield _event("content_block_delta", {
                    "type": "content_block_delta",
                    "index": anth_idx,
                    "delta": {"type": "input_json_delta", "partial_json": args},
                })

    # -----------------------------------------------------------------
    # Close helpers
    # -----------------------------------------------------------------

    def _emit_thinking_signature(self) -> Iterator[bytes]:
        """Sign the thinking block that is about to close.

        content_block_start ships signature="" because the reasoning text is
        not known until the final delta, so the real value arrives as a
        signature_delta the way Anthropic streams it. Same HMAC as
        translate.py's non-streaming path, so a given reasoning string signs
        identically whether the client streamed the response or not.
        """
        if not self.thinking_sig_key:
            return
        reasoning = "".join(self._thinking_buf)
        if not reasoning:
            return
        sig = hmac.new(
            self.thinking_sig_key, reasoning.encode("utf-8"), hashlib.sha256
        ).hexdigest()[:24]
        yield _event("content_block_delta", {
            "type": "content_block_delta",
            "index": self._current_scalar_index,
            "delta": {"type": "signature_delta", "signature": sig},
        })

    def _close_current_scalar(self) -> Iterator[bytes]:
        if self._current_scalar is not None and self._current_scalar_index >= 0:
            if self._current_scalar == "thinking":
                yield from self._emit_thinking_signature()
            yield _event("content_block_stop", {
                "type": "content_block_stop",
                "index": self._current_scalar_index,
            })
        self._current_scalar = None
        self._current_scalar_index = -1
        self._thinking_buf = []

    def _close_all_open_tools(self) -> Iterator[bytes]:
        for glm_idx in self._open_tools_order:
            anth_idx, _, _ = self._open_tools[glm_idx]
            yield _event("content_block_stop", {
                "type": "content_block_stop",
                "index": anth_idx,
            })
        self._open_tools.clear()
        self._open_tools_order.clear()

    def _close_all_open_blocks(self) -> Iterator[bytes]:
        yield from self._close_current_scalar()
        yield from self._close_all_open_tools()

    # -----------------------------------------------------------------
    # Terminal emit
    # -----------------------------------------------------------------

    def _emit_message_start(self, data: dict[str, Any]) -> Iterator[bytes]:
        raw_id = data.get("id", "")
        if raw_id and not str(raw_id).startswith("msg_"):
            msg_id = f"msg_{raw_id}"
        elif raw_id:
            msg_id = str(raw_id)
        else:
            msg_id = self._msg_id
        model = self.model or data.get("model") or "glm-5.3"
        yield _event("message_start", {
            "type": "message_start",
            "message": {
                "id": msg_id,
                "type": "message",
                "role": "assistant",
                "model": model,
                "content": [],
                "stop_reason": None,
                "usage": {"input_tokens": 0, "output_tokens": 0},
            },
        })

    def _flush_terminal(self) -> Iterator[bytes]:
        """Emit the deferred terminal, or synthesise one (rule 5.5)."""
        if self._pending_finish is not None:
            yield from self._emit_terminal(self._pending_finish, self._pending_usage)
        else:
            yield from self._synthesize_terminal()

    def _emit_terminal(self, finish: str, usage: Any) -> Iterator[bytes]:
        yield from self._close_all_open_blocks()
        stop_reason = _FINISH_REASON_MAP.get(finish, "end_turn")
        out_tokens = 0
        out_usage: dict[str, Any] | None = None
        if isinstance(usage, dict):
            out_tokens = int(usage.get("completion_tokens", 0) or 0)
            if self.usage_mapper is not None:
                # Full Anthropic split: input_tokens excludes cache reads, and
                # cache fields appear only when upstream reported cached_tokens.
                out_usage = self.usage_mapper(usage)
        if out_usage is None:
            out_usage = {"output_tokens": out_tokens}
        yield _event("message_delta", {
            "type": "message_delta",
            "delta": {"stop_reason": stop_reason, "stop_sequence": None},
            "usage": out_usage,
        })
        yield _event("message_stop", {"type": "message_stop"})
        self._terminal_emitted = True

    def _synthesize_terminal(self) -> Iterator[bytes]:
        """Rule 5.5: `[DONE]` arrived without a prior terminal frame.

        Close all open blocks, synthesise a benign end_turn terminal so the
        client sees a complete stream.
        """
        yield from self._close_all_open_blocks()
        yield _event("message_delta", {
            "type": "message_delta",
            "delta": {"stop_reason": "end_turn", "stop_sequence": None},
            "usage": {"output_tokens": self._output_tokens_estimate},
        })
        yield _event("message_stop", {"type": "message_stop"})
        self._terminal_emitted = True
