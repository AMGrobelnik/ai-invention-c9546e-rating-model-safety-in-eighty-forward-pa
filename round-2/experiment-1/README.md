# How much push does refusal cost?

`demo/` — Self-contained demo (Colab-ready notebook or markdown). Run without setup.  
`src/` — Full source code, data, and outputs from the experiment execution.

**Type:** experiment  
**ID:** `art_r3PqOtpvcIsK`

## Layman Summary

Measures how hard you must push a language model's internals before it refuses a harmless question, then tests whether that number really tracks safety — and finds it mostly does not.

## Full Summary

POWERED, DE-CONFOUNDED RE-MEASUREMENT OF alpha_50 (the steering coefficient, in units of NORM_L, at which a fresh constant-alpha generation on a BENIGN prompt refuses half the time). 45,900 steered generations: 6 checkpoints (Qwen3-0.6B and Qwen3-1.7B x base/instruct/abliterated) x 5 axes x 20 frozen benign prompts x 5 seeds x a coarse(0-2.0/0.20)+dense(0.05) grid, 32 tokens, temperature 0.7, EOS banned, bf16. Iteration-1 steering code (models/direction/classify/ramp/stats/prompts.py) reused VERBATIM, sha256-verified byte-identical in reuse_manifest. LLM spend $0.021 of a $1.50 cap. tier_completed=4.

GATES ALL PASSED (results/tier0.json): iteration-1 replication a50=0.483 vs 0.475 (greedy, 5 prompts, verbatim config); NORM_L 21.14 vs 21.21; hook-fires / alpha=0-identity / determinism exact; an independent outcome-blind site scan re-selects layer 7 of 28 (score 0.778), the pre-registered site; estimator recovers a50=0.500 (bias 0.0004) with 90.8% bootstrap CI coverage at the REAL geometry; MDE@80% power = 0.05, below the 0.075 gap it had to resolve — so claim (b) was answerable before it was asked.

HEADLINE — THE METRIC LARGELY DOES NOT SURVIVE THE POWER.
(1) H1c LEXICALITY, the decisive control: a token-disjoint paraphrase axis with EQUAL held-out AUROC (1.0) and cos(A,B)=0.38 never reaches a 50% refusal rate on 6/6 checkpoints (max 0.07-0.30). alpha_50 is substantially a property of the canned-apology token direction, not of refusal in general.
(2) H1a REACHABILITY WITHDRAWN: iteration 1 called base unreachable (max 0.20, 5 greedy prompts); at full power BOTH base checkpoints cross 50% (0.64, 0.84). Base-vs-tuned is a margin in alpha, not a yes/no gate; the gate agrees with member class on only 0.67 of 6.
(3) H1b PRICE SPLITS BY SCALE: 0.6B delta=+0.1049 [+0.0680,+0.1440] SUPPORTED and estimator-robust (rising-branch refit +0.1027); 1.7B delta=-0.0698 [-0.1675,+0.0199] -> WITHDRAWN_SIGN_NOT_ESTIMATOR_ROBUST, because the rising-branch refit gives +0.0785 [+0.0459,+0.1060], the OPPOSITE sign.
(4) EXTERNAL VALIDITY (the benchmark alpha_50 claims to replace, run once here on xstest/plain_harmful-core80/jailbreak_suite): alpha_50 ranks checkpoints DIFFERENTLY from the benchmark. Judge-scored harmful-refusal orders instruct>base>abliterated at both scales (1.7B: 0.88/0.62/0.08), while alpha_50 orders instruct<abliterated<base. Spearman(alpha_50, judge harmful refusal) = -0.257 (p=0.62, n=6); a valid cheap metric needs a clearly negative correlation.
CLEAN NULLS: the norm-matched formal-vs-casual stylistic axis reaches 0.00 refusal on every checkpoint (cos to canned -0.05), and matched random directions 0.00-0.06. So the effect is NOT 'any axis at that site steers'.
BASELINE COMPARATOR replicated in-run: the harmful-vs-benign PROMPT axis reaches held-out AUROC 0.967-0.997 yet its steered refusal rate tops out at 0.01-0.52 (a50=1.82 where defined) — classification quality is not steering quality.

alpha_50 [95% CI] on the canned axis: base_0p6 0.844 [0.600,0.933] (non-parametric; the logistic extrapolated to 3.33 past a grid ending at 2.0, so a range guard forbids it), instruct_0p6 0.443 [0.398,0.483], abliterated_0p6 0.548 [0.500,0.605], base_1p7 0.579 [0.484,0.773], instruct_1p7 0.553 [0.493,0.644], abliterated_1p7 0.675 [0.615,0.736]. NORM_L 19.3/21.1/21.2 (0.6B) and 51.2/46.4/45.8 (1.7B); raw and axis-contrast-unit columns also shipped.

METHOD NOTES A PAPER CAN RELY ON: cluster bootstrap over PROMPTS (5000 resamples) via IRLS on aggregated counts; 2p/4p/non-parametric estimators with an explicit primary-selection rule; per-alpha Wilson intervals (the plan's [0.087,0.491] reference is the Clopper-Pearson exact interval, not Wilson — both reported); dose-response MONOTONICITY diagnostics, since several curves rise then fall as steering degrades the text; judge control = llama-3.3-70b with EVALUATOR_SYSTEM verbatim (12/12 on a probe, 432 items, kappa 0.00-0.72) cross-checked against gemini-3.6-flash; a padded-batch mismatch proven to be bf16 batch-shape numerics (max |logit delta| 0.31 vs logit scale 30.4, argmax agrees, and the ZERO-padding sequence differs equally) rather than a positional bug — the steered sweep never pads at all. 15 pre-registration deviations, each with when_decided, including the one decided AFTER seeing the curves. Audit cost 4.2 GPU-min per 0.6B and 6.7 per 1.7B checkpoint on one RTX 4000 Ada.

## Dependencies

- `art_CKWQh2cOQLLQ` — dataset
- `art_0UsKSgsMHome` — methodology

## Output Files

- `method.py`
- `full_method_out.json`
- `mini_method_out.json`
- `preview_method_out.json`

## Demo Files

- **method.py** — Research methodology implementation

---
*Generated by AI Inventor Pipeline*
