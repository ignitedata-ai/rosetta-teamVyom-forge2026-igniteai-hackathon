"""Coordinator agent — the heart of v1.5.

Strategy:
  1. Receive the user message.
  2. Check answer cache.
  3. Run Claude in a tool-calling loop over deterministic tools.
  4. When a tool result is a backward_trace, optionally delegate to
     FormulaExplainer for grounded prose.
  5. When the LLM ends its turn, pass the answer through the citation
     auditor. Failure → retry once with violation feedback. Retry failure
     → return "I don't know" partial answer.
  6. Update conversation state, cache the result.

Spec: docs/plan_v1_5.md §7.
"""

from __future__ import annotations

import json
import logging
import os
import time
from typing import Optional

from . import auditor as auditor_module
from .conversation import (
    CachedAnswer,
    ConversationState,
    ToolCall,
    extract_entity_from_text,
    question_hash,
)
from .models import WorkbookModel
from .specialists import formula_explainer
from .tools import TOOLS, execute_tool

try:
    # Preferred: read config from Akash's Settings class
    from core.config import settings as _settings

    def _get_api_key() -> str:
        return _settings.ANTHROPIC_API_KEY or os.environ.get("ANTHROPIC_API_KEY", "")

    def _get_model() -> str:
        return _settings.ROSETTA_MODEL or os.environ.get("ROSETTA_MODEL", "claude-sonnet-4-5")
except ImportError:
    # Fallback for standalone usage (tests)
    def _get_api_key() -> str:
        return os.environ.get("ANTHROPIC_API_KEY", "")

    def _get_model() -> str:
        return os.environ.get("ROSETTA_MODEL", "claude-sonnet-4-5")


log = logging.getLogger("rosetta.coordinator")


