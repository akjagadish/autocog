# generation_iter_07_attempt_01

## System Prompt

You are a renowned cognitive scientist and an expert Python programmer.

Your job is to propose a new theory and its model instantiation in the Decision Making (Binary Features) domain based on the feedback provided by an arbiter. The feedback contains diagnoses of mechanistic failures of the previous theory along with suggestions for a new theory family that overcomes those failures. The newly proposed theory and model should display human-like behavior when simulated on experiment(s). 
The goal of the theory generation process is to SURFACE theories that are EXPERIMENT-INVARIANT: that is,theories that explain data across the majority of experiments. 
You will see a list of theories that have been proposed in the past but you should only use them as inspiration and not to choose from them. Propose a new theory that is different. 
If they fail to do so, you will receive feedback on their performance on the same experiment(s) and you will have to propose another new theory and model that meet the requirements, iterating until you succeed.

If you think the failure to capture human behavior is due to arbiter feedback that is inaccurate or unhelpful, you can propose a new theory and model that ignore the feedback, but you must provide rationale for why you are ignoring it and how your proposal overcomes the identified mechanistic failures.

## ACCEPT GATE & LOSS TRAJECTORY — HOW THE LOOP HANDLES YOUR EDITS
This propose-loop has a programmatic accept gate: after every iteration the candidate's `aggregate_loss` is compared against the running-best loss; strict improvement -> ACCEPTED (the candidate becomes the new running-best base); otherwise -> REJECTED (the candidate is discarded and the base is unchanged). You do NOT need to manually "revert" a regressed edit — the gate already does that for you.

The block rendered below as `## PREVIOUS CANDIDATE (this loop)` is ALWAYS the running-best (last ACCEPTED) candidate, NEVER your most recent attempt if it was rejected. So:
  * Treat `## PREVIOUS CANDIDATE` as a known-good base. Build on it.
  * The `## LOSS TRAJECTORY` block tags every iteration ACCEPTED or REJECTED. Use this as ground truth on which past critic advice actually moved the loop forward and which didn't.
  * The `## PRIOR FEEDBACK ITERATIONS` block annotates each prior critique with the same ACCEPTED/REJECTED tag of the candidate it elicited. Down-weight critic advice whose previous candidates were REJECTED, and reinforce / extend advice whose candidates were ACCEPTED.
  * Treat the best ACCEPTED iteration's loss as a soft floor — the next edit should plausibly land at-or-below it, otherwise the gate will reject your attempt and the base stays put.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

## PARAMETER NOTATION
`parameters` is a JSON object mapping each parameter name (snake_case string) to a *string* value that specifies its domain. Every value MUST be a string — never a bare list, number, tuple, or expression. Use exactly one of these notations per parameter:

1. Continuous interval — square brackets, two numeric bounds:
   "[min, max]"
   Examples: "[0, 1]", "[1.0, 10.0]", "[10, 1000]"

2. Discrete set — curly braces, comma-separated values:
   "{v1, v2, ...}"
   Example: "{1, 2}"

3. Vector of intervals whose length is set by the experiment — a bracketed tuple repeated by a symbolic length variable:
   "[(min, max)] * length_var"
   Example: "[(0, 1)] * n_features"

4. Symbolic reference — a bare variable name (no brackets, no angle brackets), used when the parameter takes its value from an experiment-defined constant rather than a range:
   "variable_name"
   Example: "n_features"

Rules:
- Do not use parentheses for intervals; square brackets only. Tuples `(a, b)` are reserved for the vector-of-intervals notation in (3).
- Do not mix notations within a single value (e.g., no "[0, 1] or {2, 3}").
- Do not quote numbers inside the notation (write "[0, 1]", not "['0', '1']").
- Every parameter referenced by `predict` or `policy` must appear as a key in `parameters`, and vice versa.
- Notations 3 and 4 may ONLY reference the experiment-defined symbolic identifiers listed under "ALLOWED SYMBOLIC IDENTIFIERS" below. Do not invent new identifier names. If a parameter's shape doesn't fit any of those variables, fall back to a literal interval (notation 1) or discrete set (notation 2). Use these names so the model adapts to any experiment in this domain instead of hardcoding shapes.

## ALLOWED SYMBOLIC IDENTIFIERS (for notations 3 and 4 above)
- n_features: Number of expert ratings per option (LLM-proposed via `validities` length).
- validities: Per-expert validities (LLM-proposed; each in [0.5, 1.0]); fixed across all trials.

## AVAILABLE IMPORTS inside `predict` and `policy`
- numpy as np
- pandas as pd
- scipy and its submodules
- torch and torch.nn.functional as F
- sklearn and its submodules
- math, random, and other standard Python libraries

## RUNTIME CONTRACT (function signatures and argument shapes)
`predict(parameters, state, history) -> np.ndarray`:
- `parameters`: dict[str, value]. One sample drawn from your declared `parameters` ranges, applied for the entire subject run.
- `state`: the per-trial input delivered by the experiment (shape is domain-specific — see the experiment description above and the `history` key list below, which mirrors the per-trial variables carried in `state`). Convert to an array with `np.asarray(state)` if you need array ops.
- `history`: dict-of-lists for past trials in this subject's run, NOT a list-of-dicts. The per-trial keys are:
  Each value below is a Python list in trial order; entry `i` is the value for trial `i`. On the first trial all lists are empty.
  - `"option_a_ratings"`: List of n_features binary expert ratings (each 0 or 1) for option A on this trial.
  - `"option_b_ratings"`: List of n_features binary expert ratings (each 0 or 1) for option B on this trial.
  - `"response"`: 0 if subject chose A, 1 if subject chose B.
Iterating `for x in history:` iterates the dict KEYS (strings); to walk trials index the lists in lock-step, e.g. `for i in range(len(next(iter(history.values())))): ...`.
- Returns: 1-D `np.ndarray` of choice probabilities over the experiment's discrete action set, summing to 1.

`policy(probs) -> int`:
- Receives the probability vector produced by `predict`.
- Returns: integer index in `[0, len(probs))` identifying the chosen action. If you sample with `np.random.choice(..., p=probs)`, normalise first (`probs = np.asarray(probs, dtype=np.float64); probs /= probs.sum()`) to avoid the "probabilities do not sum to 1" ValueError from float drift.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

Each subject completes ~96 trials in a single block, with order randomized independently per subject. On every trial the subject sees two options A and B, each described by `n_features` binary expert ratings (each 0 or 1). The per-feature validities and n_features are fixed per experiment (design-time choices). Validities are communicated to the subject in the instructions. Both `n_features` and `validities` are exposed to your `predict` via the `parameters` dict. The subject chooses A or B; no correctness feedback is provided after the choice.

## ARBITER GUIDE
The arbiter labelled this round's two theories in its recommendation as follows:
- THEORY 1 = `pi_3_1`
- THEORY 2 = `pi_6`
- The recommendation below acts on THEORY 1 (= `pi_3_1`).

Replace THEORY 1 (SCWI) with a new theory, tentatively 'Compressive Anti-Validity Integration with a Moderate Deterministic Tail' (CAVI), designed as a stronger competitor to CNNAI rather than a return of SCWI. Mechanism sketch: (1) Keep the sign inversion — a rating of 1 is comprehended as a defect, per-cue defect magnitude d_j = v_j + tau*v_j^2 with tau in [0.35, 0.65] (a wider, higher range than SCWI's, needed for Experiment 1's +2.88 near-knife excess). (2) NEW: within-option diminishing sensitivity — the option's subjective defect load is D = (sum_j d_j * x_j)^kappa with kappa in [0.55, 0.85] (or equivalently a log-compressive map), so an option's value is -D. Small stacks (near-knife cells like AL, S-cells, M-cells) keep near-linear sharp margins, while large stacked endorsements grow sub-proportionally aversive — this flattens the high-ratio psychometrics that both current theories overshoot (Exp 10's 5x0.90-vs-11x0.50 kill cells down toward 0.60, Exp 12's rise down toward 0.30, Exp 4's disagreement-vs-agreement gap up toward 0.27 because compressed margins sit closer to the noise scale). (3) Population mixture: ~14% true guessers (beta ~ 0.02-0.10), ~70% engaged with lognormal beta (median ~2.0, log-sd 0.35, clipped [0.8, 6.0]), and ~16% deterministic tail (beta uniform [4.0, 6.5], lapse 0.02-0.04) — this reproduces Experiment 2's g ≈ 0.09 (a small but nonzero near-ceiling bloc, refuting both CNNAI's 0.00 and SCWI's 0.36) while keeping population means CNNAI-like on Exps 5-9. (4) Context elasticity retained but recalibrated: per-bucket eta redraw keyed on the rounded mean endorsed validity (as in CNNAI), with the stable-to-redraw variance ratio set for latent cross-context consistency r ≈ 0.20-0.25, matching Experiment 11's observed 0.196 between SCWI's 0.37 and CNNAI's 0.11. (5) Softmax(beta * (D_B - D_A)) plus symmetric lapse (0.03-0.09 engaged) and per-trial attention diffusion (sd ~0.05). This theory differs from SCWI by the compressive nonlinearity, the smaller deterministic bloc, and the context-keyed elasticity; it differs from CNNAI by the stronger supralinear per-cue contrast, the explicit deterministic tail, and the compression that CNNAI lacks. Parameter ranges should be tuned so that: Exp 1 AL excess lands in [+2.4, +3.2]; Exp 2 g in [0.06, 0.15]; Exp 10 kill-composite in [0.55, 0.65]; Exp 12 rise in [0.22, 0.36]; Exp 11 cross-ladder correlation in [0.15, 0.30].

## THEORY LEADERBOARD
A small set of prior picked theories shown for reference. Overall score is in `[0, 1]`, higher = better, computed as `1 - L2_norm(normalized_per_experiment_distances) / max_L2_norm`. 1.0 means closest to the real value on every experiment+metric pair; 0.0 means farthest. Each entry below carries the same depth of detail as the PREVIOUS MODEL INSTANCE above so you can borrow concrete mechanisms when useful.

### `pi_3` (overall score: 0.858)

**Description**
Signed-Cue Weighted Integration (SCWI). When choosing between two options described by binary expert ratings, subjects do not use a lexicographic cascade (TTB) and do not merely count wins (Tallying). Instead they integrate ALL cues additively into a single subjective value per option — but the mapping from a rating to evidence carries a systematic SIGN INVERSION: a rating of 1 is treated as a defect/criticism rather than an endorsement (a comprehension inversion of the rating direction). Moreover, the inversion is not uniform across cues: the subjective weight of cue j is w_j = -(v_j + tau * v_j^2), i.e. an anti-validity weighting that grows SUPRALINEARLY with the instructed validity — the endorsements of the most trusted experts are avoided most strongly, while low-validity experts are nearly ignored (their anti-weight is small in magnitude). The option with the higher (less negative) signed value is preferred, with softmax noise (inverse temperature beta) and an independent lapse (epsilon) capturing response variability. This single task-invariant mechanism predicts both experimental signatures simultaneously: in Experiment 1, the top-cue-favored option carries more 1s and hence more 'defects', so P(choose the top-cue-favored option) DECREASES with its tally margin (negative slope); in Experiment 2, on margin-1 trials where TTB and the tally disagree the two options' signed values are close together (so noise frequently flips the subject onto the tally winner), whereas when they agree the value gap is large (so the subject reliably anti-follows) — yielding p_disagree > p_agree, a positive metric.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    # Signed-Cue Weighted Integration (SCWI).
    # Stimulus: array-like of shape (2, n_features); row 0 = option A,
    # row 1 = option B; entries are binary expert ratings.
    # Each cue contributes signed evidence w_j = -(v_j + tau * v_j^2)
    # per unit rating (anti-validity weighting, supralinear in the
    # instructed validity). Option values are the cue-weighted sums;
    # choice is a numerically stable softmax over beta * values, mixed
    # with a symmetric lapse. History is ignored (no feedback).
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"SCWI expects a (2, n_features) stimulus; got shape {stim.shape}."
        )
    n_features = stim.shape[1]

    raw = parameters.get("validities")
    if isinstance(raw, str):
        s = raw.strip().strip('[]()')
        val = np.array([float(t) for t in s.replace(',', ' ').split()])
    else:
        val = np.asarray(raw, dtype=float).ravel()
    if val.size != n_features:
        # Defensive fallback: uniform mid-range validities.
        val = np.full(n_features, 0.75)

    beta = float(parameters["beta"])
    tau = float(parameters["tau"])
    epsilon = float(parameters["epsilon"])

    # Signed (anti-validity) cue weights: a rating of 1 is evidence
    # AGAINST an option, and the inversion strength grows supralinearly
    # with the instructed validity of the expert.
    w = -(val + tau * np.square(val))

    scores = np.array([float(np.dot(w, stim[0])), float(np.dot(w, stim[1]))])

    # Numerically stable softmax over the two option values.
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()

    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)

`policy(probs) -> int`:
def policy(probabilities):
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()  # Guard against float drift.
    return np.random.choice(len(probabilities), p=probabilities)

`parameters`:
- beta: [1.1, 1.7]
- tau: [0.25, 0.45]
- epsilon: [0.05, 0.15]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=-0.1747 (var=0.0108) vs this=-0.1877 (var=0.0014)
- Experiment 2: real=0.2737 (var=0.0930) vs this=0.1862 (var=0.0095)
- Experiment 3: real=0.1227 (var=0.0008) vs this=0.1378 (var=0.0002)
- Experiment 4: real=0.1625 (var=0.0119) vs this=0.1608 (var=0.0029)
- Experiment 5: real=0.6837 (var=0.0643) vs this=0.5531 (var=0.0069)
- Experiment 6: real=0.6300 (var=0.0703) vs this=0.5687 (var=0.0053)
- Experiment 7: real=0.6462 (var=0.0395) vs this=0.6412 (var=0.0050)
- Experiment 8: real=0.6044 (var=0.0653) vs this=0.6056 (var=0.0099)
- Experiment 9: real=0.1963 (var=0.0601) vs this=0.2390 (var=0.0208)
- Experiment 10: real=0.2963 (var=0.0806) vs this=0.3713 (var=0.0215)
- Experiment 11: real=2.8800 (var=0.0015) vs this=1.0800 (var=0.0009)
- Experiment 12: real=0.0913 (var=0.0729) vs this=0.0000 (var=0.0000)


---

### `pi_6` (overall score: 0.842)

**Description**
Context-Normalized Noisy Anti-Validity Integration (CNNAI), knife-avoidance recalibration. Subjects integrate all binary expert ratings additively into a per-option value, but a rating of 1 is comprehended as a DEFECT (sign inversion). The anti-weight of expert j is context-normalized: w_j = -v_j * (v_j / v_ref)^eta, where v_ref is the mean instructed validity of the cues endorsed on the current trial and eta is a per-context elasticity drawn at the level of coarse validity CONTEXT BUCKETS (the mean endorsed validity rounded to 0.1), so all trials sharing a bucket inherit one shared per-subject draw. The elasticity decomposes into a small stable per-subject component (eta_base ~ N(0.02, 0.09)) and a larger per-bucket redraw (~N(0.10, 0.19)), total hard-clipped to [-0.25, 0.70]; the variance ratio fixes latent cross-context consistency at r ~ 0.18 by construction. The engaged eta distribution (mean ~0.12, sd ~0.21) is deliberately centered well BELOW the kill-design knife region (eta ~ 0.31-0.34 where high-validity stacks flip to low-validity stacks), so the engaged bulk behaves SCWI-like in effective curvature while margins on the below-knife side stay large. A modest per-trial multiplicative attention diffusion (sd 0.05) supplies within-context stochasticity, choice is softmax(beta * values) with nearly homogeneous engaged beta (lognormal median ~2.14, log-sd 0.20) plus a narrow symmetric lapse (0.03-0.09), and a 13% true-guesser subpopulation is retained, uncorrelated with eta.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    # Context-Normalized Noisy Anti-Validity Integration (CNNAI),
    # iter 6 -- knife-avoidance recalibration of the accepted iter-5 base
    # per the iter-5 critic diagnosis. Mechanism family UNCHANGED:
    # additive anti-validity integration, context-referenced elasticity
    # w_j = -v_j * (v_j / v_ref)^eta with v_ref = mean validity of the
    # endorsed cues, per-trial attention diffusion, softmax + symmetric
    # lapse, guesser mixture. Changes vs the accepted iter-5 base:
    #   (A) ETA CENTER LOWERED 0.23 -> 0.12 (eta_base ~ N(0.02, 0.09) plus
    #       per-context redraw ~ N(0.10, 0.19), total clipped [-0.25, 0.70]).
    #       The kill composites (Exps 5/6/8) are near-knife statistics:
    #       their flip knives sit at eta ~ 0.30-0.34, and on the
    #       below-knife side the score margins GROW as eta decreases
    #       (e.g. Exp 5's 2x1.00-vs-5x0.50 cell: margin 0.14 at eta 0.23
    #       vs 0.33 at eta 0.10). Centering at 0.12 both moves engaged
    #       mass below the knives (P(eta < 0.33) ~ 0.83) and enlarges
    #       the margins, lifting the undershooting composites.
    #   (B) ATTENTION DIFFUSION CUT 0.10 -> 0.05: at 0.10 the per-trial
    #       margin noise (sd ~ 0.25 on a 12-cue cell) was comparable to
    #       the near-knife signals (~0.15-0.35), damping below-knife
    #       subjects to p ~ 0.55-0.6 -- the main softening channel on
    #       Exps 5/6/8. Per-trial noise averages out within a subject
    #       (iter-2 critic), so cutting it lifts means without touching
    #       between-subject variance.
    #   (C) CONTEXT KEY COARSENED to the mean endorsed validity rounded
    #       to 0.1 (a bucketed v_ref / ladder identifier). The critic's
    #       'rounded MAX endorsed validity' variant was NOT used: both
    #       Exp-9 ladders ({1.00,0.50} and {1.00,0.60} cells) have max
    #       validity 1.0, so a max-based key would map them to the SAME
    #       draw and re-couple them -- recreating the iter-1 r = 0.44
    #       failure the critic itself warns against. Bucketed mean keeps
    #       them distinct (0.6 vs 0.7) while merging within-experiment
    #       fragmentation (Exp 2: ~2-3 keys instead of ~6; Exp 5: 2 keys),
    #       so per-subject composites stop averaging over many
    #       independent eta draws.
    #   (D) EXP-9 COUPLING CHANNELS CLOSED: engaged epsilon narrowed
    #       0.02-0.17 -> 0.03-0.09 (stable lapse was the dominant
    #       residual cross-ladder trait), eta_base sd cut 0.13 -> 0.09
    #       (latent r = 0.0081/(0.0081+0.0361) ~ 0.18), beta median
    #       trimmed 2.34 -> 2.14 with log-sd 0.25 -> 0.20 (guards Exps
    #       1/3/10 against the noise cut, and removes the last sizeable
    #       stable-trait correlation channel).
    #   (E) v_ref STAYS MEAN-REFERENCED (not max): the weight ratio
    #       w(v_h)/w(v_l) = (v_h/v_l)^(1+eta) is invariant to v_ref, and
    #       max-referencing multiplies every margin by v_max^(-eta) <= 1,
    #       which would DEFLATE exactly the near-knife margins the
    #       composites need. The critic's goal (steeper high-validity
    #       region) is achieved via (A)+(B) instead.
    import hashlib
    import math
    import numpy as np
    from scipy.special import ndtri

    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"CNNAI expects a (2, n_features) stimulus; got shape {stim.shape}."
        )
    n_features = stim.shape[1]
    ra, rb = stim[0], stim[1]

    def _to_vec(raw):
        if raw is None:
            return None
        if isinstance(raw, str):
            s = raw.strip().strip('[]()')
            toks = [t for t in s.replace(',', ' ').split() if t != '']
            if not toks:
                return None
            return np.array([float(t) for t in toks])
        arr = np.asarray(raw, dtype=float).ravel()
        return arr if arr.size > 0 else None

    val = _to_vec(parameters.get("validities"))
    if val is None or val.size != n_features:
        # Defensive fallback: uniform mid-range validities.
        val = np.full(n_features, 0.75)
    val = np.clip(val, 1e-3, 1.0)

    def _seed(name):
        try:
            x = float(parameters[name])
        except (KeyError, TypeError, ValueError):
            x = 0.5
        if not np.isfinite(x):
            x = 0.5
        return min(max(x, 0.0), 1.0)

    u = _seed("regime_seed")
    es = _seed("eta_base_seed")
    bs = min(max(_seed("beta_seed"), 1e-6), 1.0 - 1e-6)
    ps = _seed("epsilon_seed")
    ss = _seed("subject_seed")

    # --- Population mixture (uncorrelated with eta). ---
    if u < 0.13:
        # Guesser subpopulation (~13%): beta ~ 0 -> uniform core on
        # every trial; elevated lapse. These subjects sit at ~0.5 on
        # every diagnostic cell and dilute population means/slopes.
        t = u / 0.13
        beta = 0.02 + 0.08 * t            # 0.02 .. 0.10
        epsilon = 0.12 + 0.13 * ps       # 0.12 .. 0.25
        eta_base = 0.10                  # irrelevant at beta ~ 0
    else:
        # Engaged subpopulation (~87%). Small stable elasticity
        # component (sd 0.09) paired with a larger per-context redraw
        # (sd 0.19): the variance ratio fixes latent cross-context
        # consistency at r ~ 0.18 by construction. The stable lapse
        # range is NARROW (0.03-0.09) so it can no longer act as a
        # hidden coupling channel across contexts, and beta is nearly
        # homogeneous (lognormal sd 0.20).
        zs = min(max(es, 1e-6), 1.0 - 1e-6)
        eta_base = 0.02 + 0.09 * float(ndtri(zs))
        eta_base = min(max(eta_base, -0.15), 0.20)

        beta = math.exp(0.76 + 0.20 * float(ndtri(bs)))  # median ~2.14
        beta = min(max(beta, 0.9), 4.5)
        epsilon = 0.03 + 0.06 * ps       # 0.03 .. 0.09

    # --- Context: bucketed mean endorsed validity. ---
    active = np.flatnonzero((ra > 0.5) | (rb > 0.5))
    if active.size == 0:
        # Nothing endorsed by either option: no evidence either way.
        return np.full(2, 0.5)

    # v_ref = mean validity of the cues actually displayed (endorsed)
    # this trial; the context key is v_ref rounded to one decimal, so
    # all cells of one validity ladder share a single per-subject eta
    # draw while different ladders (e.g. Exp 9's 0.50-ladder at bucket
    # 0.6 vs its 0.60-ladder at bucket 0.7) draw independently.
    v_ref = float(np.mean(val[active]))
    bucket = float(np.round(v_ref, 1))
    key = f"{bucket:.1f}"
    h = int(hashlib.md5(f"{ss:.9f}|{key}".encode("utf-8")).hexdigest()[:14], 16)
    uc = ((h % 999983) + 0.5) / 999984.0
    uc = min(max(uc, 1e-6), 1.0 - 1e-6)

    # Per-context redraw, centered low so the engaged bulk sits below
    # the kill knives (~0.31-0.34) with large below-knife margins:
    # engaged eta ~ N(0.12, 0.21), P(eta < 0.33) ~ 0.83.
    eta_ctx = eta_base + 0.10 + 0.19 * float(ndtri(uc))
    eta_ctx = min(max(eta_ctx, -0.25), 0.70)

    # Context-normalized anti-validity weights.
    w = -val * np.power(val / v_ref, eta_ctx)

    # Per-trial multiplicative attention diffusion on cue weights,
    # sd cut 0.10 -> 0.05: at 0.10 the margin noise on near-knife cells
    # was comparable to the signal and was the main softening channel
    # on the Exp 5/6/8 composites.
    att = np.exp(0.05 * np.random.randn(n_features))
    w = w * att

    scores = np.array([float(np.dot(w, ra)), float(np.dot(w, rb))])

    # Numerically stable softmax over the two option values.
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()

    return (1.0 - epsilon) * p_core + epsilon * 0.5 * np.ones(2)

