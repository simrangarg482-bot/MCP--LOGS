"""Investigation Agent Sub-stage B: hypothesis generation -- the only place
raw evidence becomes an AI-generated conclusion (AGENT_WORKFLOWS.md section
2.4 / PROJECT_PLAN.md section 6.4). See `agents.investigation.evidence`'s
module docstring for why sub-stage A/B are separate modules, not just
separate prompt sections.

One LLM call over the assembled `list[EvidenceItem]` (already gathered by
sub-stage A) produces root-cause hypotheses, a suggested owner team, and
suggested next steps. Every hypothesis must cite at least one real
`EvidenceItem.reference` value copied verbatim from the evidence handed to
the model -- a hypothesis with no valid citation is rejected by
`_validate_hypotheses` and never surfaced (AGENT_WORKFLOWS.md section 2.4's
own literal requirement), the same "verified vs. AI-generated" boundary
`shared.schemas.agent_contracts.RootCauseHypothesis`'s docstring describes.

No LangChain structured-output helper (`.with_structured_output()`) is used
here -- this codebase's established pattern for LLM output that needs
parsing is a plain-text prompt asking for a specific format, parsed by hand
(`agents.answer.generation`'s citation markers, `agents.answer.grounding`'s
yes/no check); a JSON-object prompt + `json.loads` follows that same
convention rather than introducing a second LLM-calling pattern.
"""

from __future__ import annotations

import json
from typing import Any

from langchain_core.language_models import BaseChatModel

from app.agents.prompt_safety import build_messages
from app.shared.config.logging import get_logger
from app.shared.schemas import EvidenceItem, RootCauseHypothesis

logger = get_logger(__name__)


class _HypothesisParsingError(Exception):
    """Raised internally when the model's response isn't valid, expected-
    shape JSON. Caught by `agents.retry.call_with_retry` (in
    `agents.investigation.node`) as a retryable failure -- mirroring
    `agents.answer.node`'s `_UngroundedAnswerError`, a fresh generation
    attempt is the only principled fix for a malformed response, not an
    attempt to repair it in place.
    """


def _build_evidence_block(evidence: list[EvidenceItem]) -> str:
    """Render `evidence` as a block the model can cite back by reference --
    each item's own `reference` value is the exact string the model must
    copy into `supporting_evidence_ids`, not an assigned index (unlike
    `agents.answer.generation.build_context_block`'s `[1]`/`[2]` numbering),
    since `RootCauseHypothesis.supporting_evidence_ids` is documented to hold
    real `EvidenceItem.reference` values, not positional indices.
    """
    lines = [_format_evidence_line(item) for item in evidence]
    return "\n\n".join(lines)


def _format_evidence_line(item: EvidenceItem) -> str:
    """One evidence item's rendered line: reference/source header (plus
    `source_timestamp`, when known -- when this GitHub commit/PR/issue was
    actually authored/opened, not when this investigation ran), the
    summary, and any kind-specific facts from `item.metadata` (author,
    changed files, labels, ...) on a trailing line -- these are the exact
    structured facts `agents.investigation.evidence._chunk_to_evidence`
    attaches for commit/PR/issue evidence (see that function's docstring),
    surfaced here so the model can reason over "who authored this, when,
    what files it touched" without that information being invisible outside
    `summary`'s prose.
    """
    header = f"[{item.reference}] ({item.source}"
    if item.source_timestamp is not None:
        header += f", {item.source_timestamp.isoformat()}"
    header += f"): {item.summary}"

    if not item.metadata:
        return header

    facts = ", ".join(f"{key}={value}" for key, value in sorted(item.metadata.items()))
    return f"{header}\n  [{facts}]"


