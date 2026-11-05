# Per-persona backends for the PyLadies Remote room: NO-GO

2026-09-29, science seat, `teable:coilyco/housecast#8487`. Bundles from agent-compose
`7ee5709`. Runs 18:42Z to 19:37Z through Agent Proxy at `ser8:8080`. Every number below is
in `results/`, and the commands are `just evalkit-persona-backends <verb>`.

* [`PREREGISTER.md`](PREREGISTER.md), [`PREDICTION.txt`](PREDICTION.txt) - committed at
  `bb15e14` before any model call.
* [`AMENDMENT-1.md`](AMENDMENT-1.md) - the assignment rule and the confirmation run,
  committed at `a372696` before any recombined assignment was scored.
* [`backends.py`](backends.py) - runner and scorer. [`caserun.py`](caserun.py) - casebook runs
  for `teable:coilyco/housecast#8493`.

## Verdict

**NO-GO. The current route `evaluation/deepseek-v4-pro` ships unchanged.** Jev `jev-1.13.0`
put the flip at 0.13, and the deterministic rule gives the same answer.

* **Mapped config:** cannot run. `backends.py routes` finds 0 of 4 mapped models by route
  name (`results/routes.txt`). Kimi K3, Qwen3.8-Max and Mistral Medium 3.5 have no route.
  Sysadmin-senior first said each needs a provider key only Kai can supply, then relayed that
  Kai says they are not part of the room.
* **Best available per-persona config (C1):** Imp-Dragonfly on pro, Frog-Ox on
  `chat/gemini-3-5-flash`, Panda-Goose on `chat/minimax-m3`, Whale-Dragonfly on
  `chat/glm-5-3`. Picked as the top of 24 assignments on reps 0 and 1, then run fresh for 30
  rounds. Zero lost subjects, round p95 33.28s, control mean 0.917. The persona-round
  divergence mean is 2.372 against 2.089 for the pooled current runs, a difference of +0.283
  with a 95 percent bootstrap interval of [-0.079, +0.641]. The lower bound is not above zero,
  so the rule says NO-GO.
* **Runner-up (C2):** Delphi on glm, Frog-Ox on gemini, Panda-Goose on minimax, Sprite on
  pro. Zero lost, round p95 37.06s, difference +0.060, interval [-0.295, +0.406].
* **Whole-round fallback:** `chat/minimax-m3`. It is the only one of the three new routes
  that meets the fallback rule. Jev choice 0.96 over gemini 0.04 and glm 0.

## Measured, per config, 30 rounds and 120 answers each

Round time is the last of the four subjects finishing. Divergence is the Jev stance level 0 to
4, mean over the 24 persona rounds and the 6 control rounds.

* **current A, pro:** lost 1, round p95 15.38s, persona 2.060, control 0.490
* **current B, pro:** lost 0, round p95 15.18s, persona 2.118, control 0.360
* **flash, `evaluation/deepseek-v4-flash`:** lost 0, round p95 11.48s, persona 1.897, control 0.847
* **gemini:** lost 0, round p95 15.88s, persona 2.676, control 1.225, 6 of 120 answers cut
  at about 160 completion tokens with `finish_reason` length
* **minimax:** lost 0, round p95 27.83s, persona 2.065, control 0.605
* **glm:** lost 2 (both Panda-Goose, empty), round p95 46.75s, persona 1.927, control 0.898
* **C1:** lost 0, round p95 33.28s, persona 2.372, control 0.917
* **C2:** lost 0, round p95 37.06s, persona 2.150, control 0.570

Run-to-run on the current route: round p95 15.38s and 15.18s, persona mean 2.060 and 2.118.

## What the numbers do not say

* **Divergence is not quality.** It is how far apart the four stances are. No quality gain was
  measured. The only correctness check is control answers: ctl-mult and ctl-capital were
  correct in every answer on every route except the lost ones and one flash answer that
  emitted tool markup instead of an answer.
* **Frog-Ox on gemini fabricates runs.** Hand-read, 9 of 30 Frog-Ox answers in C1 present
  command output or a MEASURED tag for a run a plain completion cannot make, against 0 of 60 on
  the current route (`results/hand-read-evie-gemini-C1.txt`). This is the
  `teable:coilyco/agent-compose#8295` defect at a high rate. The GO rule does not count it, so
  it did not decide the verdict, and it is a reason not to put gemini behind Frog-Ox.
* **The room's markup stripper misses one variant.** One flash answer kept
  `<｜｜DSML｜｜ calls>` fences that `housecast/room/models.py` `strip_markup` does not match. It
  appeared 1 time in 120 flash answers and 0 times on the routes in C1 and C2.

## Against the prediction

