# Pre-registration: Selection or Discovery?

Committed 31 Oct 2026, before any run of the `sd/` code that will be reported. The Kaggle smoke
tests (3 steps, 128 tokens) only check that the code runs. The 0.6B pilot on Kaggle is
exploratory and is reported as such.

## Question

When RL with a defective checker learns a hack, is the hack selected from answers the starting
model already writes, or discovered by climbing a slope in the reward? Can audits of the starting
model, made before training, tell which will happen?

## Audit numbers (measured on the starting model, before training)

- **Mass h**: share of starting-model answers the checker pays (reward > 0.5) and Math-Verify
  rejects.
- **Slope s**: mean rise in the checker's payout when each edit in `checkers.EDITS` is applied to a
  wrong starting-model answer. The edit library is frozen in this commit.
- **Novelty n**: per-token log-likelihood of a late hack answer (steps >= 75) under the starting
  model, as a percentile of the starting model's own answers.

## Outcomes

- **fp**: per step, share of completions the checker pays (> 0.5) while Math-Verify rejects them.
- **Exploitation**: mean fp over the last 20 steps minus mean fp over the first 10.
- **Exploited**: exploitation >= 0.10.
- **Onset**: first step where the 5-step mean fp exceeds 0.30. SimHack's definition (half of
  rollouts hack) is reported too.

## Hypotheses (confirmatory)

| # | Hypothesis | Pass threshold |
| --- | --- | --- |
| H1 | Hacks against cliff checkers are selection, hacks against judges are discovery | Novelty separates late hack answers of the two groups with AUROC >= 0.80 |
| H2 | Mass h predicts exploitation for cliff checkers | Spearman >= 0.60 between h and mean exploitation across seeds |
| H3 | h fails for judges, s works | Spearman for h < 0.30 and for s >= 0.60, over judge conditions |
| H4 | The combined audit beats existing audits on real environments | AUROC for "exploited" above the static flag and fuzzing by >= 0.10 |
| H5 | h is a risk level, not a verdict | Logistic slope of per-seed exploited on h > 0, 95% CI excludes 0 |

H6 (exploratory): at larger models, selection hacks shrink with h while discovery hacks persist.

Causal test (confirmatory, part of H3): `substring_tail50` alone (low h, no slope) is not
exploited, and `tail50_slope` (the same cliff plus partial credit) is exploited, in at least 2 of
3 seeds at each model size run.

## Design

- Task: MATH training problems, levels 1-3, integer answers of at least two digits. Held-out
  checks on MATH-500.
- Algorithm: TRL 1.17.1 GRPOTrainer, `loss_type="dr_grpo"`, `scale_rewards="none"`, beta 0,
  8 questions x 8 answers per step, temperature 1.0, LoRA rank 16 on all linear layers, learning
  rate 5e-6 constant, 512-token answers (1,024 at 4B).
- Conditions: `checkers.CONDITIONS`. Judges: Qwen3-1.7B at 0.6B/1.7B policies; a 7-8B judge is an
  added condition, not a replacement.
- Models: Qwen3-0.6B and Qwen3-1.7B, 3 seeds; Qwen3-4B, key conditions, 2-3 seeds.
- Steps: 120.

## Analysis

Bootstrap 95% intervals over conditions (10,000 resamples). All runs are reported, including
failed ones. A run that crashes is rerun once with the same seed; if it crashes again it is
reported as failed. No run is dropped after its result is seen.

## Amendment 1 (31 Oct 2026, before any main run)

Made after an independent review of the method and before any run that will be reported. The
0.6B Kaggle pilot launched earlier the same day used the original code and stays exploratory.

1. **Gold label.** Math-Verify on the last boxed answer, and the reply must give one distinct
   boxed answer (`checkers.strict`). Math-Verify on the whole reply falls back to the last
   expression, which marks a reply that ends by dumping the gold as correct and would hide the
   tail and substring hacks. The whole-reply version is logged as `strict_mv_any`, and
   Math-Verify exceptions are counted.
2. **Primary selection-vs-discovery measure: base reachability.** For each run's late hack
   answers (steps >= 75), the starting model draws K = 64 answers on the same problems. Reach is
   the share of those problems where at least one base answer is paid-but-wrong under the same
   checker. Selection predicts high reach, discovery low reach. Novelty becomes secondary, because
   per-token likelihood rewards repetitive spam and shifts with RL sharpening.
3. **H1 restated.** Reach is lower for conditions whose measured slope s is above the median than
   for those below it (one-sided permutation test over conditions, p < 0.05). Grouping is by
   measured s, not by checker family.
