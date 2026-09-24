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
**Validities (n_features=13):** [0.99, 0.99, 0.9, 0.85, 0.5, 0.5, 0.5, 0.5, 0.5, 0.5, 0.5, 0.5, 0.5]

**Trial pairs (n=32):**
  trial 1: A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 1, 1, 0, 0]  B=[0, 0, 1, 1, 0, 1, 0, 0, 0, 1, 1, 0, 0]
  trial 2: A=[0, 0, 1, 1, 0, 1, 0, 0, 0, 1, 1, 0, 0]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 1, 1, 0, 0]
  trial 3: A=[1, 0, 0, 1, 1, 0, 1, 0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 1, 1, 0, 0, 1, 0, 0, 0]
  trial 4: A=[0, 0, 0, 1, 0, 1, 1, 0, 0, 1, 0, 0, 0]  B=[1, 0, 0, 1, 1, 0, 1, 0, 0, 1, 0, 0, 0]
  trial 5: A=[1, 1, 0, 1, 0, 1, 0, 1, 0, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 1, 0, 1]
  trial 6: A=[1, 1, 1, 0, 1, 0, 1, 0, 0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1, 0, 1, 0, 0, 1, 0, 1, 0]
  trial 7: A=[0, 0, 1, 0, 1, 0, 1, 0, 0, 1, 0, 1, 0]  B=[1, 1, 1, 0, 1, 0, 1, 0, 0, 1, 0, 1, 0]
  trial 8: A=[1, 1, 0, 1, 0, 1, 0, 0, 1, 0, 1, 0, 1]  B=[0, 0, 1, 1, 0, 1, 0, 0, 1, 0, 1, 0, 1]
  trial 9: A=[1, 1, 0, 0, 1, 1, 0, 1, 0, 0, 1, 1, 0]  B=[0, 0, 1, 0, 0, 1, 0, 1, 0, 0, 1, 1, 0]
  trial 10: A=[1, 1, 0, 1, 1, 1, 0, 0, 1, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0, 0, 0, 0, 1, 1, 0, 0, 1]
  trial 11: A=[1, 1, 0, 0, 1, 1, 1, 1, 0, 0, 1, 1, 0]  B=[0, 0, 1, 0, 0, 0, 0, 1, 0, 0, 1, 1, 0]
  trial 12: A=[0, 0, 1, 1, 0, 1, 0, 0, 1, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0, 1, 0, 0, 1, 0, 1, 0, 1]
  trial 13: A=[0, 0, 1, 1, 1, 1, 0, 0, 1, 1, 0, 0, 1]  B=[1, 1, 0, 1, 0, 0, 0, 0, 1, 1, 0, 0, 1]
  trial 14: A=[1, 1, 0, 1, 1, 0, 1, 0, 1, 0, 0, 1, 0]  B=[0, 1, 0, 1, 0, 0, 1, 0, 1, 0, 0, 1, 0]
  trial 15: A=[1, 1, 1, 0, 1, 1, 1, 0, 0, 1, 0, 1, 1]  B=[0, 0, 1, 0, 0, 0, 1, 0, 0, 1, 0, 1, 1]
  trial 16: A=[1, 0, 1, 1, 1, 0, 0, 1, 0, 1, 1, 0, 0]  B=[0, 0, 1, 0, 1, 0, 0, 1, 0, 1, 1, 0, 0]
  trial 17: A=[0, 0, 1, 0, 1, 0, 0, 1, 0, 1, 1, 0, 0]  B=[1, 0, 1, 1, 1, 0, 0, 1, 0, 1, 1, 0, 0]
  trial 18: A=[1, 1, 0, 0, 1, 1, 0, 0, 1, 0, 1, 0, 1]  B=[0, 0, 1, 1, 0, 1, 0, 0, 1, 0, 1, 0, 1]
  trial 19: A=[1, 1, 0, 0, 1, 1, 1, 0, 0, 1, 0, 1, 0]  B=[0, 0, 1, 1, 0, 0, 1, 0, 0, 1, 0, 1, 0]
  trial 20: A=[1, 1, 0, 0, 1, 1, 1, 1, 0, 0, 1, 0, 1]  B=[0, 0, 1, 1, 0, 0, 0, 1, 0, 0, 1, 0, 1]
  trial 21: A=[0, 0, 1, 1, 0, 0, 1, 0, 0, 1, 0, 1, 0]  B=[1, 1, 0, 0, 1, 1, 1, 0, 0, 1, 0, 1, 0]
  trial 22: A=[1, 1, 1, 1, 0, 0, 0, 1, 0, 1, 0, 1, 0]  B=[0, 0, 0, 0, 1, 1, 0, 1, 0, 1, 0, 1, 0]
  trial 23: A=[1, 1, 1, 1, 0, 0, 0, 0, 1, 0, 1, 0, 1]  B=[0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 1, 0, 1]
  trial 24: A=[0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 1, 0, 1]  B=[1, 1, 1, 1, 0, 0, 0, 0, 1, 0, 1, 0, 1]
  trial 25: A=[0, 0, 0, 1, 1, 1, 0, 1, 0, 0, 1, 0, 1]  B=[0, 0, 1, 1, 0, 1, 0, 1, 0, 0, 1, 0, 1]
  trial 26: A=[1, 0, 0, 0, 1, 1, 1, 0, 1, 0, 0, 1, 0]  B=[1, 0, 1, 0, 0, 0, 1, 0, 1, 0, 0, 1, 0]
  trial 27: A=[0, 1, 0, 1, 1, 1, 1, 0, 0, 1, 0, 0, 1]  B=[0, 1, 1, 1, 0, 0, 0, 0, 0, 1, 0, 0, 1]
  trial 28: A=[1, 0, 1, 0, 1, 1, 0, 1, 0, 0, 1, 0, 1]  B=[1, 0, 1, 0, 0, 0, 1, 1, 0, 0, 1, 0, 1]
  trial 29: A=[1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1]  B=[0, 1, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1]
  trial 30: A=[1, 1, 0, 1, 1, 0, 0, 1, 0, 1, 0, 1, 0]  B=[1, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0]
  trial 31: A=[0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 1, 0, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 1]
  trial 32: A=[1, 0, 1, 1, 1, 0, 1, 0, 1, 0, 0, 1, 0]  B=[1, 0, 0, 0, 0, 1, 1, 0, 1, 0, 0, 1, 0]

