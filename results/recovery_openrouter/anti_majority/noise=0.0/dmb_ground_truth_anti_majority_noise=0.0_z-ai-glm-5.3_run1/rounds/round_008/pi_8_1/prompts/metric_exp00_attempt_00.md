# metric_exp00_attempt_00

## System Prompt

You are a psychology researcher proposing a metric in the Decision Making (Binary Features) domain.

Your goal is adversarial: propose a metric that DISCRIMINATES the two theories — i.e., its value, computed on data simulated under your advocated theory, should be as far as possible from its value computed on data simulated under the competing theory. The direction of the gap does not matter; what matters is that the two theories produce visibly different numbers on this metric. The metric is computed on the data collected from the experimental design provided in the prompt. Produce a metric where you're prediction will be much more accurate than the competing theory's prediction on human data.

Your metric is a Python function

    metric(data: pd.DataFrame) -> float

Available imports inside `metric`:
- numpy as np
- pandas as pd

The system evaluates your metric in two ways and reports the pair as `point_estimate (var=between_subject_variance)` everywhere downstream:
- `point_estimate` is `metric(data)` applied to the FULL pooled DataFrame (all subjects together) — the canonical scalar;
- `between_subject_variance` is the population variance (`ddof=0`) of `metric(subj_df)` re-applied per `subject_id`, summarising how stable the metric is across subjects. If your metric only makes sense on multi-subject data this will fall back to `n/a` and the metric is rejected (the acceptance test below cannot run without it). Prefer metrics that work both on the pooled DataFrame and on a single subject's slice.

Acceptance rule: the system simulates each theory and runs Welch's two-sample t-test on `(point_estimate_self, between_subject_variance_self, N)` vs. `(point_estimate_adv, between_subject_variance_adv, N)`, where N is the number of HUMAN subjects the experiment will actually be run with (a fixed small number, currently 25). Your metric is admitted iff the two-sided p-value is below the significance level (currently alpha=0.01). Implication: a large between-theory gap is NOT enough — if either theory's metric is also highly variable across subjects, N humans won't reliably distinguish them and the metric will be rejected. Aim for contrasts that are both large in mean AND tight per subject.

Do NOT propose metrics that are trivially true for your theory.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

Each subject completes ~96 trials in a single block, with order randomized independently per subject. On every trial the subject sees two options A and B, each described by `n_features` binary expert ratings (each 0 or 1). The per-feature validities and n_features are fixed per experiment (design-time choices). Validities are communicated to the subject in the instructions. Both `n_features` and `validities` are exposed to your `predict` via the `parameters` dict. The subject chooses A or B; no correctness feedback is provided after the choice.

## CHOSEN EXPERIMENTAL DESIGN
**Validities (n_features=25):** [0.9, 0.9, 0.9, 0.9, 0.9, 0.9, 0.75, 0.75, 0.75, 0.75, 0.75, 0.75, 0.65, 0.65, 0.65, 0.5, 0.5, 0.5, 0.5, 0.5, 0.5, 0.5, 0.5, 0.5, 0.5]

**Trial pairs (n=24):**
  trial 1: A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0]
  trial 2: A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0]
  trial 3: A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0]
  trial 4: A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0]
  trial 5: A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0]
  trial 6: A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0]
  trial 7: A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0]
  trial 8: A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1]
  trial 9: A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  trial 10: A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0]
  trial 11: A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  trial 12: A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0]
  trial 13: A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  trial 14: A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0]
  trial 15: A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0]
  trial 16: A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0]
  trial 17: A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  trial 18: A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  trial 19: A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  trial 20: A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  trial 21: A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0]
  trial 22: A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0]
  trial 23: A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1]
  trial 24: A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]