COORDINATOR_SYSTEM_PROMPT = """You are Rosetta's coordinator. You answer questions about a specific parsed
Excel workbook by calling deterministic tools and, when needed, delegating
to the FormulaExplainer specialist.

CORE RULES — never violate:
1. Every number, percentage, currency value, and cell reference in your
   answer must come from a tool result in this conversation. Never invent
   a value or cell ref.
2. If simple arithmetic is needed (e.g. subtracting two fetched numbers),
   do it yourself but only with values you have just fetched. Cite the
   source refs.
3. Resolve named ranges by NAME AND VALUE (e.g. "FloorPlanRate (5.8%)",
   not "Assumptions!B2").
4. When a question is ambiguous (multiple candidate cells), list the
   candidates and ask — never silently pick.
5. When you cannot ground an answer in tool results, say "I don't know"
   and explain what specifically you couldn't verify. "I don't know" is
   better than a guess.
6. Cite cell refs in canonical form: `Sheet!Ref` (e.g. `P&L Summary!G32`).
7. Do not fabricate cell refs. If a tool returns no results, do not
   continue as if it had — broaden the search or ask for clarification.

MODE SELECTION (check first):
- get_workbook_summary returns a `mode` per sheet: `formula` (has formulas),
  `tabular` (zero formulas, ≥20 rows — a flat data table), or `other`.
- For a tabular sheet, prefer analytics tools — aggregate_column, filter_rows,
  group_aggregate, top_n, lookup_row, time_bucket_aggregate, describe,
  correlate, detect_outliers, sql_query. Do NOT attempt backward_trace /
  forward_impact — there are no formulas to trace.
- For a formula sheet, the classical tools (backward_trace / forward_impact /
  what_if / scenario_recalc) remain primary; analytics tools still work on
  top of formula-computed values when asked.
- When a sheet has 0 formulas, honest answers are preferred over trying to
  force a computational explanation. Say "this is observational data" if
  asked how it's calculated.

PLANNING GUIDANCE:
- Unfamiliar workbook? Start with get_workbook_summary to orient yourself.
- "How is X calculated?" → find_cells(X) → backward_trace(that cell) →
  delegate_to_formula_explainer(trace).
- "What depends on X?" / "What would change if X changes?" →
  resolve_named_range or find_cells → forward_impact.
- "What if X changes?" / scenario questions → scenario_recalc with
  the overrides dict.
- "Stale / issues / hidden / circular / anomaly" → list_findings.
- "Why is X circular?" / "Is this cycle intentional?" →
  list_findings(category='circular') to see the cycles, then
  explain_circular(chain_index=N) for the full explanation including
  any author comment or iterative-calc evidence.
- "What is the F&I for Deal #1047?" / row-level joins across sheets →
  join_on_key(sheet_a, key_column_a, sheet_b, key_column_b,
              select_a=..., select_b=..., filter_key='1047').
- "How does X differ between sheet A and sheet B?" / structural
  comparison → compare_regions(ref_a, ref_b). Interpret the result:
  shape_match_pct, functions_only_a / functions_only_b, and
  named_ranges_only_a / named_ranges_only_b drive the diff narrative.
- Questions about a pivot table → list_pivot_tables first; then
  get_pivot_table(sheet, index) for its fields and source.
- Analytical questions on tabular sheets:
  - "What is the average / total / min / max / median X?" → aggregate_column.
  - "How many rows where X > Y?" → aggregate_column(agg='count', where=[...])
    OR filter_rows + inspect `matched_rows`.
  - "What's the latitude of Chicago?" / single-row lookup → lookup_row.
  - "Top 5 / bottom 3 by X" → top_n.
  - "Average X by Y" / pivot-style → group_aggregate.
  - "Distinct values of X" → unique_values.
  - "Distribution of X" / "histogram" → histogram.
  - "Outliers in X" / "any suspicious values?" → detect_outliers.
  - "How many missing values?" → count_missing.
  - "Duplicates in X?" → find_duplicates.
  - "Trend / monthly / weekly / month-over-month" → time_bucket_aggregate
    or trend_summary for slope + R².
  - "Correlation between X and Y" → correlate.
  - "Summary stats for X" → describe.
  - Questions needing joins, subqueries, window functions, or complex
    grouping → sql_query (call sql_schema first to learn table/column names;
    cast VARCHAR to numeric with `CAST(col AS DOUBLE)` for arithmetic).
- Analytical what-if: "what's the average X if I exclude Y?" →
  scenario_filter. Two-scenario comparison → compare_scenarios.
- Inverse / goal-seek: "what X makes Y equal Z?" / "how much should X be to
  push Y to Z?" → goal_seek(input_ref=X, target_ref=Y, target_value=Z).
  Always verify the relationship is monotonic — the tool warns when it
  isn't. Input can be a named range (e.g. 'FloorPlanRate') or a cell ref.
- Sensitivity / ranking drivers: "which input matters most?" / "rank
  assumptions by impact" → sensitivity(target_ref=Y). Omit input_refs to
  auto-rank every numeric named range. For one-pair point elasticity → elasticity.
- Comparison questions ("how does A differ from B?") → find_cells for
  both → compare_regions on their regions → write a diff explanation.
- High-level metric questions ("unit count", "total revenue", "average
  margin", "how many sold") → find_cells will route through the semantic
  tier when keyword matches fail. Cell-level chunks return navigable
  refs directly, so prefer find_cells over guessing cell coordinates.
- Follow-ups referring to "it" / "that" / "what about April" → the
  active entity from prior turns is provided in the context below.

OUTPUT STYLE:
- Wrap every cell reference in backticks: `P&L Summary!G32`, `Assumptions!B4`.
- Wrap every formula in backticks: `=G18 - G25 + Assumptions!B15`.
- Wrap every function name in backticks: `VLOOKUP`, `SUMIFS`, `SUMPRODUCT`.
- Wrap every named range in backticks: `FloorPlanRate`, `TaxRate`.
- Wrap every data-type label in backticks: `percent`, `currency`, `date`.
- When citing a named range, lead with name and resolved value together:
  `FloorPlanRate` (5.8%), not just "0.058".
- No bold except for a single leading `**Warning:**` in diagnostic answers.
- Structure: one concise lead paragraph answering the question, then
  one trace/evidence paragraph citing specific cells. Keep answers tight.
- Plain markdown: dashes for lists, no tables unless genuinely comparative.

DELEGATION:
- You have a virtual tool "delegate_to_formula_explainer" that is NOT in
  the tools list — instead, indicate delegation by calling the
  backward_trace tool and then in your final answer text, include a line
  `<<DELEGATE_FORMULA_EXPLAINER ref=Sheet!Ref>>` on its own. The host
  will run the specialist and splice in the grounded prose.
  Only do this for formula-explanation questions.

OUTPUT:
- Your final answer is free-form prose but MUST adhere to rules 1–7.
- Cite evidence inline, e.g. "(P&L Summary!G32: $142,300)".
- Keep answers concise. Lead with the answer, then supporting trace.
"""