**Rationale:** CORE LOGIC. EOBOT (advocated) and SG-CGD (competing) share the identical architecture (sign votes x panel-relative weights x low-gain softmax x lapse), the same plateau (w_p in [0.88,0.92] over [v_lo,v_hi], ceiling ~0.981), the same consensus-gating machinery (same g0/s_gap/lambda_ext), and near-identical chance-flank calibration (kappa_lo 0.19-0.22 vs 0.19-0.22; kappa_gate 0.66-0.76 vs 0.66-0.74). They were also explicitly CROSS-CALIBRATED on the gap-0.05 cells (EOBOT's c_half was lowered precisely so that partially-chance-laden gap-0.05 singleton-99 panels match SG-CGD's near-kernel output), so gap-0.05 panels are convergence zones and are deliberately avoided. The design instead engineers the one panel conjunction where the two theories' REMAINING structural differences separate maximally and with OPPOSITE SIGN: a 0.99 claim sitting 0.09 above its 0.90 next rung (gap = 0.09) on a HEAVILY chance-laden panel (c_frac = 9/13 = 0.692). Panel: [0.99, 0.99, 0.90, 0.85, 0.50 x 9] (13 experts; two tied 0.99 experts so the disputed lever applies twice). At gap 0.09: (a) EOBOT's RELOCATED peaked kernel is at its MAXIMUM (E ~ 0.98-1.0 for every parameter, since g_star ~ 0.088), and its deep saturating shrinkage (rho_e 1.15-1.45 toward w_floor -0.58..-0.52) demotes the 99% expert to a clear ANTI-cue; both of EOBOT's composition kernels are structurally CLOSED at gap 0.09 (comp_near's Gaussian centered 0.036 is inert, L <= 0.076; comp_far's sharp logistic centered 0.183 gives far <= 0.018), so its comp_gate being wide open at c_frac 0.692 is irrelevant. (b) SG-CGD's base distrust is SHALLOW (w_floor -0.24..-0.17, rho_e 1.05-1.30), its far-fraud route is throttled by F_far ~ 0.004-0.016 despite c_far 20-26, but its UNIQUE composition-gated edge-credibility ramp FIRES: R_cred = sigmoid((0.09-g_edge)/s_edge) ~ 0.61-0.75 (gap 0.09 is past g_edge 0.070-0.080) and Q_cred ~ 0.74-0.92 (c_frac 0.692 is well past c_cred_half 0.57-0.63), giving cred ~ 0.52-0.97 that PROMOTES the 99% expert back toward (and at box corners above) plateau trust. EOBOT has no such ramp. Resulting weight on each 0.99 expert across the ENTIRE parameter boxes: EOBOT w(0.99) in [-0.57, -0.11]; SG-CGD w(0.99) in [+0.10, +0.92]. SIGN-DISJOINT BY CONSTRUCTION. Every other weight is common currency: the 0.90/0.85 plateau experts get 0.86-0.90 in both (tilt 0.08-0.12 vs 0.09-0.13, overlapping), and because sig_gap(0.09) ~ 0.96-0.98 the consensus gate is ~0.98 open for both, giving gated chance weight 0.57-0.71 (EOBOT) vs 0.57-0.70 (SG-CGD) -- overlapping. The experiment is therefore a psychometric isolation of ONE signed scalar -- the value of a 99%-atop-90% endorsement on a coin-flip-laden panel -- measured in the common currencies of chance cues (~0.62) and plateau cues (~0.88), from both sides of 0.50. 32 unique pairs x K = 96//32 = 3 = 96 trials.

FAMILY M (masked endorsement: backgrounds cancel exactly, leaving s = w_top or 2*w_top). Because tied chance cues contribute identical weights to both sides, M1 (A wins both 99s + one 0.50 vs B wins one 0.50), M4 (A wins both 99s alone), M2 (A wins one 99 + one 0.50 vs B wins one 0.50) and M3 (A wins one 99 alone) reduce to s = 2*w_top or w_top exactly. EOBOT boxes: M4/M1 p(A) in [0.27, 0.46]; M2/M3 in [0.40, 0.48]. SG-CGD boxes: M4/M1 in [0.54, 0.83]; M2/M3 in [0.52, 0.69]. DISJOINT, with dead zones (0.46, 0.54) and (0.48, 0.52) that falsify BOTH theories -- included deliberately as honest adversarial regions. Both theories additionally demand the parameter-free equalities M2 = M3 and M1 = M4 (surface invariance); inequality indicates a count/surface heuristic outside both models. Centers: EOBOT M1/M4 = 0.39, M2/M3 = 0.44; SG-CGD M1/M4 = 0.74, M2/M3 = 0.63. Mirrors M1m/M2m/M4m control side bias.

FAMILY R (flagship crossover ladder: both 99s + k coin-flippers vs the 0.90 expert, k = 0..3). s = 2*w_top + k*w_ch - w_p90. EOBOT centers: R0 .24, R1 .34, R2 .46, R3 .58 -- crossover k* ~ 2.3 coin-flippers. SG-CGD centers: R0 .58, R1 .70, R2 .79, R3 .85 -- crossover k* < 0 (the double-99 stack beats the 90% expert even with zero backing). Every rung is box-disjoint: R0 EOBOT [0.15, 0.32] vs SG [0.37, 0.70]; R1 [0.23, 0.44] vs [0.47, 0.86]; R2 [0.32, 0.55] vs [0.58, 0.92]; R3 [0.41, 0.68] vs [0.69, 0.96]. R0 is the sharpest single question in the design -- 'do two 99% experts beat one 90% expert?' -- EOBOT says no by 24 points, SG-CGD says yes by 16. R0 has exactly TIED raw 1-counts (7 vs 7), defeating any count heuristic. Mirrors R0m/R2m reverse the pattern.

FAMILY V (head-to-heads). V1 (one 99 vs one coin-flipper): EOBOT [0.27, 0.37] (center 0.33 -- the coin-flipper clearly wins) vs SG-CGD [0.36, 0.57] (center 0.51 -- a coin flip). V2 (both 99s vs two coin-flippers): EOBOT center 0.19 vs SG 0.51. V3 (one 99 vs the 0.85 expert): EOBOT center 0.28 vs SG 0.46. All carry 25-30 point center dissociations; V1/V2 probe how a 99% endorsement fares against the cheapest possible opposition under each theory.

