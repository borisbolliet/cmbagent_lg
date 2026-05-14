"""Four propose-critique nodes for the planner ↔ plan_reviewer loop.

Flow (ends on planner — the plan is the deliverable):

    planner ─► format_plan ─► [END if round==num_rounds else continue]
                              │
                              ▼
                          plan_reviewer ─► format_review ─► planner …

Generators write free-form prose; tiny downstream formatters convert that
prose into typed Pydantic objects via `with_structured_output`.

`format_review` appends `(current_plan, current_review)` to `state["history"]`
so every subsequent planner pass sees the **full** prior transcript, not just
the latest review. Catches regressions where the planner re-introduces a
mistake an earlier reviewer already corrected.
"""

from typing import List, Literal, Optional, Tuple

from langchain_core.messages import HumanMessage, SystemMessage
from langgraph.runtime import Runtime
from pydantic import BaseModel, Field, create_model

from functools import lru_cache

from cmbagent_lg.context import PlanContext
from cmbagent_lg.llms import proposer, critic, formatter
from cmbagent_lg.prompts import (
    planner_instructions,
    plan_reviewer_instructions,
    schema_field_brief,
)
from cmbagent_lg.schemas import Plan, Review, Step
from cmbagent_lg.state import PlanState


# Lazy-init: building a ChatGoogleGenerativeAI prints a warning to stdout
# ("Both GOOGLE_API_KEY and GEMINI_API_KEY are set…"). Deferring instantiation
# means importing the package (e.g. for the CLI) doesn't trigger them.
@lru_cache(maxsize=1)
def _proposer():
    return proposer()


@lru_cache(maxsize=1)
def _critic():
    return critic()


@lru_cache(maxsize=1)
def _formatter():
    return formatter()


# ── dynamic agent constraint ────────────────────────────────────────────


def _agent_brief(available: List[Tuple[str, str]]) -> str:
    """Render the agent inventory for injection into planner/reviewer prompts."""
    return "\n".join(f"  - **{name}**: {desc}" for name, desc in available)


def _build_dynamic_plan_model(available: List[Tuple[str, str]]):
    """Build a `Plan` Pydantic model whose `Step.sub_task_agent` is constrained
    to `Literal[*available_agents]` for this run.

    cmbagent hard-codes this Literal in `planner_response_evaluator.Subtasks`.
    Here we build it per-invocation from `PlanContext.available_agents`, so a
    different team can be plugged in without recompiling the graph.
    """
    names = tuple(name for name, _ in available)
    if not names:
        raise ValueError("PlanContext.available_agents is empty — no agents to plan with.")

    DynStep = create_model(
        "DynStep",
        sub_task=(str, Field(description="The sub-task to be performed.")),
        sub_task_agent=(
            Literal[names],  # type: ignore[valid-type]
            Field(description="Name of the agent in charge of the sub-task."),
        ),
        bullet_points=(
            List[str],
            Field(description="Bullet-point instructions for the agent."),
        ),
        code_execution_timeout=(
            Optional[int],
            Field(default=None, description="Max seconds for code execution. None = default."),
        ),
        __base__=BaseModel,
    )
    DynPlan = create_model(
        "DynPlan",
        sub_tasks=(List[DynStep], Field(description="Ordered list of plan steps.")),
        __base__=BaseModel,
    )
    return DynPlan


# ── generators ──────────────────────────────────────────────────────────


def _render_history(history) -> str:
    """Render the full prior-rounds transcript for the planner's prompt."""
    if not history:
        return ""
    lines = ["**Prior rounds (for your context — do not repeat past mistakes):**\n"]
    for i, (plan, review) in enumerate(history, start=1):
        lines.append(f"--- Round {i} ---")
        lines.append(plan.format())
        lines.append("")
        lines.append(review.format())
        lines.append("")
    lines.append(
        "Now produce the revised plan, taking into account **every** review above. "
        "Pay special attention to the most recent review."
    )
    return "\n".join(lines)


