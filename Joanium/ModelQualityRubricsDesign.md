---
name: Model Quality Rubrics Design
trigger: model quality rubrics design, help with model quality rubrics design, plan model quality rubrics design, improve model quality rubrics design, expert model quality rubrics design
description: Expert-level guidance for model quality rubrics design, including decision criteria, workflow, tradeoffs, signals, review checkpoints, and failure modes.
---

Model Quality Rubrics Design is an expert-level AI systems skill for making model-assisted behavior reliable, auditable, and economically sane in production. The emphasis here is on interfaces, invariants, failure handling, and why one structure is safer than its alternatives.

## When To Use

- Use this when Model Quality Rubrics Design influences user-visible output, automation, or safety-sensitive decisions.
- Use this when prompts, retrieval, tools, and policies interact in ways that are hard to reason about informally.
- Use this when you need explicit acceptance criteria before increasing traffic, autonomy, or model authority.
- Use this when regressions, unsafe behavior, or cost spikes require a more disciplined operating model.

## Core Principles

- Separate model behavior from system behavior; both need design.
- Assume variance and clamp it with contracts, validation, and fallback paths.
- Evaluate against adversarial, ambiguous, and low-context cases, not only happy-path prompts.
- Make prompt, model, retrieval, and tool changes attributable so debugging stays causal.
- Human escalation should be deliberate, fast, and observable.

## Decision Questions

- What are the core boundaries, contracts, and invariants in Model Quality Rubrics Design?
- Which failure modes should be absorbed, and which should surface immediately?
- How will the design evolve without breaking consumers or operators?
- Where is coupling acceptable, and where is it too expensive?
- What assumptions does the design make about scale, behavior, or inputs?

## Workflow

1. Clarify requirements, non-goals, and the constraints that shape the design.
2. Map the boundary diagram, responsibilities, and trust or data flows.
3. Define contracts, state transitions, and invariants that must hold.
4. Design failure handling, fallback behavior, and operability hooks.
5. Stress the design against realistic scenarios, edge cases, and growth patterns.
6. Review the tradeoffs, migration path, and reversibility before adoption.

## Deliverables

- An architecture or boundary diagram for Model Quality Rubrics Design.
- A contract or state model that captures invariants explicitly.
- A migration and compatibility sketch for affected consumers.
- A tradeoff record describing why this design beat the alternatives.

## Tradeoffs

- Modularity versus coordination overhead.
- Strict contracts versus flexibility of change.
- Simplicity now versus extensibility later.
- Immediate performance versus debuggability and safety.

## Signals To Watch

- Task success rate against a human-reviewed gold set.
- Fallback frequency, escalation rate, and unresolved exception count.
- Latency and token cost by path, prompt family, and customer tier.
- Tool call failure rate and recovery success percentage.
- Unsafe output rate, policy violation rate, and false-positive review burden.

## Review Checklist

- [ ] Boundaries and responsibilities are explicit.
- [ ] Invariants are named and testable.
- [ ] Failure handling is designed, not implied.
- [ ] Compatibility and migration are addressed.
- [ ] The design was tested against realistic scenarios.
- [ ] Rejected alternatives are captured honestly.

## Common Failure Modes

- Designs that describe components but not their contracts.
- No explanation of failure behavior or degraded mode.
- Coupling hidden behind convenience abstractions.
- Migration concerns deferred until implementation is underway.
