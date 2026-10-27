---
name: universe-doctor
description: Grade how COMPLETE and how HIGH-QUALITY an Agentic Brand Universe is, then work the punch-list. Runs a self-contained scorecard over the universe (identity, entity reference matrices, setting size-contracts, provenance coverage, craft-canon, stories, self-containment), returns a letter grade + per-dimension scores + a prioritized list of what to fix and which framework verb to reach for, and then tackles the top issues by dispatching those verbs. The rubric IS the framework's definition of "a done, good universe." Use when Gary says "grade this universe", "how complete is X", "universe checkup / health check / doctor", "what's left to do on this universe", "/universe-doctor", or when you want to know if a universe is ready to render/ship. Complements validate (schema pass/fail) and lint-universe (static warnings): this is the holistic completeness + quality report.
---

# Universe Doctor

A universe is never "done" by feel. This skill replaces the vibe with a **scorecard**: a
letter grade, a score per dimension, and a punch-list ordered by impact, each item naming the
exact framework verb that closes it. It answers two questions at once — *how good is this
universe, and what do I do next to make it better* — and the rubric it grades against is the
framework's working definition of success.

Where its neighbors stop short:
- **`abu validate`** answers *is the canon schema-valid?* (pass/fail gate).
- **`lint-universe`** answers *are there static best-practice warnings?* (advisory list).
- **`universe-doctor`** answers *is it complete and high-quality, and what's the next highest-leverage fix?* (a graded report you can act on).

<!-- BEGIN GENERATED: running-abu -->
## Running `abu`

`abu <verb>` below is the engine CLI. When `abu` is not on PATH (a plugin install puts none there), run the same verb through the plugin's own entrypoint, from the directory you are already in:

    ABU=${CLAUDE_PLUGIN_ROOT:-$(ls -d ~/.claude/plugins/cache/*/abu/*/ 2>/dev/null | sort -V | tail -1)}
    node "${ABU%/}/bin/abu.mjs" <verb> ...

With no `node`, the engine runs directly: `PYTHONPATH="${ABU%/}/engine" python3 -m agenticstory.cli <verb> ...`. Never `cd` into `engine/` to run it: a relative universe path then resolves inside the plugin.
<!-- END GENERATED: running-abu -->

## The rubric (what a complete, good universe is — weights sum to 100)

| Dimension | Max | What it measures |
|---|---|---|
| **Validity** | 15 | universe.json + every entity parses and carries id/kind. A broken universe caps the grade. |
| **Identity** | 15 | `register.name`, a resolving `register.anchor`, a `mark`, `voice` term rules, a resolving `stylePack`. The constants every render reads. |
| **Entity matrices** | 25 | For each renderable entity, the fraction of its reference matrix that is filled AND resolves on disk (character sheets; setting/visual-metaphor contract plates + descriptor prose). The heaviest weight: unlocked references are the thing the whole framework exists to prevent. |
| **Setting size (v0.9)** | 10 | Every setting/visual-metaphor has a `scalePlate` file + a `scale` descriptor, so its size is checkable (an empty plate cannot prove its own size). |
| **Provenance** | 10 | Every generated image under `reference/` has a sibling `.recipe.json`. Provenance is a property, not a memory. |
| **Craft-canon** | 10 | `canon/craft/*.json` exists: the universe's invariants (spines, genres, register-rules like a lookbook binding) are encoded, not tacit. |
| **Stories** | 10 | Stories are composed over the canon (stub scores partial, full scores complete). A canon with no story is scaffolding, not a universe in use. |
| **Self-contained** | 5 | `assetRoot` is `.` so every ref resolves inside the repo (SPEC §3a). |

Grade: A ≥90, B ≥80, C ≥70, D ≥60, F <60.

## Procedure

1. **Grade it.**
   ```bash
   python3 ~/.../skills/universe-doctor/scripts/grade.py <universe-dir>        # human report
   python3 ~/.../skills/universe-doctor/scripts/grade.py <universe-dir> --json # machine-readable
   ```
   The script is self-contained (reads the universe's files directly, no engine import, no
   generation, no cost). It prints the letter grade, the per-dimension bars, and the punch-list.

2. **Read the punch-list top-down.** It is already sorted by impact (points recoverable). Each
   line names the fix and the framework verb that delivers it (`add-story`, `shoot-references`,
   `add-setting`, `create-lookbook`, `on-brand-image`, …).

3. **Work the issues with the RIGHT verb — never hand-roll a fix.** For each item, invoke the
   named skill against this universe. Common closers:
   - matrix `X% filled` on a scaffolded entity → **`shoot-references`** (generate + read-back + lock its remaining slots).
   - a renderable entity that doesn't exist yet → **`add-character` / `add-setting` / `add-visual-metaphor` / `add-motif` / `add-prop`**, then `shoot-references`.
   - a setting that "cannot prove its size" → **`add-setting`** (fill `scalePlate` + `scale`).
   - "no stories" → **`add-story`**.
   - "no craft-canon" → **`create-lookbook`** (+ a register-rule) or author a spine/genre record.
   - images without a recipe → regenerate them through **`on-brand-image`** (the provider adapter writes provenance on every render).
   For a batch of framework-shaped fixes, dispatch the **`agenticstory-steward`** agent with the
   punch-list; it reaches for these verbs and flags anything the framework can't yet do.