4. **Slope.** s is reported net of neutral edits (`checkers.NULL_EDITS`), in reward units and as the
   change in P(pay > 0.5). The edit library was fixed after seeing the earlier MLX pilot's judge
   hacks; this is disclosed, and s is therefore treated as descriptive, not confirmatory.
5. **Causal test.** Three conditions with 8 seeds each at 0.6B: `substring_tail50`, `tail50_slope`,
   and a density-matched control `tail50_density` (the same 0.2 credit paid on a fixed hash of the
   reply, at the base rate of "gold appears outside the last 50 characters", measured on the base
   samples before the main runs). Prediction: exploitation in `tail50_slope` is higher than in both
   others (one-sided permutation tests on continuous exploitation, p < 0.05 each).
6. **Outcomes.** Co-primary: reward-weighted fp (`fp_mass`, the reward paid to answers the gold
   rejects) alongside fp at 0.5. Exploitation is also reported normalised by headroom,
   (last - first) / (1 - first).
7. **Statistics.** H2 is tested with a mixed model (exploitation ~ h + (1 | condition)); H3, H4 and
   H5 become exploratory. The per-seed logistic in H5 is dropped as pseudo-replication; the
   seed-level starting fp (`h_seed`) is reported instead.
8. **Conditions.** `judge_noref_*` answers YES to almost everything in the self-test, so one
   `judge_noref_bin` seed is kept as a sanity row and excluded from all tests. `judge_ref_bin` is
   cut.
9. **Scaling ablation.** `substring_tail50`, `tail50_slope` and `judge_ref_prob` are rerun with
   group-standardised rewards (`--scale-rewards group`), 3 seeds each at 0.6B, because Dr. GRPO's
   unscaled advantages differ in size across reward types.
10. **Code.** Runs refuse to write into a directory that already has a log; the analysis lists
    every run, including failed and incomplete ones; samples are saved every 5 steps from step 50;
    one model per audit directory.

## Amendment 2 (31 Oct 2026, before any main run)

Made after the base audit and a judge calibration on the starting model's answers, before any run
that will be reported.

1. **Judge.** Qwen3-4B with the original prompt (v1) replaces Qwen3-1.7B. On 768 base answers the
   1.7B judge, shown the reference, paid 96% of boxed wrong answers (h = 0.21), so it cannot test
   discovery. Qwen3-4B v1 with the reference: h = 0.022, accepts 99.8% of correct answers, pays
   1.7% of boxed wrong answers. A stricter prompt (v2) was worse and is not used.
2. **Judge conditions.** `judge_ref_prob` and `judge_noref_prob` (Qwen3-4B; without the reference
   h = 0.035, accepts 80% of correct answers) are both confirmatory conditions. The earlier
   `judge_noref_bin` sanity row is dropped. The 0.6B Kaggle pilot's judge run used the 1.7B judge
   and is reported as an exploratory example of a judge that is fooled from the start.
3. **Density control.** `DENSITY_RATE` = 0.066, the base rate of "gold appears outside the last 50
   characters" over 2,048 Qwen3-0.6B answers.
4. **Slope.** An edit counts towards s only if the edited answer is still rejected by the gold, so
   payout gained by fixing an answer is not counted as slope.

## Amendment 3 (31 Oct 2026, 18:40 IST, before the calibration results are read)

The 0.6B pilot on the TRL pipeline (learning rate 5e-6) learned almost nothing in 120 steps:
true accuracy rose about 3 points in every condition, including the strict control. Its
effective update is roughly ten times smaller than the earlier MLX pilot's (MLX LoRA scale 20 vs
TRL alpha/r = 2, and Adam without bias correction). A learning-rate calibration is running on
`substring_all` at 2e-5, 5e-5 and 1e-4 (unscaled rewards) and 5e-5 (group-scaled), 80 steps.

**Selection rule, fixed now:** choose the largest learning rate whose run (a) does not collapse
(held-in true accuracy never falls more than 10 points below its first-10-step mean, and the
answers stay readable), and (b) raises true accuracy over the run. The paid-but-wrong rate (fp)
in these runs is **not** used to choose, and the calibration runs are not reported as results.
If group-scaled rewards are needed for (b) while unscaled are not, the main runs use group
scaling and the unscaled runs become the ablation; this swap is reported.

## Amendment 3b (31 Oct 2026, 19:05 IST, replaces Amendment 3's rule; calibration results not yet read)