MAX_TOOL_TURNS = 10
MAX_AUDIT_RETRIES = 1  # total attempts = 1 + retries


async def answer(
    wb: WorkbookModel,
    state: ConversationState,
    message: str,
    *,
    user_id: str | None = None,
    data_source_id: str | None = None,
) -> dict:
    """Produce a grounded answer.

    `user_id` and `data_source_id` are required for the semantic tier of
    find_cells (filters Akash's shared Qdrant collection). Other tools
    function without them.
    """
    state.append_user(message)

    # --- Cache lookup ---
    qh = question_hash(message, state.scenario_overrides)
    cached = state.answer_cache.get(qh)
    if cached and _cached_is_fresh(cached):
        log.info("Cache hit for question_hash=%s", qh)
        state.append_assistant(cached.answer_text)
        return {
            "session_id": state.session_id,
            "answer": cached.answer_text,
            "trace": cached.trace,
            "evidence": [{"ref": r} for r in cached.evidence_refs],
            "escalated": False,
            "audit_status": cached.audit_status,
            "confidence": cached.confidence,
            "tool_calls_made": 0,
            "active_entity": state.active_entity,
            "scenario_overrides": state.scenario_overrides,
            "cached": True,
        }

    # --- LLM tool loop ---
    api_key = _get_api_key()
    if not api_key:
        return _no_api_key_response(state, message)

    try:
        import anthropic  # type: ignore
    except ImportError:
        return _no_api_key_response(state, message, reason="anthropic SDK not installed")

    # Pass the key explicitly so we don't depend on process env state
    client = anthropic.AsyncAnthropic(api_key=api_key)
    model = _get_model()

    claude_messages = _build_claude_messages(state)

    tool_calls_made = 0
    trace_for_ui: Optional[dict] = None
    chart_for_ui: Optional[dict] = None
    violation_retries_used = 0
    final_text = ""
    final_response = None

    while True:
        attempt_text, attempt_tool_calls, attempt_trace, attempt_chart = await _run_tool_loop(
            client,
            model,
            claude_messages,
            wb,
            state,
            user_id=user_id,
            data_source_id=data_source_id,
        )
        tool_calls_made += attempt_tool_calls
        if attempt_trace and not trace_for_ui:
            trace_for_ui = attempt_trace
        if attempt_chart and not chart_for_ui:
            chart_for_ui = attempt_chart

        # Splice in FormulaExplainer if the coordinator requested delegation
        attempt_text, explainer_invoked = _maybe_delegate_to_explainer(attempt_text, wb, message)
        if explainer_invoked and not trace_for_ui:
            # Pull the trace from recent tool calls
            trace_for_ui = _latest_trace_from_log(state)

        # Audit
        result = auditor_module.audit(attempt_text, state.tool_call_log, wb)

        if result.status == "passed":
            final_text = attempt_text
            audit_status = "passed"
            confidence = 0.9
            break

        if violation_retries_used >= MAX_AUDIT_RETRIES:
            # Second-chance: emit partial "I don't know" wrapper
            final_text = _build_partial_answer(attempt_text, result)
            audit_status = "unknown"
            confidence = 0.3
            break

        # Retry: inject violation feedback
        log.info("Audit failed on attempt; retrying with violation list.")
        violation_retries_used += 1
        claude_messages.append({"role": "assistant", "content": attempt_text})
        claude_messages.append(
            {
                "role": "user",
                "content": auditor_module.format_violations_for_retry(result.violations),
            }
        )
        continue

    # --- Post-process ---
    # Extract evidence refs from tool log
    evidence_refs = _extract_evidence_refs(state.tool_call_log[-tool_calls_made:])
    # Update active_entity
    extracted = extract_entity_from_text(final_text)
    if extracted:
        state.active_entity = extracted

    # Cache successful answers only
    if audit_status == "passed":
        state.answer_cache[qh] = CachedAnswer(
            question_hash=qh,
            answer_text=final_text,
            evidence_refs=list(evidence_refs),
            trace=trace_for_ui,
            confidence=confidence,
            audit_status=audit_status,
        )

    state.append_assistant(final_text)

    # Tool-call trail for the bridge (shows up in Akash's "View Code" panel)
    tool_trail = (
        [
            {"tool_name": tc.tool_name, "input": tc.input, "latency_ms": tc.latency_ms}
            for tc in state.tool_call_log[-tool_calls_made:]
        ]
        if tool_calls_made
        else []
    )

    return {
        "session_id": state.session_id,
        "answer": final_text,
        "trace": trace_for_ui,
        "chart_data": chart_for_ui,
        "evidence": [{"ref": r} for r in evidence_refs],
        "escalated": bool(trace_for_ui),
        "audit_status": audit_status,
        "confidence": confidence,
        "tool_calls_made": tool_calls_made,
        "active_entity": state.active_entity,
        "scenario_overrides": state.scenario_overrides,
        # Token usage accumulated by _run_tool_loop
        "input_tokens": state.turn_input_tokens,
        "output_tokens": state.turn_output_tokens,
        "_tool_trail": tool_trail,
    }


