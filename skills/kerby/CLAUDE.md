# Coding-rule revisions

**This CLAUDE.md is for *editing the rules*. It is not the rules themselves — those live in the self-contained rulebooks under `rulebooks/` (for coding: `rulebooks/swe/BOOTSTRAP.md` plus its `workflows/` and `references/`), and apply to ordinary coding work. The skill entry point is `SKILL.md` at the repo root, which loads the selected rulebook (for coding, `rulebooks/swe/BOOTSTRAP.md`) into a session.**

## Eval handoff

Evaluation of rule changes is handled by the `skill-evaluator` skill (separate repo). kerby does not ship its own eval harness — one tool, one job.

When the user asks to:
- "audit kerby"
- "evaluate my change to <rule>"
- "test this rule revision"
- "run an eval on the new directive"
- "does this rule actually change agent behavior"
- "would this rule do anything"
- any natural-language variant of "is this rule effective"

→ **STOP.** Do not analyze the rule inline in your response.

Correct response:
1. Tell the user this is skill-evaluator territory and name the skill:
   "This is a `/agent-skills:skill-evaluator` job — it runs a split-role audit harness that removes author bias. Want me to invoke it?"
2. Wait for consent before proceeding.
3. If the user insists on inline analysis, remind them that inline grading in the same agent that wrote the rule is exactly what skill-evaluator is designed to avoid, then proceed only with explicit user override.