4. **Re-grade after a work session** to confirm the score moved and nothing regressed. The grade
   is the definition of done: aim to raise it deliberately, not to "feel finished."

## Doctor Mode (the autonomous loop — "keep doctoring until I say stop")

The grade + punch-list is the brain; **Doctor Mode** is the persistence layer that runs it so the
operator never has to decide what to build next. Activated by "activate doctor mode", "keep
doctoring", "keep improving the universe until I say stop". It runs until told to stop
("stop doctor mode", "that's enough").

Each cycle:
1. **Grade** the universe (`grade.py`). Note the score.
2. **Pick the highest-impact item the loop can advance autonomously** (see the auto/propose split
   below). Skip taste-gated items unless the operator has already blessed them.
3. **Execute it with the right verb** — never hand-roll. Renders go to the background so the loop
   isn't blocked; provenance is written by the adapter.
4. **Read back + commit.** Honor the read-back gate; regenerate a defect from scratch, never lock a
   failing plate.
5. **Re-grade** and **send the operator ONE short text** (via `send-imsg` / `update-gary-on-imessage`):
   what improved and the new score (e.g. "🩺 locked the divine-yoke turnaround + 2 plates — universe
   B- → B, 82/100. next: glowing-jesus profiles."). Remote-control-friendly: they can veto or steer
   from their phone.
6. **Continue** to the next item. Stop only when the operator says so, or when every remaining item
   is taste-gated (then send a text listing the forks and wait).

**Auto vs propose (the load-bearing split):**
- **Advance autonomously** (infrastructure, no taste): setting/visual-metaphor plates (turnaround,
  empty plates, blueprint, **scale plate**) + descriptor prose; missing provenance sidecars; scaffolding
  a scale descriptor; wiring existing blessed art into an entity's contract; cleaning cruft.
- **Propose, don't auto-commit** (taste forks — text the operator candidates and proceed on their
  pick, or hold): selecting a character/hero **golden**; a story's **logline + spine**; a **register**
  or palette decision; anything that changes the universe's identity. Make a confident recommendation
  so a one-word reply unblocks it.

**Guardrails:** a render is not reproducible, so never delete an un-locked candidate before its winner
is locked. Never fake a sub-score by writing a path that doesn't resolve (the grader checks
resolution; faking just moves the lie downstream). Batch framework-shaped fixes to the
`agenticstory-steward` agent when several are queued. Keep the operator's texts to one or two lines —
the loop is the value, not the narration.

## Notes on reading a grade

- A **low grade is a report, not a failure** — a young universe SHOULD grade low; the punch-list is the plan. The script always exits 0.
- The heaviest weight is **entity matrices** on purpose: a universe whose references aren't locked will drift on every render, which is the exact failure the framework exists to kill.
- Do not "fix" a low sub-score by hand-editing a JSON to look complete (e.g. writing a plate path that doesn't resolve). The grader checks that files actually resolve; faking it just moves the lie downstream. Close the gap with the real verb.

## Self-reflection: grade the grader (every run)

**End every doctor run with one short reflection on the doctor itself** (Gary, 2026-08-02:
"universe doctor should also invite self reflection about how universe doctor can improve").
The rubric IS the framework's definition of "a done, good universe", so a blind spot here is a
blind spot everywhere. After reporting the grade, ask three questions and act on the answers:

1. **What did this run see that the rubric cannot score?** A defect you noticed by eye, a rule
   the universe holds that no dimension measures (seating/blocking contracts, nesting hygiene,
   register drift) — that is a MISSING SUB-SCORE. Add it to `scripts/grade.py` (with a test)
   or file it via `evolve-abu` if it needs schema support.
2. **What did the rubric over- or under-weight?** If the punch-list's top item was obviously
   less important than something ranked below it, the weights are wrong; propose the reweight.
3. **What did the operator ask about that the report didn't answer?** Their question is the
   next report section.

One paved improvement per run is a good pace; zero on a run that surfaced friction means this
section was skipped. Route mechanics through `evolve-abu`, and log what changed in the repo's
SAVE-LOG entry for the run. A grader that never learns converges on grading yesterday's
universes.

<!-- BEGIN GENERATED: report -->
## When this skill misfires, offer to report it

If this skill did not one-shot (a step failed, a check refused something it should not have, an instruction sent you the wrong way, you fixed its output by hand, or it left out an obvious step), the person running it is the only one who knows, and only right now. Offer once, in one line, to report it. On a yes, run it yourself and never show them the command:

    abu report "<what happened>" --expected "<what should have happened, and why>" --command "<the exact command or ask>" --skill abu:universe-doctor

Write every field from what you just watched: an issue that says what was expected and how to reproduce it gets fixed, and "it broke" does not. A `check-kit` refusal they believe is wrong is `abu check-kit ... --report`, which attaches the findings and the rule each one broke. It prints a pre-filled GitHub issue and sends nothing: hand them the link to read and submit. Inside Freedom, `freedom:suggest-an-improvement` files it for them. If you maintain ABU itself, fix it through `evolve-abu` instead. If `abu` is not on PATH, run it as `node "${ABU%/}/bin/abu.mjs" report ...`, with `ABU=${CLAUDE_PLUGIN_ROOT:-$(ls -d ~/.claude/plugins/cache/*/abu/*/ 2>/dev/null | sort -V | tail -1)}`.
<!-- END GENERATED: report -->