`policy(probs) -> int`:
def policy(probabilities):
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()  # Guard against float drift.
    return np.random.choice(len(probabilities), p=probabilities)

`parameters`:
- subject_seed: [0, 1]
- regime_seed: [0, 1]
- eta_base_seed: [0, 1]
- beta_seed: [0, 1]
- epsilon_seed: [0, 1]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=-0.1747 (var=0.0108) vs this=-0.1968 (var=0.0072)
- Experiment 2: real=0.2737 (var=0.0930) vs this=0.1650 (var=0.0201)
- Experiment 3: real=0.1227 (var=0.0008) vs this=0.1497 (var=0.0011)
- Experiment 4: real=0.1625 (var=0.0119) vs this=0.1342 (var=0.0135)
- Experiment 5: real=0.6837 (var=0.0643) vs this=0.6150 (var=0.0208)
- Experiment 6: real=0.6300 (var=0.0703) vs this=0.6208 (var=0.0179)
- Experiment 7: real=0.6462 (var=0.0395) vs this=0.6581 (var=0.0250)
- Experiment 8: real=0.6044 (var=0.0653) vs this=0.7011 (var=0.0213)
- Experiment 9: real=0.1963 (var=0.0601) vs this=0.1113 (var=0.0229)
- Experiment 10: real=0.2963 (var=0.0806) vs this=0.3438 (var=0.0509)
- Experiment 11: real=2.8800 (var=0.0015) vs this=0.3200 (var=0.0016)
- Experiment 12: real=0.0913 (var=0.0729) vs this=0.0000 (var=0.0000)


---

### `pi_5` (overall score: 0.638)

**Description**
Heterogeneous-Elasticity Anti-Validity Integration (HEAI), bimodal-population refinement. Subjects integrate ALL expert ratings additively into a per-option subjective value, but a rating of 1 is comprehended as a DEFECT (evidence against the option) — a sign inversion of the rating direction. The anti-weight of expert j is a per-subject power law of the instructed validity, w_j = -v_j^gamma, where gamma ('validity elasticity') is drawn from a BIMODAL continuous population: a shallow majority (75% of engaged subjects, gamma ~ N(1.04, 0.22) truncated [0.60, 1.42]) that sits cleanly below the kill-design count-ratio thresholds (~1.31-1.34) and therefore follows the high-validity stack, and a steep minority (25% of engaged subjects, gamma ~ N(2.10, 0.26) truncated [1.65, 2.75]) that sits cleanly above them, whose near-lexicographic top-cue dominance drives the Exp-2 dissociation and keeps the Exp-8/Exp-4 composites from overshooting. Inverse temperature is mode-linked (shallow: lognormal median ~2.6; steep: lognormal median ~3.3; both heavy-tailed), a 16% guesser subpopulation (beta ~ 0) and a symmetric lapse epsilon are retained unchanged. The population mean elasticity (~1.30) stays below the arbiter's 1.4 ceiling. The key change from the falsified wide-unimodal shape is that almost no mass is wasted in the ambiguous 1.2-1.6 band where subjects sit at chance on the diagnostic cells: the shallow mode's thin upper shoulder (1.32-1.42) is retained deliberately, because subjects just above the kill thresholds miss Exp 8 while still hitting the higher-threshold Exp 5/7 ladder cells — the lever that lets Exp 8's mean and variance stay calibrated without capping Exp 5/6/7.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    # Heterogeneous-Elasticity Anti-Validity Integration (HEAI), iter 3.
    # Stimulus: array-like of shape (2, n_features); row 0 = option A,
    # row 1 = option B; entries are binary expert ratings.
    # Mechanism (UNCHANGED from the accepted iter-2 base): every cue
    # contributes signed evidence w_j = -v_j**gamma per unit rating
    # (a rating of 1 is a defect; the anti-weight is a per-subject
    # power law of the instructed validity). Choice is a numerically
    # stable softmax over beta * option values, mixed with a symmetric
    # lapse epsilon. History is ignored (no trial-by-trial feedback).
    #
    # Population edits on top of the accepted iter-2 base (mechanism
    # untouched), implementing the iter-2 critic's diagnosis that a
    # wide UNIMODAL gamma dumps its spread into the ambiguous
    # threshold band (gamma ~ 1.2-1.6) where subjects sit at ~chance
    # on every diagnostic cell, capping the means on BOTH sides:
    #   * GAMMA MADE BIMODAL: the engaged population is now a mixture
    #     of a SHALLOW majority (75%: N(1.04, 0.22) trunc [0.60, 1.42])
    #     and a STEEP minority (25%: N(2.10, 0.26) trunc [1.65, 2.75]),
    #     with minimal mass in between. The shallow mode sits cleanly
    #     below the kill-design count-ratio thresholds (~1.31-1.34 on
    #     Exp 8; ~1.32+ on the Exp 5 ladder), so it drives high-stack
    #     adherence on Exp 5/6/7/8; its thin upper shoulder (1.32-1.42,
    #     ~10% of the mode) deliberately remains to keep Exp 8's mean
    #     and between-subject variance calibrated. The steep mode sits
    #     cleanly above ~1.8 (critic's prescription; extends to 2.75 so
    #     the top cue can dominate three lower cues), which is what
    #     lifts the Exp 2 dissociation mean/variance and holds Exp 4
    #     down. Population mean elasticity ~ 1.30 < 1.4 (arbiter box).
    #   * BETA MODE-LINKED AND HOTTER: shallow subjects draw lognormal
    #     beta, median exp(0.95) ~ 2.6 (up from ~2.3), sigma 0.70,
    #     clip [0.6, 7.0]; steep subjects draw a hotter lognormal,
    #     median exp(1.20) ~ 3.3, sigma 0.60, clip [1.2, 8.0] (the
    #     steep 'confident lexicographic' subjects are also the
    #     sharpest). Hotter shallow beta sharpens engaged adherence on
    #     Exp 5/6/7; hotter steep beta maximizes the Exp 2 contribution
    #     per steep subject while pushing steep Exp 8/Exp 4 hits down.
    #   * Guesser fraction (16%), epsilon ranges, seeds, and everything
    #     else are untouched.
    import math
    import numpy as np
    from scipy.special import ndtri

    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"HEAI expects a (2, n_features) stimulus; got shape {stim.shape}."
        )
    n_features = stim.shape[1]

    def _to_vec(raw):
        if raw is None:
            return None
        if isinstance(raw, str):
            s = raw.strip().strip('[]()')
            toks = [t for t in s.replace(',', ' ').split() if t != '']
            if not toks:
                return None
            return np.array([float(t) for t in toks])
        arr = np.asarray(raw, dtype=float).ravel()
        return arr if arr.size > 0 else None

    val = _to_vec(parameters.get("validities"))
    if val is None or val.size != n_features:
        # Defensive fallback: uniform mid-range validities.
        val = np.full(n_features, 0.75)
    val = np.clip(val, 1e-3, 1.0)

    def _seed(name):
        try:
            x = float(parameters[name])
        except (KeyError, TypeError, ValueError):
            x = 0.5
        if not np.isfinite(x):
            x = 0.5
        return min(max(x, 0.0), 1.0)

    u = _seed("regime_seed")
    # Keep CDF seeds strictly inside (0, 1) so ndtri stays finite.
    gs = min(max(_seed("gamma_seed"), 1e-6), 1.0 - 1e-6)
    bs = min(max(_seed("beta_seed"), 1e-6), 1.0 - 1e-6)
    es = _seed("epsilon_seed")

    if u < 0.16:
        # Guesser subpopulation (~16%): beta ~ 0 makes the softmax core
        # essentially uniform on every trial; lapse is elevated.
        t = u / 0.16
        beta = 0.02 + 0.08 * t          # 0.02 .. 0.10
        epsilon = 0.12 + 0.13 * es      # 0.12 .. 0.25
        gamma = 1.12                    # irrelevant at beta ~ 0
    else:
        if gs < 0.75:
            # SHALLOW majority (~75% of engaged): gamma ~ N(1.04, 0.22)
            # truncated to [0.60, 1.42]. Cleanly below the kill-design
            # thresholds (~1.31-1.34), with a thin upper shoulder that
            # keeps Exp 8's mean/variance calibrated.
            t = gs / 0.75
            tt = min(max(t, 1e-4), 1.0 - 1e-4)
            gamma = 1.04 + 0.22 * float(ndtri(tt))
            gamma = min(max(gamma, 0.60), 1.42)

            # Hot shallow beta: lognormal median ~2.6, heavy tail.
            z_b = float(ndtri(bs))
            beta = math.exp(0.95 + 0.70 * z_b)
            beta = min(max(beta, 0.6), 7.0)
        else:
            # STEEP minority (~25% of engaged): gamma ~ N(2.10, 0.26)
            # truncated to [1.65, 2.75]. Cleanly above ~1.8 so the top
            # cue can dominate three lower cues (the Exp 2 lever).
            t = (gs - 0.75) / 0.25
            tt = min(max(t, 1e-4), 1.0 - 1e-4)
            gamma = 2.10 + 0.26 * float(ndtri(tt))
            gamma = min(max(gamma, 1.65), 2.75)

            # Steep subjects are also sharper: lognormal median ~3.3.
            z_b = float(ndtri(bs))
            beta = math.exp(1.20 + 0.60 * z_b)
            beta = min(max(beta, 1.2), 8.0)

        # Symmetric lapse for engaged subjects (unchanged).
        epsilon = 0.03 + 0.14 * es      # 0.03 .. 0.17

    # Anti-validity power-law cue weights: a rating of 1 counts AGAINST
    # the option, with magnitude v_j**gamma.
    w = -np.power(val, gamma)

    scores = np.array([float(np.dot(w, stim[0])), float(np.dot(w, stim[1]))])

    # Numerically stable softmax over the two option values.
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()

    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)

`policy(probs) -> int`:
def policy(probabilities):
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()  # Guard against float drift.
    return np.random.choice(len(probabilities), p=probabilities)

`parameters`:
- regime_seed: [0, 1]
- gamma_seed: [0, 1]
- beta_seed: [0, 1]
- epsilon_seed: [0, 1]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=-0.1747 (var=0.0108) vs this=-0.1898 (var=0.0057)
- Experiment 2: real=0.2737 (var=0.0930) vs this=0.1550 (var=0.0256)
- Experiment 3: real=0.1227 (var=0.0008) vs this=0.1165 (var=0.0040)
- Experiment 4: real=0.1625 (var=0.0119) vs this=0.1979 (var=0.0276)
- Experiment 5: real=0.6837 (var=0.0643) vs this=0.6019 (var=0.0710)
- Experiment 6: real=0.6300 (var=0.0703) vs this=0.7004 (var=0.0351)
- Experiment 7: real=0.6462 (var=0.0395) vs this=0.6056 (var=0.0640)
- Experiment 8: real=0.6044 (var=0.0653) vs this=0.6122 (var=0.0654)
- Experiment 9: real=0.1963 (var=0.0601) vs this=0.9529 (var=0.0191)
- Experiment 10: real=0.2963 (var=0.0806) vs this=0.1713 (var=0.0509)
- Experiment 11: real=2.8800 (var=0.0015) vs this=0.7200 (var=0.0008)
- Experiment 12: real=0.0913 (var=0.0729) vs this=0.0823 (var=0.0589)


## LOSS TRAJECTORY (this propose-loop)
Aggregate loss across iterations of THIS propose-loop (lower = better, 0 = perfect, `+inf` = unscorable). The ACCEPTED / REJECTED tag is the loop's programmatic accept-gate decision — only ACCEPTED candidates have ever been used as the base for a subsequent iteration. Use this together with PRIOR FEEDBACK ITERATIONS below to grade which past critic advice actually paid off.

- iter 1: loss=0.1319 -> ACCEPTED
- iter 2: loss=0.1783 -> REJECTED
- iter 3: loss=0.1705 -> REJECTED
- iter 4: loss=0.1231 -> ACCEPTED
- iter 5: loss=0.1030 -> ACCEPTED
- iter 6: loss=0.1465 -> REJECTED
- iter 7: loss=0.1276 -> REJECTED
Running-best (last ACCEPTED) base: iter 5 at loss=0.1030 — this is the source shown verbatim below under `## PREVIOUS CANDIDATE (this loop)`. Push the next edit's loss strictly below that floor or the gate will reject it.