An independent review showed Amendment 3's rule cannot work: per-step accuracy on 8 problems has
a standard deviation near 0.15, so "never more than 10 points below" fails on noise alone, and a
3-point gain over 120 steps is inside the noise. Calibrating on `substring_all` also ties the
choice to the outcome.

**New rule.** The learning rate is chosen on the **strict control only**: three runs at 2e-5, 5e-5
and 1e-4 (120 steps, unscaled rewards, seed 0), run first on Modal. The largest rate is chosen
whose run does not collapse, where collapse is any of: the 10-step rolling mean of true accuracy
falls more than 0.15 below its first-20-step mean; the share of answers with a box falls below
0.5; mean answer length exceeds twice its first-20-step mean. There is no "must improve" test.
The `substring_all` calibration runs on Kaggle are not used for the choice.

**Run set for the preprint (budget about $30, Qwen3-0.6B only):** `substring_all`,
`substring_tail50`, `tail50_slope`, `tail50_density` with 5 seeds each; `strict` with 2 seeds;
`judge_ref_prob` (Qwen3-4B judge) with 3 seeds; plus the base audit with the 4B judge and the
reachability step. Deviations from Amendment 1, disclosed: 5 seeds instead of 8 for the causal
conditions; the other mass-dial checkers, the 1.7B and 4B tiers, `judge_noref_prob` and the
scaling ablation move to follow-up work if the budget runs out; H6 becomes future work.

**Interpretation fixed in advance.** If no cliff condition is exploited at the chosen rate, that is
reported as the finding (selection needs amplification the chosen optimiser does not supply), and
the learning rate is not raised further to produce hacking. Truncated answers are logged
separately, because `substring_all` can pay a cut-off answer that contains the gold.

## Decision log: learning rate (1 Nov 2026, 00:30 IST)

Applied the Amendment 3b rule to the strict calibration (Qwen3-0.6B, 120 steps, seed 0). 1e-4: no
collapse (worst 10-step rolling accuracy drop -0.09, boxed share >= 0.76, length ratio 1.16;
entropy fell from 0.41 to 0.10). 2e-5: no collapse. 5e-5 failed to start (a port clash between two
GPU lanes on Kaggle, fixed afterwards) and is not needed, since the largest rate passed.
**Chosen rate: 1e-4.** The exploratory `substring_all` calibration was read only after this choice.

## Amendment 4 (1 Nov 2026, 02:00 IST, before any main run)

**Power check on the cross-condition tests.** Amendment 3b cut the run set to five conditions that
can produce hacks (`substring_all`, `substring_tail50`, `tail50_slope`, `tail50_density`,
`judge_ref_prob`). A permutation test that splits five conditions by median slope has at most 10
distinct splits, so its smallest possible one-sided p is 0.10. H1 as written in Amendment 1 cannot
reach p < 0.05 with this run set, and H2's mixed model has five groups. Therefore:

1. **Primary confirmatory test:** the causal triple of Amendment 1 item 5, unchanged: exploitation in
   `tail50_slope` is higher than in `substring_tail50` and higher than in `tail50_density`
   (one-sided permutation tests over 5 vs 5 seeds, 252 splits, p < 0.05 each, Holm-corrected).
2. **H1 and H2 become descriptive:** reach and exploitation are reported per condition with cluster
   bootstrap intervals, and are not tested.
3. **Rehearsal disclosed:** one exploratory seed (100) of each causal-triple condition runs on Kaggle
   before the main runs, to check the setup end to end. It is reported as a rehearsal and is not
   pooled with the main seeds.

## Amendment 5 (1 Nov 2026, 02:40 IST, before any main run)

**Gold label.** Reading traces from the exploratory `substring_all` run showed that half of the
answers counted as paid-but-wrong at steps 65-75 had the right final answer but no box (11 of 22 at
step 65). Under `substring_all` nothing rewards the box, so the model stops boxing, and the
box-required label of Amendment 1 counted that format drift as hacking. From now on every outcome
and audit uses `checkers.gold_label`: Math-Verify on the reply's stated final answer, which is its
boxed answer, or its last number when it boxes nothing; two different boxed answers count as wrong.
A reply that boxes a wrong answer and mentions the gold elsewhere still counts as wrong, so the
substring and tail hacks are still caught. The box-required label is logged as `fp_boxed` and
`acc_boxed`, and right-but-unboxed answers as `unboxed_correct`. The `strict` training condition
keeps its box-required reward (the one the learning rate was calibrated on). The base audit is rerun
with the new label on Modal (it was planned anyway with the 4B judge). On the existing 2,048 base
answers, the new label changes h only slightly (`substring_all` 0.095 to 0.086, `substring_tail50`
0.037 to 0.029).