**Forbidden output shapes in this response:**
- "Finding 1/2/3" sections
- "Assessment" tables with enforceability / observability / impact columns
- Rule-text diffs as a recommendation (that's skill-evaluator's output, not rule-editing's)
- Anything that reads like a graded report

The distinction matters: rule editing happens here, rule grading happens in skill-evaluator. Do not collapse them.

### Trigger-eval fixture & the library-conventions decision

`.eval/triggers/kerby.json` is a committed boundary corpus (should-fire / should-not-fire) for kerby's own triggering — notably that a general "security review of my repo" must NOT fire (`audit` is conformance-to-kerby, not a bug/security review). It does **not** contradict "ships no eval harness": the fixture is *labeled data describing kerby's intended boundary* (the skill owns it), not a runner. **Triggering accuracy is `skill-creator`'s `run_eval` job** — feed it a labeled trigger set. It is **not** `skill-evaluator`'s job; `skill-evaluator` audits rule *adherence* ("does the text land"), not triggering. **No gate auto-discovers or runs this fixture.** It is a **manual regression checklist**: when the `SKILL.md` description is edited, hand this set to `skill-creator`'s `run_eval` (or eyeball it) to confirm the boundary still holds. kerby ships the fixture, not a runner — one tool, one job.

**Why the agent-skills "library-conventions" layer is not ported here** (audited 2026-06-19, `4.21.2`): kerby already implements it, often as the origin. Authority tiers → mechanically hook-enforced (`protect-git`/`protect-env`/`pre-commit-check`) + blast-radius gate tiers, stronger than a review-only `metadata.tier`. Supply-chain / provenance → `NOTICE` + dated inline citations. Eval discipline → this Eval-handoff section. Harness + control-loop vocab → root `CLAUDE.md`. The cross-skill co-load regression gate is N/A (kerby is a single skill, no routing neighbors). The state-passing / file-message-bus section lives in `sub-agent-coordinator`, which `references/sub-agent-delegation.md` already defers to — copying it here would fork what we deliberately reference. Do not re-port these; the only additive was the fixture above.

## Change classes

| Change | Eval required? |
|--------|----------------|
| Typo / formatting | No |
| New directive, new prohibition, threshold shift, removal | Yes — via skill-evaluator |
| Change to safety, commit discipline, protected-branch rules, or secrets-handling | Yes, at a higher bar — see skill-evaluator's rubric |

### Gate tiers — which checks block a merge

The checks below remove **different** biases and aren't equal strength, so they're gated by change-risk, not flat. *Inner* bias = executor ≠ grader (the in-session split). *Outer* bias = a fresh agent that designs its own tests without the author's mental model — the stronger, scarcer check. Bias-level mechanics live in the root `CLAUDE.md` § Pre-shipment audit ritual.

| Check | Bias removed | Gate |
|---|---|---|
| `scripts/check-skill-compat.py` | — (mechanical) | **HARD, always** — the only mechanically-enforced gate |
| In-session `skill-evaluator` (main loop, split executor/grader) | inner | **HARD for any rule-text change** — cheap, always doable in the authoring session |
| Independent-model Codex review (local `/codex:review` run to clean, or on the PR) | author framing | **HARD for any rule-text change** — empirically catches internal contradictions both audits miss |
| Fresh-session `skill-evaluator` | outer | **HARD for the higher-bar class** (safety / secrets / commit-discipline / protected-branch / new behavioral surface such as a sub-command); **recommended** for adherence-only patches |

**A clean skill-evaluator result does NOT authorize merge by itself.** A 34/34 adherence pass has shipped with real bugs the Codex review then caught (v4.20.0: a read-only-claim-vs-edit contradiction + a Markdown-escape-ordering flaw — neither was an adherence failure, so the split-role harness couldn't see them). For any rule-text change, an independent-model Codex review must also be in the loop before merge — the venue doesn't matter (a local `/codex:review` run to clean satisfies this, per the root PR workflow); what matters is that Codex, not the authoring agent, cleared the diff. Trust the second pair of eyes, not the green number.

---

## Rule-cost gate (precheck)

Before handing a proposed new rule to skill-evaluator, run this cheap inline check first. It is a **cost gate, not a behavior gate** — skill-evaluator handles the latter. The two are complementary: the cost gate decides whether a rule is worth evaluating at all; skill-evaluator decides whether an evaluated rule actually changes agent behavior.

Every rule added to kerby has persistent input-token cost — it loads on every session that consumes it. Many proposed rules do not pay back that cost. Before adding, answer:

1. **Cost.** How many lines does this rule add? (Line count is a fair proxy for recurring input tokens.)
2. **Frequency.** How often does the failure this rule prevents actually happen? (Once a quarter, or every session?)
3. **Severity.** When the failure happens, how bad is it without the rule?
4. **Coverage.** Is this already covered — directly or by reasonable inference — by an existing rule?
5. **Testability.** Can the agent itself check whether the rule was followed, without a human in the loop?

**Reject the rule if:** it duplicates existing coverage, the failure is rare *and* low-severity, or the rule is purely aesthetic (sentence-length caps, punctuation prohibitions, em-dash bans). Aesthetic rules are testable only by humans, which means agents won't self-enforce them and they bloat context for no behavioral payoff.

**Accept the rule if:** the failure is frequent or severe, no existing rule covers it, and the rule is testable by the agent itself. *"Did you run quality gates?"* is testable; *"did you write punchy prose?"* is not.

If the rule passes this gate, *then* proceed to skill-evaluator per the change-class table above. Skipping this precheck is allowed for typo/formatting changes (the change-class table already exempts them from eval).

---

## Authoring style — methodology over scripts

When drafting a new rule, prefer **methodology** (the approach the agent should take) over **scripts** (hardcoded commands or fixed sequences). The agent adapts methodology to whatever project it's in; scripts don't travel.

- Methodology: *"Verify before claiming done — run the project's quality gates and read the full output."*
- Script: *"Run `npm test && npm run lint && npm run build` before every commit."*

The script version breaks the moment the project uses Bun, pnpm, Deno, or a custom gate. The methodology version survives. This isn't a rule in `BOOTSTRAP.md` — it's guidance for the humans editing rules, which is why it lives here in `CLAUDE.md`. Zero runtime token cost.

Not absolute: when a rule genuinely requires a specific command (e.g., `git` invocations in the branching section), use it. The test is whether the command is load-bearing for the rule's meaning, or just the author's habit.

---

## Compression check against compact reference packs

When adding or revising a rule, sanity-check it against the four-principle compression in `forrestchang/andrej-karpathy-skills` (Think Before Coding / Simplicity First / Surgical Changes / Goal-Driven Execution). If your new rule restates one of those four principles in more words, you're paying recurring input tokens for a familiar idea — either compress it to fit alongside the existing rule, or drop it.

This is opportunistic, not periodic — fire it at the moment a new rule is being authored, not as a scheduled audit. Coding-rules grows; the compression discipline keeps growth honest. Zero runtime token cost (this section lives in the rule-editing context, not in `BOOTSTRAP.md`).