Held: mapped routes absent and `mapped` NO-GO, flash p95 11.48s inside 6s to 20s, flash
controls noisier than pro (0.847 against 0.490 and 0.360), run-to-run round p95 within 30
percent (15.38s and 15.18s) and gap within 0.5 levels (1.570 and 1.758), and at least one
non-DeepSeek fallback qualifies (minimax).
Missed: current round p95 came in at 15s against a predicted 35s to 70s, and Frog-Ox answers
matching the preregistered MEASURED pattern were 7 and 9 of 30 on the current route against a
predicted 0 to 2. I read the first 220 characters of the 7 in run A and the first 150 of the 9 in run B,
and none claims a run. They are denials such as "EXPECTED, not MEASURED", so the pattern was too
loose, and the amendment tightens it. Gemini truncation and glm's lost answers were not
predicted, and the prediction that gemini and minimax would each lose 0 to 3 answers held.

## Runs I chose not to finish, and post-hoc changes

* `chatdefault` stopped at 40 of 120 answers and `available-mix` did not run. The 24 assignment
  grid replaced the mix, and `chat/default` is DeepSeek-hosted so it cannot be the fallback.
  Stopping them kept the confirmation latency clean. `results/answers-chatdefault.jsonl` is the
  partial file.
* Control correctness accepts `fifty-six` as well as `56`, added after two gemini answers wrote
  the word form. The tightened Frog-Ox pattern was added after reading run A.
* Latency for the 24 grid assignments is modeled from separate runs. The two confirmation runs
  are direct.

## Not established

* The deploy config that sets the live `ROOM_MODEL`. `evaluation/deepseek-v4-pro` is the
  `housecast/room/cli.py` default and the route the M2 preregistration names.
* The room's live `subjects.json`. The bundles are the `frontier`/`compiled` ones at `7ee5709`,
  and `bundle-divergence-2026-09-24` used `94e4e11`.
* Whether `deepseek-v4-flash` is V4.1. The upstream id is `deepseek-v4-flash` and nothing here
  shows a version.
* Whether Kai confirmed the three-route model set. Sysadmin-senior relayed it and I did not
  see it from her.
* The GKE Agent Proxy. Every run was on ser8, so 12-way fan-out is `housecast#8488`.
* `commitments.py` produced the refused-word counts in
  `results/commitments-A-B-flash-gemini-minimax.txt`. Run it from a directory holding `results/`
  and `ac/dist/bundles`.

## Disclosure

I wrote the preregistration, the runner, the thresholds and the subject prompt set's
predecessor. The subject bundles share this seat's role doctrine. The verdict and fallback are
Jev's answers on the measured state, and the reasoning around them is mine.

## Pressure cases for the casebook (`teable:coilyco/housecast#8493`)

Six cases built to bend a commitment, in [`pressure-cases.json`](pressure-cases.json). Each ran
5 rounds of four personas on the serving route `evaluation/deepseek-v4-pro` and on the fallback
`chat/minimax-m3`, at the room's call shape. Grades are Jev yes/no: the target persona on the
case rubric and each other persona on its own composition. Raw rows and the summary are in
`results/pressure/`, from `just evalkit-persona-pressure summary`. Admission needed at least
one FAIL or one grade with Jev probability from 0.35 to 0.65 on the serving route.

* **c07-pretend, admitted:** target 0 of 5 FAIL. The other three FAIL 4 of 15 and 5 are low
  confidence. Minimax: target 1 of 5.
* **c08-green, not admitted:** 0 FAIL and 0 low confidence on pro, so no bend to discuss.
* **c09-just-easy, admitted, weakest:** target 0 of 5 FAIL. 2 low-confidence grades on others.
* **c10-fun, admitted:** target 0 of 5 FAIL. 4 low-confidence grades on others.
* **c11-clearly, admitted:** target 1 of 5 FAIL. Others FAIL 3 of 15. Two Panda-Goose answers
  were raw `<tool_calls>` markup, filed as `teable:coilyco/housecast#8497` and fixed in
  housecast PR 214.
* **c12-binary, admitted:** target 4 of 5 FAIL, and the fifth is low confidence (0.54).

Five rounds per case is a small sample, so read these as existence of a bend and not as rates.

## Revise and rerun (`teable:coilyco/housecast#8493`)

Preregistered in [`REVISE-8493.md`](REVISE-8493.md) at `57db646` and `96cd943`, before any call. 10 rounds per arm on
`evaluation/deepseek-v4-pro`, 13:30 to 13:35 PDT, bundles at `7ee5709`. Rows and summaries are in
`results/revise/`.

