---
name: render-readback
description: After EVERY render in an Agentic Brand Universe, read the image back and crop-zoom each of the in-frame entity's invariants, returning a per-invariant PASS or DEFECT verdict. Any DEFECT means regenerate the image FROM SCRATCH (never stack an edit pass). Use immediately after each generated image, before accepting or locking it. Generic and universe-parameterized: the invariants come from the entity's `structured.invariants`.
---

# Render Read-back

The quality gate that catches a defective render before it ships or locks. A render that looks fine at thumbnail can be wrong at the invariant level (a lens that should not be there, a missing patch, a wrong pendant). Read-back forces a per-invariant check.

## Procedure
1. **Load the entity's invariants.** From the render's own `<image>.recipe.json`, key `entityGate` (v0.46: one entry per bound entity, `{id, look, invariants}`), which is what that render was actually conditioned on; fall back to `canon/entities/<id>.json` `structured.invariants` for a render made before v0.46 or without `--entity`. If there are none, there is nothing to check and the render passes trivially.
2. **Read the image back.** Open the just-generated image. For EACH invariant, crop-zoom the relevant region (the face for a face rule, the chest for a patch rule, the feet for a shoe rule) and judge it directly against the invariant. Do not judge from the thumbnail or from memory of the prompt.

   Use the two scripts in `scripts/` rather than writing PIL by hand. Both take FRACTIONS of the image, so a box survives a re-render at another size:
   - `contact_sheet.py OUT.png --cols N IMG...` — the WIDE pass over a batch. For anything shown SMALL (an avatar, an icon, a thumbnail), add `--at-size 64,240 --background '#RRGGBB'` to see every image at exactly the size and on the ground the surface uses; detail that reads at 690 px turns to mud at 64.
   - `crop_zoom.py OUT.png IMG --box X0,Y0,X1,Y1 --label "what this must show"` (repeatable) — the NARROW pass, which is where most invariants actually live: a pendant that must be a four-point star and not a crucifix, two gold incisors, a patch on the correct side, a face-down phone.

   Pass `--grid 4x4` instead of `--box` when you do not already know where the detail sits. Guessing a box, getting back a rectangle of empty shadow, and guessing again costs two round trips; the grid costs one. (Earned on the-little-door, 2026-07-30, which guessed wrong twice in one run.)
2a. **The GUARD GATE, from the recipe (v0.47).** The recipe's `guardGate` lists one read-back
   assertion per standing prompt guard that fired on this render (`guards` names them:
   device-anatomy, readable-surface, travel-direction, vehicle-seat-facing, two-hander-staging,
   seated-at-table, no-ui-chrome). Evaluate EVERY one, PASS or DEFECT, the same way as an
   entity invariant, and crop-zoom to do it: for device-anatomy that means each device
   together with its user, asking which side the glowing display is on. A prompt guard is an
   instruction to the model and it loses some fraction of the time; this gate is what refuses
   when it lost. Earned 2026-09-12 on an appliedai.wiki hero: the guard fired, the prompt
   carried it verbatim, the render put the screen toward the camera with its user behind the
   lid, and the read-back passed it because no line told the reader to look. A recipe with
   `guards` but no `guardGate` was written before v0.47; apply the same table from
   `providers/gpt-image-2/prompt_guards.py` (`READBACK_GATE`) by hand.

   **RECORD THE VERDICT, because otherwise nothing knows you looked (v0.49).** v0.47 gave
   the reader the line and gave nobody a way to tell whether the line was read, so a
   skipped gate and a passed gate look identical from outside. That is the same shape of
   failure one level up: "evaluate every entry" is an instruction, and an instruction loses
   some fraction of the time. So `verify_render.py` now FAILS on any render whose recipe
   records a fired guard with no recorded verdict, and prints the assertion you are
   supposed to be looking at:

   ```bash
   python3 <abu>/skills/render-readback/scripts/verify_render.py OUT.png                       # refuses
   python3 <abu>/skills/render-readback/scripts/verify_render.py OUT.png --guard device-anatomy=pass
   python3 <abu>/skills/render-readback/scripts/verify_render.py OUT.png --guard no-ui-chrome=defect:"invented menu bar"
   ```

   A DEFECT is a failure, not a note: regenerate FROM SCRATCH. A waiver is the recorded
   exception (`--guard NAME=waived:"why"`) and a written reason is required, the same shape
   as a voice-gate waiver. Verdicts land in `<image>.readback.json`, a build artifact that
   never ships. One image at a time is enforced: a verdict is a statement about one
   picture, and letting one look cover a batch of four is the failure this gate exists to
   stop.