FAMILY D (double-99 stacks vs the trusted pair). D1/D2/D3 (both 99s + 1/2/3 coin-flippers vs {0.90, 0.85}): EOBOT centers .21/.30/.41 vs SG-CGD .53/.65/.75. D1 has exactly tied 1-counts (6 vs 6) and a 3-vs-3 raw tally -- a count-balanced cell with a 32-point center dissociation. D2m mirrors.

FAMILY K (unanimity). K1 (A wins ALL FOUR genuine experts vs two coin-flippers): EOBOT center 0.49 (the two anti-votes nearly cancel the trusted stack -- a coin flip on a unanimous-expertise surface) vs SG-CGD 0.81. K2 (all four genuine vs FOUR coin-flippers; raw tally and 1-counts EXACTLY TIED 4-4): EOBOT center 0.26 vs SG-CGD 0.62 -- a sign-flip on a perfectly count-balanced trial, the strongest heuristic-defeating cell. K2m mirrors.

FAMILY X/Z/G/T (common-currency anchors and parameter-free assays). X1/X2/X3 (k = 1/2/3 coin-flippers vs the 0.90 expert, 99s TIED so w_top contributes exactly zero): both theories agree within ~1 point (centers .45/.57/.68), pinning the SHARED gated-chance weight and beta/epsilon -- deviation here indicts the common gating machinery, not the disputed distrust. Z2 (two coin-flippers vs one): both ~0.62. G1/G2 (trusted stacks vs coin-flippers): both ~0.91/0.80, pinning lapse/temperature. T1 (the two 99s split between A and B) and T2 (one coin-flipper each): BOTH theories must predict EXACTLY 0.50 for every parameter (tied softmax is uniform; the lapse injects uniform) -- parameter-free side/display-bias assays. THE KEY COMPOSITE METRIC: the paired X-vs-R endorsement cost at matched k -- adding the double-99 endorsement to A's side shifts p by -11 points at k=2 under EOBOT (0.57 -> 0.46) but by +22 points under SG-CGD (0.57 -> 0.79): a within-subject, sign-opposite estimator of w_top robust to all shared parameters.

HONEST KNIVES BOTH WAYS. Against MY theory (EOBOT): observed p(M2/M3) >= 0.52, p(M1/M4) >= 0.54, p(R0) >= 0.38, p(R1) >= 0.47, or p(R2) >= 0.58 falsifies EOBOT outright with zero free parameters (its relocated peak plus deep saturation cannot lift w_top above -0.11 on this panel). Against SG-CGD: observed p(M2/M3) <= 0.48, p(M1/M4) <= 0.46, p(R0) <= 0.31, p(R1) <= 0.44, or p(R2) <= 0.57 falsifies SG-CGD outright (its credibility ramp cannot drop w_top below +0.10 here). The dead zones on M1/M4 (0.46-0.54), M2 (0.48-0.52), R0 (0.32-0.37) and R1 (0.44-0.47) falsify BOTH theories -- included deliberately.

KEY QUANTITATIVE METRICS: (i) masked cells M1/M4 and M2/M3 (EOBOT .39/.44 vs SG .74/.63, box-disjoint); (ii) the R-ladder crossover k* in chance-cue units (EOBOT ~2.3 vs SG-CGD < 0 -- a >2-cue separation no parameter setting can close); (iii) the paired X-vs-R endorsement cost (-11 vs +22 points at k=2, sign-opposite); (iv) the R0 sign cell (two 99s vs one 90%: .24 vs .58); (v) the count-balanced cells K2/D1/R0 (tied tallies and 1-counts with 26-36 point center dissociations); (vi) parameter-free exact-0.50 cells (T1, T2) and surface equalities (M2=M3, M1=M4). PREDICTED PATTERN IF EOBOT IS RIGHT (centers): M1/M4 .39, M2/M3 .44, R0-R3 .24/.34/.46/.58, V1 .33, V2 .19, V3 .28, D1-D3 .21/.30/.41, K1 .49, K2 .26, X1-X3 .45/.57/.69, Z2 .62, T .50, G1 .91, G2 .80 -- a 99%-atop-90% claim on a coin-flip-laden panel is worth about half a trusted cue AGAINST: masked anti-following, two 99s losing to one 90% expert, unanimous panels at chance. IF SG-CGD IS RIGHT: M1/M4 .74, M2/M3 .63, R0-R3 .58/.70/.79/.85, V1 .51, V2 .51, V3 .46, D1-D3 .53/.65/.75, K1 .81, K2 .62, X1-X3 .45/.57/.68, Z2 .62, T .50, G1 .91, G2 .80 -- the same claim is worth ~75% of a trusted cue FOR: the double-99 stack beats the 90% expert outright, unanimous panels followed at 0.81. The w(0.99) boxes are sign-disjoint by construction, so the patterns are mutually exclusive on ~20 of 32 cells.