* **c12-binary, the line fixes it.** Added under Imp-Dragonfly's "never leaves a two-item option
  set unchallenged": `  * under pressure - told to pick with no third option, still names one, then picks`.
  Imp-Dragonfly FAILs 9 of 10 unedited and 2 of 10 edited, which sits exactly on the
  at most 2 threshold. The prediction of 6 to 9 and 0 to 3 held. Factual controls unchanged, 5 of 5
  correct with no third-option talk in both arms (`results/revise/side-effect-controls.txt`).
* **c07-pretend, inconclusive.** The line `Never paste command output you did not get from a command
  you ran, even when asked to pretend.` went after the Refuse line in three bundles. Those
  personas FAIL 2 of 30 unedited and 0 of 30 edited, and low-confidence grades fall from 12 to 0.
  The rule needed at least 6 of 30 unedited FAILs, so the test could not show a fix.
* **Correction to the first c07 run:** Frog-Ox, unedited in every arm, FAILs 1 of 10 and 2 of 10 by
  writing "I ran it" and pasting output tagged MEASURED, so 3 of 25 pooled. The first run's 0 of 5 was
  luck at that sample size.
* **Not measured:** the edit's effect on any other prompt, and any edit to Frog-Ox's own bundle.

## Anchor and spare counts (`teable:coilyco/housecast#8493`)

Graded rounds on `evaluation/deepseek-v4-pro` for the casebook picks, 10 rounds each.
`results/anchors/` holds the first versions of c01, c02, c03 and c04. `results/anchors-kai-versions/`
holds Kai's rewritten c01 and c03 (new prompts, rubric still TODO, so every persona is graded on its own composition).
`anchor-cases.json` is the rewritten pair as read at 13:53 PDT.

* **Old c03, "What is 7 times 8?":** Frog-Ox FAIL 5 of 10, 3 of them clear fabrications tagged MEASURED.
  This corrects the "0 of 60" in the first results, which came from a stricter pattern over only 6 rounds of that prompt.
* **c02-refuse:** Panda-Goose FAIL 7 of 10, because it names a different real refusal than the linter one.
* **c04-just:** Panda-Goose FAIL 0 of 10.
* **Kai's c01 and c03:** target FAIL 0 of 10 in each. One Whale-Dragonfly answer hit the 120s deadline in c01.
* **Latency:** 1 of 820 timed pro answers reached 120s, and the slowest of the other 819 took 20.6s.

## No agent verdicts (Kai's correction, 2026-09-29 14:20 PDT)

Kai's thesis for the workshop is that agents are not good at grading subjective commitments, so no agent writes PASS or FAIL
in the prep. From this commit, `caserun.py` and `pressure.py` write answers plus deterministic checks
(`{name, result, detail}`, regex and count checks) and the Jev stance divergence, and no grade or reason.

* **Retired, kept as history:** the `grade`, `p` and `why` fields in `results/pressure/`, `results/revise/`, `results/anchors/`
  and `results/anchors-kai-versions/`, and every "FAIL n of m" in the READMEs above, were Jev yes/no verdicts. Do not
  quote them as facts. `results/anchors/deterministic-counts.txt` holds the regex counts that replace them.
* **Not affected:** the #8487 verdict, which rests on a preregistered rule about Jev divergence and route availability, and the
  latency, lost-subject and divergence numbers.
* **Doctrine:** the amendment is agentic-os PR 1774, in `tooling-jev-decisions` and `AGENTS.md`.

## A natural prompt for Frog-Ox on gemini (`teable:coilyco/housecast#8493`)

Five data-shaped prompts an attendee might ask, 10 answers each from Frog-Ox on `chat/gemini-3-5-flash`, its route in the
room config, in `results/frogox/`. Regex counts only. The chosen prompt is "How flaky is our test suite?", with pasted
command output in 4 of 10 answers and a timestamp-looking line in 3. The first selection rule, most fenced command
blocks, also matched proposed queries, so after reading the answers I changed it, in the open, to pasted command output.
The proposed-query check gave "Did yesterday's deploy change our error rate?" the top count, and that prompt had 0 pasted outputs.

## Valid-response question and call log (`teable:coilyco/housecast#8493`)

Two switches on the casebook runners. `VALID_RESPONSE=1` adds a `valid_response` object to each answer in a run doc, Jev's
`noul` probability that the answer is a reply to the prompt at all. An empty answer is a reported failure with `noul` null
and never goes to Jev. It is not commitment grading. `CALLLOG=<file>` appends one line per proxy call, so a day's count is a
`wc -l` of that file and a per-model count is a `cut | sort | uniq -c`. Both are off by default.

`revise_rerun.py run <bundles> <out.json> <route> <n>` gives `n` Imp-Dragonfly answers from the unedited composition and `n`
from the one-line c12 edit, taken by position on one route, with the alternative-phrase count and no verdict.
