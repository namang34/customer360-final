"""Critique Agent -- the adversarial second pass, and the HITL stub."""

from __future__ import annotations

from dataclasses import dataclass, field
from datetime import datetime

from .action import ActionProposal
from .guardrail import GuardrailVerdict
from . import prompts
from .llm import LLM, LLMUnavailable, NullLLM, complete_json
from .schema import Action, ConfidenceBand, HitlStatus, InferredState
from .synthesis import Synthesis

# States where a sales offer is the wrong instinct however good the numbers look.
NO_SELL_STATES = frozenset({
    InferredState.MEDICAL_HARDSHIP,
    InferredState.FINANCIAL_DISTRESS_GENERAL,
    InferredState.JOB_LOSS_OR_INCOME_DISRUPTION,
    InferredState.CHURN_RISK,
    InferredState.ELDER_VULNERABILITY_OR_SCAM_RISK,
})

SELL_ACTIONS = frozenset({Action.PERSONALIZED_OFFER})


@dataclass
class Critique:
    verdict: str                      # accept | downgrade | reject
    reason: str
    checks: dict[str, bool] = field(default_factory=dict)
    decided_by: str = "rules"
    revised_action: Action | None = None
    revised_subtype: str | None = None

    @property
    def accepted(self) -> bool:
        return self.verdict == "accept"


class CritiqueAgent:
    """One adversarial pass with one bounded retry."""

    def __init__(self, llm: LLM | None = None, max_retries: int = 1) -> None:
        self.llm = llm or NullLLM()
        self.max_retries = max_retries
        self.llm_uses = 0
        self.llm_failures = 0
        self.rejections = 0
        self.downgrades = 0

    def review(
        self,
        proposal: ActionProposal,
        synthesis: Synthesis,
        guardrail: GuardrailVerdict,
    ) -> Critique:
        checks: dict[str, bool] = {}

        # no_action needs no defending. Reviewing it would burn quota on the ~70
        # of 74 checkpoints where nothing is being proposed.
        if proposal.action is Action.NO_ACTION:
            return Critique("accept", "no_action requires no justification", {"trivial": True})

        # check 1: the red-herring pattern (code)
        checks["corroborated"] = guardrail.passed
        if not guardrail.passed:
            self.rejections += 1
            return Critique("reject", guardrail.reason, checks)

        # check 2: policy actually authorises this (code)
        checks["policy_backed"] = bool(proposal.policy_ids)
        if not proposal.policy_ids:
            self.rejections += 1
            return Critique(
                "reject",
                f"No retrieved policy authorises {proposal.action.value}.",
                checks,
            )

        # check 3: the action contradicts the diagnosis (code)
        contradiction = _contradiction(proposal.action, synthesis.inferred_state)
        checks["no_contradiction"] = contradiction is None
        if contradiction:
            self.rejections += 1
            return Critique("reject", contradiction, checks)

        # check 4: single-event dominance (code)
        distinct_events = len(set(synthesis.corroboration.event_ids))
        checks["multiple_events"] = distinct_events >= 2
        if distinct_events < 2:
            self.rejections += 1
            return Critique(
                "reject",
                f"{proposal.action.value} rests on {distinct_events} distinct event(s).",
                checks,
            )

        # check 5: proportionality (judgement -> model)
        judged = self._ask_llm(proposal, synthesis)
        if judged is None:
            return Critique(
                "accept",
                f"All mechanical checks passed: {guardrail.reason}",
                checks,
                decided_by="rules",
            )

        verdict, reason = judged
        if verdict == "reject":
            self.rejections += 1
            return Critique("reject", reason, checks, decided_by=f"llm:{getattr(self.llm,'model','?')}")
        if verdict == "downgrade":
            self.downgrades += 1
            revised = _downgrade(proposal.action)
            return Critique(
                "downgrade",
                reason,
                checks,
                decided_by=f"llm:{getattr(self.llm,'model','?')}",
                revised_action=revised,
                revised_subtype=None if revised is Action.NO_ACTION else proposal.action_subtype,
            )
        return Critique("accept", reason, checks, decided_by=f"llm:{getattr(self.llm,'model','?')}")

    def _ask_llm(self, proposal: ActionProposal, synthesis: Synthesis):
        if isinstance(self.llm, NullLLM):
            return None
        evidence = "\n".join(
            f"- [{f.agent}] {f.signal} ({f.strength.value}): {f.detail}"
            for f in synthesis.corroboration.findings
        )
        user = (
            f"Inferred state: {synthesis.inferred_state.value} "
            f"({synthesis.confidence_band.value} confidence)\n"
            f"Proposed action: {proposal.action.value}"
            f"{f' / {proposal.action_subtype}' if proposal.action_subtype else ''}\n"
            f"Authorising policy: {proposal.policy_text[:900]}\n\n"
            f"Evidence:\n{evidence}"
        )
        for attempt in range(self.max_retries + 1):
            try:
                result = complete_json(self.llm, prompts.CRITIC, user, role="critique")
                verdict = str(result.get("verdict", "")).strip().lower()
                if verdict in ("accept", "downgrade", "reject"):
                    self.llm_uses += 1
                    return verdict, str(result.get("reason", ""))[:200]
            except (LLMUnavailable, ValueError, KeyError, TypeError):
                self.llm_failures += 1
                break
        return None