**Budget rule, fixed before the timing runs.** Step 1 (two runs) measures the cost of one run, C.
If the 23 core runs plus the audit and reachability steps would cost more than the credit left, runs
are cut in this order until they fit: `strict` seed 1, `judge_ref_prob` seed 2, `substring_all`
seed 4, then `substring_all` seed 3. The causal triple keeps all 5 seeds; if it cannot, the study
stops and the budget is reported instead of running a smaller confirmatory test.

## Amendment 6 (1 Nov 2026, 03:00 IST, before any main run)

Decided with the PI after comparing the setup with the closest papers (SimHack: Qwen3-0.6B,
1,536-token answers, thinking off, up to 400 steps; Egashira: 2,048 tokens, 500 steps; Zhang:
640 tokens, 400 steps, 5 seeds, MBPP vs MBPP+).

1. **One model, done fully.** Qwen3-0.6B only; the 1.7B tier and H6 move to future work (budget).
2. **Answer length 1,536 tokens** (was 512, where 22% of starting answers were cut off). Thinking
   mode stays off, as in SimHack.
3. **A real checker flaw: MBPP.** Reward = the original MBPP tests (`code_env.mbpp_base`), referee =
   the original tests plus MBPP+ (`code_env.mbpp_plus`). Task 590 is excluded because its own
   reference solution fails MBPP+. 299 training tasks, 78 held out (fixed split, seed 20261101).
   Conditions: `mbpp_base` 3 seeds, `mbpp_plus` (honest control) 2 seeds. The audit reports h and
   reachability for code; the edit-slope library is for maths answers and is not applied to code.
4. **Seeds.** The causal triple keeps 5 seeds if the budget allows and never fewer than 4 (4 vs 4
   is the smallest design whose permutation test can pass Holm-corrected p < 0.05); `substring_all`
   and `judge_ref_prob` 3 seeds; `strict` 2.
5. **Steps.** One step count S for every run, fixed from the timing step before the core runs: the
   largest S in {120, 200, 300} for which the whole run list fits in $38 at the measured cost per
   step. The learning rate stays 1e-4; the timing step's `strict` run at the final settings is
   checked against the Amendment 3b collapse rule before the core runs start, and if it collapses
   the core runs do not start.
6. **One platform for reported runs.** Every reported run uses Modal L40S GPUs (bf16). Kaggle T4
   runs (fp16) are rehearsals and tests only and are not pooled with reported runs.
7. **Stop and resume.** Full checkpoints every 20 steps; a stopped run continues from its latest
   checkpoint with log lines and samples after it dropped first, so no step is counted twice. Any
   resumed run is listed as resumed.

## Amendment 7 (1 Nov 2026, 03:45 IST, before the Modal timing test and any main run)

**Measured cost.** On Kaggle T4, Qwen3-0.6B at 1,536 tokens takes 134 s per step (about 5% of
answers cut off, mean answer about 490 tokens); at 1,024 tokens 93 s (about 9% cut off). This is
slower than assumed in Amendment 6, so the budget rule is replaced.

**Timing test.** 20 steps of `strict` on Modal L40S and 20 on H100, with micro-batch 16 and
gradient checkpointing off (speed and memory only; the update is the same). The GPU with the lower
cost per step is used for every reported run. These timing runs are not reported.

**Run list and cut order.** Full list (28 runs): `tail50_slope`, `substring_tail50`,
`tail50_density` 5 seeds each; `substring_all` 3; `judge_ref_prob` 3; `strict` 2; `mbpp_base` 3;
`mbpp_plus` 2. With C the measured cost of a 120-step run and $33.5 for runs:
1. If the full list fits at 120 steps, the step count is the largest of 120, 200, 300 that fits.
2. Otherwise steps stay at 120 and runs are cut in this order until the list fits: `strict` s1,
   `judge_ref_prob` s2, `mbpp_plus` s1, `substring_all` s2, `judge_ref_prob` s1, `mbpp_base` s2,
   then seed 4 of each causal-triple condition. The floor (18 runs) is the triple with 4 seeds
   each, plus one seed of `strict`, `substring_all`, `judge_ref_prob`, `mbpp_plus` and two of
   `mbpp_base`.
3. If the floor does not fit, answers are capped at 1,024 tokens instead of 1,536 and steps 1-2 are
   repeated. If it still does not fit, nothing is launched and the PI decides.