**Rationale:** NOVEL AXIS (vs. Exps 0-16): THE SUB-PERFECT VALIDITY CONTOUR. Exp 16, the only prior GDRD-B vs HT-GDRD design, ran every trust-mode assay on PERFECT experts (v=1.0), where the capped logit (3.0) gives the trust mode a huge, ceiling-pinned asset margin. This design contains NO v=1.0 expert anywhere. It sweeps validity across the UNCAPPED logit regime (v = 0.55-0.90) at MATCHED endorsement counts, where the count route sits at exactly 0.5, the c0 terms cancel exactly, and the per-endorsement decision variable is the pure validity trade-off d(v) = c1*(0.5^kappa - v^kappa) + alpha*logit(v). STRUCTURAL KEY: for every GDRD-B subject (alpha <= 0.05) d(v) < 0 at every v > 0.5 (worst corner: alpha*logit(0.90) = 0.110 vs distrust gap c1*(0.9^1.6 - 0.5^1.6) = 0.516), so validity is ALWAYS a liability and every subject's p(v-side) is STRICTLY DECREASING in v. For HT-GDRD's trust mode (alpha in [0.5, 0.68]) d(v) > 0 at every v >= 0.55 (worst corner: alpha*logit(0.55) = 0.100 vs gap 1.35*(0.55^2.1 - 0.5^2.1) = 0.070), so validity is ALWAYS an asset and p(v-side) is STRICTLY INCREASING. The validity contour at matched counts is therefore a pure opposite-signed-slope assay. Validities (25 experts): 0.90 x6, 0.75 x6, 0.65 x3, 0.55 x3, 0.50 x7. 12 base pairs, each exactly A/B-mirrored (24 unique pairs, K = 96//24 = 4, 96 trials, 8 samples per base cell per subject), perfectly side-balanced. Mid parameters: GDRD-B skeptic (c0=.095, c1=1.175, kappa=1.85, beta=1.85, w=.90, eps=.19), counter (w=.49, eps=.17); HT skeptic (beta=2.4, w=.89, eps=.21), counter (w=.58, eps=.18), trust (alpha=.59, w=.50, eps=.30); box ranges verified at box corners. FAMILY V -- VALIDITY CONTOUR AT k=3 (pairs 1-4): A = 3 endorsements at v = 0.55/0.65/0.75/0.90 vs B = 3 coins. GDRD-B population: 0.446, 0.335, 0.248, 0.181 -- monotone descending; HT population: 0.452, 0.342, 0.259, 0.206 -- also descending pooled (the 6% trust mode only attenuates), so the pooled curves are similar by construction; the dissociation is PER-SUBJECT. The trust mode's contour RISES 0.53 -> 0.59 -> 0.64 -> 0.67 while every GDRD-B subject's contour FALLS 0.44 -> 0.33 -> 0.23 -> 0.16 (skeptics) / 0.47 -> 0.40 -> 0.35 -> 0.31 (counters). BOX-DISJOINT THRESHOLD CELLS: pair 4 (3x0.90 vs 3 coins): GDRD-B ceiling for ANY subject at ANY corner = 0.40 (counter w=.42, beta=1.3, c1=1.0, kappa=1.6, alpha=.05, eps=.22) vs trust-mode FLOOR = 0.63 (alpha=.5, c1=1.35, kappa=2.1, beta=1.8, w=.56, eps=.34) -- DISJOINT BY 23 POINTS in a novel arithmetic regime (uncapped logit 2.20 vs distrust gap 0.52-0.77 per endorsement). Pair 3 (v=0.75) is the threshold rung: 0.43 vs 0.53. SIGNATURE 1 (slope): any subject with a non-negative validity slope (pair-4 rate >= pair-1 rate) or a v-side rate >= 0.55 on pair 4 is outside GDRD-B's entire box; ZERO such subjects in N >= 60 rejects HT's trust mode (P = 0.94^60 = 2.4%). FAMILY K -- k-DOSE LADDERS (pairs 3, 6, 7 at v=0.75; pairs 4, 5, 10 at v=0.90): endorsement count k = 1, 2, 3, 6 at fixed validity, matched counts throughout, so the count route stays pinned at 0.5 and the dose amplifies route 1 LINEARLY in k for every mode. Trust mode RISES in k (0.58 -> 0.60 -> 0.64 -> 0.67 at v=0.90); every GDRD-B mode FALLS (0.33 -> 0.31 -> 0.16 -> 0.15 skeptics) -- opposite-signed k-slopes, parameter-independent (both routes' decision variables are linear in k with fixed sign). The k=6 rungs are box-disjoint: pair 7 (6x0.75 vs 6 coins): GDRD-B ceiling 0.39 vs trust floor 0.61; pair 10 (6x0.90 vs 6 coins, the parity cell): GDRD-B ceiling 0.40 vs trust floor 0.63. FAMILY C -- SATURATION ANCHORS WITHOUT PERFECT EXPERTS: pair 8 (conflict: 6x0.90 vs 7 coins; skeptic route saturated toward the coin side at every corner, |D| >= 2.7, count route votes the 6-endorsement side): trust mode 0.77-0.85 (trust AND count both favor the 0.90 side -- this cell proves the trust mode is not a v=1.0 artifact, since alpha*logit(0.90)*6 = 6.6-9.0 exceeds the distrust gap 4.2-5.0 at every trust corner) vs GDRD-B ceiling 0.56 -- DISJOINT BY 21 POINTS. Pairs 9/11 (asymptote: 1-2 coins vs 6x0.90; both routes saturate toward the coin side for every GDRD-B subject): GDRD-B subjects ALL in [0.885, 0.94] (pure lapse readout, 1 - eps/2); the HT trust mode sits at 0.47-0.75 (its route 1 flips toward the 0.90 side: 6*alpha*2.197 = 6.6-9.0 vs distrust 5.0-6.9) -- any subject with an asymptote rate < 0.85 (16 trials) is outside GDRD-B's box. POOLED DOUBLE DISSOCIATION: HT runs 2.5-4.5 points ABOVE GDRD-B on the high-validity cells (V4 0.206 vs 0.181; K1 0.202 vs 0.167; C1 0.258 vs 0.209; C3 0.197 vs 0.154) and 2.5 points BELOW on the asymptote cells (0.881 vs 0.906) -- an interaction no reparameterization of either theory can mimic, since the trust mode pushes in opposite directions on the two families. FAMILY B -- BETA PSYCHOMETRIC (pairs 1-3, low-v rungs with |D| in [0.17, 1.0]): fitting each non-trust subject's contour (amplitude (1-eps)w jointly with slope) over the low-v rungs estimates the analytic sigmoid's beta: GDRD-B (beta in [1.3, 2.4]) predicts ~45% of subjects with implied beta < 1.8 and 0% above 2.4; HT (beta in [1.8, 3.0]) predicts 0% below 1.8 and ~50% above 2.4 -- disjoint beta distributions outside the overlap [1.8, 2.4]. This is the GDRD-B-favored direction: the existence of shallow-contour subjects is impossible under HT. Pair 12 (exchange: 1x0.90 vs 2 coins) is a mode-classification cell (skeptic ~0.49, counter ~0.65, trust ~0.79 at mid; boxes overlap by design -- secondary). UNFAKEABILITY IN BOTH DIRECTIONS: (i) no GDRD-B parameterization can produce ANY subject with a rising validity contour, a v-side rate >= 0.55 on pair 4, a k=6 v-side rate >= 0.45, a conflict rate >= 0.60, or an asymptote rate < 0.85 -- alpha <= 0.05 cannot flip the sign of a per-endorsement gap >= 0.29 at any v >= 0.65, and the trust-mode envelope is disjoint by 21-23 points on pairs 4, 7, 8, 10; (ii) no HT parameterization can produce a subject with implied beta < 1.8 (beta >= 1.8 for every mode), and the HT corner that best mimics GDRD-B's pooled high-v means (minimal trust-mode contribution is impossible -- the mode is 6% of the population by construction) still predicts the asymptote deficit and the 6% validity-asset cluster; (iii) the parameters trade off oppositely: the GDRD-B corner that climbs highest on pair 4 (counter w=.42, beta=1.3) simultaneously sits lowest on the beta distribution and on the asymptote; the HT trust corner that sinks lowest on the asymptote (alpha=.68) simultaneously climbs highest on the validity contour. POWER: the trust-mode tail assay needs N >= 60 (6% mode; P(zero) = 2.4%); the pooled double dissociation needs only ~20-30 subjects (2.5-4.5-point gaps at 4+ SE); per-subject readouts rest on a 56-trial high-validity index (pairs 3,4,5,6,7,8,10), 16 asymptote trials, and 8 trials per base cell (thresholds set >= 2 SE from box edges: high-v index >= 0.57, asymptote < 0.85, pair-4 rate >= 0.55). PREDICTED OUTCOMES: a GDRD-B population shows descending validity contours for ALL subjects (none with pair-4 rate >= 0.55 or non-negative slope), all asymptote rates in [0.885, 0.94], all conflict rates <= 0.56, ~45% of subjects with implied beta < 1.8 and none above 2.4, and no validity-asset cluster. An HT-GDRD population shows the same shared-core majority PLUS a distinct ~6% cluster with RISING validity contours (0.53-0.67), k=6 v-side rates 0.61-0.75, conflict rates 0.77-0.85, asymptote rates 0.47-0.75, and exchange rates ~0.79; a beta distribution with no subject below 1.8 and ~50% above 2.4; and the pooled double dissociation (above on high-v cells, below on asymptote). All 24 pairs are non-degenerate (every pair has discriminating endorsements, both options carry >= 1 endorsement and >= 1 non-endorsement, no all-tie pairs, no pair where both theories guess -- the closest cells, pairs 3 and 5, are exactly the threshold/dose rungs where the trust envelope separates), and every trial requires actually comparing the two rating vectors. Both theories are history-free (validities in the instructions), so K = 4 repetition is harmless.

**Computed schedule:** 24 unique pairs × 4 reps = 96 trials per subject.



## ADVOCATED THEORY
**Description:** Graded Dual-Route Distrust with a Bimodal Strategy Population (GDRD-B). Subjects evaluate expert endorsements through two concurrent routes. ROUTE 1 (analytic distrust): every endorsement is a liability whose magnitude grows monotonically in the endorser's RAW claimed validity, d_j = c0 + c1*v_j^kappa; accumulated suspicion P(X) = sum_j x_j*d_j is compared across options through sigmoid(beta*(P(B)-P(A))), plus a small residual micro-trust edge alpha*sum_j clip(logit(v_j),0,3)*(a_j-b_j) (capped so perfect experts exert bounded, not unbounded, trust pull). ROUTE 2 (graded counting): a continuous preference for the fewer-endorsement option, sigmoid(gamma*(cnt_B-cnt_A)). The population is BIMODAL in the route weight w: a large majority (~88%) of 'skeptics' (w in [0.85, 0.95], moderate lapse) coexists with a minority (~12%) of 'counters' (w in [0.50, 0.62], low lapse, decisive count slope gamma >= 2). The mixture is implemented as a quantile transform of a single uniform per-subject population variable u_pop, which holds the population-MEAN route weight at its base value while exploding the between-subject behavioral variance — the empirically observed 3-12x super-binomial variance on the saturation assays (Exps 11, 12) that no uniform range-widening could reproduce.

**Parameters:**
- c0: [0.06, 0.13]
- c1: [1.00, 1.35]
- kappa: [1.6, 2.1]
- beta: [1.3, 2.4]
- alpha: [0.0, 0.05]
- u_pop: [0, 1]
- w_spread: [-0.02, 0.02]
- validities: validities

**`predict source code`:**
```python
def predict(parameters, state, history):
    # Graded Dual-Route Distrust with a Bimodal Strategy Population
    # (GDRD-B) -- neutrality-coupled skeptic-mode variant, final tuning
    # pass per the validated iter-4 critique: skeptic epsilon lowered
    # to [0.15, 0.23] (decompresses the Exp-3 contrast, raises the
    # Exp-13 ceiling prevalence toward 0.28) with the neutrality
    # pairing re-solved over the new range, and the counter w range
    # restored to the iter-2-validated [0.42, 0.56] (pulls Exp 6 back
    # toward 0.21). Everything else is unchanged.
    #
    # Stimulus: array-like of shape (2, n_features), row 0 = option A,
    # row 1 = option B; entries are binary expert ratings.
    #
    # ROUTE 1 (analytic distrust, weight w): every endorsement is a
    # LIABILITY whose magnitude grows with the endorser's RAW claimed
    # validity:
    #   d_j = c0 + c1 * v_j^kappa          (kappa >= 1, no dampening
    #                                        near v = 0.5)
    #   accumulated suspicion: P(X) = sum_j x_j * d_j
    #   D = (P(B) - P(A)) + alpha * sum_j clip(logit(v_j), 0, 3)*(a_j - b_j)
    #     (micro-trust term; the logit is CAPPED at 3 so perfect
    #      experts exert bounded, not unbounded, trust pull)
    #   P_skeptic(A) = sigmoid(beta * D)
    # ROUTE 2 (graded counting, weight 1-w): a CONTINUOUS preference
    #   for the option with fewer total endorsements:
    #   P_count(A) = sigmoid(gamma * (cnt_B - cnt_A))
    #
    # BIMODAL POPULATION: a single uniform population quantile u_pop
    # in [0, 1] maps onto a two-component mixture:
    #   u_pop < 0.13  -> 'counter' minority:  w in [0.42, 0.56],
    #                    epsilon in [0.12, 0.22], gamma in [2.0, 3.5]
    #   otherwise     -> 'skeptic' majority:   epsilon in [0.15, 0.23],
    #                    w COUPLED to epsilon along the neutrality curve
    #                        w = 1 - (0.25 - eps)/(1 - eps)
    #                    (clipped to [0.85, 0.95]) plus a tiny independent
    #                    per-subject spread w_spread in [-0.02, 0.02],
    #                    gamma in [1.5, 3.5].
    #
    # NEUTRALITY COUPLING: a skeptic's Exp-14 excess-dispersion
    # contribution is v = (x-0.21)^2 - (r-0.96)^2 with
    # x = (1-eps)(1-w) + eps/2 and r = 1 - eps/2. Setting x - 0.21 =
    # (r - 0.96) gives exactly (1-eps)(1-w) = 0.25 - eps, i.e.
    # w = 1 - (0.25 - eps)/(1 - eps). Tying w to eps along this curve
    # makes every skeptic's v approximately ZERO at ANY lapse level.
    # Re-solving over the new eps range [0.15, 0.23]: eps = 0.15 ->
    # w ~ 0.88, eps = 0.23 -> w ~ 0.97 (clipped at 0.95 -- the clip
    # only makes skeptic v slightly positive, the safe direction for
    # Exp 14). A key structural property: along the curve the
    # saturated-conflict compliance (1-eps)*w + eps/2 = 0.75 + eps/2
    # is approximately eps-invariant (~0.83-0.87 over the whole
    # range), so the excellent Exp 11/12 means are protected while
    # the epsilon reduction decompresses the lapse-sensitive assays
    # (Exp 3) and raises the Exp-13 ceiling prevalence.
    #
    # History is ignored: validities are communicated in the
    # instructions, so the distrust weights are fixed for the whole
    # block. beta is sampled per subject from [1.3, 2.4] (the range
    # validated by the iter-3 beta revert, which repaired Exps 3/10).
    if isinstance(state, dict):
        a_vec = np.asarray(state["option_a_ratings"], dtype=float).ravel()
        b_vec = np.asarray(state["option_b_ratings"], dtype=float).ravel()
        stim = np.vstack([a_vec, b_vec])
    else:
        stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"GDRD expects a (2, n_features) stimulus; got shape {stim.shape}."
        )
    a, b = stim[0], stim[1]
    n_features = stim.shape[1]

    v = np.asarray(parameters["validities"], dtype=float)
    if v.shape[0] != n_features:
        raise ValueError(
            f"validities length {v.shape[0]} != n_features {n_features}."
        )
    # Power route: v = 1 is harmless (no logs). Trust route: guard
    # the logit against v = 1 (perfect experts) and v < 0.5.
    v_pow = np.clip(v, 0.5, 1.0)
    v_tr = np.clip(v, 0.5, 1.0 - 1e-6)

    kappa = float(parameters["kappa"])
    beta = float(parameters["beta"])
    c0 = float(parameters["c0"])
    c1 = float(parameters["c1"])
    alpha = float(parameters["alpha"])
    u_pop = float(parameters["u_pop"])
    w_spread = float(parameters["w_spread"])

    # --- Bimodal population mixture over (w, epsilon, gamma) ---
    # Quantile transform of one uniform variable. No within-mode
    # jitters (they failed twice: contaminating Exp 6 and Exp 13
    # while moving no variance metric). Only a tiny +/-0.02 w spread
    # around the skeptic neutrality curve remains.
    f_counter = 0.13
    u = min(max(u_pop, 0.0), 1.0)
    if u < f_counter:
        # Counter minority: near-balanced routes, low lapse, decisive
        # graded count slope (gamma >= 2, per the theory's prose).
        # w restored to the iter-2-validated [0.42, 0.56]: the higher-w
        # counters of the iter-4 range were less count-decisive on
        # Exp 6's gap/coalition cells, elevating that assay.
        t = u / f_counter
        w_mix = 0.42 + 0.14 * t          # [0.42, 0.56]
        epsilon = 0.12 + 0.10 * t        # [0.12, 0.22]
        gamma = 2.0 + 1.5 * t            # [2.0, 3.5]
    else:
        # Skeptic majority: analytic-distrust dominant. The route
        # weight is COUPLED to the lapse along the Exp-14 neutrality
        # curve w = 1 - (0.25 - eps)/(1 - eps). The epsilon range is
        # LOWERED from [0.18, 0.27] to [0.15, 0.23] (mean ~0.19):
        # this decompresses the lapse-sensitive Exp-3 contrast back
        # toward -0.50/-0.52 and raises the Exp-13 ceiling prevalence
        # toward the observed 0.28, while the coupling keeps every
        # skeptic's Exp-14 v near zero and holds the saturated
        # compliance ~0.75 + eps/2 (eps-invariant along the curve),
        # protecting the Exp 11/12 means. Clipped to the theory's
        # skeptic band [0.85, 0.95].
        t = (u - f_counter) / (1.0 - f_counter)
        epsilon = 0.15 + 0.08 * t        # [0.15, 0.23]
        w_neutral = 1.0 - (0.25 - epsilon) / (1.0 - epsilon)
        w_mix = float(min(max(w_neutral + w_spread, 0.85), 0.95))
        gamma = 1.5 + 2.0 * t            # [1.5, 3.5]
    epsilon = float(min(max(epsilon, 0.02), 0.35))

    # --- Route 1: raw validity-proportional distrust charge ---
    d = c0 + c1 * np.power(v_pow, kappa)
    pen_a = float(np.dot(d, a))
    pen_b = float(np.dot(d, b))

    # Residual micro-trust: a small validity-weighted endorsement
    # edge. logit(0.5) = 0 (coin-flip experts contribute nothing) and
    # the logit is CAPPED at 3 so perfect experts (v = 1.0) exert a
    # bounded pull.
    lg = np.clip(np.log(v_tr / (1.0 - v_tr)), 0.0, 3.0)
    trust = float(np.dot(lg, a - b))

    # D > 0 favors A (B carries more accumulated suspicion, net of
    # the small trust edge).
    D = (pen_b - pen_a) + alpha * trust
    p_skeptic_a = 0.5 * (1.0 + np.tanh(0.5 * beta * D))  # stable sigmoid

    # --- Route 2: graded endorsement-count preference ---
    cnt_a = float(np.sum(a))
    cnt_b = float(np.sum(b))
    p_count_a = 0.5 * (1.0 + np.tanh(0.5 * gamma * (cnt_b - cnt_a)))

    # --- Dual-route mixture ---
    p_a = w_mix * p_skeptic_a + (1.0 - w_mix) * p_count_a
    p_a = float(min(max(p_a, 0.0), 1.0))
    p_core = np.array([p_a, 1.0 - p_a], dtype=float)

    # Independent lapse: with probability epsilon pick uniformly.
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)
```

**`policy source code`:**
```python
def policy(probabilities):
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()  # Ensure valid probabilities.
    return np.random.choice(len(probabilities), p=probabilities)
```


## COMPETING THEORY
**Description:** Heavy-Tailed Graded Dual-Route Distrust (HT-GDRD). Subjects evaluate expert endorsements through two concurrent routes. ROUTE 1 (analytic): every endorsement is a charge on its option — for the distrustful majority a LIABILITY whose magnitude grows with the endorser's raw claimed validity, d_j = c0 + c1*v_j^kappa; for a small 'trust-leaning' minority an ASSET proportional to the (capped) log-odds of validity, alpha*logit(v_j), that dominates the liability for high-validity endorsers. ROUTE 2 (graded counting): a continuous preference for the fewer-endorsement option, sigmoid(gamma*(cnt_B-cnt_A)). The population is an explicitly over-dispersed THREE-COMPONENT mixture driven by one uniform quantile u_pop: (i) a skeptic majority (~78%) with a wide, heavy-tailed lapse distribution (eps in [0.13, 0.27], Beta-like t^0.8 shaping) and a loose route weight w in [0.82, 0.96]; (ii) a counter minority (~16%) with near-balanced routes (w in [0.46, 0.70]), low-moderate lapse, and a steep count slope gamma >= 2.5; and (iii) a small trust-leaning mode (~6%) with a dominant positive micro-trust term (alpha in [0.50, 0.68]) and an elevated lapse. The single update this iteration concerns the analytic route's steepness: the iter-1 residual pattern — soft gradient assays (Exps 5-7, 9, 10) overshooting toward 0.5 WHILE ceiling-compliance assays (Exps 8, 11, 12) undershoot their ceilings — is the signature of an under-steep sigmoid(beta*D), not of excess lapse (three gate rejections established the lapse dimension is exhausted and sits near its local optimum). Raising the beta box from [1.3, 2.4] to [1.8, 3.0] simultaneously deepens the validity-gradient contrasts, raises saturated skeptic compliance toward the observed ceilings, and pulls the soft assays away from chance, without touching the lapse bands that the ceiling-prevalence and dispersion assays (Exps 13, 14, 16) are knife-edge calibrated to.

**Parameters:**
- c0: [0.06, 0.13]
- c1: [1.00, 1.35]
- kappa: [1.6, 2.1]
- beta: [1.8, 3.0]
- alpha: [0.0, 0.05]
- u_pop: [0, 1]
- w_spread: [-0.02, 0.02]
- validities: validities

**`predict source code`:**
```python
def predict(parameters, state, history):
    # Heavy-Tailed Graded Dual-Route Distrust (HT-GDRD), iter-5:
    # the UNCHANGED iter-1 accepted base with exactly ONE knob moved,
    # per the iter-4 critique -- the analytic-route slope beta is raised
    # from [1.3, 2.4] to [1.8, 3.0]. Three consecutive gate rejections
    # of lapse-band edits (iters 2-4) established that the lapse
    # dimension cannot resolve the Exps 5-10 vs 13/14/15 tension and
    # that iter-1's lapse bands sit near their local optimum. The
    # iter-1 residual pattern (gradient assays too soft toward 0.5 AND
    # ceiling assays below their ceilings) is instead the signature of
    # an under-steep analytic sigmoid: raising beta pushes BOTH groups
    # toward the data simultaneously. The beta-UP direction has never
    # been tested (iter-2 trimmed beta DOWN and was rejected; iter-3
    # restored it and was neutral-to-positive). Everything else --
    # lapse bands, counter w ceiling 0.70, c1 [1.00, 1.35], kappa
    # [1.6, 2.1], w_spread +/-0.02, gamma bands, mixture masses
    # (16% counter / 6% trust) -- is byte-identical to iter 1.
    #
    # Stimulus: array-like of shape (2, n_features), row 0 = option A,
    # row 1 = option B; entries are binary expert ratings.
    #
    # ROUTE 1 (weight w): per-endorsement charge
    #   d_j = c0 + c1 * v_j^kappa                     (distrust charge)
    #   D = pen(B) - pen(A) + alpha * sum_j clip(logit(v_j), 0, 3) * (a_j - b_j)
    #   P_route1(A) = sigmoid(beta * D)
    # For skeptics and counters alpha is a tiny residual micro-trust edge
    # (alpha in [0, 0.05]). For the trust-leaning mode alpha is DOMINANT
    # (0.50-0.68): high-validity endorsers become net assets.
    #
    # ROUTE 2 (weight 1-w): graded fewer-endorsement preference
    #   P_route2(A) = sigmoid(gamma * (cnt_B - cnt_A))
    #
    # THREE-COMPONENT HEAVY-TAILED POPULATION, driven by one uniform
    # quantile u_pop in [0, 1]:
    #   u < 0.16        -> COUNTER (16%):  w in [0.46, 0.70],
    #                      eps in [0.13, 0.23], gamma in [2.5, 4.0]
    #   0.16 <= u < 0.94 -> SKEPTIC (78%): eps = 0.13 + 0.14*t^0.8
    #                      (heavy-tailed over [0.13, 0.27]),
    #                      w in [0.82, 0.96] (loose, plus w_spread),
    #                      gamma in [1.5, 3.5]
    #   u >= 0.94       -> TRUST (6%):     alpha in [0.50, 0.68],
    #                      w in [0.44, 0.56] (count-leaning),
    #                      eps in [0.26, 0.34], gamma in [1.5, 3.0]
    #
    # History is ignored: validities are communicated in the
    # instructions, so all charges are fixed for the whole block.
    if isinstance(state, dict):
        a_vec = np.asarray(state["option_a_ratings"], dtype=float).ravel()
        b_vec = np.asarray(state["option_b_ratings"], dtype=float).ravel()
        stim = np.vstack([a_vec, b_vec])
    else:
        stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"HT-GDRD expects a (2, n_features) stimulus; got shape {stim.shape}."
        )
    a, b = stim[0], stim[1]
    n_features = stim.shape[1]

    v = np.asarray(parameters["validities"], dtype=float)
    if v.shape[0] != n_features:
        raise ValueError(
            f"validities length {v.shape[0]} != n_features {n_features}."
        )
    v_pow = np.clip(v, 0.5, 1.0)          # power route: v=1 harmless
    v_tr = np.clip(v, 0.5, 1.0 - 1e-6)     # guard the logit

    kappa = float(parameters["kappa"])
    beta = float(parameters["beta"])
    c0 = float(parameters["c0"])
    c1 = float(parameters["c1"])
    alpha_base = float(parameters["alpha"])
    u_pop = float(parameters["u_pop"])
    w_spread = float(parameters["w_spread"])

    # --- Three-component heavy-tailed population mixture ---
    f_counter = 0.16
    f_trust_lo = 0.94
    u = min(max(u_pop, 0.0), 1.0)
    if u < f_counter:
        # Counter minority: near-balanced routes, low-moderate lapse,
        # decisive graded count slope (gamma >= 2.5).
        t = u / f_counter
        w_mix = 0.46 + 0.24 * t          # [0.46, 0.70]
        epsilon = 0.13 + 0.10 * t        # [0.13, 0.23]
        gamma = 2.5 + 1.5 * t            # [2.5, 4.0]
        alpha_mode = alpha_base
    elif u < f_trust_lo:
        # Skeptic majority: analytic distrust dominant, with a genuinely
        # wide (heavy-tailed, Beta-like) lapse spread and a LOOSE route
        # weight (no tight neutrality coupling -- the loose version is
        # what reproduces the observed Exp-14 excess dispersion).
        t = (u - f_counter) / (f_trust_lo - f_counter)
        epsilon = 0.13 + 0.14 * (t ** 0.8)   # [0.13, 0.27], mean ~0.21
        w_mix = 0.86 + 0.08 * t + w_spread     # ~[0.82, 0.96]
        w_mix = float(min(max(w_mix, 0.82), 0.96))
        gamma = 1.5 + 2.0 * t            # [1.5, 3.5]
        alpha_mode = alpha_base
    else:
        # Trust-leaning residual mode: the positive micro-trust term is
        # DOMINANT, so near-perfect / high-validity endorsers act as net
        # assets; the route weight is count-leaning and the lapse is
        # elevated (a validity-following but inattentive subject).
        t = (u - f_trust_lo) / (1.0 - f_trust_lo)
        alpha_mode = 0.50 + 0.18 * t     # [0.50, 0.68]
        w_mix = 0.44 + 0.12 * t          # [0.44, 0.56]
        epsilon = 0.26 + 0.08 * t        # [0.26, 0.34]
        gamma = 1.5 + 1.5 * t            # [1.5, 3.0]
    epsilon = float(min(max(epsilon, 0.02), 0.45))

    # --- Route 1: validity-proportional charge plus micro-trust edge ---
    d = c0 + c1 * np.power(v_pow, kappa)
    pen_a = float(np.dot(d, a))
    pen_b = float(np.dot(d, b))

    # Micro-trust: logit(0.5) = 0 (coin-flip experts contribute nothing);
    # capped at 3 so perfect experts exert a bounded pull.
    lg = np.clip(np.log(v_tr / (1.0 - v_tr)), 0.0, 3.0)
    trust_edge = float(np.dot(lg, a - b))

    # D > 0 favors A.
    D = (pen_b - pen_a) + alpha_mode * trust_edge
    p_route1_a = 0.5 * (1.0 + np.tanh(0.5 * beta * D))  # stable sigmoid

    # --- Route 2: graded endorsement-count preference ---
    cnt_a = float(np.sum(a))
    cnt_b = float(np.sum(b))
    p_route2_a = 0.5 * (1.0 + np.tanh(0.5 * gamma * (cnt_b - cnt_a)))

    # --- Dual-route mixture ---
    p_a = w_mix * p_route1_a + (1.0 - w_mix) * p_route2_a
    p_a = float(min(max(p_a, 0.0), 1.0))
    p_core = np.array([p_a, 1.0 - p_a], dtype=float)

    # Independent lapse: with probability epsilon pick uniformly.
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)
```

**`policy source code`:**
```python
def policy(probabilities):
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()  # Ensure valid probabilities.
    return np.random.choice(len(probabilities), p=probabilities)
```


## DATA SCHEMA
Your metric receives a tidy per-trial pandas DataFrame stacking all subjects (rows grouped by `subject_id`, in trial order). Columns:
- subject_id: Subject identifier (one row per trial per subject).
- option_a_ratings: List of n_features binary expert ratings (each 0 or 1) for option A on this trial.
- option_b_ratings: List of n_features binary expert ratings (each 0 or 1) for option B on this trial.
- response: 0 if subject chose A, 1 if subject chose B.

## IMPLEMENTATION GUARDRAILS
Any column in the schema above whose description names a list / tuple / np.ndarray (i.e. a per-trial sequence of values) holds non-scalar cells. Those cells are NOT hashable, so operations that hash row values fail with `TypeError: unhashable type: 'list'`. Treating `<seq_col>` as a placeholder for any such sequence-valued column:
- Avoid: `data.groupby('<seq_col>')`, `data['<seq_col>'].value_counts()`,     `data['<seq_col>'].nunique()`, `data['<seq_col>'].unique()` (returns     an object array but downstream `set()` / `in dict` will crash),     `set(data['<seq_col>'])`, `data['<seq_col>'].isin([...])` against list     values, or using a list cell as a dict key.
- If you need a hashable surrogate, project to one first, e.g.:
    - `data['<seq_col>_key'] = data['<seq_col>'].apply(tuple)` then group by `<seq_col>_key`
    - `data['<seq_col>_str'] = data['<seq_col>'].apply(lambda x: ''.join(map(str, x)))`
    Scalar columns (ints, floats, strings like `subject_id`, integer     responses, etc.) hash fine and can be used directly.
- Generator expressions inside function calls like `map()` or `join()` MUST be     parenthesized. For example:
    - WRONG: `map(str, int(v) for v in x)` → SyntaxError
    - RIGHT: `map(str, (int(v) for v in x))` or use a list comp: `[str(int(v)) for v in x]`
- Always verify your code is syntactically valid Python before returning it.

## METRICS YOU ALREADY TRIED AND FAILED ON
Each entry below is a metric you previously proposed in this round that did NOT discriminate the two theories at the human sample size — either it errored, its between-subject variance was unavailable, or Welch's t-test on `(self mean, self var, N)` vs. `(adv mean, adv var, N)` returned p ≥ alpha. The `outcome` line is the simulation result (means, between-subject variances, t-statistic and p-value at the human N) on the same `data_self` / `data_adv` your next metric will be evaluated on. Use the numbers to see where your hypothesised contrast collapsed — small mean gap, large per-subject variance, or both — and propose something qualitatively different. Don't repeat the same idea with cosmetic tweaks.
(none yet)

## RESPONSE FORMAT
Return a JSON object with the following fields:
- metric: Python source defining def metric(data: pd.DataFrame) -> float.
- rationale: Reasoning behind this metric; used when interpreting results.


## Response

```json
{
  "metric_source": "def metric(data: pd.DataFrame) -> float:\n    \"\"\"\n    Extreme validity-following score.\n\n    Per subject:\n      score = (rate of choosing the HIGH-VALIDITY option on the 40 matched-count\n               validity-gradient trials, where one option's endorsements are all\n               v >= 0.75 experts and the other's are all coin-flip (v = 0.5)\n               experts at equal endorsement counts)\n            + (1 - rate of choosing the FEW-ENDORSEMENT option on the 16\n               'asymptote' trials, where one option carries 6 high-validity\n               endorsements and the other only 1-2 coin endorsements).\n\n    The returned value is the MAXIMUM of these scores over all subjects\n    present in the DataFrame.  For a single-subject slice the maximum is\n    simply that subject's own score, so the metric is well defined both\n    pooled and per subject.\n    \"\"\"\n    V = np.array([0.9] * 6 + [0.75] * 6 + [0.65] * 3 + [0.5] * 10, dtype=float)\n    wgt = V - 0.5  # coin-flip experts carry zero validity mass\n\n    follow_tot = {}\n    follow_hit = {}\n    few_tot = {}\n    few_hit = {}\n\n    a_lists = data[\"option_a_ratings\"].tolist()\n    b_lists = data[\"option_b_ratings\"].tolist()\n    responses = data[\"response\"].tolist()\n    subs = data[\"subject_id\"].tolist()\n\n    for sid, a_list, b_list, r in zip(subs, a_lists, b_lists, responses):\n        try:\n            a = np.asarray(a_list, dtype=float).ravel()\n            b = np.asarray(b_list, dtype=float).ravel()\n        except Exception:\n            continue\n        if a.shape[0] != V.shape[0] or b.shape[0] != V.shape[0]:\n            continue\n        r = int(r)\n        ca = int(a.sum())\n        cb = int(b.sum())\n        sa = float(np.dot(wgt, a))\n        sb = float(np.dot(wgt, b))\n\n        if ca == cb:\n            # matched-count validity-gradient trial: exactly one side has\n            # positive validity mass\n            if (sa > 0.0) != (sb > 0.0):\n                if sa > sb:\n                    v_vec, o_vec, v_is_a = a, b, True\n                else:\n                    v_vec, o_vec, v_is_a = b, a, False\n                if v_vec.sum() > 0 and o_vec.sum() > 0:\n                    v_vals = V[v_vec > 0]\n                    o_vals = V[o_vec > 0]\n                    if v_vals.min() >= 0.75 and o_vals.max() <= 0.5:\n                        chose_v = (r == 0) if v_is_a else (r == 1)\n                        follow_tot[sid] = follow_tot.get(sid, 0) + 1\n                        follow_hit[sid] = follow_hit.get(sid, 0) + (1 if chose_v else 0)\n        else:\n            # unequal counts: 'asymptote' trial (few coin endorsements vs\n            # many high-validity endorsements)\n            if ca < cb:\n                f_vec, m_vec, few_is_a = a, b, True\n            else:\n                f_vec, m_vec, few_is_a = b, a, False\n            if f_vec.sum() > 0 and m_vec.sum() > 0:\n                f_vals = V[f_vec > 0]\n                m_vals = V[m_vec > 0]\n                if f_vals.max() <= 0.5 and m_vals.min() >= 0.75:\n                    chose_few = (r == 0) if few_is_a else (r == 1)\n                    few_tot[sid] = few_tot.get(sid, 0) + 1\n                    few_hit[sid] = few_hit.get(sid, 0) + (1 if chose_few else 0)\n\n    subjects = set(follow_tot) | set(few_tot)\n    if not subjects:\n        return 0.0\n\n    scores = []\n    for sid in subjects:\n        fr = (follow_hit[sid] / follow_tot[sid]) if follow_tot.get(sid, 0) > 0 else 0.0\n        few = (few_hit[sid] / few_tot[sid]) if few_tot.get(sid, 0) > 0 else 1.0\n        scores.append(fr + (1.0 - few))\n\n    return float(np.max(scores))",
  "rationale": "The two theories share almost everything at the population-mean level (similar skeptic/counter modes, similar lapse bands, similar route weights), so any mean-based rate metric differs by only ~0.01-0.03 between them - far below the per-subject binomial noise (~0.07-0.10) and undetectable at N=25. The one structural difference that is BOX-DISJOINT is HT-GDRD's ~6% trust-leaning mode (dominant alpha in [0.50, 0.68]): such subjects treat high-validity endorsements as net ASSETS, while under GDRD-B (alpha <= 0.05) no parameterization can make any subject follow validity. The 6% mode cannot be detected by a mean (indicator-variance cap gives t~1.3), so the metric uses an EXTREME ORDER STATISTIC instead: the maximum over subjects of a per-subject 'validity-following score'.\n\nScore construction (per subject, 56 of the 96 trials): (1) the rate of choosing the high-validity option on the 40 matched-count gradient trials (pairs 3,4,5,6,7,10,16,17,18,19 x 4 reps), where the count route is exactly neutral (both options have equal endorsement counts) so the choice isolates the analytic route's validity attitude; (2) plus the deficit in choosing the few-endorsement side on the 16 asymptote trials (pairs 9,11,21,24), where every distrust/count subject saturates toward the few-coin side (>= 0.885 under GDRD-B, a pure lapse readout) but the trust mode's dominant alpha term pulls toward the 6x0.9 side (few-side rate 0.46-0.60).\n\nPredicted values: GDRD-B - every subject has follow-rate <= ~0.35 (counters) or ~0.25 (skeptics) and few-rate >= 0.885, so scores <= ~0.47, and the sample max (with binomial noise over 40+16 trials) lands around 0.45-0.55. HT-GDRD - the trust-leaning subjects score 1.0-1.2 (follow-rate 0.55-0.70 even at the weakest alpha=0.50 corner, plus few-side deficit 0.40-0.54), so the sample max lands on such a subject at ~1.0-1.2 whenever one is drawn. The two envelopes are disjoint by ~0.4-0.5, while the per-subject score SD is ~0.10 (GDRD-B) and ~0.23 (HT), giving Welch t ~ 8-11 at N=25, p << 0.01.\n\nPer-subject applicability: on a single-subject slice the maximum degenerates to that subject's own score, so between_subject_variance is well defined (it is the population variance of the per-subject scores). The max rather than the mean is essential and is the point of the metric: it converts a rare, behaviorally extreme subpopulation - which no reparameterization of GDRD-B can produce (alpha <= 0.05 cannot flip the sign of any per-endorsement validity gap at v >= 0.65) and which HT-GDRD guarantees at its fixed 6% mass - into a large, low-variance pooled contrast."
}
```

## Usage

```json
{
  "input_tokens": 13947,
  "output_tokens": 80052,
  "reasoning_tokens": 78224,
  "provider": "Sail Research"
}
```
