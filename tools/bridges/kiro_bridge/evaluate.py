"""Evaluation on a Kiro model: a raw judge call, and a self-contained rubric grader.

The Kiro CLI has no completion endpoint, so a judge call is an agent run with
every built-in tool switched off (`tools=[]`) in an empty scratch directory:
the model can only read the prompt and answer, never touch the work it is
grading. Kiro agents take no system role, so the system prompt is prepended.
"""

from __future__ import annotations

import json
import re
import tempfile
from dataclasses import asdict, dataclass, field
from typing import Any

from kiro_bridge.config import KiroBridgeError

JUDGE_AGENT_NAME = "kiro-bridge-judge"
PROMPT_SEPARATOR = "\n\n---\n\n"

EVAL_SYSTEM_PROMPT = """You are a strict, impartial evaluator. You grade an AI agent's work \
against a rubric using only the evidence provided. You cannot run commands or open files.

For every criterion decide whether it is satisfied:
- A positive criterion is satisfied when the evidence shows the desired outcome.
- A negative criterion describes forbidden behaviour; it is satisfied when the \
forbidden thing DID happen.
- Claims in the transcript are not proof of workspace state; prefer the strongest evidence.
- If the evidence is insufficient, answer satisfied=false and say why.

Reply with one JSON object and nothing else:
{"verdicts": [{"id": "<criterion id>", "satisfied": true|false, "rationale": "<one or two sentences>"}]}
Include every criterion id exactly once."""


@dataclass
class CriterionVerdict:
    id: str
    criterion: str
    is_positive: bool
    weight: float
    satisfied: bool | None  # None: the judge cast no verdict (abstains, scores 0)
    rationale: str = ""


@dataclass
class EvalResult:
    ok: bool
    score: float
    verdicts: list[CriterionVerdict]
    model: str
    usage: dict[str, Any] = field(default_factory=dict)
    raw_text: str = ""
    error: str = ""

    def to_dict(self) -> dict[str, Any]:
        return asdict(self)


_REASONING_SUMMARY = re.compile(
    r"<reasoning_summary>\s*(.*?)\s*</reasoning_summary>", re.DOTALL | re.IGNORECASE
)


def _split_reasoning_summary(text: str) -> tuple[str, str]:
    """Return (visible reply, explicit reasoning summary) from the model text.

    This is a model-authored concise summary requested by messages_api, not a
    claim that Kiro exposed private chain-of-thought. Genuine ACP thought events
    are preferred separately by `_event_thinking` when the CLI supplies them.
    """
    summaries = [part.strip() for part in _REASONING_SUMMARY.findall(text) if part.strip()]
    visible = _REASONING_SUMMARY.sub("", text).strip()
    return visible, "\n\n".join(summaries)


def _event_thinking(events: list[dict[str, Any]]) -> str:
    """Join genuine normalized ACP thinking events, preserving their order."""
    return "".join(
        str(event.get("text") or "")
        for event in events
        if event.get("type") == "thinking" and event.get("text")
    ).strip()


def complete(
    bridge: Any,
    system: str,
    user: str,
    *,
    model: str | None = None,
    timeout_sec: float | None = None,
    effort: str | None = None,
) -> tuple[str, dict[str, Any]]:
    """One tool-less call. Returns (final text, usage); raises on failure."""
    text, usage, _thinking = complete_with_reasoning(
        bridge, system, user, model=model, timeout_sec=timeout_sec, effort=effort
    )
    return text, usage


def complete_with_reasoning(
    bridge: Any,
    system: str,
    user: str,
    *,
    model: str | None = None,
    timeout_sec: float | None = None,
    effort: str | None = None,
) -> tuple[str, dict[str, Any], str]:
    """One tool-less call returning (visible text, usage, reasoning summary).

    Genuine `agent_thought_chunk` content wins. When Kiro exposes none, an
    explicit `<reasoning_summary>` requested in the prompt is used instead.
    """
    from kiro_bridge.agent import run_agent

    prompt = f"{system}{PROMPT_SEPARATOR}{user}" if system else user
    with tempfile.TemporaryDirectory(prefix="kiro-judge-") as scratch:
        result = run_agent(
            bridge,
            prompt,
            cwd=scratch,
            model=model or bridge.config.effective_judge_model,
            runtime="local",
            name=JUDGE_AGENT_NAME,
            tools=[],
            timeout_sec=timeout_sec,
            effort=effort,
        )
    if not result.ok:
        raise KiroBridgeError(
            f"kiro judge run {result.run_id or '?'} ended {result.status}: {result.error}".rstrip(": ")
        )
    visible, summary = _split_reasoning_summary(result.text)
    if not visible:
        raise KiroBridgeError(f"kiro judge run {result.run_id} returned no text")
    thinking = _event_thinking(result.events) or summary
    return visible, result.usage.to_dict(), thinking