## EXPERIMENTAL RESULTS
### Experiment 1
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[0, 0, 1, 0, 0]
  A=[1, 0, 1, 0, 1]  B=[1, 0, 1, 0, 1]
  A=[0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Slope of P(choose the top-cue-favored option) regressed on the
    # tally margin of that favored option, across all trials where the
    # highest-validity discriminating cue exists (ties like trials 17/18
    # are skipped). Under TTB this probability is flat in the tally margin
    # (slope ~ 0); under Tallying it rises monotonically with the tally
    # margin (positive slope).
    validities = np.array([0.95, 0.85, 0.75, 0.65, 0.65])
    cue_order = np.argsort(-validities, kind="stable")

    xs = []
    ys = []
    ra_col = data["option_a_ratings"]
    rb_col = data["option_b_ratings"]
    resp_col = data["response"]

    for ra, rb, resp in zip(ra_col, rb_col, resp_col):
        a = np.asarray(ra, dtype=float)
        b = np.asarray(rb, dtype=float)

        # Find the first discriminating cue in descending-validity order.
        favored = None
        for j in cue_order:
            if a[j] > b[j]:
                favored = 0
                break
            if b[j] > a[j]:
                favored = 1
                break
        if favored is None:
            # Full tie: no top cue, no tally signal. Skip.
            continue

        # Tally margin from A's perspective, then re-sign so it is from
        # the top-cue-favored option's perspective.
        d = float(np.sum(a > b) - np.sum(b > a))
        if favored == 1:
            d = -d

        xs.append(d)
        ys.append(1.0 if int(resp) == favored else 0.0)

    xs = np.asarray(xs, dtype=float)
    ys = np.asarray(ys, dtype=float)
    if xs.size < 3:
        return 0.0

    xm = xs.mean()
    ym = ys.mean()
    sxx = float(np.sum((xs - xm) ** 2))
    if sxx <= 0.0:
        return 0.0

    slope = float(np.sum((xs - xm) * (ys - ym)) / sxx)
    return slope
```

**Observed (real) value:** -0.1747 (var=0.0108)
**Previous candidate values (this loop):**
  - iter 1: -0.1797 (var=0.0087) (Δ vs real -0.0050)
  - iter 2: -0.2193 (var=0.0078) (Δ vs real -0.0447)
  - iter 3: -0.2363 (var=0.0029) (Δ vs real -0.0617)
  - iter 4: -0.2092 (var=0.0083) (Δ vs real -0.0345)
  - iter 5: -0.2175 (var=0.0090) (Δ vs real -0.0428)
  - iter 6: -0.2430 (var=0.0042) (Δ vs real -0.0683)
  - iter 7 (most recent): -0.2297 (var=0.0064) (Δ vs real -0.0550)
**Other theories' values on this metric (for reference):**
- pi_1: 0.0023 (var=0.0008)
- pi_2: 0.1952 (var=0.0019)
- pi_3: -0.1877 (var=0.0014)
- pi_4: -0.1883 (var=0.0047)
- pi_3_1: -0.2228 (var=0.0055)
- pi_5: -0.1898 (var=0.0057)
- pi_6: -0.1968 (var=0.0072)

### Experiment 2
**Design**
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[1, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 1]  B=[1, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 1]  B=[0, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1]  B=[1, 0, 1, 0, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np

    # Cue cascade order for validities [0.9, 0.8, 0.7, 0.6, 0.5]:
    # strictly descending, so TTB consults features 0,1,2,3,4 in order.
    cue_order = [0, 1, 2, 3, 4]

    def to_vec(x):
        if isinstance(x, str):
            s = x.strip().strip('[]()')
            return np.array([float(v) for v in s.replace(',', ' ').split()])
        return np.asarray(x, dtype=float).ravel()

    follow_disagree = 0
    n_disagree = 0
    follow_agree = 0
    n_agree = 0

    a_col = data['option_a_ratings'].tolist()
    b_col = data['option_b_ratings'].tolist()
    r_col = data['response'].tolist()

    for a_raw, b_raw, resp in zip(a_col, b_col, r_col):
        a = to_vec(a_raw)
        b = to_vec(b_raw)
        if a.size != 5 or b.size != 5:
            continue

        a_wins = float(np.sum(a > b))
        b_wins = float(np.sum(b > a))

        # Tallying must be decisive and the tally margin must be exactly 1:
        # on every such trial the softmax probability of following the tally
        # is sigmoid(beta * 1), identical across trials, so Tallying predicts
        # a perfectly FLAT follow-rate regardless of subset.
        if a_wins == b_wins:
            continue
        if abs(a_wins - b_wins) != 1:
            continue

        tally_picks_a = a_wins > b_wins

        ttb_picks_a = None
        for j in cue_order:
            if a[j] > b[j]:
                ttb_picks_a = True
                break
            if b[j] > a[j]:
                ttb_picks_a = False
                break
        if ttb_picks_a is None:
            continue

        chose_a = (float(resp) == 0.0)

        if ttb_picks_a == tally_picks_a:
            n_agree += 1
            if chose_a == tally_picks_a:
                follow_agree += 1
        else:
            n_disagree += 1
            if chose_a == tally_picks_a:
                follow_disagree += 1

    if n_disagree == 0 or n_agree == 0:
        return 0.0

    p_dis = follow_disagree / float(n_disagree)
    p_agr = follow_agree / float(n_agree)
    return p_dis - p_agr

```

**Observed (real) value:** 0.2737 (var=0.0930)
**Previous candidate values (this loop):**
  - iter 1: 0.2019 (var=0.0142) (Δ vs real -0.0719)
  - iter 2: 0.2213 (var=0.0157) (Δ vs real -0.0525)
  - iter 3: 0.2069 (var=0.0211) (Δ vs real -0.0669)
  - iter 4: 0.1581 (var=0.0236) (Δ vs real -0.1156)
  - iter 5: 0.2006 (var=0.0189) (Δ vs real -0.0731)
  - iter 6: 0.1687 (var=0.0222) (Δ vs real -0.1050)
  - iter 7 (most recent): 0.2306 (var=0.0098) (Δ vs real -0.0431)
**Other theories' values on this metric (for reference):**
- pi_2: -0.0006 (var=0.0060)
- pi_1: -0.6981 (var=0.0507)
- pi_3: 0.1862 (var=0.0095)
- pi_4: 0.2669 (var=0.0115)
- pi_3_1: 0.1713 (var=0.0139)
- pi_5: 0.1550 (var=0.0256)
- pi_6: 0.1650 (var=0.0201)

### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 0, 1, 0]
  A=[0, 0, 1, 0, 1]  B=[1, 0, 0, 1, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 1]  B=[1, 0, 0, 1, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Slope of P(choose A) regressed on the anti-validity weighted cue
    margin D = sum_j u_j * (b_j - a_j), with u_j = v_j + tau * v_j^2
    (tau fixed at 0.35, the midpoint of SCWI's tau range).

    D > 0 means option A carries fewer/smaller anti-validity 'defects'
    and is therefore preferred by SCWI. SCWI predicts a POSITIVE slope
    (~0.2-0.3 with beta in [1.1,1.7], epsilon in [0.05,0.15]).
    Tallying cannot produce a positive slope: on count-tied trials
    (pairs 1-8, 24) it outputs exactly 0.5 for any beta/epsilon, and on
    all remaining trials its choice probability tracks the raw count
    margin, which is strongly ANTI-correlated with D across this design
    (the tally winner is almost always the weighted-margin loser). So
    Tallying's slope is <= 0 (approximately 0 for small beta, clearly
    negative for large beta). The sign separation is parameter-free.
    """
    validities = np.array([0.95, 0.85, 0.75, 0.65, 0.5])
    tau = 0.35
    u = validities + tau * np.square(validities)

    def _to_arr(cell):
        arr = np.asarray(cell, dtype=float).ravel()
        if arr.size != u.size:
            raise ValueError(
                f"Expected {u.size} ratings, got {arr.size}"
            )
        return arr

    a = np.vstack([_to_arr(c) for c in data["option_a_ratings"]])
    b = np.vstack([_to_arr(c) for c in data["option_b_ratings"]])

    # Signed SCWI evidence in favor of A (positive -> A preferred).
    D = (b - a) @ u

    # response: 0 = chose A, 1 = chose B  ->  indicator of choosing A.
    choice_a = 1.0 - np.asarray(data["response"], dtype=float).ravel()

    Dc = D - D.mean()
    Yc = choice_a - choice_a.mean()
    denom = float(np.sum(Dc * Dc))
    if denom <= 1e-12:
        return 0.0
    return float(np.sum(Dc * Yc) / denom)
```

**Observed (real) value:** 0.1227 (var=0.0008)
**Previous candidate values (this loop):**
  - iter 1: 0.1404 (var=0.0029) (Δ vs real +0.0177)
  - iter 2: 0.1422 (var=0.0039) (Δ vs real +0.0195)
  - iter 3: 0.1497 (var=0.0028) (Δ vs real +0.0270)
  - iter 4: 0.1433 (var=0.0036) (Δ vs real +0.0206)
  - iter 5: 0.1443 (var=0.0041) (Δ vs real +0.0216)
  - iter 6: 0.1669 (var=0.0020) (Δ vs real +0.0442)
  - iter 7 (most recent): 0.1389 (var=0.0043) (Δ vs real +0.0162)
**Other theories' values on this metric (for reference):**
- pi_3: 0.1378 (var=0.0002)
- pi_2: -0.1263 (var=0.0006)
- pi_1: -0.0888 (var=0.0010)
- pi_4: 0.1448 (var=0.0005)
- pi_3_1: 0.1444 (var=0.0038)
- pi_5: 0.1165 (var=0.0040)
- pi_6: 0.1497 (var=0.0011)

### Experiment 4
**Design**
  A=[0, 0, 1, 1, 1, 0]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 1, 1]  B=[1, 1, 0, 0, 1, 0]
  A=[0, 0, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1, 0]
  A=[1, 1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 1, 1]  B=[1, 0, 0, 1, 1, 0]
  A=[1, 0, 0, 0, 1, 1]  B=[0, 0, 1, 1, 0, 0]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 1, 1]
  A=[0, 0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Conflict-set tally-following rate.
    #
    # Selection rule: keep only trials where (i) the tally is non-zero (one
    # option strictly wins more feature-wise comparisons) and (ii) a
    # validity-weighted signed integrator with anti-validity weights
    # w_j = v_j + tau * v_j^2 (tau = 0.35, the midpoint of SCWI's range)
    # STRONGLY prefers the tally LOSER (|evidence| > 0.8).
    # In this design that selects exactly Probe B (pairs 7-12, |D| in
    # [1.0, 1.3]) plus the anchors (pairs 13-14, |D| ~ 5.2), i.e. 8 of the
    # 16 unique pairs = 48 of 96 trials per subject.
    #
    # Metric value = proportion of choices that follow the TALLY WINNER on
    # those conflict trials.
    #   Tallying: P >= sigmoid(beta*|m|) with |m| in {1,3,6}  -> > 0.5 for
    #             ANY beta > 0, epsilon < 1; ~0.95+ for typical beta.
    #   SCWI:     P = (1-eps)*(1-sigmoid(beta*|D|)) + eps/2 ~ 0.16-0.20 on
    #             Probe B and ~ eps/2 ~ 0.075 on anchors -> far below 0.5.
    # The two theories are separated by ~0.4-0.8 in mean with tight
    # per-subject binomial variance (48 trials/subject).

    import numpy as np

    VALIDITIES = np.array([1.0, 0.95, 0.65, 0.5, 0.5, 0.5])
    TAU = 0.35      # midpoint of SCWI's tau box [0.25, 0.45]
    THRESH = 0.8    # cleanly above Probe A's |D| <= 0.08, below Probe B's |D| >= 1.0

    w = VALIDITIES + TAU * np.square(VALIDITIES)  # positive anti-validity magnitudes

    a_col = data["option_a_ratings"].tolist()
    b_col = data["option_b_ratings"].tolist()
    r_col = data["response"].tolist()

    n_sel = 0
    n_match = 0
    for a_raw, b_raw, resp in zip(a_col, b_col, r_col):
        a = np.asarray(a_raw, dtype=float).ravel()
        b = np.asarray(b_raw, dtype=float).ravel()
        if a.size == 0 or a.size != b.size or a.size != w.size:
            continue

        a_wins = int(np.sum(a > b))
        b_wins = int(np.sum(b > a))
        if a_wins == b_wins:
            # Full-tie trials (pairs 15/16): both theories say 0.5, uninformative.
            continue

        # Signed evidence for option A under a weighted anti-validity
        # integrator: value_A - value_B = sum_j w_j * (b_j - a_j).
        ev = float(np.dot(w, b - a))

        tally_a = a_wins > b_wins
        if tally_a:
            # A is the tally winner; keep only if the integrator strongly
            # prefers B (the tally loser).
            if ev > -THRESH:
                continue
        else:
            # B is the tally winner; keep only if the integrator strongly
            # prefers A (the tally loser).
            if ev < THRESH:
                continue

        r = int(round(float(resp)))  # 0 = chose A, 1 = chose B
        chose_tally_winner = (r == 0) if tally_a else (r == 1)
        n_sel += 1
        if chose_tally_winner:
            n_match += 1

    if n_sel == 0:
        return 0.5  # degenerate fallback (no conflict trials found)
    return float(n_match) / float(n_sel)
```

**Observed (real) value:** 0.1625 (var=0.0119)
**Previous candidate values (this loop):**
  - iter 1: 0.1862 (var=0.0219) (Δ vs real +0.0237)
  - iter 2: 0.1183 (var=0.0138) (Δ vs real -0.0442)
  - iter 3: 0.1154 (var=0.0124) (Δ vs real -0.0471)
  - iter 4: 0.0958 (var=0.0167) (Δ vs real -0.0667)
  - iter 5: 0.1192 (var=0.0264) (Δ vs real -0.0433)
  - iter 6: 0.0996 (var=0.0243) (Δ vs real -0.0629)
  - iter 7 (most recent): 0.1212 (var=0.0204) (Δ vs real -0.0413)
**Other theories' values on this metric (for reference):**
- pi_2: 0.8538 (var=0.0090)
- pi_3: 0.1608 (var=0.0029)
- pi_1: 0.6796 (var=0.0042)
- pi_4: 0.1696 (var=0.0044)
- pi_3_1: 0.1388 (var=0.0265)
- pi_5: 0.1979 (var=0.0276)
- pi_6: 0.1342 (var=0.0135)

### Experiment 5
**Design**
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0]  B=[1, 1, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0]  B=[1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 1, 0, 0, 1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1, 0, 0, 1, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    # Instructed validities of this experiment (fixed at design time).
    VAL = np.array([1.0, 1.0, 0.85, 0.85, 0.5, 0.5, 0.5, 0.5, 0.5, 0.5, 0.5, 0.5])
    n_f = VAL.size

    # Extreme points of each theory's ADMISSIBLE parameter box.
    # SCWI: w(v) = -(v + tau*v^2), tau in [0.25, 0.45].
    W_SC = [-(VAL + t * VAL ** 2) for t in (0.25, 0.45)]
    # PAHI: w(v) = -v^gamma, gamma in [1.4, 2.4].
    W_PA = [-(VAL ** g) for g in (1.4, 2.4)]

    # Minimum |evidence margin| required to call a preference "guaranteed"
    # across the whole parameter box of a theory.
    M_SC = 0.08
    M_PA = 0.05

    def parse_vec(cell):
        if isinstance(cell, str):
            s = cell.strip().strip('[]()')
            toks = [t for t in s.replace(',', ' ').split() if t != '']
            return np.array([float(t) for t in toks], dtype=float)
        return np.asarray(cell, dtype=float).ravel()

    def parse_resp(r):
        if isinstance(r, str):
            rs = r.strip().upper()
            if rs == 'A':
                return 0
            if rs == 'B':
                return 1
            return int(float(rs))
        return int(round(float(r)))

    hits = []
    for a_cell, b_cell, r_cell in zip(data['option_a_ratings'],
                                       data['option_b_ratings'],
                                       data['response']):
        try:
            a = parse_vec(a_cell)
            b = parse_vec(b_cell)
            if a.size != n_f or b.size != n_f:
                continue
            d_sc = [float(np.dot(w, a) - np.dot(w, b)) for w in W_SC]
            d_pa = [float(np.dot(w, a) - np.dot(w, b)) for w in W_PA]
            resp = parse_resp(r_cell)
        except Exception:
            continue

        sc_lo, sc_hi = min(d_sc), max(d_sc)
        if sc_lo > M_SC:
            sc_pref = 1      # SCWI prefers A for EVERY admissible tau
        elif sc_hi < -M_SC:
            sc_pref = -1     # SCWI prefers B for EVERY admissible tau
        else:
            continue         # preference not guaranteed -> skip

        pa_lo, pa_hi = min(d_pa), max(d_pa)
        if pa_lo > M_PA:
            pa_pref = 1      # PAHI prefers A for EVERY admissible gamma
        elif pa_hi < -M_PA:
            pa_pref = -1     # PAHI prefers B for EVERY admissible gamma
        else:
            continue

        if sc_pref == pa_pref:
            continue         # theories agree -> no diagnostic content

        # Trial is a guaranteed sign-opposition trial: SCWI's preferred
        # option is exactly the one PAHI rejects (and vice versa).
        scwi_option_is_a = (sc_pref == 1)
        chose_scwi = (resp == 0) if scwi_option_is_a else (resp == 1)
        hits.append(1.0 if chose_scwi else 0.0)

    if len(hits) == 0:
        return 0.5
    return float(np.mean(hits))
```

**Observed (real) value:** 0.6837 (var=0.0643)
**Previous candidate values (this loop):**
  - iter 1: 0.4556 (var=0.0237) (Δ vs real -0.2281)
  - iter 2: 0.5081 (var=0.0478) (Δ vs real -0.1756)
  - iter 3: 0.4500 (var=0.0419) (Δ vs real -0.2337)
  - iter 4: 0.5094 (var=0.0705) (Δ vs real -0.1744)
  - iter 5: 0.5162 (var=0.0534) (Δ vs real -0.1675)
  - iter 6: 0.5569 (var=0.0392) (Δ vs real -0.1269)
  - iter 7 (most recent): 0.5975 (var=0.0330) (Δ vs real -0.0862)
**Other theories' values on this metric (for reference):**
- pi_3: 0.5531 (var=0.0069)
- pi_4: 0.2281 (var=0.0125)
- pi_1: 0.8350 (var=0.0129)
- pi_2: 0.1300 (var=0.0103)
- pi_3_1: 0.6506 (var=0.0203)
- pi_5: 0.6019 (var=0.0710)
- pi_6: 0.6150 (var=0.0208)

### Experiment 6
**Design**
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 1, 0, 0, 0, 0, 1, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 1, 0, 0, 0, 0, 1, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # "Top-cue adherence" on steepness-diagnostic ladder cells.
    # The design's validity vector: 4 cues at 1.00, 5 at 0.65, 5 at 0.60,
    # 14 at 0.50 (hardcoded from the experimental design).
    VALID = np.array([1.0] * 4 + [0.65] * 5 + [0.60] * 5 + [0.50] * 14)
    NF = VALID.size

    def to_vec(x):
        if isinstance(x, str):
            s = x.strip().strip('[]()')
            return np.array([float(t) for t in s.replace(',', ' ').split()])
        return np.asarray(x, dtype=float).ravel()

    # Excluded cells (signature = (top-cue count, sorted low-cue validities)):
    #  (2, 4x0.50): both theories prefer the low option -> no separation;
    #  (2, 5x0.60) and (2, 5x0.65): PAHI splits across its gamma range on
    #  these cells -> they add between-subject noise without adding gap.
    EXCLUDE = {
        (2, (0.5, 0.5, 0.5, 0.5)),
        (2, (0.6, 0.6, 0.6, 0.6, 0.6)),
        (2, (0.65, 0.65, 0.65, 0.65, 0.65)),
    }

    hits = []
    for a_raw, b_raw, resp in zip(
        data['option_a_ratings'], data['option_b_ratings'], data['response']
    ):
        a = to_vec(a_raw)
        b = to_vec(b_raw)
        if a.size != NF or b.size != NF:
            continue
        ta = int(np.sum(a[:4] > 0.5))
        tb = int(np.sum(b[:4] > 0.5))
        # Exactly one option must carry 1s on the perfect-validity cues.
        if ta > 0 and tb > 0:
            continue
        if ta == 0 and tb == 0:
            continue
        if ta > 0:
            top_vec, low_vec, top_idx, tc = a, b, 0, ta
        else:
            top_vec, low_vec, top_idx, tc = b, a, 1, tb
        if tc not in (2, 4):
            continue
        # Top option must have 1s ONLY on perfect cues; low option none.
        if np.sum(top_vec[4:] > 0.5) > 0:
            continue
        if np.sum(low_vec[:4] > 0.5) > 0:
            continue
        low_mask = low_vec > 0.5
        if int(np.sum(low_mask)) < 4:
            continue
        sig = (tc, tuple(sorted(float(x) for x in np.round(VALID[low_mask], 2))))
        if sig in EXCLUDE:
            continue
        hits.append(1.0 if int(resp) == top_idx else 0.0)

    if len(hits) == 0:
        return 0.5
    return float(np.mean(hits))
```

**Observed (real) value:** 0.6300 (var=0.0703)
**Previous candidate values (this loop):**
  - iter 1: 0.4742 (var=0.0147) (Δ vs real -0.1558)
  - iter 2: 0.4354 (var=0.0197) (Δ vs real -0.1946)
  - iter 3: 0.4442 (var=0.0211) (Δ vs real -0.1858)
  - iter 4: 0.5096 (var=0.0235) (Δ vs real -0.1204)
  - iter 5: 0.5683 (var=0.0282) (Δ vs real -0.0617)
  - iter 6: 0.5783 (var=0.0215) (Δ vs real -0.0517)
  - iter 7 (most recent): 0.5583 (var=0.0112) (Δ vs real -0.0717)
**Other theories' values on this metric (for reference):**
- pi_4: 0.2267 (var=0.0083)
- pi_3: 0.5687 (var=0.0053)
- pi_1: 0.8783 (var=0.0092)
- pi_2: 0.1263 (var=0.0072)
- pi_3_1: 0.6646 (var=0.0194)
- pi_5: 0.7004 (var=0.0351)
- pi_6: 0.6208 (var=0.0179)

### Experiment 7
**Design**
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1]  B=[0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0, 0, 1, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 1, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np

    # Design-time constants (fixed by this experiment: 29 experts,
    # 6 @ .85, 5 @ .80, 6 @ .75, 12 @ .50).
    V = np.array([0.85] * 6 + [0.80] * 5 + [0.75] * 6 + [0.50] * 12, dtype=float)

    # Reference (midpoint) parameter values. The design guarantees that on
    # every critical cell the SIGN of each theory's evidence is constant
    # over its ENTIRE parameter box, so midpoint values classify trials
    # identically to any admissible parameter.
    TAU = 0.28      # SCWI box [0.15, 0.42]
    GAMMA = 1.9     # PAHI box [1.4, 2.4]
    w_scwi = -(V + TAU * np.square(V))   # SCWI anti-validity weights
    w_pahi = -(np.power(V, GAMMA))       # PAHI anti-validity weights

    def _to_arr(x):
        if isinstance(x, np.ndarray):
            return x.astype(float)
        if isinstance(x, (list, tuple)):
            return np.asarray(x, dtype=float)
        s = str(x).strip().strip('[]()')
        toks = [t for t in s.replace(',', ' ').split() if t != '']
        return np.array([float(t) for t in toks])

    hits = []
    for a_raw, b_raw, r_raw in zip(data['option_a_ratings'],
                                    data['option_b_ratings'],
                                    data['response']):
        try:
            a = _to_arr(a_raw)
            b = _to_arr(b_raw)
            r = int(r_raw)
        except Exception:
            continue
        if r not in (0, 1):
            continue
        n = int(min(a.size, b.size, V.size))
        if n == 0:
            continue
        diff = a[:n] - b[:n]
        d_scwi = float(np.dot(w_scwi[:n], diff))   # value_A - value_B under SCWI
        d_pahi = float(np.dot(w_pahi[:n], diff))   # value_A - value_B under PAHI

        # Keep only trials where the two theories make OPPOSITE predictions
        # with a non-trivial margin on both sides (this automatically selects
        # the knife-edge count-ratio cells and discards controls, ties,
        # anchors, and calibration trials, where the theories agree).
        if abs(d_scwi) <= 0.05 or abs(d_pahi) <= 0.05:
            continue
        if (d_scwi > 0) == (d_pahi > 0):
            continue

        scwi_option = 0 if d_scwi > 0 else 1   # 0 = A, 1 = B
        hits.append(1.0 if r == scwi_option else 0.0)

    if not hits:
        return 0.5
    return float(np.mean(hits))
```

**Observed (real) value:** 0.6462 (var=0.0395)
**Previous candidate values (this loop):**
  - iter 1: 0.5288 (var=0.0201) (Δ vs real -0.1175)
  - iter 2: 0.5150 (var=0.0226) (Δ vs real -0.1312)
  - iter 3: 0.4791 (var=0.0272) (Δ vs real -0.1672)
  - iter 4: 0.5672 (var=0.0343) (Δ vs real -0.0791)
  - iter 5: 0.5966 (var=0.0372) (Δ vs real -0.0497)
  - iter 6: 0.5447 (var=0.0270) (Δ vs real -0.1016)
  - iter 7 (most recent): 0.5409 (var=0.0298) (Δ vs real -0.1053)
**Other theories' values on this metric (for reference):**
- pi_3_1: 0.6975 (var=0.0214)
- pi_4: 0.2169 (var=0.0147)
- pi_1: 0.8762 (var=0.0079)
- pi_2: 0.1344 (var=0.0070)
- pi_3: 0.6412 (var=0.0050)
- pi_5: 0.6056 (var=0.0640)
- pi_6: 0.6581 (var=0.0250)

### Experiment 8
**Design**
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Kill-composite: fraction of choices falling on the HIGH-validity stack
    # across the parameter-free sign-kill trials of this design.
    #
    # Kill trials pit a endorsements on higher-validity cues against b
    # endorsements on lower-validity cues (all other cues 0 for both
    # options, disjoint supports, each stack within one validity block)
    # at count ratios that lie strictly between the two theories'
    # weight-ratio windows:
    #   5 x 0.90 vs 7 x 0.70   (r = 1.40)
    #   9 x 0.70 vs 14 x 0.50  (r = 1.556)
    #   5 x 0.90 vs 11 x 0.50  (r = 2.20)
    # SCWI's ratio window w(v_h)/w(v_l) is BELOW each r for every admissible
    # tau, so SCWI always prefers the high-validity stack. PAHI's power-law
    # window is ABOVE each r for every admissible gamma, so PAHI always
    # prefers the low-validity stack. The metric is the fraction of kill
    # trials on which the subject chose the high-validity stack; mirrored
    # versions of each kill pair absorb side bias. It is well defined on
    # the pooled DataFrame and on a single subject slice (18 kill trials
    # per subject: 6 unique kill pairs x 3 repetitions).
    import numpy as np

    validities = np.array([0.9] * 5 + [0.7] * 9 + [0.5] * 14)
    n_feat = validities.size

    kill_keys = set()
    kill_keys.add(((5, 0.9), (7, 0.7)))
    kill_keys.add(((9, 0.7), (14, 0.5)))
    kill_keys.add(((5, 0.9), (11, 0.5)))

    a_col = data['option_a_ratings'].tolist()
    b_col = data['option_b_ratings'].tolist()
    r_col = data['response'].tolist()

    hits = 0
    total = 0

    for i in range(len(a_col)):
        a_cell = a_col[i]
        b_cell = b_col[i]
        resp = r_col[i]
        try:
            a = np.asarray(a_cell, dtype=float).ravel()
            b = np.asarray(b_cell, dtype=float).ravel()
        except Exception:
            continue
        if a.size != n_feat or b.size != n_feat:
            continue

        ones_a = np.flatnonzero(a == 1)
        ones_b = np.flatnonzero(b == 1)
        if ones_a.size == 0 or ones_b.size == 0:
            continue
        # Kill trials have disjoint supports (no tied cues).
        if np.intersect1d(ones_a, ones_b).size > 0:
            continue

        va = validities[ones_a]
        vb = validities[ones_b]
        # Each stack must sit entirely within one validity block.
        if np.unique(va).size != 1 or np.unique(vb).size != 1:
            continue

        sig_a = (int(ones_a.size), float(va[0]))
        sig_b = (int(ones_b.size), float(vb[0]))
        key = tuple(sorted([sig_a, sig_b]))
        if key not in kill_keys:
            continue
        if sig_a[1] == sig_b[1]:
            continue

        # High-validity stack is the one whose cues have larger validity.
        h_is_a = sig_a[1] > sig_b[1]

        try:
            r = int(round(float(resp)))
        except Exception:
            continue
        # response: 0 = chose A, 1 = chose B.
        chose_h = (r == 0) if h_is_a else (r == 1)
        if chose_h:
            hits += 1
        total += 1

    if total == 0:
        return 0.5
    return float(hits) / float(total)
```

**Observed (real) value:** 0.6044 (var=0.0653)
**Previous candidate values (this loop):**
  - iter 1: 0.5222 (var=0.0200) (Δ vs real -0.0822)
  - iter 2: 0.4378 (var=0.0435) (Δ vs real -0.1667)
  - iter 3: 0.4522 (var=0.0309) (Δ vs real -0.1522)
  - iter 4: 0.5189 (var=0.0266) (Δ vs real -0.0856)
  - iter 5: 0.5322 (var=0.0426) (Δ vs real -0.0722)
  - iter 6: 0.5856 (var=0.0363) (Δ vs real -0.0189)
  - iter 7 (most recent): 0.5667 (var=0.0244) (Δ vs real -0.0378)
**Other theories' values on this metric (for reference):**
- pi_4: 0.2078 (var=0.0291)
- pi_3_1: 0.7078 (var=0.0349)
- pi_1: 0.8611 (var=0.0123)
- pi_2: 0.1200 (var=0.0071)
- pi_3: 0.6056 (var=0.0099)
- pi_5: 0.6122 (var=0.0654)
- pi_6: 0.7011 (var=0.0213)

### Experiment 9
**Design**
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    def _vec(x):
        if isinstance(x, np.ndarray):
            a = x.astype(float).ravel()
            if a.size > 0:
                return a
        try:
            a = np.asarray(x, dtype=float).ravel()
            if a.size > 0:
                return a
        except (TypeError, ValueError):
            pass
        s = str(x).strip().strip('[]()')
        toks = [t for t in s.replace(',', ' ').split() if t != '']
        return np.asarray([float(t) for t in toks], dtype=float)

    df = data.reset_index(drop=True)
    if df.shape[0] == 0 or 'response' not in df.columns:
        return 0.0

    A_list = [_vec(v) for v in df['option_a_ratings'].tolist()]
    B_list = [_vec(v) for v in df['option_b_ratings'].tolist()]
    R = np.asarray([float(r) for r in df['response'].tolist()], dtype=float)
    sids = df['subject_id'].tolist()

    rows = []
    for i in range(len(df)):
        a = A_list[i]
        b = B_list[i]
        r = R[i]
        n = a.size
        ta = float(a[:3].sum()); ma = float(a[3:12].sum()); la = float(a[12:].sum())
        tb = float(b[:3].sum()); mb = float(b[3:12].sum()); lb = float(b[12:].sum())
        row = {'anch0': np.nan, 'Lk': np.nan, 'Mk': np.nan, 'cH': np.nan}
        sa = ta + ma + la; sb = tb + mb + lb
        # ANCHOR: one option all-1s, the other all-0s. Record whether the
        # subject picked the all-0 option (engaged anti-validity subjects
        # do this with prob ~1 - eps/2; guessers 0.5).
        if n >= 12 and sa == float(n) and sb == 0.0:
            row['anch0'] = 1.0 if r == 1.0 else 0.0
        elif n >= 12 and sb == float(n) and sa == 0.0:
            row['anch0'] = 1.0 if r == 0.0 else 0.0
        # Top-stack (H) option: exactly the three v=1.00 cues endorsed.
        aH = (n >= 12) and (ta == 3.0) and (ma == 0.0) and (la == 0.0)
        bH = (n >= 12) and (tb == 3.0) and (mb == 0.0) and (lb == 0.0)
        if aH != bH:
            h = 0.0 if aH else 1.0
            opp = b if aH else a
            ot = float(opp[:3].sum()); om = float(opp[3:12].sum()); ol = float(opp[12:].sum())
            if ot == 0.0:
                if om == 0.0 and 8.0 <= ol <= 12.0:
                    # 0.50-ladder kill cell (3x1.00 vs 8-12x0.50)
                    row['Lk'] = 1.0 if r == h else 0.0
                elif ol == 0.0 and 6.0 <= om <= 9.0:
                    # 0.60-ladder kill cell (3x1.00 vs 6-9x0.60)
                    row['Mk'] = 1.0 if r == h else 0.0
                elif om == 0.0 and ol == 5.0:
                    # L-control (3x1.00 vs 5x0.50)
                    row['cH'] = 1.0 if r == h else 0.0
                elif ol == 0.0 and om == 4.0:
                    # M-control (3x1.00 vs 4x0.60)
                    row['cH'] = 1.0 if r == h else 0.0
        rows.append(row)

    tdf = pd.DataFrame(rows)
    tdf['sid'] = sids

    stats = []
    for sid, g in tdf.groupby('sid', sort=False):
        Lv = g['Lk'].dropna()
        Mv = g['Mk'].dropna()
        sL = float(Lv.mean()) if len(Lv) > 0 else 0.5
        sM = float(Mv.mean()) if len(Mv) > 0 else 0.5
        an = g['anch0'].dropna()
        ok_a = (float(an.sum()) == float(len(an))) if len(an) > 0 else True
        cv = g['cH'].dropna()
        ok_c = (float(cv.mean()) <= 0.375) if len(cv) > 0 else True
        stats.append({'sid': sid, 'sL': sL, 'sM': sM, 'keep': bool(ok_a and ok_c)})

    st = pd.DataFrame(stats)
    if st.shape[0] == 0:
        return 0.0
    scr = st[st['keep']]

    # Multi-subject (pooled) case: cross-ladder consistency = Pearson
    # correlation across engaged subjects between the 0.50-ladder and
    # 0.60-ladder top-stack choice rates.
    if scr.shape[0] >= 4:
        x = scr['sL'].to_numpy(dtype=float)
        y = scr['sM'].to_numpy(dtype=float)
        if x.std() > 1e-9 and y.std() > 1e-9:
            with np.errstate(all='ignore'):
                r = float(np.corrcoef(x, y)[0, 1])
            if np.isfinite(r):
                return r

    # Single-subject / degenerate case: within-subject cross-ladder
    # agreement, bounded in [-1, 1] and tight under both theories.
    d = np.abs(st['sL'].to_numpy(dtype=float) - st['sM'].to_numpy(dtype=float))
    return float(np.clip(1.0 - 2.0 * float(d.mean()), -1.0, 1.0))
```

**Observed (real) value:** 0.1963 (var=0.0601)
**Previous candidate values (this loop):**
  - iter 1: 0.0667 (var=0.0536) (Δ vs real -0.1296)
  - iter 2: 0.5954 (var=0.0324) (Δ vs real +0.3991)
  - iter 3: 0.3112 (var=0.0374) (Δ vs real +0.1149)
  - iter 4: 0.3877 (var=0.0375) (Δ vs real +0.1914)
  - iter 5: 0.1895 (var=0.0554) (Δ vs real -0.0068)
  - iter 6: -0.0069 (var=0.0270) (Δ vs real -0.2032)
  - iter 7 (most recent): 0.1315 (var=0.0407) (Δ vs real -0.0648)
**Other theories' values on this metric (for reference):**
- pi_3_1: 0.3684 (var=0.0180)
- pi_5: 0.9529 (var=0.0191)
- pi_1: 0.9048 (var=0.0084)
- pi_2: 0.8735 (var=0.0093)
- pi_3: 0.2390 (var=0.0208)
- pi_4: 0.8613 (var=0.0179)
- pi_6: 0.1113 (var=0.0229)

### Experiment 10
**Design**
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    # Cell patterns are (top-cue count on H option, mid-cue count on L option,
    # low-cue count on L option), where H = the option whose 1s sit exclusively
    # on the v=1.00 cues and L = the option whose 1s sit exclusively on the
    # v<=0.60 cues.
    # TWIN-KILL cells (r = 1/v_l, the gamma=1 flip point for HEAI):
    #   4x1.00 vs 8x0.50  (trials 3, 9, 13, 19)   and
    #   3x1.00 vs 5x0.60  (trials 7, 10, 17, 20)  -> 32 rows/subject.
    # HIGH-RATIO cells (r = 3.0 on ladder 1, r = 2.0 on ladder 2):
    #   4x1.00 vs 12x0.50 (trials 5, 15)          and
    #   3x1.00 vs 6x0.60  (trials 8, 18)          -> 16 rows/subject.
    TWIN_PATTERNS = {(4.0, 0.0, 8.0), (3.0, 5.0, 0.0)}
    HIGH_PATTERNS = {(4.0, 0.0, 12.0), (3.0, 6.0, 0.0)}

    def _counts(ratings):
        try:
            arr = np.asarray(list(ratings), dtype=float).ravel()
        except Exception:
            return None
        if arr.size != 22:
            return None
        return (float(arr[0:4].sum()), float(arr[4:10].sum()), float(arr[10:22].sum()))

    def _is_H(c):
        # H option: all its 1s are on the four v=1.00 cues.
        return c[0] > 0 and c[1] == 0.0 and c[2] == 0.0

    def _is_L(c):
        # L option: no top-cue 1s, at least one 1 on the v<=0.60 cues.
        return c[0] == 0.0 and (c[1] > 0 or c[2] > 0)

    twin_hits = []
    high_hits = []

    responses = data["response"].values
    a_list = data["option_a_ratings"].values
    b_list = data["option_b_ratings"].values

    for resp, ra, rb in zip(responses, a_list, b_list):
        ca = _counts(ra)
        cb = _counts(rb)
        if ca is None or cb is None:
            continue
        try:
            r = int(float(resp))
        except Exception:
            continue
        if _is_H(ca) and _is_L(cb):
            h_cnt, l_cnt, h_is_a = ca, cb, True
        elif _is_H(cb) and _is_L(ca):
            h_cnt, l_cnt, h_is_a = cb, ca, False
        else:
            continue
        pattern = (float(h_cnt[0]), float(l_cnt[1]), float(l_cnt[2]))
        chose_h = (r == 0) if h_is_a else (r == 1)
        val = 1.0 if chose_h else 0.0
        if pattern in TWIN_PATTERNS:
            twin_hits.append(val)
        elif pattern in HIGH_PATTERNS:
            high_hits.append(val)

    if len(twin_hits) == 0 or len(high_hits) == 0:
        return 0.0

    p_twin = float(np.mean(twin_hits))
    p_high = float(np.mean(high_hits))
    # Signed psychometric rise between the twin-kill ratio region and the
    # high-ratio region. SCWI (step function pinned in [2.14, 2.35] ladder 1
    # and [1.76, 1.89] ladder 2) produces a LARGE rise (~0.55-0.60); HEAI
    # (bimodal gamma, shallow mode straddling the gamma=1 flip) produces a
    # SMALL rise (~0.20).
    return p_high - p_twin
```

**Observed (real) value:** 0.2963 (var=0.0806)
**Previous candidate values (this loop):**
  - iter 1: 0.2919 (var=0.0413) (Δ vs real -0.0044)
  - iter 2: 0.3400 (var=0.0606) (Δ vs real +0.0438)
  - iter 3: 0.3900 (var=0.0463) (Δ vs real +0.0938)
  - iter 4: 0.3500 (var=0.0552) (Δ vs real +0.0537)
  - iter 5: 0.3644 (var=0.0511) (Δ vs real +0.0681)
  - iter 6: 0.4475 (var=0.0502) (Δ vs real +0.1512)
  - iter 7 (most recent): 0.4512 (var=0.0808) (Δ vs real +0.1550)
**Other theories' values on this metric (for reference):**
- pi_5: 0.1713 (var=0.0509)
- pi_3_1: 0.4531 (var=0.0906)
- pi_1: 0.0181 (var=0.0129)
- pi_2: 0.0131 (var=0.0090)
- pi_3: 0.3713 (var=0.0215)
- pi_4: 0.1175 (var=0.0341)
- pi_6: 0.3438 (var=0.0509)

### Experiment 11
**Design**
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    def _to_vec(x):
        if isinstance(x, str):
            s = x.strip().strip('[]()')
            toks = [t for t in s.replace(',', ' ').split() if t != '']
            return np.array([float(t) for t in toks], dtype=float)
        return np.asarray(x, dtype=float).ravel()

    A = np.array([_to_vec(x) for x in data['option_a_ratings']], dtype=float)
    B = np.array([_to_vec(x) for x in data['option_b_ratings']], dtype=float)

    r = np.asarray(data['response'])
    try:
        resp = r.astype(float)
    except Exception:
        resp = np.array([0.0 if str(v).strip().upper() in ('0', 'A') else 1.0 for v in r],
                        dtype=float)

    subj = np.asarray(data['subject_id'])

    n_feat = A.shape[1]
    val = np.array([0.9] * 6 + [0.85] * 11 + [0.5] * 5 + [1.0] * 6, dtype=float)
    if val.size < n_feat:
        val = np.concatenate([val, np.full(n_feat - val.size, 0.5)])
    val = val[:n_feat]

    hi = np.isclose(val, 0.9)
    mid = np.isclose(val, 0.85)

    A_hi = A[:, hi].sum(axis=1)
    A_mid = A[:, mid].sum(axis=1)
    B_hi = B[:, hi].sum(axis=1)
    B_mid = B[:, mid].sum(axis=1)
    A_other = A.sum(axis=1) - A_hi - A_mid
    B_other = B.sum(axis=1) - B_hi - B_mid

    # AL (near-knife, equal-count) cells: one option carries exactly 3 endorsements
    # on the 0.90-validity experts, the other exactly 3 on the 0.85-validity
    # experts, and every other expert is silent for both options.
    al = ((A_other == 0) & (B_other == 0)
          & (((A_hi == 3) & (A_mid == 0) & (B_hi == 0) & (B_mid == 3))
             | ((A_hi == 0) & (A_mid == 3) & (B_hi == 3) & (B_mid == 0))))

    subjects = np.unique(subj)

    if subjects.size > 1:
        # Population statistic: mean signed excess of anti-validity choices on
        # the AL cells (per subject: 2*#anti-choices - #AL-trials, in [-6, +6]).
        excess = []
        for s in subjects:
            m = al & (subj == s)
            k = int(m.sum())
            if k == 0:
                continue
            # anti-validity-preferred option = the one whose 1s sit on the
            # LOWER-validity (0.85) experts (a rating of 1 is a defect).
            anti = np.where(A_mid[m] == 3, 1.0 - resp[m], resp[m])
            excess.append(2.0 * float(anti.sum()) - float(k))
        if len(excess) == 0:
            return 0.0
        return float(np.mean(excess))
    else:
        # Single-subject slice: the population excess has no single-subject
        # analogue, so return the subject's position-bias baseline (mean A
        # response). By the design's mirror-pair symmetry this is pinned near
        # 0.5 with only binomial noise under BOTH theories, i.e. it is the
        # stable per-subject quantity against which the population-level
        # excess is defined.
        return float(np.mean(resp))
```

**Observed (real) value:** 2.8800 (var=0.0015)
**Previous candidate values (this loop):**
  - iter 1: 1.1200 (var=0.0012) (Δ vs real -1.7600)
  - iter 2: 1.5600 (var=0.0013) (Δ vs real -1.3200)
  - iter 3: 1.2000 (var=0.0012) (Δ vs real -1.6800)
  - iter 4: 2.2400 (var=0.0008) (Δ vs real -0.6400)
  - iter 5: 1.9600 (var=0.0012) (Δ vs real -0.9200)
  - iter 6: 1.8800 (var=0.0005) (Δ vs real -1.0000)
  - iter 7 (most recent): 1.9200 (var=0.0009) (Δ vs real -0.9600)
**Other theories' values on this metric (for reference):**
- pi_3_1: 1.4400 (var=0.0007)
- pi_6: 0.3200 (var=0.0016)
- pi_1: -4.3200 (var=0.0012)
- pi_2: 0.2000 (var=0.0010)
- pi_3: 1.0800 (var=0.0009)
- pi_4: 1.7600 (var=0.0014)
- pi_5: 0.7200 (var=0.0008)

### Experiment 12
**Design**
  A=[1, 1, 1, 1, 0, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0, 1, 1, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 0, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 0, 1, 1, 1, 1, 1, 1]  B=[0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0, 1, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 1]  B=[1, 1, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[1, 1, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 1]
  A=[1, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1, 1, 0, 1, 1, 1, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 1, 0, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 1, 1]  B=[0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 1, 1]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 1, 1, 1]  B=[0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0]  B=[1, 1, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0, 0, 0, 1, 1, 1, 1]  B=[0, 0, 1, 1, 0, 0, 0, 0, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    df = data.reset_index(drop=True)

    # --- Design constants for this experiment --------------------------
    # 12 experts: validities [0.9 x 4, 0.6 x 8].
    VALID = np.array([0.9] * 4 + [0.6] * 8)
    N_F = VALID.size

    # Reference anti-validity defect magnitudes: a rating of 1 is treated
    # as a defect with weight -d_j. The reference ratio d(0.9)/d(0.6)
    # = 1.58 sits between SCWI's whole-box ratio range (1.562-1.651 over
    # tau in [0.15, 0.42]) and CNNAI's median ratio (1.5^(1+0.12) ~ 1.58),
    # so the per-trial signed margins fed to the fit are theory-neutral.
    D_HI, D_LO = 1.0, 0.633
    D_REF = np.where(VALID > 0.75, D_HI, D_LO)

    # Grid for the per-subject sensitivity (softmax inverse temperature)
    # maximum-likelihood fit, and the soft-threshold ramp applied to it.
    # The ramp [3.0, 4.2] targets exactly the region where the two
    # theories' beta distributions are disjoint: SCWI's deterministic
    # regime has beta ~ U[3.8, 6.0] (34% of subjects), while CNNAI's
    # engaged beta is lognormal(median 2.14, log-sd 0.20) clipped to
    # [0.9, 4.5] with 98% of engaged subjects below 3.2.
    GRID = np.linspace(0.0, 10.0, 501)
    RAMP_LO, RAMP_HI = 3.0, 4.2

    def _vec(raw):
        if raw is None:
            return None
        if isinstance(raw, str):
            s = raw.strip().strip('[]()')
            toks = [t for t in s.replace(',', ' ').split() if t != '']
            if not toks:
                return None
            return np.array([float(t) for t in toks])
        try:
            arr = np.asarray(raw, dtype=float).ravel()
        except Exception:
            return None
        return arr if arr.size > 0 else None

    def _subject_score(sub):
        ms = []
        ys = []
        for a_cell, b_cell, resp in zip(
            sub['option_a_ratings'].values,
            sub['option_b_ratings'].values,
            sub['response'].values,
        ):
            A = _vec(a_cell)
            B = _vec(b_cell)
            if A is None or B is None or A.size == 0 or A.size != B.size:
                continue
            if A.size == N_F:
                d = D_REF
            else:
                d = np.full(A.size, 0.8)
            w = -d
            va = float(np.dot(w, A))
            vb = float(np.dot(w, B))
            m = abs(vb - va)
            if m < 1e-9 or m > 2.0:
                # identical pairs (ties) and the all-ones-vs-all-zeros
                # anchor screens carry no usable sensitivity info
                # (both theories put them at ~0.5 / lapse rate), and the
                # ~9-unit anchor margin would corrupt the fit.
                continue
            b_pred = vb > va
            r = float(resp)
            y = 1.0 if ((r > 0.5) == b_pred) else 0.0
            ms.append(m)
            ys.append(y)
        if len(ms) < 10:
            return 0.0
        m = np.asarray(ms, dtype=float)            # (n_trials,)
        y = np.asarray(ys, dtype=float)[:, None]   # (n_trials, 1)  <-- broadcast fix
        z = np.outer(m, GRID)                      # (n_trials, n_grid)
        # Bernoulli log-likelihood of P(y=1) = sigmoid(beta * margin):
        # ll(beta) = -sum_i [ y_i * log(1+e^{-z}) + (1-y_i) * log(1+e^{z}) ]
        ll = -(y * np.logaddexp(0.0, -z)
               + (1.0 - y) * np.logaddexp(0.0, z)).sum(axis=0)
        bhat = float(GRID[int(np.argmax(ll))])
        g = (bhat - RAMP_LO) / (RAMP_HI - RAMP_LO)
        return float(min(max(g, 0.0), 1.0))

    subjects = pd.unique(df['subject_id'])
    if len(subjects) == 0:
        return 0.0
    vals = []
    for sid in subjects:
        sub = df[df['subject_id'] == sid]
        vals.append(_subject_score(sub))
    return float(np.mean(vals))
```

**Observed (real) value:** 0.0913 (var=0.0729)
**Previous candidate values (this loop):**
  - iter 1: 0.0200 (var=0.0196) (Δ vs real -0.0713)
  - iter 2: 0.0263 (var=0.0148) (Δ vs real -0.0650)
  - iter 3: 0.1200 (var=0.1056) (Δ vs real +0.0287)
  - iter 4: 0.0750 (var=0.0593) (Δ vs real -0.0163)
  - iter 5: 0.0387 (var=0.0256) (Δ vs real -0.0527)
  - iter 6: 0.1467 (var=0.1005) (Δ vs real +0.0553)
  - iter 7 (most recent): 0.1877 (var=0.1307) (Δ vs real +0.0963)
**Other theories' values on this metric (for reference):**
- pi_6: 0.0000 (var=0.0000)
- pi_3_1: 0.3587 (var=0.2287)
- pi_1: 0.0000 (var=0.0000)
- pi_2: 0.0000 (var=0.0000)
- pi_3: 0.0000 (var=0.0000)
- pi_4: 0.0000 (var=0.0000)
- pi_5: 0.0823 (var=0.0589)

## PREVIOUS CANDIDATE (this loop)
The RUNNING-BEST (last ACCEPTED) candidate in this critique loop — i.e. the source the loop's accept gate kept as the best base so far. If your most recent attempt was REJECTED by the gate, this is NOT that attempt; it is the previously-accepted base the gate rolled back to. Iterate on this source — the next critic feedback should be applied on top of it.

**Description**
Kneed Compressive Anti-Validity Integration with a Moderate Deterministic Tail (CAVI-K), beta-homogenization refinement. Subjects integrate all binary expert ratings into a per-option subjective DEFECT LOAD, comprehending a rating of 1 as a defect (sign inversion). Per-cue defect magnitude is supralinear in the instructed validity, d_j = v_j + tau*v_j^2 (tau in [0.35, 0.65]), modulated by a context elasticity (v_j/v_ref)^eta keyed on the bucketed mean endorsed validity, with a zero-centered stable component (sd 0.10) plus a per-context redraw (sd 0.20), fixing latent cross-context consistency at r ~ 0.20. The defect load is compressed by a two-regime map with the knee at 4.45 — above every near-knife small stack (AL cells, 2-top-cue adherence cells, which keep full raw margins) and below the large diagnostic stacks (which grow sub-proportionally aversive under kappa in [0.55, 0.68]). Population: ~14% true guessers, ~70% engaged with a HOMOGENIZED lognormal beta (median 2.65, log-sd 0.29, clip [0.8, 6.0]) — the tightened spread removes both the saturating hot-engaged bloc (which was driving the Exp-9 cross-ladder correlation to 0.388 via beta-saturation, not latent consistency) and the soft low-beta tail (which was diluting anti-validity adherence on Exps 2/5/6/8/11) — and ~16% deterministic tail (beta 4.0-6.5, near-linear kappa, pinned eta). Choice is softmax(beta*(D_B - D_A)) with symmetric lapse and per-trial attention diffusion (sd 0.035).

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    # Kneed Compressive Anti-Validity Integration (CAVI-K), iter 5.
    # Minimal single-lever diff on the accepted iter-4 base, applying
    # the iter-4 critic diagnosis. Changes vs the accepted base:
    #   (A) ENGAGED BETA LOG-SD TRIMMED 0.35 -> 0.29 with the median
    #       nudged 2.5 -> 2.65 (clip unchanged [0.8, 6.0]). The Exp-9
    #       trajectory isolated the failure: at a CONSTANT eta split
    #       (0.10/0.20), raising the beta median 2.0 -> 2.5 swung the
    #       cross-ladder correlation 0.067 -> 0.388, i.e. the correlation
    #       is driven by the saturating HOT END of the engaged beta
    #       distribution, not by latent context consistency. Trimming the
    #       log-sd removes that bloc (pulling Exp 9 back toward its
    #       [0.15, 0.30] window) while ALSO removing the soft low-beta
    #       tail that was diluting anti-validity adherence on
    #       Exps 2/5/6/8/11 — the shared undershoot of all four prior
    #       iterations. The small median nudge (2.5 -> 2.65, well short
    #       of the critic's 3.0+ that the AL-sigmoid arithmetic rules
    #       out) targets Exp 11's remaining shortfall (2.24 vs the
    #       [2.4, 3.2] window).
    #   (B) ENGAGED KAPPA UPPER BOUND 0.70 -> 0.68 (range now
    #       [0.55, 0.68]): a single small pre-emptive guardrail step.
    #       Removing the low-beta tail raises mean adherence broadly,
    #       which will push Exp 10's rise (0.350 at iter 4, window
    #       [0.22, 0.36]) toward its ceiling; slightly stronger
    #       compression on the large diagnostic stacks holds it inside
    #       the window. This is deliberately NOT the iter-3 confounded
    #       trim (which fought a simultaneous knee raise) — the knee
    #       stays at 4.45 and only the upper bound moves by 0.02.
    #   Everything else is held verbatim from the accepted iter-4 base:
    #   knee 4.45 (above the max AL stack 4.28 for every tau), tau
    #   [0.35, 0.65], the 0.10/0.20 eta split with pinned tail eta,
    #   attention diffusion 0.035, the 14/70/16 mixture, and all lapse
    #   ranges — each either in-window or explicitly validated at
    #   iter 4.
    import hashlib
    import math
    import numpy as np
    from scipy.special import ndtri

    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"CAVI-K expects a (2, n_features) stimulus; got shape {stim.shape}."
        )
    n_features = stim.shape[1]
    ra, rb = stim[0], stim[1]

    def _to_vec(raw):
        if raw is None:
            return None
        if isinstance(raw, str):
            s = raw.strip().strip('[]()')
            toks = [t for t in s.replace(',', ' ').split() if t != '']
            if not toks:
                return None
            return np.array([float(t) for t in toks])
        arr = np.asarray(raw, dtype=float).ravel()
        return arr if arr.size > 0 else None

    val = _to_vec(parameters.get("validities"))
    if val is None or val.size != n_features:
        val = np.full(n_features, 0.75)
    val = np.clip(val, 1e-3, 1.0)

    def _seed(name):
        try:
            x = float(parameters[name])
        except (KeyError, TypeError, ValueError):
            x = 0.5
        if not np.isfinite(x):
            x = 0.5
        return min(max(x, 0.0), 1.0)

    u = _seed("regime_seed")
    ts = _seed("tau_seed")
    ks = _seed("kappa_seed")
    bs = min(max(_seed("beta_seed"), 1e-6), 1.0 - 1e-6)
    es = _seed("epsilon_seed")
    ebs = min(max(_seed("eta_base_seed"), 1e-6), 1.0 - 1e-6)
    ss = _seed("subject_seed")

    # --- Population mixture ---
    if u < 0.14:
        # True guessers (~14%).
        t = u / 0.14
        beta = 0.02 + 0.08 * t                 # 0.02 .. 0.10
        epsilon = 0.12 + 0.13 * es              # 0.12 .. 0.25
        tau = 0.50
        kappa = 0.75
        eta_base = 0.00
    elif u < 0.84:
        # Engaged bulk (~70%): HOMOGENIZED beta (median 2.65, log-sd
        # 0.29), kappa acting only above the knee, zero-centered stable
        # elasticity. The tightened beta spread removes both the
        # saturating hot bloc (Exp 9) and the soft low-beta tail
        # (adherence dilution on Exps 2/5/6/8/11).
        tau = 0.35 + 0.30 * ts                 # 0.35 .. 0.65
        kappa = 0.55 + 0.13 * ks                # 0.55 .. 0.68
        beta = math.exp(math.log(2.65) + 0.29 * float(ndtri(bs)))
        beta = min(max(beta, 0.8), 6.0)
        epsilon = 0.03 + 0.06 * es             # 0.03 .. 0.09
        eta_base = 0.10 * float(ndtri(ebs))
        eta_base = min(max(eta_base, -0.15), 0.15)
    else:
        # Deterministic tail (~16%): hot, low-lapse, strongly inverted,
        # least compressive, PINNED stable elasticity (no ndtri draw) so
        # the tail cannot act as a hidden cross-context coupling channel.
        tau = 0.55 + 0.10 * ts                 # 0.55 .. 0.65
        kappa = 0.78 + 0.07 * ks                # 0.78 .. 0.85
        beta = 4.0 + 2.5 * bs                   # 4.0 .. 6.5
        epsilon = 0.02 + 0.02 * es              # 0.02 .. 0.04
        eta_base = 0.05                         # pinned

    # --- Context: bucketed mean endorsed validity ---
    active = np.flatnonzero((ra > 0.5) | (rb > 0.5))
    if active.size == 0:
        return np.full(2, 0.5)

    v_ref = float(np.mean(val[active]))
    bucket = float(np.round(v_ref, 1))
    key = f"{bucket:.1f}"
    h = int(hashlib.md5(f"{ss:.9f}|{key}".encode("utf-8")).hexdigest()[:14], 16)
    uc = ((h % 999983) + 0.5) / 999984.0
    uc = min(max(uc, 1e-6), 1.0 - 1e-6)

    # Per-context redraw, zero-centered; stable/redraw sd ratio 0.10/0.20
    # fixes latent cross-context consistency at r ~ 0.20 by construction.
    eta_ctx = eta_base + 0.20 * float(ndtri(uc))
    eta_ctx = min(max(eta_ctx, -0.30), 0.50)

    # --- Defect weights: supralinear anti-validity, context-normalized ---
    d = val + tau * np.square(val)
    w = d * np.power(val / v_ref, eta_ctx)

    # Per-trial multiplicative attention diffusion (sd 0.035, the
    # iter-3-proven level that lets Exp-12 fitted bhat reach the ramp).
    att = np.exp(0.035 * np.random.randn(n_features))
    w = w * att

    # Raw defect loads.
    s_a = float(np.dot(w, ra))
    s_b = float(np.dot(w, rb))

    # TWO-REGIME (offset) compression: identity below the knee, power
    # compression above. Knee 4.45 > max AL stack 4.28 (at tau = 0.65),
    # so near-knife small stacks keep full raw margins for every tau;
    # the large Exp-10/12 stacks (4.7-11.5) are compressed.
    S_KNEE = 4.45

    def _compress(s):
        if s <= S_KNEE:
            return s
        return S_KNEE * ((s / S_KNEE) ** kappa)

    d_a = _compress(s_a)
    d_b = _compress(s_b)

    scores = np.array([-d_a, -d_b])

    # Numerically stable softmax over the two option values.
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()

    return (1.0 - epsilon) * p_core + epsilon * 0.5 * np.ones(2)

`policy(probs) -> int`:
def policy(probabilities):
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()  # Guard against float drift.
    return np.random.choice(len(probabilities), p=probabilities)

`parameters`:
- regime_seed: [0, 1]
- tau_seed: [0, 1]
- kappa_seed: [0, 1]
- beta_seed: [0, 1]
- epsilon_seed: [0, 1]
- eta_base_seed: [0, 1]
- subject_seed: [0, 1]
- validities: validities

`rationale`: This is a minimal single-lever diff of the accepted iter-4 base implementing the iter-4 critic's diagnosis, with one small guardrail step added. (1) PRIMARY LEVER — ENGAGED BETA LOG-SD 0.35 -> 0.29, median 2.5 -> 2.65, clip unchanged. The critic's key datum: with the eta split held constant at 0.10/0.20 across iters 1 and 4, the Exp-9 cross-ladder correlation swung 0.067 -> 0.388 purely from the beta-median raise — the correlation is driven by the saturating HOT END of the engaged beta distribution, not by latent context consistency. Trimming the log-sd removes that saturating bloc (pulling Exp 9 back toward its [0.15, 0.30] window) without touching the eta geometry that iter 2 showed is dangerously saturating (0.15/0.15 exploded Exp 9 to 0.595). Simultaneously, removing the soft low-beta tail raises mean anti-validity adherence on the persistently undershooting Exps 2/5/6/8/11 — the shared deficit of all four prior iterations that no compression-geometry edit ever fixed. The small median nudge 2.5 -> 2.65 (not the 3.0+ the AL-sigmoid arithmetic rules out: beta 2.5 -> engaged AL anti-rate 0.66, beta 3.2 -> 0.71) targets Exp 11's remaining shortfall (2.24 vs the [2.4, 3.2] window). (2) GUARDRAIL — ENGAGED KAPPA UPPER BOUND 0.70 -> 0.68, a single 0.02 step. Removing the low-beta tail raises adherence broadly, which will push Exp 10's rise (0.350 at iter 4, window [0.22, 0.36]) toward its ceiling; marginally stronger compression on the large diagnostic stacks (which are the only ones above the 4.45 knee) holds it inside the window. This is deliberately NOT the iter-3 confounded kappa trim that fought a simultaneous knee raise — the knee stays at 4.45 and only the upper bound moves. (3) HELD VERBATIM: knee 4.45 (calibrated by computed stack arithmetic: above the max AL stack 4.28 for every tau), tau [0.35, 0.65], the 0.10/0.20 eta split, the pinned tail eta, attention diffusion 0.035 (the proven Exp-12 fix), the 14/70/16 mixture, and all lapse ranges — each either in-window or explicitly validated at iter 4. Expected profile: Exp 9 -> ~0.15-0.28, Exp 11 -> ~2.3-2.6, Exps 5/6 -> ~0.55-0.60, Exp 8 -> ~0.53-0.57, Exp 2 -> ~0.18-0.22, Exp 10 held ~0.30-0.35, Exps 1/3/4/12 near their iter-4 values (Exp 1's slope may steepen slightly from removing soft subjects; the log-sd trim keeps the hot shoulder thin enough to stay above -0.23) — which should strictly beat the 0.1231 base.

## PRIOR FEEDBACK ITERATIONS
The critic's verdicts on each previous in-loop candidate, in order. Each block ends with an **Outcome of this advice** line saying whether the candidate the proposer produced AFTER this advice was ACCEPTED (loss strictly beat the running best) or REJECTED (the gate discarded it). Address the most recent iteration's feedback in your next edit, but down-weight past advice whose candidates were REJECTED.

### Iteration 1
Verdict: regenerate
Interpretation: CAVI is a faithful implementation of the arbiter's prescribed family (sign-inverted supralinear defect weights, within-option compression, three-part population mixture, context-keyed elasticity), and it clears the gate. The fit is genuinely excellent on the psychometric-shape metrics: Exp 1 (-0.180 vs -0.175), Exp 3 (0.140 vs 0.123), Exp 4 (0.186 vs 0.163), and — the round's headline win — Exp 10's rise (0.292 vs 0.296, where every prior theory overshot or undershot). The compression lever works exactly as intended on the high-ratio cells. However, the same compression is doing collateral damage everywhere margins are SMALL-to-MODERATE, and the candidate systematically undershoots the anti-validity adherence bloc: Exp 5 (0.456 vs 0.684), Exp 6 (0.474 vs 0.630), Exp 7 (0.529 vs 0.646), Exp 8 (0.522 vs 0.604, just below the arbiter's [0.55, 0.65] window), Exp 9 (0.067 vs 0.196, below the [0.15, 0.30] window), Exp 11 (1.12 vs 2.88 — far below the arbiter's [+2.4, +3.2] target, and even below the proposer's own 1.2-1.5 prediction), and Exp 12 (0.020 vs 0.091, below the [0.06, 0.15] window). The diagnosis is mechanical, not conceptual: a pure power map D = S^kappa compresses margins PROPORTIONALLY at every scale. For S > 1, the local margin slope is kappa*S^(kappa-1) < 1, so even 'small' stacks like Exp 11's AL cells (S ≈ 3.6-3.9, margin ≈ 0.28 uncompressed) get their margin roughly halved (≈ 0.14) — the theory's claim that 'small stacks keep near-linear sharp margins' is false for the power form whenever S > 1. The same halving softens the Exp 5-7 adherence cells and deflates the Exp 12 per-subject MLE beta fits (the metric fits a LINEAR-margin softmax, so the fitted bhat is the true beta scaled down by the compression slope, pushing the 16% deterministic tail below the [3.0, 4.2] ramp). Separately, the Exp 9 cross-ladder correlation (0.067) falls short of the by-construction r ≈ 0.20 because the eta-space consistency does not transfer linearly to choice-rate space: near-saturated per-ladder choice rates compress the correlation, so the stable/redraw variance split needs to be richer in the stable component than 0.20 to land at an observed 0.196.
Rationale: The candidate was accepted, so build on it — but it is not shippable yet: it misses the arbiter's explicit target windows on four experiments (8, 9, 11, 12) and undershoots real data by 0.12-0.23 on Exps 5-7. All failures point at ONE miscalibration, so the fix is a minor in-family adjustment, not a redesign: (1) Replace the pure power compression with an OFFSET/affine form that is near-identity at small S and compressive only at large S — e.g. D = (1 + S)^kappa - 1, or a two-regime map D = S for S < s0 and s0*(S/s0)^kappa for S >= s0 with s0 ≈ 2-3. This preserves the Exp 10 win (high-ratio cells have S ≈ 5-12 and stay compressed) while restoring near-linear margins on the AL cells (Exp 11 should rise from 1.12 toward the 2.4-2.9 range), the Exp 5-7 adherence composites (toward 0.60-0.68), and Exp 8's kill composite (into [0.55, 0.65]). (2) For Exp 12's g: the deterministic tail's effective slope is beta * kappa*S^(kappa-1); with the offset compression the tail's fitted bhat recovers, but also push the tail's kappa to [0.92, 1.0] (fully linear for the confidently inverted) and consider widening tail beta to [4.5, 7.5] so a larger share of tail subjects land bhat inside the [3.0, 4.2] ramp; target g ≈ 0.06-0.10. (3) For Exp 9: raise the stable share of eta — e.g. stable sd 0.15 with redraw sd 0.15 (eta-space r ≈ 0.5) — so that after choice-rate saturation the observed cross-ladder correlation lands near 0.20; verify the bucketed-mean key still separates the 0.50- and 0.60-ladders (it does: buckets ≈ 0.6 vs 0.7). (4) Keep everything else fixed: the supralinear tau range, the 14/70/16 mixture proportions, the lapse ranges, the attention diffusion, and the Exp 1-4 parameterization are all performing at or near the real values and should not be touched. Expected net effect: Exp 11 → ~2.4-2.9, Exps 5-7 → ~0.60-0.68, Exp 8 → ~0.57-0.62, Exp 9 → ~0.18-0.22, Exp 12 → ~0.06-0.09, with Exps 1-4 and 10 held (re-check Exp 10 after the compression change: the offset form slightly REDUCES compression at the twin-kill cells (S ≈ 4-5), which may nudge the rise up from 0.29 — if it drifts above 0.36, lower s0 or kappa slightly to compensate).

**Outcome of this advice:** iter 1 candidate loss=0.1319 -> iter 2 candidate loss=0.1783 -> the gate marked it REJECTED.

### Iteration 2
Verdict: regenerate
Interpretation: Iter 2 was REJECTED by the gate (loss 0.1783 vs the iter-1 base's 0.1319), and the per-experiment pattern cleanly identifies which of the three edits helped and which hurt. What HELPED: the offset (two-regime) compression. Exp 11 rose 1.12 → 1.56 (toward the real 2.88), Exp 5 rose 0.456 → 0.508 (toward 0.684), Exp 2 rose 0.202 → 0.221 (toward 0.274), and Exps 3/10 stayed acceptable. What HURT, badly: the eta enrichment (change C) plus the hot, near-linear tail now DRAWING eta (change B's side effect). Exp 9 exploded from 0.067 to 0.595 against a real value of 0.196 — a 3x overshoot of the target window. Exp 8 crashed from 0.522 to 0.438 (real 0.604) — BELOW chance, which is diagnostic: a large mass of hot subjects now flips to the LOW-validity stack on the 5x0.90-vs-7x0.70 knife cells. Mechanically, the elasticity multiplier (v_h/v_ref)^eta / (v_l/v_ref)^eta inflates the effective defect-weight ratio past the count ratio (1.40) on those cells at eta ≈ 0.25; with the enriched eta distribution (mean 0.12, sd ~0.21, now including the 16% hot tail) a substantial bloc sits past that flip, and with tail beta 4.5-7.5 they flip deterministically. The same near-linear hot tail saturates both Exp 9 ladders identically, which is what catapulted the cross-ladder correlation to 0.595. Collateral damage from the same source: Exp 6 dropped 0.474 → 0.435 (same knife-flip mechanism at high eta), Exp 4 dropped 0.186 → 0.118 (flipped subjects follow the anti-validity loser even more), and Exp 1's slope went over-negative (-0.180 → -0.219 vs real -0.175). Meanwhile the change that was specifically aimed at Exp 12 (tail kappa 0.92-1.0, beta 4.5-7.5) delivered nothing: g moved only 0.020 → 0.026 against a real 0.091. So change (B) bought nothing where it was aimed and cost where it wasn't; change (C) overshot ~3x past its target; change (A) is the one lever that moved things in the right direction and should be kept and pushed further.
Rationale: Build on the unchanged iter-1 accepted base with a partial-retention, partial-reversion diff. Do NOT repeat the full eta enrichment — the gate rejected it, and the observed-correlation response is strongly saturating (a ~2x stable-share change moved Exp 9 from 0.067 to 0.595), so take a fractional step. Concretely: (1) REVERT the eta split most of the way back to iter 1: stable eta_base sd ~0.11-0.12 with per-context redraw sd ~0.18-0.19 (between iter 1's 0.10/0.20 and iter 2's 0.15/0.15), and PIN the deterministic tail's eta_base to a fixed small value (~0.05, no ndtri draw). The tail's stable hot beta and tau are already cross-ladder traits and provide a modest, controlled consistency boost on Exp 9 (from 0.067 toward ~0.15-0.20) without flipping the Exp 6/8 knife cells — the iter-2 Exp 8 sub-0.5 crash and the Exp 6/4/1 regressions should all revert with this single change. (2) KEEP the offset compression but RAISE s0 from 3.0 to ~3.8-4.2. The remaining Exp 11 shortfall (1.56 vs 2.88) lives in the fact that the AL cells' stacks (S ≈ 3.6-3.9) still sit ABOVE s0 = 3.0 and get compressed for the engaged bulk (local slope ~0.65-0.7, margin ~0.30 → ~0.21). With s0 ≈ 4.0 the AL cells are fully in the identity regime for everyone: back-of-envelope, engaged sigmoid(2.0*0.30) ≈ 0.65, tail sigmoid(5*0.30) ≈ 0.82, guessers 0.5 → population anti-rate ≈ 0.68, which lands the mean excess near the real 2.88 (vs 1.56 now). Raising s0 also puts Exp 6's 4-5-cue low stacks (S ≈ 3.4-4.3) in or near the identity regime, raising top-cue adherence toward 0.63. The Exp 10 diagnostic stacks (S ≈ 6-9) remain compressed; if the rise drifts above ~0.33, trim the engaged kappa upper bound from 0.85 to ~0.80 to compensate — do not touch the rest of the kappa range. (3) Exp 12: the tail re-targeting failed (g stuck at 0.026), which points to a different cap — the per-trial attention diffusion (sd 0.05) injects margin noise (sd roughly 0.2-0.3 on the metric's fitted margins of 0.5-1.3) that deflates every subject's fitted bhat below the [3.0, 4.2] ramp regardless of true beta. Reduce the attention diffusion sd to ~0.03-0.04 (still within the arbiter's '~0.05' prescription) so the tail's fitted bhat can actually reach the ramp; this also nudges the undershooting Exps 5-8 up slightly, which is the right direction. (4) Leave everything else untouched: tau range [0.35, 0.65], the 14/70/16 mixture, lapse ranges, the bucketed-mean context key, and the softmax are all performing and were explicitly flagged to keep. Expected net profile: Exps 1-4 revert to their iter-1 near-real values (Exp 1 ~ -0.18, Exp 4 ~ 0.17-0.19), Exp 11 → ~2.4-2.9, Exps 5-7 → 0.55-0.65, Exp 8 → 0.55-0.62, Exp 9 → 0.12-0.22, Exp 10 held near 0.30, Exp 12 → 0.06-0.10 — which should strictly beat the 0.1319 base.

**Outcome of this advice:** iter 2 candidate loss=0.1783 -> iter 3 candidate loss=0.1705 -> the gate marked it REJECTED.

### Iteration 3
Verdict: regenerate
Interpretation: Iter 3 was REJECTED (loss 0.1705 vs the iter-1 base's 0.1319), so this verdict is regenerate. The iter-3 diff was a four-lever change whose components can now be evaluated against three iterations of evidence. What WORKED: (a) the attention-diffusion cut (0.05 -> 0.035) finally fixed Experiment 12 (g = 0.120, inside the arbiter's [0.06, 0.15] window for the first time, vs 0.020/0.026 before) — the proposer's diagnosis that per-trial margin noise was capping the fitted bhat was correct; (b) pinning the deterministic tail's eta and the partial eta reversion brought Exp 9 from the iter-2 explosion (0.595) back to 0.311, just above the [0.15, 0.30] window. What FAILED: the s0 = 4.0 knee raise did NOT deliver any of its predicted gains — Exp 11 went DOWN (1.56 -> 1.20 vs real 2.88), Exp 5 went DOWN (0.508 -> 0.450 vs real 0.684), Exp 7 went DOWN (0.515 -> 0.479), Exp 8 stayed broken (0.452 vs real 0.604, below the [0.55, 0.65] window), and Exp 10's rise overshot further (0.39 vs real 0.296, above the [0.22, 0.36] window). The proposer's back-of-envelope predictions were wrong in direction on five of twelve experiments. I can now identify the mechanical reason the s0 raise backfired: the knee at s0 = 4.0 sits INSIDE the AL-cell stack range. The AL high stack is S_h = 3*(0.9 + tau*0.81), which spans 3.55-4.43 over the engaged tau range [0.35, 0.65], while the low stack S_l = 3*(0.85 + tau*0.7225) spans 3.34-3.99. For every subject with tau > ~0.53 — which is 100% of the deterministic tail (tau 0.55-0.65) and ~40% of the engaged bulk — the HIGH-validity stack crosses the knee and gets compressed while the low stack stays in the identity regime. This asymmetric compression shrinks the AL margin exactly for the hottest, most anti-valid subjects, which is why Exp 11 fell instead of rising. The simultaneous kappa trim (upper bound 0.85 -> 0.80, i.e. stronger compression everywhere above the knee) then counteracted the s0 raise on the Exps 5/7/8 adherence cells, so the net there was negative too. Two levers pushed in opposite directions at once — the classic confound. The deeper structural finding across all three iterations: Exps 2, 5, 6, 7, 8, 11 are ALL undershooting in the same direction (too-soft anti-validity adherence), all three iterations fiddled exclusively with compression geometry and eta while the engaged beta median stayed at 2.0, and the arithmetic shows the adherence deficit is primarily a SHARPNESS deficit. On the AL cells the raw margin is structurally ~0.28-0.32 (bounded by tau <= 0.65 and the 0.90-vs-0.85 validity gap); at beta = 2.0 the engaged anti-rate is only ~0.64, giving population excess ~1.6-1.8 even with perfect identity compression. Hitting the real 2.88 requires a population anti-rate of 0.74, i.e. an engaged+tail average of ~0.78, which needs an effective beta of ~4 on those margins. The engaged beta median is the one big in-family lever never touched, and the arbiter explicitly authorized tuning parameter ranges to land the AL excess in [2.4, 3.2].
Rationale: Build on the unchanged iter-1 base with a diff that (i) keeps the two proven iter-3 wins, (ii) fixes the knee-placement bug, and (iii) pulls the one untried lever. Concretely: (1) RAISE THE ENGAGED BETA MEDIAN from 2.0 to ~3.0-3.5 (keep log-sd 0.35, clip [0.8, 6.0]). This directly attacks the shared undershoot on Exps 2, 5, 6, 7, 8, 9 and 11 simultaneously; the AL arithmetic above shows it is the only route toward the arbiter's [2.4, 3.2] AL-excess window. Guardrails: if Exp 1's slope falls below ~-0.22 (real -0.175) or Exp 10's rise exceeds ~0.36, compensate by LOWERING s0 (more compression on the large Exp-10 stacks), not by walking beta back below ~2.8. Note honestly: even at beta ~3.5 the AL excess likely lands ~2.0-2.3, still short of 2.4 because the 14% guesser bloc alone costs ~0.85 excess; if the loss weighting justifies it, a further step toward beta ~4 is the only in-family way to close the rest, priced against Exp 1 steepening. (2) FIX THE KNEE PLACEMENT: either s0 <= ~3.3 (both AL stacks compressed together — margins shrink proportionally but the sign is stable, and this is what iter 2's s0 = 3.0 did when it raised Exp 11 to 1.56) or s0 >= ~4.6 (both AL stacks in identity for every tau). s0 = 4.0 is precisely the worst choice — the knee bisects the AL stacks for the hot-tau population. Given the beta raise will already steepen Exp 10's rise, recommend s0 ~ 3.2-3.5. (3) KEEP the diffusion at 0.035 (Exp 12 is in window; if the beta raise pushes g above 0.15, revert diffusion toward 0.04 rather than touching the tail). (4) KEEP the tail's eta pinned at a fixed small value and REVERT the engaged eta split fully to the iter-1 base (stable sd 0.10 / redraw sd 0.20) — the iter-3 partial step (0.115/0.185) left Exp 9 above its window (0.311) without buying any adherence. (5) DO NOT trim the engaged kappa bounds — restore the base range; the iter-3 trim strengthened compression and canceled the s0 raise on the adherence cells. (6) Process note for the proposer: three iterations of back-of-envelope predictions have been directionally wrong on the experiments they targeted (iter 3 predicted Exp 11 ~2.4-2.9, got 1.20; predicted Exps 5-8 up, got flat-to-down). Before committing, compute the actual stack sums S = sum_j (v_j + tau*v_j^2) * (v_j/v_ref)^eta for the diagnostic cells at the extremes of tau, and check which side of the knee each option's stack falls on — the tau-dependence of the stack magnitudes is what the envelope arithmetic has been missing. Expected profile if this lands: Exp 1 ~ -0.19 to -0.22, Exp 2 ~ 0.22-0.26, Exps 5-8 ~ 0.55-0.65, Exp 9 ~ 0.10-0.20, Exp 10 ~ 0.28-0.36 (via s0), Exp 11 ~ 1.9-2.3, Exp 12 held ~0.10-0.15 — which should strictly beat the 0.1319 base.

**Outcome of this advice:** iter 3 candidate loss=0.1705 -> iter 4 candidate loss=0.1231 -> the gate marked it ACCEPTED.

### Iteration 4
Verdict: regenerate
Interpretation: Iter 4 was ACCEPTED (loss 0.1231 < 0.1319), and my iter-3 advice was followed and helped: the knee was re-placed above the AL stacks by computed arithmetic, the engaged beta median was raised (moderated from my 3.0-3.5 to 2.5), the eta split was reverted, and the two iter-3 wins (diffusion 0.035, pinned tail eta) were kept. The result is the best profile yet: Exp 11 jumped 1.20 -> 2.24 (toward real 2.88), Exps 6/7 rose to 0.510/0.567 (toward 0.630/0.646), Exp 10 landed at 0.350 (inside [0.22, 0.36]), and Exp 12 held at 0.075 (inside [0.06, 0.15]). However, the candidate is not shippable against the arbiter's explicit windows: Exp 9 now OVERSHOOTS (0.388 vs real 0.196, above the [0.15, 0.30] window), Exp 8 remains below its window (0.519 vs [0.55, 0.65]), Exp 11 sits just below its window (2.24 vs [2.4, 3.2]), and the shared adherence undershoot persists on Exps 2 (0.158 vs 0.274 — this one actually REGRESSED from iter 1's 0.202), 5 (0.509 vs 0.684), and 6 (0.510 vs 0.630). The single most informative datum is the Exp 9 trajectory: iter 1 (beta median 2.0, split 0.10/0.20) gave 0.067; iter 4 (beta median 2.5, SAME split) gave 0.388. With the eta split held constant, the entire 0.32 swing is beta-saturation: hotter engaged betas push subjects to near-deterministic choices on BOTH ladders, and a saturated bloc correlates perfectly across ladders. This means the eta split is the WRONG knob at beta 2.5 — the cross-ladder correlation is now driven by the hot end of the engaged beta distribution, not by latent context consistency.
Rationale: Regenerate with a single-lever diff on the accepted iter-4 base. (1) PRIMARY LEVER — TRIM THE ENGAGED BETA LOG-SD from 0.35 to ~0.28-0.30, keeping the median at 2.5 and the clip [0.8, 6.0]. This one change attacks three failures at once: (a) it removes the saturating hot-engaged bloc that catapulted Exp 9 from 0.067 to 0.388 at a constant eta split, pulling the cross-ladder correlation back toward the 0.15-0.30 window WITHOUT touching the eta geometry that iter 2 showed is dangerously saturating; (b) it removes the soft low-beta tail of the engaged distribution, which raises mean anti-validity adherence on Exps 5/6/8/11 simultaneously — the same shared undershoot that has persisted all four iterations; (c) it should partially recover Exp 2 (iter 1's broader-beta profile scored 0.202; the sharpening that came with the median raise appears to have crushed the disagreement-vs-agreement gap to 0.158). (2) ONLY IF Exp 11 remains below 2.4 after the log-sd trim, nudge the engaged median 2.5 -> ~2.65 — a small step; the proposer's own arithmetic shows the AL sigmoid is already saturating (beta 2.5 -> 0.66, beta 3.2 -> 0.71), so do NOT jump to 3.0+. (3) HOLD FIXED: knee 4.45, engaged kappa [0.55, 0.70], tau [0.35, 0.65], the 0.10/0.20 eta split, attention diffusion 0.035, the pinned tail eta, the 14/70/16 mixture, and all lapse ranges — every one of these is either in-window or was explicitly validated this iteration. (4) GUARDRAILS: Exp 1's slope must not fall below ~-0.23 (it is already somewhat over-steep at -0.209 vs real -0.175) and Exp 10's rise must not exceed 0.36; if the rise drifts up, trim ONLY the engaged kappa upper bound from 0.70 to ~0.66-0.68 (a single small step — not the iter-3 confounded trim that fought the knee raise). (5) DIAGNOSTIC FLAG for the next iteration: the knee at 4.45 was calibrated to the Exp 11 AL stacks (max 4.28), but Exp 9's 3x1.00 top stacks span 4.05-4.95 across the engaged tau range — the knee BISECTS those, so low-tau subjects get identity-vs-compressed (sharp) ladder margins while high-tau subjects get both-compressed (soft) margins. If Exp 9 is still above its window after the log-sd trim, this subject-heterogeneous asymmetric compression is the next suspect to examine (compute which side of 4.45 each Exp 9 stack falls on per tau, per the process note from my iter-3 critique). Expected profile: Exp 9 -> ~0.15-0.28, Exp 11 -> ~2.3-2.6, Exps 5/6 -> ~0.55-0.60, Exp 8 -> ~0.53-0.56, Exp 2 -> ~0.18-0.22, with Exps 1/3/4/10/12 held — which should strictly beat the 0.1231 base.

**Outcome of this advice:** iter 4 candidate loss=0.1231 -> iter 5 candidate loss=0.1030 -> the gate marked it ACCEPTED.

### Iteration 5
Verdict: regenerate
Interpretation: Iter 5 was ACCEPTED (loss 0.1030, best yet) and my iter-4 advice (log-sd trim 0.35→0.29 with a small median nudge, kappa guardrail) worked: Exp 9 landed almost exactly on the real value (0.1895 vs 0.1963, inside [0.15, 0.30] for the first time), Exp 2 partially recovered (0.158→0.201 vs real 0.274), and Exps 6/7 improved to 0.568/0.597 (toward 0.630/0.646). The beta-homogenization diagnosis — that Exp 9's correlation was driven by the saturating hot end of the engaged beta distribution — is now confirmed by intervention. However, the same trim had a predictable cost that materialized: Exp 11 FELL (2.24→1.96 vs real 2.88, further from the [2.4, 3.2] window) because removing the hot bloc removed the near-saturated subjects who were carrying AL-cell adherence; the small median nudge (2.65) did not compensate. Exp 12's drop (0.075→0.039) occurred with ZERO tail-relevant parameter changes and should be read as simulation noise (the tail parameters, diffusion, and knee are all identical to iter 4), not as a regression to chase with new mechanisms. The remaining genuine misses are: Exp 5 (0.516 vs 0.684 — the largest absolute miss; pure SCWI, pi_3_1, scores 0.651 there, so the candidate's deviations from the SCWI weighting are what cost ~0.13), Exp 8 (0.532 vs 0.604, below [0.55, 0.65]), Exp 11 (1.96 vs [2.4, 3.2]), Exp 1 over-steep (-0.218 vs -0.175), and Exp 10 marginally above its window (0.364 vs ceiling 0.36). The shared mechanism behind Exps 5/8/1 is per-subject weighting noise and tau excess on knife cells: the engaged tau ceiling of 0.65 sits exactly at the flip threshold tau ≈ 0.64 for Exp 8's 5x0.90-vs-7x0.70 kill cell (w(0.9)/w(0.7) crosses the 1.40 count ratio there), and the eta total sd of ~0.22 blurs the sign on Exp 5's SCWI-vs-PAHI opposition cells, which the metric classifies against the SCWI box tau ∈ [0.25, 0.45]. The candidate is close but not shippable against the arbiter's explicit windows: four experiments (5, 8, 11, 12) sit outside them.
Rationale: Regenerate with a three-lever diff on the accepted iter-5 base; every lever is now backed by an isolated diagnosis, and the levers that must NOT move are explicitly pinned. (1) PRIMARY — DETERMINISTIC-TAIL KAPPA [0.78, 0.85] → [0.88, 1.0]. This is a deliberate retry of the iter-2 lever that appeared to fail (g stuck at 0.026), but we now know it was confounded: diffusion 0.05 was capping every subject's fitted bhat below the [3.0, 4.2] ramp, and the iter-3 diffusion cut to 0.035 fixed that cap. With near-linear tail kappa, tail bhat ≈ beta × compression-slope rises from ~2.4-3.9 to ~3.2-5.2, putting roughly half the 16% tail inside the ramp → g ≈ 0.08-0.11, inside [0.06, 0.15]. Exp 10 risk is low: the tail is already near-saturated on the Exp-10 cells (compressed margins ~0.7-1.2 × beta 4-6.5), so extra tail linearity barely moves p_twin/p_high. Do NOT re-widen tail beta — iter 2 showed that buys nothing. (2) TAU CEILING + ETA VARIANCE — engaged tau [0.35, 0.65] → [0.35, 0.55], and scale the eta sds down proportionally (stable 0.10 → 0.08, redraw 0.20 → 0.15), preserving the variance ratio ≈ 0.20 so the arbiter's latent cross-context consistency prescription is intact while total eta sd drops from 0.22 to 0.18. Rationale: the Exp-8 flip threshold sits at tau ≈ 0.64, so the current ceiling parks the top of the engaged mass exactly at the knife; trimming it moves kill-cell choices toward the high-validity stack (Exp 8 → ~0.55-0.58). The same trim pushes per-subject weights toward the SCWI box that Exp 5's metric classifies against (pure SCWI scores 0.65 vs our 0.52) and softens Exp 1's over-steep slope toward pi_3's -0.19. (3) ENGAGED BETA MEDIAN 2.65 → ~3.1, log-sd HELD at 0.29, clip unchanged. The tau trim costs ~5% of the AL margin (0.28→0.265); the median raise more than restores the sigmoid argument and recovers the AL adherence the iter-5 homogenization gave up. Target engaged AL anti-rate ~0.70, population excess ~2.3-2.6 — entering the [2.4, 3.2] window for the first time. This also pushes Exp 2's gap toward 0.24-0.27. The thin log-sd is what protects Exp 9 from re-saturating, so it must not be re-widened. (4) GUARDRAILS, in order of invocation: Exp 1 must not fall below -0.23 — if it does, trade the tau ceiling down further (0.55 → 0.50), NOT beta back down; Exp 9 must stay in [0.15, 0.30] — if it drifts high, trim log-sd 0.29 → 0.26 before touching the median; Exp 10 must stay ≤ 0.36 — if the changes push it over, trim the engaged kappa upper bound 0.68 → 0.65 as a single small step; Exp 12 must stay ≤ 0.15 — if it overshoots, revert diffusion toward 0.04. (5) LAST-RESORT-ONLY knob, NOT part of the main diff: engaged epsilon [0.03, 0.09] → [0.02, 0.07] recovers ~0.02-0.03 of AL anti-rate if Exp 11 still lands below 2.3 with everything else in place — but it steepens Exp 1 and raises Exp 9/10, so deploy it only if the guardrails have headroom. (6) HOLD FIXED: knee 4.45, diffusion 0.035, the 14/70/16 mixture, the pinned tail eta, the bucketed context key, and all other ranges. Process notes: (a) before committing, compute the actual stack sums and margins for the Exp 5/8/11 diagnostic cells at the extremes of the NEW tau range and check which side of the knee each option falls on — the standing iter-3 lesson; (b) treat Exp 12's iter-4→5 movement as noise (no tail-relevant parameter changed) — verify with the variance report rather than adding mechanism; (c) do not re-widen the beta log-sd or re-enrich the eta split — both were gate-rejected in iters 2-3 and the current eta geometry plus thin beta spread is what finally landed Exp 9. Expected profile: Exp 1 → -0.19 to -0.21, Exp 2 → 0.22-0.26, Exps 5/6/7 → 0.56-0.62/0.58-0.62/0.60-0.64, Exp 8 → 0.55-0.58, Exp 9 held 0.15-0.25, Exp 10 → 0.30-0.36, Exp 11 → 2.3-2.6, Exp 12 → 0.07-0.11 — which should strictly beat the 0.1030 base.

**Outcome of this advice:** iter 5 candidate loss=0.1030 -> iter 6 candidate loss=0.1465 -> the gate marked it REJECTED.

### Iteration 6
Verdict: regenerate
Interpretation: Iter 6 was REJECTED by the gate (loss 0.1465 vs the iter-5 base's 0.1030), and the per-experiment decomposition shows my iter-5 three-lever prescription was partially wrong: the levers interacted destructively and several of my directional predictions failed. Grading each lever against the data: (B) the tau-ceiling trim (0.65->0.55, with proportional eta scaling) was the clear WIN — Exp 8 rose 0.532->0.586 (inside [0.55, 0.65] for the first time), Exp 5 rose 0.516->0.557, Exp 6 rose 0.568->0.578, all toward the real values, exactly as the flip-knife arithmetic predicted. (A) the tail-kappa raise ([0.78,0.85]->[0.88,1.0]) was MIXED — it finally fixed Exp 12 (g 0.039->0.147, inside [0.06, 0.15]), but my claim that 'Exp 10 risk is low: the tail is already near-saturated on its cells' was WRONG: Exp 10's rise jumped 0.364->0.448 against a real 0.296 and a 0.36 ceiling. Restoring tail linearity on the above-knee twin-kill stacks re-sharpened the tail's SCWI-like step, inflating the rise. (C) the engaged beta median raise (2.65->3.1) was NET HARMFUL: Exp 1 broke its -0.23 guardrail (-0.218->-0.243 vs real -0.175), Exp 2 FELL (0.201->0.169 vs real 0.274; I predicted 0.22-0.26), Exp 7 fell (0.597->0.545), and Exp 11 FELL (1.96->1.88) despite my prediction of 2.3-2.6 — the +17% sigmoid-argument raise did not overcome the tau-trim margin loss. Worst of all, Exp 9 collapsed from a near-perfect 0.190 to -0.007. The Exp 9 collapse is mechanically explicable: with the trimmed tau ceiling the 3x1.00 top stacks span 4.05-4.65, still straddling the 4.45 knee, and the 0.60-ladder low stacks (4.3-7.2) sit in the knee's maximally nonlinear, subject-heterogeneous compression zone; the beta raise then saturates subjects on whichever side of these knife-bisected margins they land, so per-subject 0.50-ladder and 0.60-ladder rates decorrelate. This is the exact knee-bisection failure mode I flagged as a 'diagnostic suspect' in iter 4, now realized. The engaged kappa trim (D) neither held Exp 10 in window nor helped Exp 9.
Rationale: Regenerate on the unchanged iter-5 base with a DECOUPLED diff — iter 6 is the second time a bundled multi-lever change has been rejected because the levers interact, so change at most two things and make attribution possible. (1) KEEP the tau trim verbatim (engaged tau [0.35, 0.55], eta sds 0.08/0.15, variance ratio preserved): it is the best-validated lever in the whole loop (Exps 5/6/8 all moved toward real; Exp 8 now in window) and it also lowers the max AL stack to 4.04, which creates new knee headroom (see 4). (2) REVERT the engaged beta median to 2.65 (log-sd 0.29, clip unchanged): it broke the Exp 1 guardrail, dropped Exps 2/7/11 against prediction, and is a prime contributor to the Exp 9 saturation collapse. Do NOT raise it again this loop — two data points (iter 4's 0.388 at median 2.5/wide sd, iter 6's collapse at 3.1) show the Exp 9 response to engaged-beta sharpening is violently non-monotonic and dominates the loss. (3) HALF-STEP the tail kappa to [0.82, 0.90] — midway between iter 5's [0.78, 0.85] and iter 6's [0.88, 1.0]. This should retain most of the Exp 12 gain (target g ~0.08-0.12, inside [0.06, 0.15]) while roughly halving the Exp 10 damage (target rise ~0.36-0.40). Also REVERT the engaged kappa upper bound to 0.68: the 0.65 trim failed to hold Exp 10 and deepens the knee-zone nonlinearity that decorrelated Exp 9. (4) If Exp 10 still exceeds 0.36 after the half-step, the correct compensating knob is now the KNEE, not kappa: with tau <= 0.55 the max AL stack is only 4.04, so the knee can be lowered from 4.45 toward ~4.2, compressing the Exp 10 diagnostic stacks harder while leaving every AL and 2-top-cue cell in identity — but apply this as a SINGLE follow-up step only if needed, and first compute (do not envelope-estimate) which side of the candidate knee every Exp 9 ladder stack falls on at tau = 0.35 and 0.55, per the standing iter-3/4 process note; the 3x1.00 stacks (4.05-4.65) straddle any knee in [4.0, 4.7], and that straddle is the confirmed Exp 9 failure mode. (5) Exp 11 will fall back toward ~1.9-2.0 with the beta revert — accept that this round rather than re-sharpening beta; if everything else lands in window and the loss budget allows one more lever, the pre-authorized engaged epsilon trim ([0.03, 0.09] -> [0.02, 0.07]) is the remaining in-family route to ~2.2-2.4, but only deploy it if Exp 1 is above -0.22 and Exp 9/10 are inside their windows, since it steepens all three. (6) HOLD FIXED: diffusion 0.035, the 14/70/16 mixture, pinned tail eta, tail beta [4.0, 6.5], the bucketed context key, knee 4.45 (absent the conditional step in 4), and all other ranges. Process discipline: my iter-5 directional predictions for Exps 2, 10, and 11 were all wrong, and iter 6's rejection is partly on that advice — so before committing, simulate the candidate's per-experiment profile at the extremes of the changed ranges and report the predicted values; do not bundle more than two levers. Expected profile: Exp 1 ~ -0.20 to -0.22, Exp 2 ~ 0.19-0.21, Exps 5/6/7 ~ 0.55/0.58/0.60, Exp 8 ~ 0.57-0.60, Exp 9 ~ 0.15-0.22 (recovered via the beta revert), Exp 10 ~ 0.34-0.40, Exp 11 ~ 1.9-2.1, Exp 12 ~ 0.08-0.12 — which should strictly beat the 0.1030 base.

**Outcome of this advice:** iter 6 candidate loss=0.1465 -> iter 7 candidate loss=0.1276 -> the gate marked it REJECTED.

### Iteration 7 (most recent — address this)
Verdict: regenerate
Interpretation: Iter 7 was REJECTED by the gate (loss 0.1276 vs the iter-5 base's 0.1030), so this verdict is regenerate. The proposer executed my iter-6 decoupled diff faithfully (tau trim kept, beta median reverted to 2.65, tail kappa half-stepped to [0.82, 0.90], engaged kappa reverted to 0.68), and the per-experiment decomposition now yields a clean and important attribution lesson. What worked as predicted: the beta revert recovered Exp 9 partway (-0.007 -> 0.132, though still below the [0.15, 0.30] window) and Exp 2 hit its best value yet (0.231 vs real 0.274); the tau trim's gains partially persisted (Exp 5: 0.516 -> 0.598 toward 0.684; Exp 8: 0.532 -> 0.567 toward 0.604). What failed: the tail-kappa half-step did NOT interpolate. Exp 10's rise came in at 0.451 — slightly WORSE than iter 6's full-linearity 0.448 — and Exp 12's g came in at 0.188, ABOVE iter 6's 0.147, despite tail kappa moving substantially toward linearity in both cases. Since tail kappa went DOWN from iter 6 to iter 7 while both metrics went UP, the tail-kappa lever is essentially spent on these two experiments: the marginal response in the [0.82, 1.0] region is flat-to-noise (Exp 12's var is 0.13). The real driver of the Exp 10 overshoot is the TAU TRIM itself, and the arithmetic is now identifiable: on the 4x1.00-vs-8x0.50 twin-kill cell the raw anti-validity margin is exactly 2*tau (S_H = 4+4tau vs S_L = 4+2tau), so cutting the engaged tau ceiling from 0.65 to 0.55 shrank the twin-kill margin ~15-20% across the whole engaged mass, dropping p_twin and inflating the rise from 0.364 to ~0.45. My iter-6 attribution of the Exp 10 jump to 'tail linearity' was wrong; the iter-6-vs-7 comparison corrects it. The same trim-plus-eta-sharpening (total eta sd 0.22 -> 0.17) also raised Exp 12's fitted bhats past the [3.0, 4.2] ramp. Collateral: Exp 7 regressed (0.597 -> 0.541), Exp 1 sits exactly on its -0.23 guardrail (-0.230), and Exp 11 remains stuck at 1.92 — but note the sigmoid/guesser arithmetic now shows Exp 11's [2.4, 3.2] window is essentially unreachable in this family: with 14% guessers and margin ~0.29, hitting excess 2.88 requires engaged anti-rate ~0.78, i.e. effective beta ~4.4 on the AL cells, which iters 4 and 6 both showed destroys Exps 1/9/10. Iter 6's beta 3.1 moved Exp 11 from 1.96 to 1.88 — the AL sigmoid is saturated; beta is not the route.
Rationale: Regenerate on the unchanged iter-5 base with a TWO-lever diff whose attribution is clean, plus explicit fallbacks. (1) PRIMARY — LOWER THE KNEE from 4.45 to ~4.20-4.25. This is the pre-authorized conditional follow-up, now triggered (Exp 10 = 0.451 >> 0.36 ceiling). With tau <= 0.55 the max AL stack is 4.04, so every AL cell and every 2-top-cue adherence cell stays in the identity regime — Exp 11 (already at its family ceiling) and Exp 6 cannot regress through the knee. Mechanism: on the 3x1.00-vs-5x0.60 twin cell the high stack (4.05-4.65) crosses a 4.2 knee for most engaged subjects while the low stack (3.99) stays in identity, shrinking D_H and raising p_twin; on the 4x1.00 cells both stacks sit further above a lower knee and their margins compress, pulling both p_twin up and p_high toward 0.5. Both effects push the rise down toward ~0.33-0.38. The knee also lowers fitted bhats on the large stacks, pulling Exp 12 down toward its window. (2) TAIL KAPPA QUARTER-STEP DOWN: [0.82, 0.90] -> [0.80, 0.87]. Two runs at kappa >= 0.82 overshot Exp 12 (0.147, 0.188) and two at [0.78, 0.85] undershot (0.075, 0.039); interpolate between the flanks rather than repeating either endpoint. If the knee lever alone already lands g in [0.06, 0.15], hold tail kappa at [0.82, 0.90] instead — do not stack both downward blindly; check the variance report first since Exp 12's var (0.13) is large. (3) DO NOT touch: engaged tau [0.35, 0.55] (its Exps 5/8/2 gains are real and the Exp 10 damage is now handled by the knee, not by walking tau back), engaged beta median 2.65 / log-sd 0.29, the eta sds 0.08/0.15, diffusion 0.035, the 14/70/16 mixture, tail beta, and lapse ranges. (4) DO NOT chase Exp 11 upward with beta or epsilon this round — the sigmoid/guesser arithmetic caps it near 2.0-2.2 in this family, the epsilon trim's guardrails (Exp 1 at -0.230, Exp 9 at 0.132, Exp 10 at 0.451) are all violated right now, and two beta-raise attempts have been gate-rejected. Accept ~1.9-2.0 and spend the lever budget on Exps 10/12, which carry 0.25 of combined correctable error. (5) GUARDRAILS AND FALLBACKS, in order: (a) if Exp 9 falls below ~0.10 after the knee change, the knee-bisection of the 3x1.00 stacks (4.05-4.65 straddles ANY knee in that range) is decorrelating the ladders — revert the knee to 4.35 and instead recover Exp 10 via a partial tau-ceiling restore (0.55 -> 0.60, still clear of the Exp-8 flip knife at 0.64); (b) if Exp 12 undershoots below 0.06, restore tail kappa to [0.82, 0.90]; (c) if Exp 1 falls below -0.235, the fallback is likewise the tau-ceiling route, not beta. (6) PROCESS DISCIPLINE, standing: before committing, COMPUTE (not envelope-estimate) the actual stack sums S = sum_j (v_j + tau*v_j^2)*(v_j/v_ref)^eta for every Exp 9, 10, and 11 diagnostic cell at tau = 0.35 and 0.55, and verify which side of the candidate knee each option's stack falls on — my iter-6 prediction that the half-step would land Exp 10 at 0.36-0.40 was wrong because I misattributed the rise to tail linearity; the iter-6-vs-7 comparison is the correction, and the same discipline applies to the knee move now. Also report predicted per-experiment values at the range extremes before submitting. Expected profile: Exp 1 ~ -0.22, Exp 2 ~ 0.22, Exps 5/6 ~ 0.58/0.56, Exp 7 ~ 0.54-0.58 (monitor — if it stays depressed, the suspect is the eta-sd reduction, and a small redraw-sd restore 0.15 -> 0.17 is the follow-up, NOT this round), Exp 8 ~ 0.56, Exp 9 ~ 0.12-0.20, Exp 10 ~ 0.33-0.38, Exp 11 ~ 1.9-2.0, Exp 12 ~ 0.08-0.13 — which should strictly beat the 0.1030 base by recovering ~0.15 of Exp 10 and ~0.07 of Exp 12 error at minimal cost elsewhere.

**Outcome of this advice:** iter 7 candidate loss=0.1276 -> next candidate accept-status=PENDING (this is the advice you are addressing now).


## IMPLEMENTATION GUARDRAILS
- The parameters should be within the specified ranges.
- The model's predictions should be valid probability distributions (non-negative and sum to 1).
- When converting logits to probabilities via softmax, always use the numerically stable form: subtract the max before exponentiating (`x = x - np.max(x); p = np.exp(x); p /= p.sum()`). A naive `np.exp(x) / np.sum(np.exp(x))` overflows to Inf/NaN for large logits. Alternatively, use `scipy.special.softmax`.


## PROPOSAL — MINIMAL-DIFF EDIT (do NOT rewrite from scratch)
The RUNNING-BEST (last ACCEPTED) candidate is shown verbatim above under `## PREVIOUS CANDIDATE (this loop)`. This is the base the loop's accept gate is currently keeping; the most recent critic feedback (see `## PRIOR FEEDBACK ITERATIONS`) should be applied on top of it. Apply the SMALLEST edit that addresses the critic's diagnosis while staying inside the arbiter's prescribed mechanism family:
  - Re-emit the previous source verbatim, then change ONLY the lines needed to address the critic (a parameter range, a normalization, a softmax temperature, an attention scheme, a gating term, a buggy indexing line, etc.).
  - Keep all unaffected functions, equations, parameter names, and the overall mechanism intact.
  - Do NOT rewrite `predict` / `policy` end-to-end if a few lines would do, and do NOT switch mechanism families — that is the arbiter's decision, not yours in this loop.
  - Briefly explain the minimal edit in `rationale`.
If you genuinely believe a larger rewrite is required, you may do one, but justify in `rationale` why the minimal-diff path was insufficient.

## RESPONSE FORMAT
Return a JSON object with the following fields:
- theory: The theoretical claim this theory makes about cognition.
- predict: Python source defining def predict(parameters, state, history) -> np.ndarray.
- policy: Python source defining def policy(probs) -> int.
- parameters: Parameter ranges (e.g. "[1.0, 10.0]") or choices (e.g. "{1, 2}"), sampled per subject.
- rationale: Reasoning behind this theory design; used to explain why this theory is better then the previous ones.


## Response

```json
```json
{
  "theory": "Kneed Compressive Anti-Validity Integration with a Moderate Deterministic Tail (CAVI-K), knee-lowering refinement. Subjects integrate all binary expert ratings into a per-option subjective DEFECT LOAD, comprehending a rating of 1 as a defect (sign inversion). Per-cue defect magnitude is supralinear in the instructed validity, d_j = v_j + tau*v_j^2, modulated by a context elasticity (v_j/v_ref)^eta keyed on the bucketed mean endorsed validity, with a zero-centered stable component (sd 0.08) plus a per-context redraw (sd 0.15), fixing latent cross-context consistency at r ~ 0.20. The defect load passes through a two-regime compression map with the knee at 4.20 — above every near-knife small stack (AL cells max 4.04 at the trimmed tau ceiling 0.55; 2-top-cue adherence stacks 2.7-3.3, which keep full raw margins) and below the large diagnostic stacks (which grow sub-proportionally aversive under kappa in [0.55, 0.68]). The knee's operative new effect is on the Exp-10 ladder-2 twin cell (3x1.00 vs 5x0.60): the low stack (3.63-3.99) stays in the identity regime while the high stack (4.05-4.65) crosses the knee for tau > 0.40, shrinking D_H and raising p_twin, while the high-ratio cells compress — both pulling the psychometric rise down toward the real 0.296. Population: ~14% true guessers, ~70% engaged with homogenized lognormal beta (median 2.65, log-sd 0.29, clip [0.8, 6.0]), and ~16% deterministic tail (beta 4.0-6.5, kappa [0.80, 0.87], pinned eta). Choice is softmax(beta*(D_B - D_A)) with symmetric lapse and per-trial attention diffusion (sd 0.035).",
  "predict": "def predict(parameters, state, history):\n    # Kneed Compressive Anti-Validity Integration (CAVI-K), iter 8.\n    # TWO-LEVER diff implementing the iter-7 critic's diagnosis, built\n    # on the tau-trimmed parameter profile whose Exps 2/5/8 gains the\n    # critic validated as real (iter-7 values: Exp2 0.231, Exp5 0.598,\n    # Exp8 0.567, all toward real). Changes vs that profile:\n    #   (A) KNEE LOWERED 4.45 -> 4.20 (PRIMARY LEVER, Exp 10).\n    #       Computed stack arithmetic at the engaged tau range\n    #       [0.35, 0.55] (per the standing iter-3/4 process note —\n    #       computed, not envelope-estimated):\n    #         * AL cells (Exp 11): high stack 3*(0.9+tau*0.81) spans\n    #           [3.55, 4.04], low stack [3.31, 3.74] -> ALL in\n    #           identity; Exp 11 cannot regress through the knee.\n    #         * 2-top-cue adherence stacks (Exps 5/6): 2*(1+tau) spans\n    #           [2.70, 3.10] -> identity.\n    #         * Exp-10 ladder-2 twin (3x1.00 vs 5x0.60): low stack\n    #           5*(0.6+0.36tau) spans [3.63, 3.99] (identity), high\n    #           stack 3*(1+tau) spans [4.05, 4.65] (crosses 4.20 for\n    #           tau > 0.40, i.e. ~75% of the engaged tau range plus\n    #           the whole tail). D_H is compressed downward -> the\n    #           high-validity option becomes MORE attractive -> p_twin\n    #           rises -> the rise p_high - p_twin falls from 0.451.\n    #         * Exp-10 high-ratio cells: both stacks above the knee,\n    #           margins compress -> p_high falls toward 0.5.\n    #         * Exp-9 3x1.00 stacks (4.05-4.65) straddle the knee for\n    #           tau > 0.40 — the known risk; the documented fallback\n    #           (revert knee to 4.35, restore tau ceiling to 0.60) is\n    #           NOT deployed this round.\n    #   (B) TAIL KAPPA QUARTER-STEP [0.82, 0.90] -> [0.80, 0.87]\n    #       (Exp 12): two runs at kappa >= 0.82 overshot g (0.147,\n    #       0.188) and two at [0.78, 0.85] undershot (0.075, 0.039);\n    #       interpolate between the flanks rather than repeating\n    #       either endpoint. On the Exp-12 large stacks (10-11) the\n    #       knee move is only a ~2% slope change, so the tail kappa is\n    #       the operative Exp-12 lever.\n    #   Everything else is the validated profile, held verbatim:\n    #   engaged tau [0.35, 0.55] (clear of the Exp-8 flip knife at\n    #   tau ~ 0.64), eta sds 0.08/0.15 (variance ratio preserved,\n    #   latent r ~ 0.20), engaged beta median 2.65 / log-sd 0.29,\n    #   engaged kappa [0.55, 0.68], pinned tail eta 0.05, tail beta\n    #   [4.0, 6.5], diffusion 0.035, the 14/70/16 mixture, lapses.\n    import hashlib\n    import math\n    import numpy as np\n    from scipy.special import ndtri\n\n    stim = np.asarray(state, dtype=float)\n    if stim.ndim != 2 or stim.shape[0] != 2:\n        raise ValueError(\n            f\"CAVI-K expects a (2, n_features) stimulus; got shape {stim.shape}.\"\n        )\n    n_features = stim.shape[1]\n    ra, rb = stim[0], stim[1]\n\n    def _to_vec(raw):\n        if raw is None:\n            return None\n        if isinstance(raw, str):\n            s = raw.strip().strip('[]()')\n            toks = [t for t in s.replace(',', ' ').split() if t != '']\n            if not toks:\n                return None\n            return np.array([float(t) for t in toks])\n        arr = np.asarray(raw, dtype=float).ravel()\n        return arr if arr.size > 0 else None\n\n    val = _to_vec(parameters.get(\"validities\"))\n    if val is None or val.size != n_features:\n        val = np.full(n_features, 0.75)\n    val = np.clip(val, 1e-3, 1.0)\n\n    def _seed(name):\n        try:\n            x = float(parameters[name])\n        except (KeyError, TypeError, ValueError):\n            x = 0.5\n        if not np.isfinite(x):\n            x = 0.5\n        return min(max(x, 0.0), 1.0)\n\n    u = _seed(\"regime_seed\")\n    ts = _seed(\"tau_seed\")\n    ks = _seed(\"kappa_seed\")\n    bs = min(max(_seed(\"beta_seed\"), 1e-6), 1.0 - 1e-6)\n    es = _seed(\"epsilon_seed\")\n    ebs = min(max(_seed(\"eta_base_seed\"), 1e-6), 1.0 - 1e-6)\n    ss = _seed(\"subject_seed\")\n\n    # --- Population mixture ---\n    if u < 0.14:\n        # True guessers (~14%).\n        t = u / 0.14\n        beta = 0.02 + 0.08 * t                 # 0.02 .. 0.10\n        epsilon = 0.12 + 0.13 * es             # 0.12 .. 0.25\n        tau = 0.50\n        kappa = 0.75\n        eta_base = 0.00\n    elif u < 0.84:\n        # Engaged bulk (~70%): trimmed tau ceiling 0.55 (clear of the\n        # Exp-8 flip knife at tau ~ 0.64; validated at iters 6-7 where\n        # it lifted Exps 5/8/2), homogenized beta (median 2.65,\n        # log-sd 0.29), kappa acting only above the knee, zero-centered\n        # stable elasticity with sd 0.08.\n        tau = 0.35 + 0.20 * ts                 # 0.35 .. 0.55\n        kappa = 0.55 + 0.13 * ks                # 0.55 .. 0.68\n        beta = math.exp(math.log(2.65) + 0.29 * float(ndtri(bs)))\n        beta = min(max(beta, 0.8), 6.0)\n        epsilon = 0.03 + 0.06 * es             # 0.03 .. 0.09\n        eta_base = 0.08 * float(ndtri(ebs))\n        eta_base = min(max(eta_base, -0.15), 0.15)\n    else:\n        # Deterministic tail (~16%): hot, low-lapse, strongly inverted,\n        # kappa quarter-stepped to [0.80, 0.87] (Exp-12 flank\n        # interpolation), PINNED stable elasticity (no ndtri draw) so\n        # the tail cannot act as a hidden cross-context coupling\n        # channel.\n        tau = 0.55 + 0.10 * ts                 # 0.55 .. 0.65\n        kappa = 0.80 + 0.07 * ks                # 0.80 .. 0.87\n        beta = 4.0 + 2.5 * bs                   # 4.0 .. 6.5\n        epsilon = 0.02 + 0.02 * es              # 0.02 .. 0.04\n        eta_base = 0.05                         # pinned\n\n    # --- Context: bucketed mean endorsed validity ---\n    active = np.flatnonzero((ra > 0.5) | (rb > 0.5))\n    if active.size == 0:\n        return np.full(2, 0.5)\n\n    v_ref = float(np.mean(val[active]))\n    bucket = float(np.round(v_ref, 1))\n    key = f\"{bucket:.1f}\"\n    h = int(hashlib.md5(f\"{ss:.9f}|{key}\".encode(\"utf-8\")).hexdigest()[:14], 16)\n    uc = ((h % 999983) + 0.5) / 999984.0\n    uc = min(max(uc, 1e-6), 1.0 - 1e-6)\n\n    # Per-context redraw, zero-centered; stable/redraw sd ratio\n    # 0.08/0.15 fixes latent cross-context consistency at r ~ 0.20 by\n    # construction (variance ratio preserved from the base).\n    eta_ctx = eta_base + 0.15 * float(ndtri(uc))\n    eta_ctx = min(max(eta_ctx, -0.30), 0.50)\n\n    # --- Defect weights: supralinear anti-validity, context-normalized ---\n    d = val + tau * np.square(val)\n    w = d * np.power(val / v_ref, eta_ctx)\n\n    # Per-trial multiplicative attention diffusion (sd 0.035, the\n    # iter-3-proven level that lets Exp-12 fitted bhat reach the ramp).\n    att = np.exp(0.035 * np.random.randn(n_features))\n    w = w * att\n\n    # Raw defect loads.\n    s_a = float(np.dot(w, ra))\n    s_b = float(np.dot(w, rb))\n\n    # TWO-REGIME (offset) compression: identity below the knee, power\n    # compression above. Knee 4.20: above the max AL stack 4.04 (at\n    # the trimmed tau ceiling 0.55) and every 2-top-cue adherence\n    # stack, so near-knife small stacks keep full raw margins; the\n    # large Exp-10/12 stacks are compressed, and the Exp-10 ladder-2\n    # twin high stack crosses the knee asymmetrically.\n    S_KNEE = 4.20\n\n    def _compress(s):\n        if s <= S_KNEE:\n            return s\n        return S_KNEE * ((s / S_KNEE) ** kappa)\n\n    d_a = _compress(s_a)\n    d_b = _compress(s_b)\n\n    scores = np.array([-d_a, -d_b])\n\n    # Numerically stable softmax over the two option values.\n    z = beta * (scores - scores.max())\n    e = np.exp(z)\n    p_core = e / e.sum()\n\n    return (1.0 - epsilon) * p_core + epsilon * 0.5 * np.ones(2)",
  "policy": "def policy(probabilities):\n    probabilities = np.asarray(probabilities, dtype=np.float64)\n    probabilities = probabilities / probabilities.sum()  # Guard against float drift.\n    return np.random.choice(len(probabilities), p=probabilities)",
  "parameters": {
    "regime_seed": "[0, 1]",
    "tau_seed": "[0, 1]",
    "kappa_seed": "[0, 1]",
    "beta_seed": "[0, 1]",
    "epsilon_seed": "[0, 1]",
    "eta_base_seed": "[0, 1]",
    "subject_seed": "[0, 1]",
    "validities": "validities"
  },
  "rationale": "This is the iter-7 critic's two-lever prescription applied to the tau-trimmed parameter profile (the profile the critic explicitly validated: 'engaged tau [0.35, 0.55] — its Exps 5/8/2 gains are real', with iter-7's Exp2 0.231 / Exp5 0.598 / Exp8 0.567 all the best-in-loop values toward real 0.274/0.684/0.604). The iter-7 candidate was rejected ONLY through Exps 10/12 (0.451 vs 0.296; 0.188 vs 0.091) plus partial Exp 9/7 slippage, and the critic's iter-6-vs-7 comparison corrected the attribution: the Exp-10 overshoot is driven by the tau trim shrinking the twin-kill margins (raw margin exactly 2*tau on the 4x1.00-vs-8x0.50 cell), NOT by tail linearity — so the compensating knob is the KNEE, not walking tau back. (1) PRIMARY LEVER — knee 4.45 -> 4.20. Per the standing process discipline I computed the actual stack sums at tau = 0.35 and 0.55: AL cells (max 4.04) and all 2-top-cue adherence stacks (2.70-3.10) remain in the identity regime, so Exps 11/5/6 cannot regress through the knee; on the Exp-10 ladder-2 twin cell the low stack (3.63-3.99) stays in identity while the high stack (4.05-4.65) crosses 4.20 for tau > 0.40, shrinking D_H and raising p_twin (at tau 0.55 the margin cuts ~29%, from 0.66 to 0.47); the high-ratio ladder-2 margin (favoring H) compresses ~40% at tau 0.55 (0.138 -> 0.078), pulling p_high toward 0.5. Both effects push the rise down from 0.451 toward the ~0.33-0.38 the critic predicts. (2) SECOND LEVER — tail kappa quarter-step [0.82, 0.90] -> [0.80, 0.87], interpolating between the two undershooting Exp-12 flanks ([0.78, 0.85]: g = 0.039/0.075) and the two overshooting runs ([0.82, 0.90]/[0.88, 1.0]: g = 0.188/0.147); on the Exp-12 large stacks (10-11 units) the knee move is only ~2% (both stacks far above any knee), so the tail kappa is the operative Exp-12 lever — at kappa ~0.80-0.87 the tail's fitted bhat range shifts from ~[2.9, 4.75] to ~[2.6, 4.3], cutting the in-ramp mass toward g ~ 0.08-0.12, inside [0.06, 0.15]. (3) HELD VERBATIM: engaged tau [0.35, 0.55] (clear of the Exp-8 flip knife at tau ~ 0.64), eta sds 0.08/0.15 (variance ratio preserved, latent r ~ 0.20), engaged beta median 2.65 / log-sd 0.29 (the thin spread that landed Exp 9 at 0.190 at iter 5 — NOT re-widened, NOT raised, per two gate-rejected attempts), engaged kappa [0.55, 0.68], pinned tail eta, tail beta [4.0, 6.5], diffusion 0.035, the 14/70/16 mixture, and all lapse ranges. (4) Documented risk, accepted: the Exp-9 3x1.00 stacks (4.05-4.65) straddle the 4.20 knee for tau > 0.40; with beta back at 2.65 (not iter-6's 3.1 that collapsed Exp 9 to -0.007) the iter-7 value was 0.132, and the critic's fallback (knee 4.35 + tau ceiling 0.60) is reserved for the next round if Exp 9 falls below ~0.10. Exp 11 is accepted at its family ceiling ~1.9-2.0 rather than chasing it with beta/epsilon — the sigmoid/guesser arithmetic (14% guessers, margin ~0.29, needing effective beta ~4.4) has twice been gate-rejected. Expected profile: Exp 1 ~ -0.22, Exp 2 ~ 0.22, Exps 5/6 ~ 0.58/0.56, Exp 7 ~ 0.54-0.58, Exp 8 ~ 0.56, Exp 9 ~ 0.12-0.20, Exp 10 ~ 0.33-0.38, Exp 11 ~ 1.9-2.0, Exp 12 ~ 0.08-0.13 — recovering ~0.10 of Exp-10 and ~0.08 of Exp-12 error relative to the rejected iter-7 while keeping its Exps 2/5/8 gains, which should strictly beat the 0.1030 base."
}
```
```

## Usage

```json
{
  "input_tokens": 75357,
  "output_tokens": 19966,
  "reasoning_tokens": 15454,
  "provider": "Sail Research"
}
```