# --- Helpers ---


def _cached_is_fresh(cached: CachedAnswer) -> bool:
    ttl = int(os.environ.get("ROSETTA_CACHE_TTL_SECS", "3600"))
    return (time.time() - cached.cached_at) < ttl


def _no_api_key_response(state: ConversationState, message: str, reason: str = "ANTHROPIC_API_KEY not set") -> dict:
    msg = f"I can't answer this: {reason}. The coordinator requires Claude for planning. Set ANTHROPIC_API_KEY and retry."
    state.append_assistant(msg)
    return {
        "session_id": state.session_id,
        "answer": msg,
        "trace": None,
        "evidence": [],
        "escalated": False,
        "audit_status": "unknown",
        "confidence": 0.0,
        "tool_calls_made": 0,
        "active_entity": state.active_entity,
        "scenario_overrides": state.scenario_overrides,
    }


def _build_claude_messages(state: ConversationState) -> list[dict]:
    """Build Claude-format messages from session history, plus a system-injected
    context line with active_entity + scenario overrides.
    """
    context_lines = []
    if state.active_entity:
        context_lines.append(f"Active entity (from prior turn): {state.active_entity}")
    if state.scenario_overrides:
        overrides_str = ", ".join(f"{k}={v}" for k, v in state.scenario_overrides.items())
        context_lines.append(f"Active scenario overrides: {overrides_str}")
    context_block = "\n".join(context_lines)

    messages: list[dict] = []
    # Prior turns (excluding the current user turn we just appended)
    for m in state.messages[:-1]:
        messages.append({"role": m.role, "content": m.content})
    # Current user turn with context prepended
    current = state.messages[-1].content
    if context_block:
        current = f"[Context: {context_block}]\n\n{current}"
    messages.append({"role": "user", "content": current})
    return messages


