---
name: autopilot
description: The unattended build-and-audit run — the "you're gone" half of the flow. Invoked by `preflight`'s handoff, or with `/autopilot` pointed at a settled spec, when Sean has walked away. The orchestrator coordinates without writing code or auditing itself: it works the spec's plan as a slice queue (a fresh Claude developer subagent per slice, each slice's check run before advancing), fires Codex as a strictly read-only auditor on three focused passes (simplicity, security, spec conformance), triages the findings with judgment, loops real fixes back to the developer, and refuses to open the PR until the spec's done-signal measurably passes (the completeness gate). Works on a branch and ends by opening a PR (which fires the deploy preview) — marked ready-for-review when the completeness gate passes clean, left draft when anything is unmet; never merges or deploys. The auditor never fixes. For the interactive setup that precedes this, see `preflight`; for picking the run back up after Sean reviews the PR, see `autopilot-iterate`.
---

# Autopilot — the unattended run

Nobody is watching. Sean set the work up in `preflight`, hit the walk-away line, and left. Your job is to run the back half — implement, audit, triage, fix, repeat — and have a clean report waiting when he's back to do his manual test. The value of this skill is that the audit no longer waits on Sean being at the keyboard; it happens automatically as the tail of the run.

## Four rules that don't bend

1. **The orchestrator judges — it does not write code, and it does not audit.** You dispatch a developer to write and Codex to audit. Your work is the judgment _between_ their outputs. You stay out of writing so you can weigh the audit impartially; you stay out of auditing so a second, independent model catches what you'd miss.
2. **The auditor is read-only, always.** Codex reviews and reports. It never edits. This is structural (see the invocation below), not a promise — but never route audits through anything that can write.
3. **Never ship.** Work on a branch and commit at clean points. Ending the run means pushing the branch and opening a **PR** for review (Phase 6) — that's the handoff, not the ship. Whether the PR is draft or ready-for-review is a signal derived from the completeness gate, never a shipping decision. Never merge the PR and never deploy; those stay the human's calls after review.
4. **Never accept "done" on self-report — measure it.** Running the spec's checks (tests, builds, greps, the done-signal) is _sensing_, and it is your job: it's not writing and it's not auditing. A developer saying "done" and an audit coming back clean are both compatible with a half-built branch; only the spec's checks passing means done. If you're about to advance a phase without having run a check, stop and run it.

## Preconditions — fail safe, because no one's here

- **A settled spec must exist** (from `preflight`, at `docs/autopilot/…`, or passed in). If it's missing, thin, or ambiguous, **do not proceed** — leave a note saying what's unclear and stop. An unattended run on a vague spec does unattended damage.
- **Be on a branch, cut from a current base.** `git fetch` and fast-forward the default branch first, then create the branch named in the spec if it doesn't exist. If the branch already exists and is behind, fast-forward it onto the updated base. Never run this on `main`. Two exceptions: a project convention in `CLAUDE.md` that bases branches elsewhere, and a base update that isn't a clean fast-forward — don't fight a merge unattended, record that the run is on a stale base and carry on.
- **When you hit something the spec doesn't cover and you can't resolve from it, stop and record it.** Don't guess to keep moving. A clear "blocked on X" beats a confident wrong turn Sean has to unwind.

## The roster

- **Orchestrator** — this session (Sean's model; Opus or Fable). Coordinates and judges.
- **Developer** — a Claude subagent (`Agent`, model `sonnet`; escalate to `opus` for a hard spec). Writes and fixes code.
- **Auditor** — Codex / GPT (via the read-only invocation below). Reviews only.

The developer and the auditor must be **different models** — that's what makes the audit independent. Since Codex is the auditor, Claude is the developer. (This is the deliberate inverse of the "GPT builds, Claude tastes" setup; here Claude builds and GPT checks.)

## Phase 1 — Implement (work the slice queue)

The spec's plan arrives as ordered vertical slices, each with its own check — preflight guarantees this for non-trivial work. Work it as a queue, not as one big dispatch:

- Dispatch a **fresh developer subagent per slice** with the spec, the branch, and that slice. Fresh contexts are cheaper and more reliable than one long-running window holding the whole scope — a full window degrades, ships the parts it remembers, and declares victory.
- When the subagent returns, **run the slice's check yourself** (rule 4). Green → clean commit point, advance the queue. Red → back to the _same_ slice with the failure output; don't advance past a red check.
- Tell each developer to commit at clean points and **not** push or open a PR.
- The queue is the ambition-keeper: Phase 1 does not end with unfinished slices. If a slice is blocked on something the spec can't resolve, stop and record it (see preconditions) rather than silently skipping it — a skipped slice is exactly the kind of quiet 60%-run this structure exists to prevent.

A spec small enough to be one slice collapses to the old behavior: one dispatch, one check. You do not edit files yourself — if you're tempted to "just fix this one line," that's the rule-1 violation that collapses your independence.

## Phase 2 — Audit (Codex, read-only, focused, separate passes)

Run **one Codex pass per lens** — simplicity, security, and spec as _separate_ invocations. Never fold multiple lenses into one prompt; a mixed review is Codex's documented failure mode and yours (it fixates on one thread and the rest slides past).

Two of the lenses are deliberately narrow so they stay in their lane; the third is the wide one that asks whether the branch is actually the thing the spec asked for.

Each pass is a **single, allowlistable command** — the wrapper script resolves the Codex plugin path and builds the prompt internally, so there's no `$(…)`/pipe for Claude Code to choke on, and the whole audit runs on one permission approval:

```sh
node "${CLAUDE_PLUGIN_ROOT}/skills/autopilot/scripts/codex-audit.mjs" --lens security --base main
```

- `--lens simplicity`, `--lens security`, or `--lens spec` — one lens per run; the prompt template lives in the script.
- **simplicity** also owns comments. Comment slop is over-engineering in prose, and an unattended run produces plenty of it — narration, dated stories, ticket references — that nobody adversarially reviews, because correctness review doesn't read prose. It matters more than tidiness: a future agent trusts a comment over the code, so a stale one misdirects the next edit. The prompt names what's protected (constraints the code can't show, "do not simplify this back" warnings, test intent) so the pass doesn't sweep the load-bearing ones.
- **spec** requires `--spec docs/autopilot/<file>.md` and errors without it, rather than quietly reviewing the diff on its own terms. This is the lens aimed at a branch that cleanly implements 60% of the work — the narrow two both pass on code that is simply absent.
- `--base <ref>` reviews the branch against a base (`git diff <ref>...HEAD`); omit it to review the uncommitted working tree, or pass `--scope "<text>"` to describe the range.
- Follow-up passes: add `--context "the developer just changed X to address prior findings; check against history"` so Codex focuses on what changed rather than re-reviewing everything.
- For a freeform (non-lens) review, pass `--prompt "<text>"` or `--prompt-file <path>` instead of `--lens`.

**Read-only is structural:** the script calls the companion's `task` with **no `--write`**, so the plugin forces `sandbox: "read-only"` / `approvalPolicy: "never"` — Codex cannot edit or even prompt to edit. The lens prompt templates (compact, XML-blocked, one job per run) live in `codex-audit.mjs`; tune them there. The model is left unset so Codex uses your `~/.codex/config.toml` default (pin `gpt-5.5` there if desired); pass `--model`/`--effort` to override.

## Phase 3 — Triage (this is where you earn your keep)

Codex hands back raw findings. **Never pass them downstream as-is.** For each finding, judge:

- **Is it real?** Open the code and confirm. Codex is confident even when wrong; low-confidence findings especially need checking.
- **Is it in scope and material?** Drop nits, style bikeshedding, and things outside the spec's intent. Simplicity findings that would _add_ complexity to satisfy get dropped.
- **Did Codex fixate?** If it spent the whole pass on one detail, ask what it likely missed and whether a second angle is worth a pass.
- **Does it invalidate a spec assumption?** A finding is evidence about the _spec_, not just the code. When one shows the spec was wrong about something — its file list, its scope, an assumption it rested on — don't just fix the found instance: re-derive the **class**. Re-run, yourself and repo-wide, the check that assumption was built on (e.g. preflight's reference sweep) and fold in whatever else it surfaces _before_ closing the round. Confirming the one finding and moving on is exactly how a single under-scoped sweep survives every downstream layer. It's read-only work — judgment, not editing — so it stays within the rules.

Produce a **judged action list** ranked by severity — only the findings a developer should actually act on, each with your reasoning. This list, not the Codex dump, is what moves forward.

## Phase 4 — Fix loop

Send the judged findings back to the **developer** subagent to fix (again: you don't fix them yourself). When it returns, **re-run any checks the fix could have disturbed** (rule 4) — audit fixes are a classic place for regressions to sneak in. Then re-audit — the follow-up passes are diff-focused: "here's what changed, check it against history." Loop until every lens comes back clean **or** you hit the spec's loop bound (default 3 rounds). Don't loop forever chasing a zero while Sean's away; a bounded stop with an honest report is the correct outcome.

## Phase 5 — The completeness gate

**Audit-clean is not the stop condition — audit-clean _and_ done-signal-met is.** This gate is the answer to the run's most common failure mode: ending early because everything _present_ looks fine.

The spec lens (Phase 2) and this gate both ask "is it done," and the difference between them is the point. The lens **reads** — Codex compares the code to the spec's intent and reports what it judges missing, which catches a requirement implemented in name only, passing its check while doing the wrong thing. The gate **measures** — you run the done-signal commands and observe what they return, which catches what a reader talks themselves out of. Running a command is sensing, not auditing, so it stays with you (rule 4) and doesn't compromise the independence that keeps you out of your own review. Neither substitutes for the other; a lens finding is a claim, a failed check is a fact.

Re-read the spec from disk — don't trust your memory of it; a long run may have compacted it away. Then walk the done-signal item by item and **run each check**: the test command, the greps, the build, plus any slice checks you have doubts about. Every item gets a verdict — met, with the command output as evidence, or unmet.

- **Unmet items are findings.** Send them back through the fix loop (Phase 4) like any other judged finding — dispatch the developer, re-check, re-audit the delta. They count against the same loop bound.
- If the loop bound is exhausted with items still unmet, a bounded stop is legitimate — but the PR must say so plainly: which items are unmet and why the run stopped.
- `human-verify` items from the spec aren't run here — copy them into the PR's verify note for Sean.

## Phase 6 — Open the PR and stop

Close the run by handing off through the `open-pr` skill: push the branch and open a **PR** for review. On Netlify (and similar), the PR is what triggers the deploy preview Sean needs for his smoke test — so opening it _is_ the handoff, not a violation of "never ship."

**Draft vs. ready is a measurement, not a mood.** If the completeness gate passed with nothing unmet, let the PR open **ready for review** — `open-pr`'s default, so hand it nothing: every measurable claim passed, and the only work left is Sean's — the smoke test, the `human-verify` items, the merge call. If the run bounded out with unmet items or a blocked slice, hand `--draft` to `open-pr`: draft is the run's own admission that something is unfinished. This gives Sean a triage signal across open PRs — ready means "review and decide," draft means "needs attention; read the verify note first." `human-verify` items don't block ready — they're Sean's expected share of the work, not incompleteness.

The PR body is the report, kept to `open-pr`'s concise convention (summary + what changed), plus a short **verify** note carrying the two things Sean most needs:

- **What to check** — the deploy-preview smoke test, the spec's `human-verify` items, and anything the run _couldn't_ self-verify (e.g. DB-query wiring, `.astro` UX where the repo has no route/query tests by convention). Because the completeness gate already measured everything measurable, this list should be short — that's the point.
- **Findings deferred** — anything real you chose not to fix, and why; plus any done-signal items left unmet at the loop bound.

Keep the deeper detail (full audit history, per-round findings) in `docs/autopilot/{YYYY-MM-DD}-{slug}-report.md` and link it from the PR rather than pasting it all in — the PR stays skimmable.

Then stop. Never merge the PR and never deploy — Sean reviews the preview and ships.

## Guardrails, in one place

- Start from a freshly fetched base; work on a branch; commit at clean points; end by pushing + opening a PR (via `open-pr`) — ready-for-review when the completeness gate passed clean, draft when anything is unmet. Never merge or deploy.
- Orchestrator never edits code and never audits — but it always measures: every slice check and done-signal item gets _run_, never taken on self-report.
- Auditor is read-only (`task` without `--write`); developer and auditor are different models.
- Fresh developer per slice; never advance the queue past a red check.
- Audit-clean alone never ends the run — the completeness gate (Phase 5) must pass first.
- Bounded loop; stop-and-note on anything the spec can't resolve.

## Permissions — how to launch it unattended

Autopilot only walks away cleanly if nothing blocks on a human approval — and the Codex audit is just the first of several: the developer subagent's edits, the test run, and the git commits would all prompt too. Two ways to run it:

- **Unattended → bypass-in-a-sandbox.** Launch the session in bypass-permissions mode. That sounds reckless but it fits autopilot's design: it works on a branch, only ever opens a PR (never merges or deploys), and you review before it ships — so the blast radius is one branch you inspect. Lean on the guardrails as the safety net instead of approving command by command.
- **Attended → allowlist the audit command.** When you're around, a `permissions.allow` rule for the `codex-audit.mjs` wrapper stops the audit from nagging while everything else still prompts (the recommended entries live in your user settings). This works only because the audit is a single clean `node …` command — a compound `$(…)`/piped command can't be allowlisted at all.

Either way the read-only auditor guarantee holds: `task` without `--write` can't modify files regardless of permission mode.

## Related skills

- `preflight` — the interactive setup and spec that this consumes.
- `autopilot-iterate` — the follow-up loop after Sean reviews the PR; his review comments become the next control signal.
- `grill-me` / `paper-trail` — heavier alignment and session logging, upstream of preflight.
