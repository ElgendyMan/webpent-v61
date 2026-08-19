# src/webpent/agents/cvss_engine/agent.py
"""webpent.agents.cvss_engine.agent

LangGraph node that calculates CVSS v3.1 scores for confirmed findings.

The CVSS engine iterates over all findings whose confidence is
``CONFIRMED`` and asks the LLM to produce a CVSS v3.1 vector string
and numeric score based on each finding's description. The score is
stored in the finding's ``cvss_score`` field via ``model_copy``.

Resilience:
    LLM invocation is wrapped per-finding in ``try/except``. A failure
    on one finding does not abort scoring for the others — the finding
    is left with ``cvss_score=None`` and the error is logged.

Mutation safety:
    ``model_copy(update=...)`` is used (no validators run, so we pass
    plain strings). The ``cvss_score`` field is ``str | None``, so a
    string value is always valid regardless of ``use_enum_values``.
"""

from __future__ import annotations

import logging
from typing import Any
from uuid import UUID

from langchain_core.messages import AIMessage, HumanMessage, SystemMessage

from webpent.models.findings import Finding
from webpent.shared.llm import (
    TaskType,
    get_safety_system_instruction,
    safe_prompt_format,
    try_get_llm,
)
from webpent.state.state import PentestState

logger = logging.getLogger(__name__)

_SYSTEM_PROMPT = (
    "You are a CVSS v3.1 scoring expert. Given a vulnerability "
    "description, produce a CVSS v3.1 vector string, the "
    "corresponding numeric base score, and a brief one-sentence "
    "justification for the score. "
    "Format your response EXACTLY as: "
    "CVSS:3.1/AV:N/AC:L/PR:N/UI:N/S:U/C:H/I:H/A:H | 9.8 | <justification>\n"
    "Use the official CVSS v3.1 specification."
)

_HUMAN_TEMPLATE = (
    "Vulnerability title: {title}\n"
    "Severity: {severity}\n"
    "URL: {url}\n"
    "Description: {description}\n\n"
    "Produce the CVSS v3.1 vector and base score."
)


def _parse_cvss_response(raw_response: str) -> tuple[str, str] | None:
    """Extract a CVSS vector + score string from the LLM response.

    Expected format: ``CVSS:3.1/AV:N/... | 9.8 | <justification>``. We
    tolerate minor drift (extra whitespace, missing pipe, reversed order)
    but always return a single clean string.

    V5 Audit Trail: Now returns a tuple of ``(cvss_string, reasoning)``
    where ``reasoning`` is the LLM's one-sentence justification extracted
    from the third pipe-separated field. Returns ``None`` if no CVSS
    vector can be located in the response.
    """
    text = raw_response.strip()
    if not text:
        return None

    # Strip markdown code fences if present.
    if text.startswith("```"):
        lines = text.splitlines()
        if lines and lines[0].startswith("```"):
            lines = lines[1:]
        if lines and lines[-1].strip() == "```":
            lines = lines[:-1]
        text = "\n".join(lines).strip()

    # The response should contain a CVSS:3.1 vector. Find it.
    cvss_start = text.find("CVSS:3.1")
    if cvss_start == -1:
        logger.warning("CVSS vector not found in LLM response: %s", text[:100])
        return None

    # Take everything from "CVSS:3.1" to the end of the line (or
    # to the pipe separator).
    rest = text[cvss_start:]
    # Split on pipe first (up to 3 parts: vector | score | reasoning).
    # Computed here (moved up from below) because the score-search
    # fix immediately below needs it.
    parts = rest.split("|", 2)
    # Split on newline or pipe to isolate the vector.
    vector = rest.split("\n")[0].split("|")[0].strip()

    # Try to find a numeric score (pattern: X.X).
    import re

    # V10 HOSTILE-AUDIT FIX: this used to run
    # `re.search(r"(\d+\.\d+)", rest)` — but `rest` STARTS with
    # "CVSS:3.1", and "3.1" (the spec *version number*, not a score)
    # itself matches \d+\.\d+ and is always the first match in the
    # string. Every successful parse therefore set `score = "3.1"`
    # regardless of the finding's real severity: a 9.8 CRITICAL RCE
    # and a 4.0 MEDIUM info-disclosure finding were both stored with
    # cvss_score ending in "| 3.1". This is 100% reproducible on the
    # documented expected LLM output format (see _SYSTEM_PROMPT's own
    # example) — not an edge case. Fix: search only the score FIELD
    # (parts[1], the text between the first and second pipe) instead
    # of the whole vector+score+reasoning blob. Falls back to
    # searching after the vector text if the LLM didn't use pipes.
    score_search_text = parts[1] if len(parts) >= 2 else rest[len(vector):]
    score_match = re.search(r"(\d+\.\d+)", score_search_text)
    score = score_match.group(1) if score_match else None

    # V5 Audit Trail: Extract reasoning (text after the second pipe).
    reasoning = ""
    if len(parts) >= 3:
        reasoning = parts[2].strip().split("\n")[0].strip()

    cvss_str = f"{vector} | {score}" if score else vector

    # Return tuple: (cvss_string, reasoning)
    return cvss_str, reasoning