def _contradiction(action: Action, state: InferredState) -> str | None:
    """Actions that contradict the diagnosis, regardless of evidence strength."""
    if action in SELL_ACTIONS and state in NO_SELL_STATES:
        return (
            f"REJECTED: {action.value} contradicts an inferred state of {state.value}. "
            "A sales offer to a customer in distress or disengagement is harmful even when "
            "the evidence is strong."
        )
    if action is Action.COMPLIANCE_FRAUD_HOLD and state not in (
        InferredState.POTENTIAL_FRAUD_OR_TAKEOVER,
        InferredState.ELDER_VULNERABILITY_OR_SCAM_RISK,
    ):
        return (
            f"REJECTED: compliance_fraud_hold freezes customer funds and is not appropriate for "
            f"an inferred state of {state.value}."
        )
    return None


def _downgrade(action: Action) -> Action:
    """One step less intrusive."""
    return {
        Action.COMPLIANCE_FRAUD_HOLD: Action.RELATIONSHIP_MANAGER_ESCALATION,
        Action.RELATIONSHIP_MANAGER_ESCALATION: Action.PROACTIVE_RETENTION_OUTREACH,
        Action.PERSONALIZED_OFFER: Action.NO_ACTION,
        Action.PROACTIVE_RETENTION_OUTREACH: Action.NO_ACTION,
        Action.SUPPORT_INTERVENTION: Action.NO_ACTION,
    }.get(action, Action.NO_ACTION)


# HITL

@dataclass
class HitlDecision:
    status: HitlStatus
    action: Action
    action_subtype: str | None
    note: str = ""


class HitlStub:
    """Human-in-the-loop checkpoint."""

    def __init__(self, interactive: bool = False, responses: list[str] | None = None) -> None:
        self.interactive = interactive
        self.responses = list(responses or [])
        self.escalated = 0
        self.reviewed = 0

    def route(self, proposal: ActionProposal, synthesis: Synthesis) -> HitlDecision:
        if proposal.action is Action.NO_ACTION:
            return HitlDecision(HitlStatus.AUTO_APPROVED, Action.NO_ACTION, None, "no action to review")

        self.escalated += 1
        if not (self.interactive or self.responses):
            return HitlDecision(
                HitlStatus.ESCALATED,
                proposal.action,
                proposal.action_subtype,
                "Escalated to a human reviewer; no reviewer response recorded.",
            )
        return self._collect(proposal, synthesis)

    def _collect(self, proposal: ActionProposal, synthesis: Synthesis) -> HitlDecision:
        self.reviewed += 1
        if self.responses:
            answer = self.responses.pop(0).strip().lower()
        else:  # pragma: no cover -- interactive path
            print("\n" + "=" * 70)
            print(f"  HUMAN REVIEW  {proposal.as_of:%Y-%m-%d}")
            print(f"  state    : {synthesis.inferred_state.value} ({synthesis.confidence_band.value})")
            print(f"  action   : {proposal.action.value} / {proposal.action_subtype}")
            print(f"  evidence : {', '.join(synthesis.event_ids[:6])}")
            print(f"  policy   : {', '.join(proposal.policy_ids)}")
            print(f"  rationale: {proposal.rationale}")
            answer = input("  [a]pprove / [r]eject / [m]odify / [s]kip > ").strip().lower()

        if answer.startswith("a"):
            return HitlDecision(HitlStatus.HUMAN_APPROVED, proposal.action, proposal.action_subtype,
                                "Approved by reviewer.")
        if answer.startswith("r"):
            # A rejected action becomes no_action, and the output must say so.
            return HitlDecision(HitlStatus.HUMAN_REJECTED, Action.NO_ACTION, None,
                                "Rejected by reviewer; no action taken.")
        if answer.startswith("m"):
            downgraded = _downgrade(proposal.action)
            return HitlDecision(HitlStatus.HUMAN_MODIFIED, downgraded,
                                None if downgraded is Action.NO_ACTION else proposal.action_subtype,
                                f"Modified by reviewer to {downgraded.value}.")
        return HitlDecision(HitlStatus.ESCALATED, proposal.action, proposal.action_subtype,
                            "Left pending by reviewer.")