def planner(state: PlanState, runtime: Runtime[PlanContext]) -> PlanState:
    ctx = runtime.context
    round_n = state.get("round", 0) + 1
    history = state.get("history", [])

    system = planner_instructions(ctx, recommendations=_render_history(history))
    system += (
        "\n\n-----AVAILABLE AGENTS-------------\n"
        "You must assign each step to **exactly one** of these agents — no others:\n"
        f"{_agent_brief(ctx.available_agents)}\n"
        "----------------------------------"
    )
    user = (
        "Produce the plan now, in the format described above. Write in natural prose — "
        "a downstream specialist will extract structured fields. Make sure every "
        "Step covers:\n\n" + schema_field_brief(Step)
    )
    msg = _proposer().invoke(
        [SystemMessage(system), HumanMessage(user)],
        config={"tags": ["planner"]},
    )
    return {"raw_plan": msg.text, "round": round_n}


def plan_reviewer(state: PlanState, runtime: Runtime[PlanContext]) -> PlanState:
    ctx = runtime.context
    plan = state["current_plan"]
    system = plan_reviewer_instructions(ctx, proposed_plan=plan.format())
    system += (
        "\n\n-----AVAILABLE AGENTS-------------\n"
        "The plan may only assign work to these agents — flag any step that "
        "names someone else, or assigns work outside an agent's stated capability:\n"
        f"{_agent_brief(ctx.available_agents)}\n"
        "----------------------------------"
    )
    user = (
        "Critique the plan above. Write in natural prose — a downstream specialist "
        "will extract structured fields. Be sure to cover:\n\n"
        + schema_field_brief(Review)
    )
    msg = _critic().invoke(
        [SystemMessage(system), HumanMessage(user)],
        config={"tags": ["plan_reviewer"]},
    )
    return {"raw_review": msg.text}


# ── formatters ──────────────────────────────────────────────────────────


def _make_formatter(schema, input_field: str, output_field: str, tag: str):
    sys = SystemMessage(
        f"You are a formatter. Convert the user's text into a {schema.__name__} "
        f"object. Preserve all substantive content. Do not invent new facts. "
        f"If a field is not explicitly stated, infer it conservatively from context."
    )

    def node(state: PlanState, runtime: Runtime[PlanContext]) -> PlanState:
        structured = _formatter().with_structured_output(schema)
        obj = structured.invoke(
            [sys, HumanMessage(state[input_field])], config={"tags": [tag]}
        )
        return {output_field: obj}

    node.__name__ = tag
    return node


def format_plan(state: PlanState, runtime: Runtime[PlanContext]) -> PlanState:
    """Like `_make_formatter(Plan, …)` but builds the model dynamically so
    `sub_task_agent` is constrained to `Literal[*ctx.available_agents]` at the
    structured-output boundary. Result is converted back to the static `Plan`
    type so downstream nodes (and consumers) keep getting the same shape.
    """
    ctx = runtime.context
    DynPlan = _build_dynamic_plan_model(ctx.available_agents)
    structured = _formatter().with_structured_output(DynPlan)
    sys = SystemMessage(
        "You are a formatter. Convert the user's text into a Plan object. "
        "Preserve all substantive content. Do not invent new facts. "
        "If a field is not explicitly stated, infer it conservatively from context."
    )
    dyn = structured.invoke(
        [sys, HumanMessage(state["raw_plan"])],
        config={"tags": ["format_plan"]},
    )
    # `dyn` is a DynPlan; round-trip through dict into the static Plan so
    # the rest of the graph and external callers see a stable type.
    return {"current_plan": Plan(**dyn.model_dump())}


_format_review_inner = _make_formatter(
    Review, "raw_review", "current_review", "format_review"
)


def format_review(state: PlanState, runtime: Runtime[PlanContext]) -> PlanState:
    """Format the review, then snapshot (plan, review) into the history."""
    out = _format_review_inner(state, runtime)
    review = out["current_review"]
    history = list(state.get("history", []))
    history.append((state["current_plan"], review))
    out["history"] = history
    return out


# ── router ──────────────────────────────────────────────────────────────


def route_after_format_plan(state: PlanState, runtime: Runtime[PlanContext]) -> str:
    """End on a planner pass: after format_plan, decide review-or-stop.

    `num_rounds` = number of **review cycles**. The graph runs:
        planner → format_plan → plan_reviewer → format_review  (× num_rounds)
                ↓
        planner → format_plan → END  (the final, un-reviewed planner pass)

    So total planner passes = num_rounds + 1. With `num_rounds=2`:
    plan_v1 → review_1 → plan_v2 → review_2 → plan_v3 (final).
    """
    from langgraph.graph import END

    if state["round"] <= runtime.context.num_rounds:
        return "plan_reviewer"
    return END