def _score_finding(finding: Finding, llm: Any) -> Finding:
    """Score a single confirmed finding via the LLM.

    Returns the original finding unchanged on any failure; returns a
    mutated copy with ``cvss_score`` set on success.
    """
    if llm is None:
        # CVSS enrichment is optional in deterministic offline mode.
        # Leave the finding unchanged rather than relying on None.invoke().
        return finding

    human_prompt = safe_prompt_format(
        _HUMAN_TEMPLATE,
        title=finding.title,
        severity=finding.severity,
        url=finding.url,
        description=finding.description,
    )

    try:
        response = llm.invoke(
            [
                SystemMessage(content=get_safety_system_instruction()),
                SystemMessage(content=_SYSTEM_PROMPT),
                HumanMessage(content=human_prompt),
            ]
        )
        raw_text: str = (
            response.content
            if isinstance(response.content, str)
            else str(response.content)
        )
    except Exception as exc:  # noqa: BLE001 — all fallbacks exhausted
        logger.error(
            "LLM failed for CVSS scoring of finding %s: %s",
            finding.id,
            exc,
        )
        return finding

    result = _parse_cvss_response(raw_text)
    if result is None:
        logger.warning(
            "Could not parse CVSS response for finding %s — leaving unscored",
            finding.id,
        )
        return finding

    cvss, reasoning = result

    logger.info(
        "CVSS score for finding %s (%s): %s",
        finding.id,
        finding.title,
        cvss,
    )

    # V10 P1-1 FIX: APPEND the CVSS reasoning to the finding's existing
    # ``reasoning`` field instead of OVERWRITING it. The original
    # finding's reasoning (e.g. the validator's evidence summary, the
    # exploit chain's narrative) is valuable context and must be
    # preserved — the CVSS reasoning is a complement, not a replacement.
    existing_reasoning = finding.reasoning or ""
    combined_reasoning = (
        f"{existing_reasoning}\n{reasoning}".strip()
        if existing_reasoning
        else reasoning
    )

    return finding.model_copy(
        update={"cvss_score": cvss, "reasoning": combined_reasoning}
    )


def cvss_node(state: PentestState) -> dict:
    """LangGraph node implementing the CVSS scoring phase.

    V4.5 Sprint 3: Scores ALL findings, not just confirmed ones.
    Previously, only findings with ``confidence == CONFIRMED`` were
    scored. Now, every finding regardless of ``vuln_class`` or
    ``confidence`` receives a CVSS score. For UNKNOWN classes, the
    LLM is guided by the original ``severity`` from the scanning tool.
    For non-confirmed findings, the score helps prioritise manual review.

    Args:
        state: Current graph state. Must contain ``findings``.

    Returns:
        A partial state update with two keys:
          * ``findings`` — the full findings list with CVSS scores.
          * ``messages`` — a single :class:`AIMessage` summarising the
            phase outcome.
    """
    findings: list[Finding] = list(state.get("findings") or [])

    logger.info(
        "CVSS engine starting: %d total finding(s)", len(findings)
    )

    # Index findings by UUID for in-place substitution.
    findings_by_id: dict[UUID, Finding] = {f.id: f for f in findings}

    llm = try_get_llm(TaskType.ANALYSIS)

    scored_count = 0

    for finding in findings:
        # V4.5 Sprint 3: Score ALL findings, not just confirmed ones.
        updated = _score_finding(finding, llm)
        if updated.cvss_score is not None:
            scored_count += 1
            findings_by_id[finding.id] = updated

    # Rebuild the findings list in original order.
    updated_findings: list[Finding] = [
        findings_by_id[f.id] for f in findings if f.id in findings_by_id
    ]

    summary = (
        f"CVSS scoring completed. Scored {scored_count} of "
        f"{len(findings)} total finding(s)."
    )
    logger.info(summary)

    return {
        "findings": updated_findings,
        "messages": [AIMessage(content=summary)],
    }