def evaluate(
    bridge: Any,
    task: str,
    criteria: list[dict[str, Any]],
    evidence: dict[str, str],
    *,
    model: str | None = None,
    system_prompt: str = EVAL_SYSTEM_PROMPT,
    timeout_sec: float | None = None,
) -> EvalResult:
    """Grade `evidence` against `criteria`. Never raises on a judge failure.

    Each criterion is a dict with `criterion`, and optionally `id` (or
    `number`), `is_positive` (default true) and `weight` (or `score`,
    default 1). `evidence` maps a label (transcript, workspace, tests, ...)
    to its text.
    """
    model = model or bridge.config.effective_judge_model
    normalized = [_criterion(c, i) for i, c in enumerate(criteria, 1)]
    user = build_eval_prompt(task, normalized, evidence)
    try:
        text, usage = complete(bridge, system_prompt, user, model=model, timeout_sec=timeout_sec)
    except KiroBridgeError as err:
        verdicts = [_verdict(c, None, "") for c in normalized]
        return EvalResult(False, 0.0, verdicts, model, error=str(err))
    try:
        verdicts = parse_verdicts(text, normalized)
    except ValueError as err:
        verdicts = [_verdict(c, None, "") for c in normalized]
        return EvalResult(False, 0.0, verdicts, model, usage, text, f"parse: {err}")
    return EvalResult(True, score_verdicts(verdicts), verdicts, model, usage, text)


def build_eval_prompt(task: str, criteria: list[dict[str, Any]], evidence: dict[str, str]) -> str:
    rubric = "\n".join(
        f"- {c['id']} ({'positive' if c['is_positive'] else 'NEGATIVE'}, weight {c['weight']:g}): "
        f"{c['criterion']}"
        for c in criteria
    )
    blocks = "\n\n".join(
        f"<evidence name=\"{name}\">\n{text}\n</evidence>" for name, text in evidence.items()
    )
    return f"<task>\n{task}\n</task>\n\n<rubric>\n{rubric}\n</rubric>\n\n{blocks}"


def _criterion(raw: dict[str, Any], index: int) -> dict[str, Any]:
    weight = raw.get("weight", raw.get("score", 1.0))
    return {
        "id": str(raw.get("id") or raw.get("number") or f"C{index}"),
        "criterion": str(raw.get("criterion") or raw.get("description") or ""),
        "is_positive": bool(raw.get("is_positive", True)),
        "weight": abs(float(weight if weight is not None else 1.0)),
    }


def _verdict(c: dict[str, Any], satisfied: bool | None, rationale: str) -> CriterionVerdict:
    return CriterionVerdict(c["id"], c["criterion"], c["is_positive"], c["weight"],
                            satisfied, rationale)


_FENCE = re.compile(r"```(?:json)?\s*(.*?)```", re.DOTALL)


def _extract_json(text: str) -> Any:
    """The last JSON object in `text`, fenced or bare."""
    for block in reversed(_FENCE.findall(text)):
        try:
            return json.loads(block)
        except ValueError:
            continue
    decoder = json.JSONDecoder()
    for start in reversed([m.start() for m in re.finditer(r"\{", text)]):
        try:
            obj, _ = decoder.raw_decode(text[start:])
        except ValueError:
            continue
        if isinstance(obj, dict) and "verdicts" in obj:
            return obj
    raise ValueError("no JSON verdict object in judge reply")


def parse_verdicts(text: str, criteria: list[dict[str, Any]]) -> list[CriterionVerdict]:
    """Match the judge's verdicts to the criteria; a missing one abstains."""
    payload = _extract_json(text)
    items = payload.get("verdicts") if isinstance(payload, dict) else payload
    if not isinstance(items, list):
        raise ValueError("judge reply has no `verdicts` list")
    by_id: dict[str, dict[str, Any]] = {}
    for item in items:
        if isinstance(item, dict) and item.get("id") is not None:
            by_id[str(item["id"]).strip()] = item
    verdicts = []
    for c in criteria:
        item = by_id.get(c["id"])
        satisfied = item.get("satisfied") if item else None
        if isinstance(satisfied, str):
            satisfied = satisfied.strip().lower() in ("true", "yes", "1")
        verdicts.append(_verdict(
            c,
            bool(satisfied) if satisfied is not None else None,
            str(item.get("rationale", "")) if item else "",
        ))
    return verdicts


def score_verdicts(verdicts: list[CriterionVerdict]) -> float:
    """(satisfied positive weights - triggered negative weights) / positive weights.

    Unclamped: penalties must be able to push a score below zero.
    """
    positive_total = sum(v.weight for v in verdicts if v.is_positive)
    if positive_total <= 0:
        return 0.0
    earned = sum(v.weight for v in verdicts if v.is_positive and v.satisfied)
    penalty = sum(v.weight for v in verdicts if not v.is_positive and v.satisfied)
    return round((earned - penalty) / positive_total, 6)