async def generate_hypotheses(
    llm: BaseChatModel, query: str, evidence: list[EvidenceItem]
) -> tuple[list[RootCauseHypothesis], str | None, list[str]]:
    """Run one LLM call over `evidence`, returning
    `(hypotheses, suggested_owner_team, suggested_next_steps)`.

    `evidence` must be non-empty -- callers with zero gathered evidence
    should never reach this function (see `investigation.node`'s guard,
    mirroring `answer.node`'s equivalent zero-chunks guard); there is
    nothing for the model to reason over otherwise.

    Raises `_HypothesisParsingError` if the model's response isn't valid,
    expected-shape JSON -- callers should run this through
    `agents.retry.call_with_retry` the same way `agents.answer.node` does
    for `_UngroundedAnswerError`.
    """
    evidence_block = _build_evidence_block(evidence)
    messages = build_messages(
        system_instructions=(
            "You are investigating an incident using ONLY the evidence listed "
            "below. Do not use outside knowledge and do not invent evidence.\n\n"
            "Respond with ONLY a single JSON object (no markdown code fences, no "
            "commentary before or after it) with exactly this shape:\n"
            '{"hypotheses": [{"description": "...", "confidence": 0.0, '
            '"supporting_evidence_ids": ["..."]}], '
            '"suggested_owner_team": "team name, or null if unclear", '
            '"suggested_next_steps": ["short actionable step", "..."]}\n\n'
            "Rules: `confidence` is a number from 0.0 to 1.0. Every "
            "`supporting_evidence_ids` entry MUST be copied verbatim from one of "
            "the bracketed reference strings in the evidence (the text inside "
            "the square brackets) -- never invent a reference that isn't "
            "listed. Every hypothesis MUST cite at least one such reference; "
            "if the evidence doesn't support any hypothesis, return an empty "
            "`hypotheses` list rather than a weakly-supported guess."
        ),
        evidence_block=evidence_block,
        task=f"Incident: {query}",
    )
    response = await llm.ainvoke(messages)
    raw_text = str(response.content).strip()

    parsed = _parse_response(raw_text)
    if parsed is None:
        raise _HypothesisParsingError(f"model response was not valid JSON: {raw_text[:200]!r}")

    known_references = {item.reference for item in evidence}
    hypotheses = _validate_hypotheses(parsed.get("hypotheses", []), known_references)

    suggested_owner_team = parsed.get("suggested_owner_team")
    if not isinstance(suggested_owner_team, str) or not suggested_owner_team.strip():
        suggested_owner_team = None

    raw_next_steps = parsed.get("suggested_next_steps", [])
    suggested_next_steps = (
        [step for step in raw_next_steps if isinstance(step, str) and step.strip()]
        if isinstance(raw_next_steps, list)
        else []
    )

    return hypotheses, suggested_owner_team, suggested_next_steps


def _parse_response(raw_text: str) -> dict[str, Any] | None:
    """Parse `raw_text` as a JSON object, tolerating a markdown code fence
    the model added despite being told not to (the same defensive tolerance
    `agents.answer.generation`'s exact-marker matching does not need, but a
    JSON-shaped prompt commonly triggers in practice). Returns `None` -- not
    an exception -- for anything that isn't a JSON object; the caller turns
    that into `_HypothesisParsingError`.
    """
    text = raw_text.strip()
    if text.startswith("```"):
        text = text.strip("`").strip()
        if text.lower().startswith("json"):
            text = text[len("json") :].strip()

    try:
        parsed = json.loads(text)
    except (json.JSONDecodeError, ValueError) as exc:
        logger.warning("investigation_hypothesis_parse_failed", error=str(exc))
        return None

    if not isinstance(parsed, dict):
        logger.warning(
            "investigation_hypothesis_unexpected_shape", raw_type=type(parsed).__name__
        )
        return None
    return parsed


def _validate_hypotheses(
    raw_hypotheses: Any, known_references: set[str]
) -> list[RootCauseHypothesis]:
    """Keep only well-formed hypotheses that cite at least one *real*
    evidence reference -- AGENT_WORKFLOWS.md section 2.4: "a hypothesis with
    no cited evidence is rejected by a validation step, never surfaced."

    A reference the model fabricated (not present in `known_references`) is
    dropped before the "at least one" check runs, not counted toward it --
    a hypothesis citing only fabricated references is exactly as unsupported
    as one citing nothing at all.
    """
    if not isinstance(raw_hypotheses, list):
        return []

    validated: list[RootCauseHypothesis] = []
    for raw in raw_hypotheses:
        if not isinstance(raw, dict):
            continue

        description = raw.get("description")
        confidence = raw.get("confidence")
        raw_ids = raw.get("supporting_evidence_ids")

        if not isinstance(description, str) or not description.strip():
            continue
        if not isinstance(confidence, int | float) or isinstance(confidence, bool):
            continue
        if not isinstance(raw_ids, list):
            continue

        real_ids = [ref for ref in raw_ids if isinstance(ref, str) and ref in known_references]
        if not real_ids:
            logger.info(
                "investigation_hypothesis_rejected_no_evidence", description=description[:200]
            )
            continue

        validated.append(
            RootCauseHypothesis(
                description=description.strip(),
                confidence=max(0.0, min(1.0, float(confidence))),
                supporting_evidence_ids=real_ids,
            )
        )
    return validated
