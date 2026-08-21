---
name: ps-skill-eval
description: "Compare a skill or prompt variant with its control through blinded recorded trials."
disable-model-invocation: true
---

# Evaluate a skill variant

Run a declared, reproducible comparison within the selected evaluation fixtures and skill source.

## Required contract

Define the control and variant, task set, rubric, randomized or blinded assignment, retry policy, budget, and stopping rule before trials. Keep control and variant isolated and retain failed trials in the result.

Observable trial inputs, outputs, and checks are sufficient evidence. Transcript or run-history evidence is optional and may be used only through an available adapter after the user explicitly selects its source and scope; never scan unrelated workspaces or assume private history access.

Do not switch models secretly, claim performance without measurements, retry failures away, or change unrelated skill sources. Store only bounded evaluation fixtures and results.

## Completion report and next steps

This invocation has one root skill: `/ps-skill-eval`. Internal capabilities and bounded helpers stay inside this run and never appear as separately used skills. Present the result directly in chat and create no secondary result artifact or URL.

Normalize explicit flags first, then clear natural-language intent, then defaults. `effort=quick|standard|deep` controls evidence depth and defaults to `standard`; `report=brief|full` controls presentation and defaults to `brief`. Neither changes mutation authority.

Use `complete`, `continuation-required`, `input-required`, or `failed`. Emit exactly three ranked copy-ready prompts: one preferred route and two alternatives. Failed required checks or actionable P0/P1 findings prohibit `complete`.

Default routes: `/qs-skill-write`, `/qs-plan-clarify`, `/qs-flow-handoff`. Failure routes: `/qs-plan-clarify`, `/qs-skill-write`, `/qs-flow-handoff`. Tailor every prompt to the completed work.

Before responding, apply the internal clear-writing pass: lead with the outcome, use concrete nouns and verbs, preserve necessary qualifications and technical terms, and remove repetition. It never appears as another skill, status, or continuation.

Brief output contains status, outcome, up to three important findings or decisions, noteworthy failed checks, material outputs, and all three prompts. Full adds the evidence trail, never more prompts. Omit empty sections and routine success detail.

Status: Complete | Continuation required | Input required | Failed
Skills used: /ps-skill-eval
Outcome: Concise verified result.
Preferred next prompt: one copy-ready prompt in a fenced `text` block
Alternative next prompts: two copy-ready prompts, each in its own fenced `text` block

Label prompts `Preferred next prompt:` and `Alternative next prompt:`. Put each in its own fenced `text` block, beginning with its exact Codex literal ($qs-specialists:qs-skill-write, $qs-skills:qs-plan-clarify, $qs-skills:qs-flow-handoff); Claude uses `/qs-skill-write`, `/qs-plan-clarify`, `/qs-flow-handoff`. Carry forward only the outcome and highest-value evidence. Keep model guidance outside the fence and never change the active model or reasoning setting.