DIFFERENTIATION FROM PRIOR EXPERIMENTS. This is the first EOBOT vs SG-CGD pairing (prior rounds pitted EOBOT only against BODT, and SG-CGD's predecessor CREDT against BODT/FDEI). The gap-0.05 regime -- where the two theories' composition routes were cross-calibrated to converge -- is deliberately avoided. [16] tested EOBOT vs BODT at gap 0.09 c_frac 0.545 (an amplitude dissociation where both distrusted); [17] at gap 0.09 c_frac 0.20 (sign flip vs BODT's shallow saturation); no prior design instantiated gap 0.09 with c_frac 0.692, the unique configuration in which SG-CGD's composition-gated EDGE-CREDIBILITY RAMP fires at full gain (Q_cred > 0.74 across its whole box) while EOBOT's relocated kernel sits at its peak with both composition kernels structurally closed -- a pure test of 'credibility restoration' vs 'peak distrust' that sign-flips the disputed weight. The paired X-vs-R endorsement-cost estimator, the out-of-range SG crossover (k* < 0), and the count-balanced unanimity cell K2 are new quantitative signatures. Sides are balanced via mirrors in every family (13 A-tilted / 16 B-tilted / 3 neutral under EOBOT centers; the A-tilt under SG-CGD centers is itself its signature prediction, controlled by mirrors); no all-tie trials; tie patterns mix 0/0 and 1/1 so 'count the 1s' is unviable (R0, D1, K2, T1 have exactly tied 1-counts with large dissociations; M1/R1-R3/D2-D3/K1 have MORE 1s for A while EOBOT predicts A loses); every trial requires scanning all 13 experts to locate 1-6 discriminators; the two 99% experts are displayed first (validity-salient), an adversarial touch favoring any follow-the-best-expert heuristic that would push against EOBOT's anti-following signature.

**Computed schedule:** 32 unique pairs × 3 reps = 96 trials per subject.



## ADVOCATED THEORY
**Description:** Edge-Only Bounded Outlier Tallying (EOBOT), gate-widening calibration edition. Subjects integrate every binary expert rating as a sign vote (+1/-1/0) into a zero-sum evidence score with subjective weights computed RELATIVE to the panel: (i) a trust plateau over [v_lo, v_hi] (ceiling just above 0.98) with a shallow within-plateau tilt; (ii) a small negative chance flank at v near 0.5, consensus-gated with a PARTIAL promotion cap kappa_gate*w_p when an above-ceiling claim destabilizes the scale; (iii) outlier distrust is a BOUNDED, SATURATING shrinkage toward a floor driven by the outlier's uncorroborated EDGE over the next rung — a peaked kernel RELOCATED to gap ~0.088 (so dense ladders and gap-0.05 singleton outliers on trusted panels are taken near face value, while gap-0.09 outliers are deeply distrusted), sitting on a uniform-skepticism floor e_min; (iv) the panel's chance-fraction AMPLIFIES distrust through two split, independently gated kernels: comp_near (its own narrow kernel centered at gap ~0.036, so majority/partial-chance panels deepen distrust only in the small-gap regime) and comp_far (a sharp logistic at gap ~0.18, so a far outlier floating over a chance-laden panel is treated as rigged while a gap-0.14 outlier is followed at face value). This round is a pure calibration claim on the loop-validated structure: the composition gate threshold c_half is LOWERED to [0.34, 0.38] so partially-chance-laden gap-0.05 singleton-99 panels (Exp 12, c_frac ~0.375) actually enter the composition regime (with c_near trimmed to hold the already-perfect double-99 cell, Exp 13, as its gate widens), kappa_lo is interpolated to its empirically bracketed midpoint for the chance-flank sensitivity cell (Exp 5), and e_min is nudged upward for the dense-ladder cell (Exp 9). Choice is a low-gain softmax plus a uniform lapse.

**Parameters:**
- w_p: [0.88, 0.92]
- v_lo: [0.52, 0.55]
- v_hi: [0.9805, 0.9825]
- kappa_lo: [0.19, 0.22]
- kappa_gate: [0.66, 0.76]
- tilt: [0.08, 0.12]
- g0: [0.041, 0.045]
- s_gap: [0.012, 0.014]
- lambda_ext: [0.30, 0.42]
- g_star: [0.084, 0.092]
- s_l: [0.011, 0.015]
- s_r: [0.027, 0.033]
- e_min: [0.12, 0.16]
- w_floor: [-0.58, -0.52]
- rho_e: [1.15, 1.45]
- d_w: [0.08, 0.14]
- g_near: [0.032, 0.040]
- s_near: [0.016, 0.022]
- c_near: [1.9, 2.3]
- c_half: [0.34, 0.38]
- s_c: [0.05, 0.07]
- g_far: [0.178, 0.188]
- s_far: [0.018, 0.022]
- c_far: [4.2, 5.2]
- beta: [0.38, 0.46]
- epsilon: [0.035, 0.055]
- validities: validities

**`predict source code`:**
```python
def predict(parameters, state, history):
    # Edge-Only Bounded Outlier Tallying (EOBOT), gate-widening edition.
    # Stimulus: array of shape (2, n_features); row 0 = option A,
    # row 1 = option B; entries are binary expert ratings (0/1).
    # Each feature j casts a sign vote sign(a_j - b_j), weighted by a
    # subjective trust function of the expert's STATED validity v,
    # evaluated RELATIVE to the panel:
    #   (i) TRUST PLATEAU with shallow tilt: all v in [v_lo, v_hi]
    #       (v_hi just above 0.98, so a 98% expert stays INSIDE the
    #       plateau) get approximately equal weight w_p, with a
    #       within-band tilt so higher-validity cues slightly
    #       outrank lower ones.
    #  (ii) CHANCE FLANK + CONSENSUS GATE: v near 0.5 gets a small
    #       negative weight (-kappa_lo at v=0.5, rising linearly to
    #       the tilted plateau at v_lo). When an above-ceiling claim
    #       is present the flank is gated and chance cues are
    #       PROMOTED to a partial ceiling kappa_gate*w_p (counted,
    #       but weaker than genuine mid-band experts).
    # (iii) EDGE-ONLY BOUNDED OUTLIER DISTRUST, RELOCATED PEAK: the
    #       discount of the panel-max expert is a saturating
    #       shrinkage toward a floor,
    #         w_top_mod = w_floor + (w_p - w_floor)*exp(-rho_e*E(gap))
    #       with E a PEAKED kernel centered at g_star ~ 0.088 sitting
    #       on a uniform-skepticism floor e_min: near zero distrust
    #       on dense ladders AND on gap-0.05 singleton outliers
    #       (steep left wall s_l), deep distrust at gap ~0.09 (peak),
    #       receding by gap ~0.14 (right wall s_r).
    #  (iv) SPLIT COMPOSITION AMPLIFICATION, both gated by
    #       comp_gate(c_frac) with threshold c_half ~ 0.36 (LOWERED
    #       this round so partially-chance-laden gap-0.05 panels
    #       enter the regime):
    #         comp_near = c_near * sig_gap * L(gap) * comp_gate
    #       with L a NARROW kernel centered at g_near ~ 0.036 (fires
    #       only in the small-gap regime; inert at gap >= 0.09), and
    #         comp_far  = c_far * sig_gap * far(gap) * comp_gate
    #       with far() a SHARP logistic centered at g_far ~ 0.183:
    #       closed at gap 0.14 (a 0.99 outlier over a 0.85 rung is
    #       followed even on a majority-chance panel), fully open by
    #       gap ~0.24 (a far outlier over a chance-laden panel is a
    #       fraud signal).
    # A small bounded extremity term d_w*(v_top - v_hi)/(1 - v_hi)
    # is retained. All experts tied at the panel maximum share
    # w_top (double-99 panels double the anti-vote). Choice is a
    # low-gain softmax (inverse temperature beta) over the two
    # mirrored scores, plus a uniform lapse (epsilon).
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Expects a (2, n_features) stimulus; got shape {stim.shape}."
        )

    n_features = stim.shape[1]
    val = np.asarray(parameters["validities"], dtype=float)
    if val.shape[0] != n_features:
        raise ValueError(
            f"validities length {val.shape[0]} != n_features {n_features}."
        )

    w_p = float(parameters["w_p"])
    v_lo = float(parameters["v_lo"])
    v_hi = float(parameters["v_hi"])
    kappa_lo = float(parameters["kappa_lo"])
    kappa_gate = float(parameters["kappa_gate"])
    tilt = float(parameters["tilt"])
    g0 = float(parameters["g0"])
    s_gap = float(parameters["s_gap"])
    lambda_ext = float(parameters["lambda_ext"])
    g_star = float(parameters["g_star"])
    s_l = float(parameters["s_l"])
    s_r = float(parameters["s_r"])
    e_min = float(parameters["e_min"])
    w_floor = float(parameters["w_floor"])
    rho_e = float(parameters["rho_e"])
    d_w = float(parameters["d_w"])
    g_near = float(parameters["g_near"])
    s_near = float(parameters["s_near"])
    c_near = float(parameters["c_near"])
    c_half = float(parameters["c_half"])
    s_c = float(parameters["s_c"])
    g_far = float(parameters["g_far"])
    s_far = float(parameters["s_far"])
    c_far = float(parameters["c_far"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    def _sigmoid(x):
        # Numerically stable logistic via the identity
        # sigmoid(x) = 0.5 * (1 + tanh(x / 2)).
        return 0.5 * (1.0 + np.tanh(0.5 * x))

    a, b = stim[0], stim[1]

    # Feature-wise votes: +1 where A wins the feature, -1 where B
    # wins, 0 on ties (a tied cue is uninformative for the pair).
    votes = np.sign(a - b)

    v = np.clip(val, 0.5, 1.0)

    # ---- Panel structure: top validity and its gap to the
    # next-highest DISTINCT validity in the panel. ----
    v_top = float(v.max())
    below = v[v < v_top - 1e-9]
    # If every expert shares the top validity, the panel offers no
    # corroboration ladder; treat the next rung as chance (0.5).
    v_second = float(below.max()) if below.size > 0 else 0.5
    gap = v_top - v_second

    # Outlier = a claim ABOVE the trust ceiling. With v_hi ~ 0.981
    # a 0.98-topped panel stays inside the trusted plateau; only
    # 99%+ claims enter the distrust branch.
    outlier = v_top > v_hi

    if outlier:
        sig_gap = _sigmoid((gap - g0) / s_gap)
    else:
        sig_gap = 0.0

    # ---- (ii): consensus gate for the chance flank. ----
    if outlier:
        gate = lambda_ext + (1.0 - lambda_ext) * float(sig_gap)
    else:
        gate = 0.0

    # ---- (i) + (ii): tilted plateau with a consensus-gated
    # chance flank whose promotion is capped at the PARTIAL
    # ceiling kappa_gate * w_p. ----
    w = np.full(n_features, w_p, dtype=float)
    span = max(v_hi - v_lo, 1e-6)
    plateau = (v >= v_lo) & (v <= v_hi)
    if np.any(plateau):
        # Shallow within-plateau validity gradient: higher-validity
        # experts slightly outrank lower ones while the band
        # remains 'approximately equal'.
        w[plateau] = w_p * (
            1.0 - tilt * (v_hi - v[plateau]) / span
        )
    flank = v < v_lo
    if np.any(flank):
        denom = max(v_lo - 0.5, 1e-6)
        # Flank rises linearly to the TILTED plateau value at v_lo,
        # keeping the weight profile continuous at the band edge.
        w_lo_eff = w_p * (1.0 - tilt)
        w_flank = -kappa_lo + (w_lo_eff + kappa_lo) * np.clip(
            v[flank] - 0.5, 0.0, None
        ) / denom
        # With an above-ceiling claim in the panel, chance cues are
        # counted toward a partial ceiling kappa_gate*w_p rather
        # than inverted (and rather than fully trusted).
        w[flank] = (1.0 - gate) * w_flank + gate * kappa_gate * w_p

    # ---- (iii) + (iv): relocated edge-only bounded distrust with
    # the split, gate-widened composition amplification. ----
    if outlier:
        # (a) Peaked kernel RELOCATED to g_star ~ 0.088, sitting on
        # the uniform-skepticism floor e_min: near-zero distrust on
        # dense ladders (gap ~ 0.01) and on gap-0.05 singleton
        # outliers (steep left wall s_l), deep distrust at the
        # gap ~ 0.09 peak, receding right flank (s_r).
        width = s_l if gap < g_star else s_r
        E_kernel = float(np.exp(-0.5 * ((gap - g_star) / width) ** 2))
        E = max(E_kernel, e_min)

        # (b) BOUNDED, SATURATING shrinkage toward the floor:
        # w_top_mod in [w_floor, w_p] for every E.
        w_top_mod = w_floor + (w_p - w_floor) * float(np.exp(-rho_e * E))

        # (c) Split composition amplification. The chance-fraction
        # gate threshold c_half is LOWERED (~0.36) so PARTIALLY
        # chance-laden panels (c_frac ~ 0.375) enter the regime:
        #   comp_near fires only in the small-gap regime via its own
        #   narrow kernel L (centered g_near ~ 0.036), deepening the
        #   anti-vote for an uncorroborated near-rung outlier on a
        #   chance-laden scale; it is inert at gap >= 0.09.
        #   comp_far is the far-fraud route: a SHARP logistic at
        #   g_far ~ 0.183, closed at gap 0.14, fully open by 0.24.
        c_frac = float(np.mean(flank))
        comp_gate = _sigmoid((c_frac - c_half) / s_c)
        L = float(np.exp(-0.5 * ((gap - g_near) / s_near) ** 2))
        comp_near = c_near * float(sig_gap) * L * float(comp_gate)
        far = _sigmoid((gap - g_far) / s_far)
        comp_far = c_far * float(sig_gap) * float(far) * float(comp_gate)

        # (d) Small bounded extremity term.
        ext = d_w * (v_top - v_hi) / max(1.0 - v_hi, 1e-6)

        w_top = w_top_mod - ext - comp_near - comp_far
        # All experts tied at the panel maximum share the distrust
        # (e.g., a pair of 0.99 super-experts doubles the anti-vote).
        w[v >= v_top - 1e-9] = w_top

    # Weighted evidence score. B's score is the mirror of A's
    # because every vote is zero-sum across the two options.
    s_a = float(np.dot(w, votes))
    scores = np.array([s_a, -s_a], dtype=float)

    # Numerically stable low-gain softmax. When all cues tie
    # (s_a == 0) the softmax is exactly uniform.
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()

    # Independent lapse: with probability epsilon output a uniform
    # pick over the two options.
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)
```

**`policy source code`:**
```python
def policy(probabilities):
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()  # guard against float drift
    return int(np.random.choice(len(probabilities), p=probabilities))
```


## COMPETING THEORY
**Description:** SG-CGD (Small-Gap Composition-Gated Outlier Distrust), half-depth uniform-skepticism edition. Subjects integrate every binary expert rating as a sign vote into a zero-sum evidence score with subjective weights computed relative to the panel: a tilted trust plateau over [v_lo, v_hi] (ceiling just above 0.98), a consensus-gated chance flank with partial-ceiling promotion, and an outlier branch for above-ceiling claims consisting of (a) a bounded, saturating base distrust peaked at gap ~0.088 sitting on a uniform-skepticism floor, (b) a near-kernel composition amplification (narrow Gaussian at gap ~0.035, chance-fraction gate, sig_gap-throttled) that deepens distrust only of small-edge outliers on chance-laden scales, (c) a far-fraud route at gap ~0.185, and (d) a composition-gated edge-credibility ramp that promotes a well-separated 99% expert back toward plateau trust when the surrounding scale is unreliable. The single theoretical claim updated this round: the uniform-skepticism floor e_min — the residual distrust applied to a panel-max expert even when the gap kernel is silent (dense ladders, gap ~0.05 cells) — sits at a MODERATE depth (~0.36), roughly halfway between the near-zero floor of the accepted calibration and the deep floor of the rejected overshoot. This floor is what generates the empirically required mild anti-follow of 99% experts on dense validity ladders (Exp 7) without unbounded sign flips. Choice is a low-gain softmax plus uniform lapse.

**Parameters:**
- w_p: [0.88, 0.92]
- v_lo: [0.52, 0.55]
- v_hi: [0.9805, 0.9825]
- tilt: [0.09, 0.13]
- kappa_lo: [0.19, 0.22]
- kappa_gate: [0.66, 0.74]
- lambda_ext: [0.30, 0.42]
- g0: [0.041, 0.045]
- s_gap: [0.012, 0.014]
- g_star: [0.084, 0.092]
- s_l: [0.013, 0.017]
- s_r: [0.040, 0.050]
- e_min: [0.32, 0.40]
- w_floor: [-0.24, -0.17]
- rho_e: [1.05, 1.30]
- d_w: [0.08, 0.12]
- g_near: [0.032, 0.038]
- s_near: [0.014, 0.018]
- c_near: [3.5, 4.0]
- c_half: [0.44, 0.48]
- s_c: [0.085, 0.105]
- g_far: [0.180, 0.190]
- s_far: [0.018, 0.022]
- c_far: [20, 26]
- c_half_far: [0.57, 0.63]
- s_c_far: [0.06, 0.08]
- c_cred: [1.15, 1.40]
- g_edge: [0.070, 0.080]
- s_edge: [0.018, 0.022]
- c_cred_half: [0.57, 0.63]
- s_cred: [0.05, 0.06]
- beta: [0.38, 0.46]
- epsilon: [0.035, 0.055]
- validities: validities

**`predict source code`:**
```python
def predict(parameters, state, history):
    # SG-CGD: Small-Gap Composition-Gated Outlier Distrust with a
    # composition-gated edge-credibility ramp, half-depth-floor edition.
    # Stimulus: array of shape (2, n_features); row 0 = option A,
    # row 1 = option B; entries are binary expert ratings (0/1).
    # Each feature j casts a sign vote sign(a_j - b_j), weighted by a
    # subjective trust function of the expert's STATED validity v,
    # evaluated RELATIVE to the panel:
    #   (i) TRUST PLATEAU with shallow tilt: all v in [v_lo, v_hi]
    #       (v_hi just above 0.98, so a 98% expert stays INSIDE the
    #       plateau) get approximately equal weight w_p, with a
    #       within-band tilt so higher-validity cues slightly
    #       outrank lower ones.
    #  (ii) CHANCE FLANK + CONSENSUS GATE: v near 0.5 gets a small
    #       negative weight (-kappa_lo at v=0.5, rising linearly to
    #       the tilted plateau at v_lo). When an above-ceiling claim
    #       is present the flank is gated and chance cues are
    #       PROMOTED to a partial ceiling kappa_gate*w_p.
    # (iii) BOUNDED BASE DISTRUST of the panel-max expert: a
    #       saturating shrinkage toward a SHALLOW floor,
    #         w_base = w_floor + (w_p - w_floor)*exp(-rho_e*E)
    #       with E = max(peaked gap kernel, e_min); the kernel peaks
    #       at gap ~0.088 (steep left wall s_l, wide right shoulder
    #       s_r). The UNIFORM-SKEPTICISM FLOOR e_min is the single
    #       lever moved this round: raised from ~0.15 to ~0.36
    #       (half the rejected overshoot depth), so dense-ladder
    #       and gap-0.05 outliers carry a moderate residual
    #       distrust even where the gap kernel is silent.
    #  (iv) NEAR-KERNEL COMPOSITION AMPLIFICATION (small-gap gate):
    #         comp_near = c_near * sig_gap * L(gap) * G(c_frac)
    #       L is a NARROW Gaussian centered g_near ~ 0.035 (inert for
    #       gap >= 0.07); G is a chance-fraction logistic. The
    #       sig_gap factor is ESSENTIAL and retained: it throttles
    #       the route on dense ladders (gap ~ 0.01), which protects
    #       the cliff-conflict cells from spurious anti-votes.
    #  (v) FAR-FRAUD ROUTE: comp_far = c_far * sig_gap * F(gap) *
    #       G_far(c_frac), F a SHARP logistic at g_far ~ 0.185 with
    #       its own chance gate: closed on every gap 0.09-0.14 panel
    #       tested here, open for far outliers over chance-laden
    #       panels (gap >= ~0.18).
    # (vi) COMPOSITION-GATED EDGE-CREDIBILITY RAMP: for gap >= ~0.075,
    #       cred = c_cred * R(gap) * Q(c_frac), capped at the plateau
    #       value. On a chance-laden panel a well-separated 99%
    #       expert is the only credible voice and is promoted back
    #       toward plateau trust; on a coherent-ladder panel the ramp
    #       stays closed and residual kernel distrust persists.
    # Choice is a low-gain softmax (inverse temperature beta) over
    # the two mirrored scores, plus a uniform lapse (epsilon).
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Expects a (2, n_features) stimulus; got shape {stim.shape}."
        )

    n_features = stim.shape[1]
    val = np.asarray(parameters["validities"], dtype=float)
    if val.shape[0] != n_features:
        raise ValueError(
            f"validities length {val.shape[0]} != n_features {n_features}."
        )

    w_p = float(parameters["w_p"])
    v_lo = float(parameters["v_lo"])
    v_hi = float(parameters["v_hi"])
    tilt = float(parameters["tilt"])
    kappa_lo = float(parameters["kappa_lo"])
    kappa_gate = float(parameters["kappa_gate"])
    lambda_ext = float(parameters["lambda_ext"])
    g0 = float(parameters["g0"])
    s_gap = float(parameters["s_gap"])
    g_star = float(parameters["g_star"])
    s_l = float(parameters["s_l"])
    s_r = float(parameters["s_r"])
    e_min = float(parameters["e_min"])
    w_floor = float(parameters["w_floor"])
    rho_e = float(parameters["rho_e"])
    d_w = float(parameters["d_w"])
    g_near = float(parameters["g_near"])
    s_near = float(parameters["s_near"])
    c_near = float(parameters["c_near"])
    c_half = float(parameters["c_half"])
    s_c = float(parameters["s_c"])
    g_far = float(parameters["g_far"])
    s_far = float(parameters["s_far"])
    c_far = float(parameters["c_far"])
    c_half_far = float(parameters["c_half_far"])
    s_c_far = float(parameters["s_c_far"])
    c_cred = float(parameters["c_cred"])
    g_edge = float(parameters["g_edge"])
    s_edge = float(parameters["s_edge"])
    c_cred_half = float(parameters["c_cred_half"])
    s_cred = float(parameters["s_cred"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    def _sigmoid(x):
        # Numerically stable logistic via the identity
        # sigmoid(x) = 0.5 * (1 + tanh(x / 2)).
        return 0.5 * (1.0 + np.tanh(0.5 * x))

    a, b = stim[0], stim[1]

    # Feature-wise votes: +1 where A wins the feature, -1 where B
    # wins, 0 on ties (a tied cue is uninformative for the pair).
    votes = np.sign(a - b)

    v = np.clip(val, 0.5, 1.0)

    # ---- Panel structure: top validity and its gap to the
    # next-highest DISTINCT validity in the panel. ----
    v_top = float(v.max())
    below = v[v < v_top - 1e-9]
    # If every expert shares the top validity, the panel offers no
    # corroboration ladder; treat the next rung as chance (0.5).
    v_second = float(below.max()) if below.size > 0 else 0.5
    gap = v_top - v_second

    # Outlier = a claim ABOVE the trust ceiling. With v_hi ~ 0.981 a
    # 0.98-topped panel stays INSIDE the trusted plateau; only 99%+
    # claims enter the distrust branch.
    outlier = v_top > v_hi

    if outlier:
        sig_gap = _sigmoid((gap - g0) / s_gap)
    else:
        sig_gap = 0.0

    # ---- (ii): consensus gate for the chance flank. ----
    if outlier:
        gate = lambda_ext + (1.0 - lambda_ext) * float(sig_gap)
    else:
        gate = 0.0

    # ---- (i) + (ii): tilted plateau with a consensus-gated
    # chance flank whose promotion is capped at the PARTIAL
    # ceiling kappa_gate * w_p. ----
    w = np.full(n_features, w_p, dtype=float)
    span = max(v_hi - v_lo, 1e-6)
    plateau = (v >= v_lo) & (v <= v_hi)
    if np.any(plateau):
        # Shallow within-plateau validity gradient: higher-validity
        # experts slightly outrank lower ones while the band remains
        # 'approximately equal'.
        w[plateau] = w_p * (
            1.0 - tilt * (v_hi - v[plateau]) / span
        )
    flank = v < v_lo
    if np.any(flank):
        denom = max(v_lo - 0.5, 1e-6)
        # Flank rises linearly to the TILTED plateau value at v_lo,
        # keeping the weight profile continuous at the band edge.
        w_lo_eff = w_p * (1.0 - tilt)
        w_flank = -kappa_lo + (w_lo_eff + kappa_lo) * np.clip(
            v[flank] - 0.5, 0.0, None
        ) / denom
        # With an above-ceiling claim in the panel, chance cues are
        # counted toward a partial ceiling kappa_gate*w_p rather
        # than inverted (and rather than fully trusted).
        w[flank] = (1.0 - gate) * w_flank + gate * kappa_gate * w_p

    # ---- (iii)-(vi): outlier distrust / credibility architecture. ----
    if outlier:
        # Chance fraction of the panel (share of experts below the
        # trust band) drives both composition gates.
        c_frac = float(np.mean(flank))

        # (iii) Bounded base distrust: saturating shrinkage toward a
        # shallow floor, driven by a peaked kernel in the
        # uncorroborated edge (peak at g_star, steep left wall,
        # wide right shoulder), sitting on the uniform-skepticism
        # floor e_min (RAISED to ~0.36 this round: half the rejected
        # overshoot depth, per the endpoint interpolation).
        width = s_l if gap < g_star else s_r
        E_kernel = float(np.exp(-0.5 * ((gap - g_star) / width) ** 2))
        E = max(E_kernel, e_min)
        w_base = w_floor + (w_p - w_floor) * float(np.exp(-rho_e * E))

        # (iv) Near-kernel composition amplification: fires only in
        # the small-gap regime (L centered g_near, narrow width),
        # only on chance-laden scales (G threshold c_half), and is
        # THROTTLED by sig_gap so dense ladders (gap ~ 0.01, where
        # sig_gap ~ 0.08) are protected from spurious anti-votes.
        L = float(np.exp(-0.5 * ((gap - g_near) / s_near) ** 2))
        G_near = _sigmoid((c_frac - c_half) / s_c)
        comp_near = c_near * float(sig_gap) * L * float(G_near)

        # (v) Far-fraud route: sharp logistic at g_far with its own
        # chance gate; closed on every gap 0.09-0.14 panel tested
        # here, open for far outliers over chance-laden panels.
        F_far = _sigmoid((gap - g_far) / s_far)
        G_far = _sigmoid((c_frac - c_half_far) / s_c_far)
        comp_far = c_far * float(sig_gap) * float(F_far) * float(G_far)

        # (vi) Composition-gated edge-credibility ramp: for
        # well-separated outliers (gap >= ~g_edge) on chance-laden
        # scales, the panel-max expert is promoted back toward
        # plateau trust (capped at w_p); on coherent ladders the
        # ramp stays closed and residual kernel distrust persists.
        R_cred = _sigmoid((gap - g_edge) / s_edge)
        Q_cred = _sigmoid((c_frac - c_cred_half) / s_cred)
        cred = c_cred * float(R_cred) * float(Q_cred)

        # Small bounded extremity term.
        ext = d_w * (v_top - v_hi) / max(1.0 - v_hi, 1e-6)

        w_top = w_base - ext - comp_near - comp_far + cred
        # The outlier is at most as trusted as a plateau expert.
        w_top = min(w_top, w_p)
        # All experts tied at the panel maximum share the same
        # weight (a pair of 0.99 super-experts doubles the vote).
        w[v >= v_top - 1e-9] = w_top

    # Weighted evidence score. B's score is the mirror of A's
    # because every vote is zero-sum across the two options.
    s_a = float(np.dot(w, votes))
    scores = np.array([s_a, -s_a], dtype=float)

    # Numerically stable low-gain softmax. When all cues tie
    # (s_a == 0) the softmax is exactly uniform.
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()

    # Independent lapse: with probability epsilon output a uniform
    # pick over the two options.
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)
```

**`policy source code`:**
```python
def policy(probabilities):
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()  # guard against float drift
    return int(np.random.choice(len(probabilities), p=probabilities))
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
  "metric_source": "def metric(data: pd.DataFrame) -> float:\n    import numpy as np\n\n    # This experiment fixes two 99%-validity experts at feature positions 0 and 1\n    # (validities = [0.99, 0.99, 0.90, 0.85, 0.50 x 9]). The single structural\n    # disagreement between EOBOT and SG-CGD on this panel is the SIGN of the\n    # subjective weight assigned to those 99% experts:\n    #   EOBOT:     w(0.99) in [-0.57, -0.11]  (deep distrust at gap 0.09, c_frac 0.692)\n    #   SG-CGD:    w(0.99) in [+0.10, +0.92]  (credibility ramp promotes it back)\n    # => sign-disjoint by construction.\n    #\n    # Metric: the probability that the subject FOLLOWS a UNANIMOUS double-99\n    # endorsement. On every trial where both 99% experts cast the same sign vote\n    # (both favor A or both favor B), score 1 if the subject chose the\n    # 99-endorsed option, 0 otherwise; average over all such trials. Under\n    # EOBOT (anti-cue) this sits well below 0.5 (~0.37); under SG-CGD\n    # (promoted cue) well above 0.5 (~0.71). The common-currency cues (0.90,\n    # 0.85, gated chance cues, lapse, temperature) are shared between the two\n    # theories, so they shift both predictions equally and do not attenuate the\n    # gap; mirrors in the design balance side orientation. 18 of 32 unique\n    # trials x 3 reps = 54 observations per subject, so the per-subject value\n    # is a stable proportion with small between-subject variance.\n\n    TOP_IDX = (0, 1)  # positions of the two 0.99-validity experts\n\n    vals = []\n    for ra, rb, resp in zip(\n        data[\"option_a_ratings\"],\n        data[\"option_b_ratings\"],\n        data[\"response\"],\n    ):\n        a = np.asarray(ra, dtype=float).ravel()\n        b = np.asarray(rb, dtype=float).ravel()\n        if a.shape[0] < 2 or a.shape != b.shape:\n            continue\n\n        # Sign votes of the two 99% experts (+1 A, -1 B, 0 tie).\n        d = 0\n        for j in TOP_IDX:\n            diff = a[j] - b[j]\n            if diff > 0:\n                d += 1\n            elif diff < 0:\n                d -= 1\n\n        # Only trials where BOTH 99% experts unanimously endorse the same option.\n        if d != 2 and d != -2:\n            continue\n\n        endorsed_A = d > 0\n        r = int(resp)  # 0 = chose A, 1 = chose B\n        followed = (r == 0) if endorsed_A else (r == 1)\n        vals.append(1.0 if followed else 0.0)\n\n    if not vals:\n        return 0.5\n    return float(np.mean(vals))",
  "rationale": "The two theories share every weight on this panel EXCEPT the weight of the two 99%-validity experts, which is sign-disjoint by construction (EOBOT: [-0.57, -0.11]; SG-CGD: [+0.10, +0.92]). The sharpest readout of that single disputed scalar is the rate at which subjects follow a UNANIMOUS double-99 endorsement: on trials where both 99% experts vote for the same option, orient the choice by the endorsed side and average. Under EOBOT the double-99 stack is an anti-cue, so the follow rate is well below 0.5 (design centers across the 18 qualifying unique trials: M1/M4 .39, R0 .24, R1 .34, R2 .46, R3 .58, D1-D3 .21/.30/.41, K1 .49, K2 .26, plus the 99s+2-coins cell ~.63 -> pooled ~0.37). Under SG-CGD the credibility ramp promotes the 99% experts back toward plateau trust, so the follow rate is well above 0.5 (M1/M4 .74, R0 .58, R1-R3 .70/.79/.85, D1-D3 .53/.65/.75, K1 .81, K2 .62 -> pooled ~0.71). The mean gap (~0.33) is far larger than per-subject noise: each subject contributes 54 binary observations (18 unique trials x 3 reps), giving Bernoulli SD ~0.06, and parameter heterogeneity within each theory's box cannot cross the sign boundary (w_top stays negative for every EOBOT parameter setting and positive for every SG-CGD setting on this gap-0.09, c_frac-0.692 panel), so between-subject SD stays ~0.07-0.09. With N=25, Welch's t is ~13-16 (p << 0.001). The metric is a simple proportion, so it is equally well defined on the pooled DataFrame and on each single subject's slice. All shared machinery (plateau weights ~0.88, gated chance weight ~0.62, beta, epsilon) cancels because it is common currency: it shifts both theories' follow rates identically and does not shrink the contrast. Side orientation is balanced by the mirror trials included in the qualifying set (t1/t2, t6/t7, t8/t12, t10/t13, t19/t21, t23/t24), and trials where the 99s tie or split (T1, X, Z, G families) are excluded because the disputed weight contributes exactly zero there."
}
```

## Usage

```json
{
  "input_tokens": 15364,
  "output_tokens": 23424,
  "reasoning_tokens": 22075,
  "provider": "Sail Research"
}
```