2b. **The standing EYELINE check, on every scene with a conversation in it (v0.38).** Beyond the
   entity invariants, any render whose scene has people talking with, laughing with, showing
   something to, or being introduced to someone gets one extra look: crop-zoom each
   participant's eyes and ask WHO THEY ARE LOOKING AT. Eyes on the interlocutor: PASS. Eyes on
   the camera or the middle distance while the scene says they are engaging someone: DEFECT,
   re-roll from scratch, naming the gaze in the re-roll ("her eyes are on HIS face, not the
   camera"). The one exception is a scene that explicitly hands the camera the interlocutor's
   role (a direct-address closing spread). Earned 2026-08-08 (the-introducer): three renders in
   one batch put the subject's eyes on the lens mid-conversation, because a warm grin toward
   camera is the model's strongest prior for a likeable subject; the operator's rule is "if the
   camera is not representing your interlocutor's eyes, why are you looking at it?" The prompt
   half of the same rule is `EYE_CONTACT_GUARD` in compose-spread.
3. **Verdict per invariant.** PASS (the invariant holds) or DEFECT (it does not), with a one-line reason on any DEFECT.
4. **Act on the result.** All PASS: the render is accepted. Any DEFECT: regenerate the image FROM SCRATCH with the defect named as an explicit negative. Never stack an edit pass on a defective render (it compounds artifacts).

## Not this skill
- Generating the image (that is the caller, e.g. `shoot-references` or a renderer).
- Locking the passed shot into canon (that is `shoot-references` / the renderer).

## Measuring a numeric invariant

Some invariants are NUMBERS: a character's head-to-body proportion, a mark's
height-to-width ratio, how coarse a screen is, how far a blue is off-target.
Cropping and zooming answers "does this look right"; it cannot answer "is this
1:8 or 1:6.5". `scripts/measure.py` does.

    measure.py figure   <image> --chin Y [--overlay out.png]
    measure.py periodic <image> --patch 0.08,0.18,0.42,0.42       # dot pitch / weave / grid
    measure.py patch    <image> --patch 0.08,0.18,0.42,0.42 --target '#8FAACC'

**`figure` measures a BODY; `periodic` and `patch` measure a MEDIUM (SPEC §3.5.1,
v0.40).** Reach for the second pair whenever a register's argument rests on a
number: a screen ruling, a weave count, a paper colour, an ink density. Those are
the properties that regress silently, because a look is reviewed by eye and a
pitch is invisible by eye at any size a person reviews at. proof-of-vibes asked a
halftone plate for a COARSE screen three rounds running and got a fine one every
time; nobody could tell, because "coarse" is not a number.

**`--patch` is REQUIRED for both, in FRACTIONS of the frame, and it is recorded.**
A pitch read over a cloud is not a pitch read over open sky, and a mean colour is
entirely a statement about which pixels were averaged. There is no default patch,
because a default would silently make two runs incomparable while looking like one
method. Use the SAME patch across a set or the numbers mean nothing.

**A dot-pitch or colour bound in a Style Pack's gate should name the exact
invocation**, not describe the property. `"run measure.py periodic <out> --patch
... and require dotsAcrossWidth between 190 and 310"` is checkable; "the screen is
fine" is a vibe.

**`periodic` refuses in three situations and each is informative**: a flat patch,
a patch at FULL INK COVERAGE (a halftone at solid has no dots left to measure), and
a peak ladder with no harmonic in it (usually a DAMAGED screen — plugged shadows,
broken dot). Move the patch and re-measure; never skip the check.

**It records HOW it measured, beside the image, as `<image>.measure.json`.** That
is the point, not a convenience. Three consecutive sessions hand-rolled this
ruler and reported 1:6.5 -> 1:7.6, then "both plates 1:7.2", then 1:7.04 ->
1:7.26 for overlapping plates, because none of them recorded their landmarks.
Nobody could tell whether a plate had improved or the method had changed. A bare
number is not a measurement.

**The chin is not auto-detected, deliberately.** A luminance-minimum detector
locks onto the shadow under the lower lip rather than the chin base and returns a
confident 1:8.8-1:9.2 on a figure that is really about 1:7.2. Pass `--chin Y`, or
render `--overlay` and read it off the ruler. The record says which you did, and
reports how much a 5px error would move the result.

**It refuses rather than guessing.** A predecessor scanner returned crown=0,
sole=1534 on a 1536px plate: the whole frame, silently, as if the figure filled
it. Every detector here validates its own output, and `star` refuses any result
above 3:1 because no rendering of a four-point mark with equal top and side arms
can be that narrow. If you get `UNMEASURABLE`, the crop is wrong; tighten it.
Do not hand-roll a ruler around a refusal.


## What NOT to measure: a mark's geometry

`measure star` existed for one afternoon and was WITHDRAWN the same day. It
answered "is this four-point mark the right shape" with a ratio, and it was wrong
five times out of five on real plates: it masked a warm backdrop and returned
0.93, locked onto a jacket button and returned 0.74 PASS, measured a chain
connected to the pendant at 6.11, returned 11.25 on a crop that isolated nothing,
and finally passed an obviously equilateral compass star that the operator
rejected on sight. That last one was disqualifying: the function assumed "top arm
equals side arm, by spec" and so never measured the top arm, which is precisely
what turns this mark from a cross into a compass star. It assumed away the defect
it existed to catch.

**Judge a mark by eye against its blessed plate. Then condition every render on
that plate.** That is not a workaround, it is the framework's thesis: a golden IS
human judgement, frozen. Reaching for a computed proxy replaces the one instrument
that actually works with one that produces false precision, and false precision is
worse than no number, because it survives review.

Gary, 2026-08-01, after four rerolls: *"I'm clearly going to need to just keep
rerolling with you until it's good, then you just use those goldens. Reminds me of
the importance of the human eye."*

`measure figure` remains, because head-to-body is a genuine ratio between two
unambiguous landmarks, and because it REFUSES rather than guessing when it cannot
find them. The distinction worth keeping: measure a quantity a human cannot
eyeball reliably, never a judgement a human makes instantly.

<!-- BEGIN GENERATED: report -->
## When this skill misfires, offer to report it

If this skill did not one-shot (a step failed, a check refused something it should not have, an instruction sent you the wrong way, you fixed its output by hand, or it left out an obvious step), the person running it is the only one who knows, and only right now. Offer once, in one line, to report it. On a yes, run it yourself and never show them the command:

    abu report "<what happened>" --expected "<what should have happened, and why>" --command "<the exact command or ask>" --skill abu:render-readback

Write every field from what you just watched: an issue that says what was expected and how to reproduce it gets fixed, and "it broke" does not. A `check-kit` refusal they believe is wrong is `abu check-kit ... --report`, which attaches the findings and the rule each one broke. It prints a pre-filled GitHub issue and sends nothing: hand them the link to read and submit. Inside Freedom, `freedom:suggest-an-improvement` files it for them. If you maintain ABU itself, fix it through `evolve-abu` instead.
<!-- END GENERATED: report -->