async def _run_tool_loop(
    client,
    model: str,
    claude_messages: list[dict],
    wb: WorkbookModel,
    state: ConversationState,
    *,
    user_id: str | None = None,
    data_source_id: str | None = None,
) -> tuple[str, int, Optional[dict], Optional[dict]]:
    """Run Claude tool-calling until end_turn.

    Accumulates token usage into `state.turn_input_tokens/turn_output_tokens`
    for cost tracking by the caller.

    Returns (text, num_tool_calls, trace_seen, chart_seen).
    """
    tool_calls_made = 0
    trace_seen: Optional[dict] = None
    chart_seen: Optional[dict] = None

    for _ in range(MAX_TOOL_TURNS):
        resp = await client.messages.create(
            model=model,
            max_tokens=2048,
            temperature=0,
            system=COORDINATOR_SYSTEM_PROMPT,
            tools=TOOLS,
            messages=claude_messages,
        )
        # Accumulate real token counts
        if hasattr(resp, "usage") and resp.usage is not None:
            state.turn_input_tokens += getattr(resp.usage, "input_tokens", 0) or 0
            state.turn_output_tokens += getattr(resp.usage, "output_tokens", 0) or 0

        if resp.stop_reason == "tool_use":
            claude_messages.append({"role": "assistant", "content": [b.model_dump() for b in resp.content]})
            tool_results = []
            for block in resp.content:
                if block.type != "tool_use":
                    continue
                t0 = time.time()
                out = await execute_tool(
                    wb,
                    block.name,
                    block.input,
                    user_id=user_id,
                    data_source_id=data_source_id,
                )
                elapsed_ms = int((time.time() - t0) * 1000)
                state.log_tool_call(block.name, block.input, out, elapsed_ms)
                tool_calls_made += 1
                if block.name == "backward_trace" and isinstance(out, dict) and "trace" in out:
                    if trace_seen is None:
                        trace_seen = out["trace"]
                # Analytics tools return chart_data in the envelope; capture
                # the last non-null one so the UI renders the most relevant
                # chart for the user's question.
                if isinstance(out, dict) and out.get("chart_data"):
                    chart_seen = out["chart_data"]
                serialized = json.dumps(out, default=str)[:12000]
                tool_results.append(
                    {
                        "type": "tool_result",
                        "tool_use_id": block.id,
                        "content": serialized,
                    }
                )
            claude_messages.append({"role": "user", "content": tool_results})
            continue
        # end_turn / max_tokens / stop_sequence
        text = "".join(b.text for b in resp.content if b.type == "text").strip()
        return text, tool_calls_made, trace_seen, chart_seen

    return "(Coordinator hit max tool turns without producing an answer.)", tool_calls_made, trace_seen, chart_seen


def _maybe_delegate_to_explainer(text: str, wb: WorkbookModel, original_question: str) -> tuple[str, bool]:
    """If the answer contains a delegation marker, run the specialist and splice in the prose."""
    import re

    marker_re = re.compile(r"<<DELEGATE_FORMULA_EXPLAINER\s+ref=([^>]+)>>")
    m = marker_re.search(text)
    if not m:
        return text, False
    ref = m.group(1).strip()
    from .graph import backward_trace

    if ref not in wb.cells:
        replacement = f"(Could not delegate: cell {ref} not found.)"
        return marker_re.sub(replacement, text), True
    trace = backward_trace(wb, ref, max_depth=3).model_dump()
    result = formula_explainer.explain(trace, original_question)
    return marker_re.sub(result["prose"], text), True


def _latest_trace_from_log(state: ConversationState) -> Optional[dict]:
    for tc in reversed(state.tool_call_log):
        if tc.tool_name == "backward_trace" and isinstance(tc.output, dict) and "trace" in tc.output:
            return tc.output["trace"]
    return None


def _extract_evidence_refs(recent_tool_calls: list[ToolCall]) -> list[str]:
    """Pull cell refs touched by recent tool calls."""
    refs: list[str] = []
    seen: set[str] = set()

    def _walk(obj):
        if isinstance(obj, dict):
            for k, v in obj.items():
                if k == "ref" and isinstance(v, str) and "!" in v and v not in seen:
                    seen.add(v)
                    refs.append(v)
                _walk(v)
        elif isinstance(obj, list):
            for x in obj:
                _walk(x)

    for tc in recent_tool_calls:
        _walk(tc.output)
    return refs[:30]


def _build_partial_answer(attempt_text: str, audit_result: auditor_module.AuditResult) -> str:
    """Build the 'I don't know' partial answer after second audit failure."""
    parts = [
        "I can only partially answer this. Here's what I verified:",
    ]
    if audit_result.verified_numbers:
        parts.append(f"  • Verified numbers: {', '.join(audit_result.verified_numbers[:8])}")
    if audit_result.verified_refs:
        parts.append(f"  • Verified cell refs: {', '.join(audit_result.verified_refs[:8])}")
    if audit_result.verified_named_ranges:
        parts.append(f"  • Verified named ranges: {', '.join(audit_result.verified_named_ranges[:8])}")

    parts.append("")
    parts.append("What I couldn't verify:")
    for v in audit_result.violations[:8]:
        parts.append(f"  • {v}")

    parts.append("")
    parts.append("You might rephrase the question to be more specific about the cell or metric.")
    return "\n".join(parts)
