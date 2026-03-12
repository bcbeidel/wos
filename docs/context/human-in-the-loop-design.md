---
name: "Human-in-the-Loop Design"
description: "When AI agents should gate on human approval vs. act autonomously, based on reversibility, confidence, and trust calibration research"
type: reference
sources:
  - https://nap.nationalacademies.org/read/26355/chapter/9
  - https://ieeexplore.ieee.org/document/844354
  - https://journals.sagepub.com/doi/10.1518/001872097778543886
  - https://link.springer.com/article/10.1007/s00146-025-02422-7
  - https://www.smashingmagazine.com/2026/02/designing-agentic-ai-practical-ux-patterns/
related:
  - docs/research/human-in-the-loop-design.md
  - docs/context/agentic-planning-execution.md
  - docs/context/tool-design-for-llms.md
---

Human-in-the-loop (HITL) design is not a binary choice between full autonomy and full oversight. It is a spectrum, and the optimal point shifts with context, risk, and accumulated trust. Getting it wrong in either direction hurts: too much autonomy causes automation bias and missed errors; too little creates bottleneck fatigue and disuse.

## The Automation Spectrum

Parasuraman, Sheridan, and Wickens (2000) established that automation decisions should be made independently across four functions: information acquisition, analysis, decision selection, and action implementation. A system can fully automate information gathering while requiring human approval for action implementation. This per-function decomposition is more useful than a single global autonomy setting.

## When to Require Approval

Gate on human approval when:

- **Action is irreversible** or difficult to reverse (data deletion, external communications)
- **Consequence magnitude is high** (financial transactions, significant state changes)
- **System confidence is below threshold** for the specific action type
- **Action falls outside defined scope** boundaries
- **Regulatory requirements mandate oversight** (EU AI Act Article 14 requires human oversight for high-risk AI systems, effective August 2026)

Automate when actions are reversible, within well-defined scope, above confidence thresholds, and captured in an audit trail for post-hoc review.

## Automation Bias: The Dominant Failure Mode

Users systematically over-rely on AI recommendations. This manifests as commission errors (following wrong advice) and omission errors (failing to notice problems the AI does not flag). Parasuraman and Riley (1997) identified four responses to automation: appropriate use, misuse (over-reliance), disuse (underutilization from eroded trust), and abuse (automating without regard for human performance consequences).

Users with intermediate knowledge are most susceptible to automation bias -- enough familiarity to feel confident but insufficient depth to recognize AI limitations. The XAI paradox compounds this: explanations designed to build appropriate trust can reinforce misplaced trust when poorly calibrated to the user's expertise level.

## Trust Calibration

Communicating AI confidence and uncertainty is the single most impactful trust calibration mechanism. Explicit likelihood information promotes appropriate trust more effectively than explanations of reasoning. Systems should provide confidence signals, verification prompts, and feedback on automation accuracy.

Trust miscalibration takes two forms: over-trust (believing AI performs better than it does, leading to complacency) and under-trust (believing AI performs worse, leading to disuse). Neither transparency alone nor experience alone produces appropriate reliance -- active calibration intervention is required.

## Progressive Autonomy

A three-level model maps to the natural trust calibration cycle:

1. **Audit mode**: 100% human review. Use for initial deployment or after trust-breaking incidents. Builds accuracy baseline.
2. **Assist mode**: Exception-based review. Routine cases proceed autonomously; confidence-based routing sends uncertain cases to humans. Sustainable steady state.
3. **Autopilot mode**: Monitored autonomy with intervention capability. Appropriate only after extended successful operation, and only for reversible actions.

Autonomy level should be dynamic -- tighten after errors, loosen after sustained success.

## Decision Presentation

Present decisions needing input with intent previews (what the agent plans, reversibility status, edit controls), confidence signals, and collapsible reasoning. Use inline review over separate approval screens to maintain flow. Progressive disclosure works: show the conclusion first, make reasoning available on demand. Always provide undo capability as a safety net.

## Limitations

Confidence-based routing depends on accurate AI self-assessment, but current LLMs are poorly calibrated and often overconfident on wrong answers. The progressive autonomy model assumes trust calibration is gradual, but trust can be brittle -- a single failure after sustained success may shatter rather than merely reduce trust. At scale, human reviewers tend toward rubber-stamping, making oversight performative rather than functional.