The chosen GPU, step count, token cap and run list are recorded here with a timestamp before the
main runs launch, and are not changed afterwards.

## Amendment 8 (1 Nov 2026, 06:30 IST): the locked main run set, before any main run

Timing on Modal (20 steps of `strict` at 1,536 tokens, micro-batch 8 with gradient checkpointing;
micro-batch 16 without checkpointing ran out of memory on both GPUs): L40S 23.5 s per step
(about $0.0127 per step), H100 11.9 s per step (about $0.0131). The L40S has the lower cost per
step and is used for every reported run. The kill-and-resume check passed (killed after
checkpoint 9, resumed, steps 1-40 each logged once). All 378 MBPP+ reference solutions pass on the
Modal image, so `EXCLUDE` stays {590} as fixed in Amendment 6.

Applying Amendment 7 with the measured cost (full list at 120 steps: about $48; at 200: about $78):
steps stay at **120**, answers at **1,536 tokens**, and the run list is cut to the floor in the
written order. **Locked run set (19 runs):** `tail50_slope`, `substring_tail50`, `tail50_density`
seeds 0-3; `substring_all` seeds 0-1; `strict` seed 0; `judge_ref_prob` seed 0; `mbpp_base` seeds
0-1; `mbpp_plus` seed 0 (`sd/plans/main_runs.txt`). Base audits (`main_audit.txt`) and
reachability (`main_post.txt`) as planned. The primary test is the causal triple, 4 vs 4 seeds.
Nothing in this set changes after launch.

**Amendment 8a (1 Nov 2026, 06:40 IST, before launch):** at the PI's request the set is 20 runs:
`mbpp_base` seed 2 is restored (the last cut before the triple's seed 4, and the cheapest run,
about $0.74). Estimated cost of the run set: about $33.3. Nothing else changes.

**Budget note (1 Nov 2026, 07:02 IST):** the PI set a hard cap of $43 total Modal spend for November. Measured speed in the main runs is about 25 s per step; projected total about $42.

## Amendment 9 (1 Nov 2026, 08:55 IST): a grader fix found after the main runs, disclosed

**This amendment was made after the main runs had finished and their first numbers had been read.**
Reading the late paid-but-wrong answers showed that many were right answers written in a format
`checkers.gold_label` could not read: nested boxes and bold (`\boxed{\boxed{\mathbf{110}}}`), and
a second box holding only words (`\boxed{973} \boxed{\text{as an integer}}`). In `tail50_slope`
seed 1, 214 of 307 such answers were right; in `substring_all` seed 1, 330 of 512; in the judge
run, 86 of 208. The label is fixed: formatting around a box is removed and boxes with no digit are
ignored; two different numeric boxes still count as wrong, and a wrong boxed answer next to the
gold elsewhere still counts as wrong.

Consequences, fixed now:
1. Both labels are reported for every run. The fixed label is primary, because the box-required
   label demonstrably scores right answers as wrong.
2. The per-step log used the old label, so exploitation is recomputed from the saved samples:
   paid-but-wrong rate over the samples at steps 105-120 minus that over steps 1 and 10 (the saved
   steps closest to the pre-registered last-20 and first-10 windows). The old-label value from the
   full log is reported beside it.
3. Reachability is recomputed with the fixed label (the referee is re-applied to saved answers).
   The MBPP referee is unchanged, so its reachability stands.
4. The primary test is run on the fixed-label exploitation. Under the old label the triple's mean
   was driven by one seed whose "hacks" were mostly right answers; this is reported as a cautionary
   result about graders.

**Amendment 9, final form (1 Nov 2026, 09:10 IST).** A hand check of the remaining flagged
answers after the first fix found more right answers in other formats (`\boxed{60 \text{ square
units}}`, `\boxed{y = 28}`, `\boxed{\boxed{\frac{50}{5}} = \boxed{10}}`, an earlier `\boxed{a_8}`
before a final `\boxed{21}`). The "two different boxes are wrong" rule is dropped. The label now
grades the value of the **last box that holds a number** (formatting, words and a leading "y ="
removed), or the last number when nothing is boxed, with Math-Verify, as in Open-R1's last-boxed
extraction; 18 test cases are in the commit. A wrong final box beside the gold elsewhere, and a
rambling reply cut off without a final answer, still count as wrong. All three labels (box-required,
first fix, final) are reported. Share of old-label "hacks" that are right under the final label:
judge 190 of 208, `tail50_slope` s1 294 of 307, `substring_all` s1 396 of 512, `substring_all` s0
26 of 320. Reachability is rerun with the final label on 124 maths problems.
