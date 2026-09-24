# generation_iter_04_attempt_00

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
- THEORY 1 = `pi_9`
- THEORY 2 = `pi_10`
- The recommendation below acts on THEORY 2 (= `pi_10`).

Replace pi_10 with ISC-GDRD (Independent-quantile Steep-Core Graded Dual-Route Distrust), which differs from both siblings in exactly the four directions the pooled residuals demand. (1) STEEP CORE: keep Route 1's charge d_j = c0 + c1*v_j^kappa but raise beta to [2.4, 3.4] with c1 in [1.05, 1.30] (theta ~2.5-4.4, mean ~3.0), so the population theta-hat lands at the observed 2.72 (Exp 1) and saturated skeptic compliance rises to the observed 0.79-0.83 ceilings (Exps 13/14). (2) FULLY DECOUPLED, COMPRESSED POPULATION: drive the trimodal mixture with THREE independent uniform quantiles (u_mode for mode membership, u_w for route weight, u_eps for lapse) rather than HT's single coupled quantile; keep T3's homogeneous minority bands and compress further — counter mode ~12% at w in [0.47, 0.53], eps [0.14, 0.18], gamma [2.2, 3.2]; trust mode ~4% at alpha [0.48, 0.58], eps [0.17, 0.21], w [0.47, 0.53]; skeptic majority ~84% with w in [0.85, 0.95] independent of eps. This is what Exp 2's +21.6 Bayes factor (exceeding T3's own +9.3) demands: more decoupling and compression than T3, guaranteeing a large positive BF against HT's coupled structure. (3) LIGHTER LAPSE TAIL: skeptic eps = 0.12 + 0.09*t^0.9 over [0.12, 0.21] (below both current bands), lifting asymptote/coin-side ceilings while simultaneously shrinking between-subject dispersion toward the observed 0.115/0.143 (Exps 16/18) rather than the 0.15-0.19 both theories overproduce. (4) SOFTER COUNT ROUTE: gamma in [1.4, 2.8] with a slightly higher skeptic w-mean, attenuating the conflict-on-asymptote coupling slope toward the observed 1.88 (Exp 20) and -0.60 (Exp 19) instead of the 2.4-3.1 / -0.8 both theories overpredict. History-free as before (validities in instructions). This theory is falsifiable against pi_9 on exactly the axes where the data already sit beyond both siblings: it predicts theta-hat >= 2.65 (Exp 1), a BF vs HT of +15 or more (Exp 2), ceiling rates >= 0.80 on saturated coin-side assays (Exps 13/14), dispersion <= 0.13 (Exps 16/18), and coupling slopes near 1.9 (Exp 20) — none of which pi_9's coupled, lower-beta box can simultaneously produce.

## THEORY LEADERBOARD
A small set of prior picked theories shown for reference. Overall score is in `[0, 1]`, higher = better, computed as `1 - L2_norm(normalized_per_experiment_distances) / max_L2_norm`. 1.0 means closest to the real value on every experiment+metric pair; 0.0 means farthest. Each entry below carries the same depth of detail as the PREVIOUS MODEL INSTANCE above so you can borrow concrete mechanisms when useful.

### `pi_9` (overall score: 0.835)

**Description**
Heavy-Tailed Graded Dual-Route Distrust (HT-GDRD). Subjects evaluate expert endorsements through two concurrent routes. ROUTE 1 (analytic): every endorsement is a charge on its option — for the distrustful majority a LIABILITY whose magnitude grows with the endorser's raw claimed validity, d_j = c0 + c1*v_j^kappa; for a small 'trust-leaning' minority an ASSET proportional to the (capped) log-odds of validity, alpha*logit(v_j), that dominates the liability for high-validity endorsers. ROUTE 2 (graded counting): a continuous preference for the fewer-endorsement option, sigmoid(gamma*(cnt_B-cnt_A)). The population is an explicitly over-dispersed THREE-COMPONENT mixture driven by one uniform quantile u_pop: (i) a skeptic majority (~78%) with a wide, heavy-tailed lapse distribution (eps in [0.13, 0.27], Beta-like t^0.8 shaping) and a loose route weight w in [0.82, 0.96]; (ii) a counter minority (~16%) with near-balanced routes (w in [0.46, 0.70]), low-moderate lapse, and a steep count slope gamma >= 2.5; and (iii) a small trust-leaning mode (~6%) with a dominant positive micro-trust term (alpha in [0.50, 0.68]) and an elevated lapse. The single update this iteration concerns the analytic route's steepness: the iter-1 residual pattern — soft gradient assays (Exps 5-7, 9, 10) overshooting toward 0.5 WHILE ceiling-compliance assays (Exps 8, 11, 12) undershoot their ceilings — is the signature of an under-steep sigmoid(beta*D), not of excess lapse (three gate rejections established the lapse dimension is exhausted and sits near its local optimum). Raising the beta box from [1.3, 2.4] to [1.8, 3.0] simultaneously deepens the validity-gradient contrasts, raises saturated skeptic compliance toward the observed ceilings, and pulls the soft assays away from chance, without touching the lapse bands that the ceiling-prevalence and dispersion assays (Exps 13, 14, 16) are knife-edge calibrated to.

`predict(parameters, state, history) -> np.ndarray`:
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

`policy(probs) -> int`:
def policy(probabilities):
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()  # Ensure valid probabilities.
    return np.random.choice(len(probabilities), p=probabilities)

`parameters`:
- c0: [0.06, 0.13]
- c1: [1.00, 1.35]
- kappa: [1.6, 2.1]
- beta: [1.8, 3.0]
- alpha: [0.0, 0.05]
- u_pop: [0, 1]
- w_spread: [-0.02, 0.02]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.7117 (var=0.0205) vs this=0.7689 (var=0.0029)
- Experiment 2: real=-0.2562 (var=0.0128) vs this=-0.2931 (var=0.0031)
- Experiment 3: real=-0.5467 (var=0.0421) vs this=-0.5383 (var=0.0227)
- Experiment 4: real=-0.1938 (var=0.0027) vs this=-0.1995 (var=0.0006)
- Experiment 5: real=0.1143 (var=0.0077) vs this=0.1300 (var=0.0057)
- Experiment 6: real=0.1925 (var=0.0159) vs this=0.2425 (var=0.0146)
- Experiment 7: real=0.3815 (var=0.0238) vs this=0.3754 (var=0.0130)
- Experiment 8: real=0.7808 (var=0.0201) vs this=0.7767 (var=0.0076)
- Experiment 9: real=0.3729 (var=0.0159) vs this=0.3760 (var=0.0061)
- Experiment 10: real=0.5096 (var=0.0121) vs this=0.5469 (var=0.0057)
- Experiment 11: real=0.7875 (var=0.0537) vs this=0.7500 (var=0.0405)
- Experiment 12: real=0.8320 (var=0.0438) vs this=0.7725 (var=0.0315)
- Experiment 13: real=0.2800 (var=0.0133) vs this=0.2800 (var=0.0125)
- Experiment 14: real=0.1152 (var=0.0110) vs this=0.1489 (var=0.0031)
- Experiment 15: real=0.9846 (var=0.0914) vs this=0.9995 (var=0.0592)
- Experiment 16: real=0.1433 (var=0.0000) vs this=0.1873 (var=0.0000)
- Experiment 17: real=-0.5985 (var=0.0503) vs this=-0.8020 (var=0.0877)
- Experiment 18: real=1.8844 (var=0.0249) vs this=2.4428 (var=0.0181)
- Experiment 19: real=2.7176 (var=0.0000) vs this=2.4050 (var=0.0054)
- Experiment 20: real=21.6467 (var=2.4113) vs this=-6.8217 (var=0.2698)


---

### `pi_10` (overall score: 0.754)

**Description**
GDRD-T3 (Trimodal Calibrated-Tail Graded Dual-Route Distrust), variance-reduced minority modes. Subjects evaluate expert endorsements through two concurrent, history-free routes. ROUTE 1 (analytic distrust): every endorsement is a charge on its option whose magnitude grows with the endorser's raw claimed validity, d_j = c0 + c1*v_j^kappa; D = pen(B) - pen(A) + alpha_mode*sum_j clip(logit(v_j),0,3)*(a_j-b_j); P1(A) = sigmoid(beta*D). ROUTE 2 (graded counting): P2(A) = sigmoid(gamma*(cnt_B-cnt_A)). Mixture p = w*P1 + (1-w)*P2 plus independent lapse eps. The population is TRIMODAL via one uniform u_pop: (a) skeptic majority ~83% with heavy-tailed lapse (eps = 0.14+0.10*t^0.8 over [0.14,0.24]) and a route weight drawn from an INDEPENDENT second uniform quantile u_w (w in [0.83,0.95]); (b) counter minority ~13% with parameter-HOMOGENEOUS bands (w in [0.46,0.54], eps in [0.14,0.18], same means as before); (c) a mild trust-leaning mode ~4%, also parameter-homogeneous (alpha in [0.47,0.57], eps in [0.18,0.22], w in [0.47,0.53], gamma in [1.9,2.6]). The novelty this iteration: the minority modes are claimed to be behaviorally near-homogeneous within mode — the between-mode structure, not within-mode parameter scatter, carries the population dispersion. This is a falsifiable fifth register: if the minority modes were truly heterogeneous, the small-N population statistics (cross-subject slopes, population maxima) would show run-to-run swings far larger than binomial noise; homogenized modes predict draw-stable statistics centered between the two extreme draws already observed.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    # GDRD-T3, iter-6: VARIANCE-REDUCED minority modes on the iter-3
    # accepted base, per the iter-5 critique. The iter-5 event proved
    # the run-to-run SD of the aggregate loss (~0.017) exceeds every
    # tuning margin: byte-identical code scored 0.0794 and 0.0964 on
    # two draws, with the swings concentrated in the small-N
    # population statistics (Exps 17/15/18/13) that are leveraged by
    # the 0-2 trust subjects and 2-6 counter subjects per sample.
    # The single untried in-family lever is WITHIN-MODE SPREAD
    # COMPRESSION of the minority modes, holding means and masses:
    #   (1) TRUST MODE: alpha [0.43,0.61] -> [0.47,0.57] (same ~0.52
    #       mean), eps [0.16,0.24] -> [0.18,0.22] (same 0.20 mean),
    #       w [0.44,0.56] -> [0.47,0.53], gamma [1.5,3.0] -> [1.9,2.6].
    #       4% mass EXACTLY (the calibration logic for Exps 1/17/18
    #       depends on it).
    #   (2) COUNTER MODE: w [0.42,0.58] -> [0.46,0.54], eps
    #       [0.12,0.20] -> [0.14,0.18], same means, same 13% mass.
    #   (3) Skeptic branch, beta, c0/c1/kappa boxes, and all mode
    #       masses: UNTOUCHED (skeptic eps narrowing was falsified in
    #       iter 4 in both directions; the trust branch means were
    #       flanked to exhaustion in iters 1-3).
    if isinstance(state, dict):
        a_vec = np.asarray(state["option_a_ratings"], dtype=float).ravel()
        b_vec = np.asarray(state["option_b_ratings"], dtype=float).ravel()
        stim = np.vstack([a_vec, b_vec])
    else:
        stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"GDRD-T3 expects a (2, n_features) stimulus; got shape {stim.shape}."
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
    u_w = float(parameters["u_w"])
    w_spread = float(parameters["w_spread"])

    # --- Trimodal population mixture (variance-reduced minorities) ---
    f_counter = 0.13
    f_trust_lo = 0.96
    u = min(max(u_pop, 0.0), 1.0)
    if u < f_counter:
        # Counter minority (13%), COMPRESSED: same means as the
        # validated band, tighter within-mode scatter. The saturated
        # coin-side registers (Exps 11/12/14) depend on the counter
        # MEAN, not its spread; the compression only stabilizes the
        # small-N slope statistics (Exps 17/18) against draw luck.
        t = u / f_counter
        w_mix = 0.46 + 0.08 * t          # [0.46, 0.54]
        epsilon = 0.14 + 0.04 * t        # [0.14, 0.18]
        gamma = 2.0 + 1.5 * t            # [2.0, 3.5]
        alpha_mode = alpha_base
    elif u < f_trust_lo:
        # Skeptic majority (83%): analytic distrust dominant. The
        # lapse is heavy-tailed (Beta-like t^0.8 shaping) over
        # [0.14, 0.24]. The route weight is drawn from an INDEPENDENT
        # uniform quantile u_w -- w and eps are statistically
        # independent across skeptics (banked since iter 2).
        t = (u - f_counter) / (f_trust_lo - f_counter)
        epsilon = 0.14 + 0.10 * (t ** 0.8)   # [0.14, 0.24], mean ~0.19
        tw = min(max(u_w, 0.0), 1.0)
        w_mix = 0.83 + 0.12 * tw + w_spread    # ~[0.83, 0.95], indep of eps
        w_mix = float(min(max(w_mix, 0.83), 0.95))
        gamma = 1.5 + 2.0 * t            # [1.5, 3.5]
        alpha_mode = alpha_base
    else:
        # Trust-leaning residual mode (4%, MILD and now HOMOGENIZED):
        # alpha [0.47, 0.57] and eps [0.18, 0.22] hold the iter-3
        # means (~0.52, ~0.20) with half the spread, so whichever 0-2
        # trust subjects land in a sample sit near the cluster center
        # rather than at the band edges. w and gamma similarly
        # compressed. This targets the demonstrated draw-to-draw
        # swings in Exps 17/15/18 without moving any mode mean.
        t = (u - f_trust_lo) / (1.0 - f_trust_lo)
        alpha_mode = 0.47 + 0.10 * t     # [0.47, 0.57]
        w_mix = 0.47 + 0.06 * t          # [0.47, 0.53]
        epsilon = 0.18 + 0.04 * t        # [0.18, 0.22]
        gamma = 1.9 + 0.7 * t            # [1.9, 2.6]
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

`policy(probs) -> int`:
def policy(probabilities):
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()  # Ensure valid probabilities.
    return np.random.choice(len(probabilities), p=probabilities)

`parameters`:
- c0: [0.05, 0.14]
- c1: [1.0, 1.3]
- kappa: [1.6, 2.0]
- beta: [1.5, 2.6]
- alpha: [0.0, 0.05]
- u_pop: [0, 1]
- u_w: [0, 1]
- w_spread: [-0.02, 0.02]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.7117 (var=0.0205) vs this=0.7708 (var=0.0030)
- Experiment 2: real=-0.2562 (var=0.0128) vs this=-0.2791 (var=0.0036)
- Experiment 3: real=-0.5467 (var=0.0421) vs this=-0.5125 (var=0.0166)
- Experiment 4: real=-0.1938 (var=0.0027) vs this=-0.1950 (var=0.0004)
- Experiment 5: real=0.1143 (var=0.0077) vs this=0.1424 (var=0.0064)
- Experiment 6: real=0.1925 (var=0.0159) vs this=0.2375 (var=0.0123)
- Experiment 7: real=0.3815 (var=0.0238) vs this=0.3841 (var=0.0089)
- Experiment 8: real=0.7808 (var=0.0201) vs this=0.7192 (var=0.0178)
- Experiment 9: real=0.3729 (var=0.0159) vs this=0.4242 (var=0.0058)
- Experiment 10: real=0.5096 (var=0.0121) vs this=0.5508 (var=0.0041)
- Experiment 11: real=0.7875 (var=0.0537) vs this=0.7400 (var=0.0332)
- Experiment 12: real=0.8320 (var=0.0438) vs this=0.7630 (var=0.0419)
- Experiment 13: real=0.2800 (var=0.0133) vs this=0.1800 (var=0.0084)
- Experiment 14: real=0.1152 (var=0.0110) vs this=0.1263 (var=0.0026)
- Experiment 15: real=0.9846 (var=0.0914) vs this=0.9991 (var=0.0833)
- Experiment 16: real=0.1433 (var=0.0000) vs this=0.1711 (var=0.0000)
- Experiment 17: real=-0.5985 (var=0.0503) vs this=-0.8137 (var=0.0548)
- Experiment 18: real=1.8844 (var=0.0249) vs this=3.0879 (var=0.0215)
- Experiment 19: real=2.7176 (var=0.0000) vs this=2.2250 (var=0.0064)
- Experiment 20: real=21.6467 (var=2.4113) vs this=9.2931 (var=0.5515)


---

### `pi_8_1` (overall score: 0.681)

**Description**
Graded Dual-Route Distrust with a Bimodal Strategy Population (GDRD-B). Subjects evaluate expert endorsements through two concurrent routes. ROUTE 1 (analytic distrust): every endorsement is a liability whose magnitude grows monotonically in the endorser's RAW claimed validity, d_j = c0 + c1*v_j^kappa; accumulated suspicion P(X) = sum_j x_j*d_j is compared across options through sigmoid(beta*(P(B)-P(A))), plus a small residual micro-trust edge alpha*sum_j clip(logit(v_j),0,3)*(a_j-b_j) (capped so perfect experts exert bounded, not unbounded, trust pull). ROUTE 2 (graded counting): a continuous preference for the fewer-endorsement option, sigmoid(gamma*(cnt_B-cnt_A)). The population is BIMODAL in the route weight w: a large majority (~88%) of 'skeptics' (w in [0.85, 0.95], moderate lapse) coexists with a minority (~12%) of 'counters' (w in [0.50, 0.62], low lapse, decisive count slope gamma >= 2). The mixture is implemented as a quantile transform of a single uniform per-subject population variable u_pop, which holds the population-MEAN route weight at its base value while exploding the between-subject behavioral variance — the empirically observed 3-12x super-binomial variance on the saturation assays (Exps 11, 12) that no uniform range-widening could reproduce.

`predict(parameters, state, history) -> np.ndarray`:
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

`policy(probs) -> int`:
def policy(probabilities):
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()  # Ensure valid probabilities.
    return np.random.choice(len(probabilities), p=probabilities)

`parameters`:
- c0: [0.06, 0.13]
- c1: [1.00, 1.35]
- kappa: [1.6, 2.1]
- beta: [1.3, 2.4]
- alpha: [0.0, 0.05]
- u_pop: [0, 1]
- w_spread: [-0.02, 0.02]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.7117 (var=0.0205) vs this=0.7278 (var=0.0040)
- Experiment 2: real=-0.2562 (var=0.0128) vs this=-0.2659 (var=0.0036)
- Experiment 3: real=-0.5467 (var=0.0421) vs this=-0.5054 (var=0.0118)
- Experiment 4: real=-0.1938 (var=0.0027) vs this=-0.1963 (var=0.0008)
- Experiment 5: real=0.1143 (var=0.0077) vs this=0.1390 (var=0.0031)
- Experiment 6: real=0.1925 (var=0.0159) vs this=0.2350 (var=0.0077)
- Experiment 7: real=0.3815 (var=0.0238) vs this=0.3931 (var=0.0044)
- Experiment 8: real=0.7808 (var=0.0201) vs this=0.7629 (var=0.0041)
- Experiment 9: real=0.3729 (var=0.0159) vs this=0.4000 (var=0.0040)
- Experiment 10: real=0.5096 (var=0.0121) vs this=0.5415 (var=0.0033)
- Experiment 11: real=0.7875 (var=0.0537) vs this=0.7937 (var=0.0271)
- Experiment 12: real=0.8320 (var=0.0438) vs this=0.8320 (var=0.0072)
- Experiment 13: real=0.2800 (var=0.0133) vs this=0.3200 (var=0.0029)
- Experiment 14: real=0.1152 (var=0.0110) vs this=0.0594 (var=0.0004)
- Experiment 15: real=0.9846 (var=0.0914) vs this=0.7372 (var=0.0287)
- Experiment 16: real=0.1433 (var=0.0000) vs this=0.1323 (var=0.0000)
- Experiment 17: real=-0.5985 (var=0.0503) vs this=0.2631 (var=0.0122)
- Experiment 18: real=1.8844 (var=0.0249) vs this=1.5470 (var=0.0163)
- Experiment 19: real=2.7176 (var=0.0000) vs this=2.3929 (var=0.0062)
- Experiment 20: real=21.6467 (var=2.4113) vs this=6.0620 (var=0.8500)


## LOSS TRAJECTORY (this propose-loop)
Aggregate loss across iterations of THIS propose-loop (lower = better, 0 = perfect, `+inf` = unscorable). The ACCEPTED / REJECTED tag is the loop's programmatic accept-gate decision — only ACCEPTED candidates have ever been used as the base for a subsequent iteration. Use this together with PRIOR FEEDBACK ITERATIONS below to grade which past critic advice actually paid off.

- iter 1: loss=0.0894 -> ACCEPTED
- iter 2: loss=0.0745 -> ACCEPTED
- iter 3: loss=0.0777 -> REJECTED
- iter 4: loss=0.0947 -> REJECTED
Running-best (last ACCEPTED) base: iter 2 at loss=0.0745 — this is the source shown verbatim below under `## PREVIOUS CANDIDATE (this loop)`. Push the next edit's loss strictly below that floor or the gate will reject it.

## EXPERIMENTAL RESULTS
### Experiment 1
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[0, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """P(choose the Take-The-Best winner) on trials where TTB and Tallying
    make OPPOSITE deterministic predictions (i.e., trials where the two
    options win on different numbers of features, so the tallies disagree).

    High value -> TTB behavior; low value -> Tallying behavior.
    Works on the pooled DataFrame and on a single subject's slice.
    """
    validities = np.array([0.9, 0.8, 0.7, 0.6, 0.5])
    cue_order = np.argsort(-validities, kind="stable")

    def _to_matrix(col):
        rows = [list(r) for r in col]
        return np.array(rows, dtype=float)

    a = _to_matrix(data["option_a_ratings"])
    b = _to_matrix(data["option_b_ratings"])
    resp = np.asarray(data["response"].to_numpy(), dtype=float)

    n_trials = a.shape[0]

    # --- TTB winner per trial (cue cascade, first discriminating cue) ---
    winners = np.full(n_trials, -1, dtype=int)
    for j in cue_order:
        undecided = winners < 0
        a_better = undecided & (a[:, j] > b[:, j])
        b_better = undecided & (b[:, j] > a[:, j])
        winners[a_better] = 0
        winners[b_better] = 1

    # --- Tallying score per trial (number of strict feature-wise wins) ---
    a_wins = (a > b).sum(axis=1)
    b_wins = (b > a).sum(axis=1)

    # Conflict trials: tallies differ (so Tallying has a strict winner that,
    # in this design, is always the option OPPOSITE to the TTB winner),
    # and TTB also has a strict winner.
    conflict = (a_wins != b_wins) & (winners >= 0)

    if not np.any(conflict):
        # No diagnostic trials -> uninformative, return chance.
        return 0.5

    agree = float(np.mean(resp[conflict] == winners[conflict]))
    return agree
```

**Observed (real) value:** 0.7117 (var=0.0205)
**Previous candidate values (this loop):**
  - iter 1: 0.8089 (var=0.0029) (Δ vs real +0.0972)
  - iter 2: 0.8050 (var=0.0022) (Δ vs real +0.0933)
  - iter 3: 0.7769 (var=0.0027) (Δ vs real +0.0653)
  - iter 4 (most recent): 0.7883 (var=0.0036) (Δ vs real +0.0767)
**Other theories' values on this metric (for reference):**
- pi_1: 0.8444 (var=0.0125)
- pi_2: 0.1203 (var=0.0072)
- pi_3: 0.6869 (var=0.0033)
- pi_4: 0.7792 (var=0.0018)
- pi_5: 0.7272 (var=0.0025)
- pi_6: 0.6844 (var=0.0026)
- pi_7: 0.7453 (var=0.0030)
- pi_8: 0.7667 (var=0.0024)
- pi_8_1: 0.7278 (var=0.0040)
- pi_9: 0.7689 (var=0.0029)
- pi_10: 0.7708 (var=0.0030)

### Experiment 2
**Design**
  A=[0, 1, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1, 0]
  A=[0, 0, 1, 1, 0, 1]  B=[0, 1, 0, 0, 1, 0]
  A=[0, 0, 0, 1, 1, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1]  B=[0, 0, 0, 1, 0, 0]
  A=[1, 0, 1, 1, 0, 0]  B=[0, 1, 0, 0, 1, 0]
  A=[0, 0, 1, 0, 1, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 1, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[0, 0, 1, 1, 1, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[0, 0, 1, 0, 0, 0]
  A=[1, 0, 1, 1, 1, 0]  B=[0, 1, 0, 0, 0, 1]
  A=[0, 1, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 1, 1, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 1, 0]  B=[0, 1, 1, 1, 0, 0]
  A=[0, 1, 0, 0, 1, 0]  B=[0, 0, 1, 1, 0, 1]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 1, 0]  B=[1, 0, 1, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 1, 0, 1, 0]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Signature: allegiance to the tally winner on CONFLICT trials
    # (trials where the single top-validity discriminating cue favors
    # the tally LOSER). Tallying predicts P(choose tally winner) > 0.5
    # there (it follows the cue majority against the best cue);
    # Take-The-Best predicts P < 0.5 (it follows the top cue against
    # the majority). We return P(W | conflict) - 0.5, so the sign
    # itself identifies the theory for any noise level beta > 0.
    validities = np.array([0.95, 0.90, 0.85, 0.65, 0.60, 0.50])
    cue_order = np.argsort(-validities, kind="stable")

    a_list = data["option_a_ratings"].tolist()
    b_list = data["option_b_ratings"].tolist()
    resp = data["response"].to_numpy()

    conflict_w = []
    for a_raw, b_raw, r in zip(a_list, b_list, resp):
        a = np.asarray(a_raw, dtype=float)
        b = np.asarray(b_raw, dtype=float)

        a_w = float(np.sum(a > b))
        b_w = float(np.sum(b > a))
        if a_w == b_w:
            # Tally is tied -> heuristic guesses; uninformative cell.
            continue
        winner = 0 if a_w > b_w else 1

        # First discriminating cue in descending-validity order.
        top_favors = None
        for j in cue_order:
            if a[j] > b[j]:
                top_favors = 0
                break
            if b[j] > a[j]:
                top_favors = 1
                break
        if top_favors is None:
            continue  # no discriminating cue at all

        if top_favors == winner:
            continue  # congruent trial: both heuristics point the same way

        # Conflict trial: tally winner opposes the top cue's favorite.
        conflict_w.append(1.0 if int(r) == winner else 0.0)

    if len(conflict_w) == 0:
        return 0.0
    return float(np.mean(conflict_w)) - 0.5
```

**Observed (real) value:** -0.2562 (var=0.0128)
**Previous candidate values (this loop):**
  - iter 1: -0.3031 (var=0.0024) (Δ vs real -0.0469)
  - iter 2: -0.2737 (var=0.0028) (Δ vs real -0.0175)
  - iter 3: -0.2716 (var=0.0035) (Δ vs real -0.0153)
  - iter 4 (most recent): -0.2844 (var=0.0025) (Δ vs real -0.0281)
**Other theories' values on this metric (for reference):**
- pi_2: 0.3394 (var=0.0118)
- pi_1: -0.3231 (var=0.0164)
- pi_3: -0.2566 (var=0.0023)
- pi_4: -0.2684 (var=0.0040)
- pi_5: -0.2456 (var=0.0038)
- pi_6: -0.1978 (var=0.0023)
- pi_7: -0.2559 (var=0.0043)
- pi_8: -0.2728 (var=0.0044)
- pi_8_1: -0.2659 (var=0.0036)
- pi_9: -0.2931 (var=0.0031)
- pi_10: -0.2791 (var=0.0036)

### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 1, 1, 1, 1, 1, 1, 1]  B=[0, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 1]  B=[0, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """
    Validity-sensitivity contrast for the cue-2 cascade design.

    For every trial we compute (a) the Take-The-Best winner (first
    discriminating cue in validity order) and (b) the VWEI evidence
    E = sum_j [log(v_j/(1-v_j))]^3 * sign(a_j - b_j), expressed
    relative to the TTB winner (Erel = E * (+1 if TTB winner is A
    else -1)).

    Two trial classes:
      HIGH  : Erel >  3   -> pairs 1-4, where the 90% expert decides
             and VWEI strongly agrees (P(pick TTB winner) ~ 0.85).
      LOW   : Erel < -0.5 -> pairs 7-12 and 15-16, where cue 2 (or 3)
             decides but the weighted evidence of the opposing
             coalition dominates (P(pick TTB winner) ~ 0.35-0.47).

    Metric = P(choose TTB winner | HIGH) - P(choose TTB winner | LOW).

    TTB predicts the SAME choice probability on every non-tied pair
    (its score is binary), so this difference is 0 in expectation.
    VWEI predicts a large positive difference (~ +0.42). The contrast
    cancels each subject's overall response rate (beta / epsilon),
    leaving only the stimulus-driven validity sensitivity.
    """
    v = np.array([0.90, 0.78, 0.76, 0.74, 0.72, 0.70, 0.68, 0.66, 0.64])
    lo = np.log(v / (1.0 - v))
    w = lo ** 3.0
    order = np.argsort(-v, kind="stable")

    highs = []
    lows = []

    for a_cell, b_cell, r in zip(
        data["option_a_ratings"], data["option_b_ratings"], data["response"]
    ):
        a = np.asarray(a_cell, dtype=float)
        b = np.asarray(b_cell, dtype=float)
        if a.shape[0] != 9 or b.shape[0] != 9:
            continue

        # VWEI-style evidence for A over B (gamma = 3).
        d = np.sign(a - b)
        E = float(np.dot(w, d))

        # TTB winner: first discriminating cue in validity order.
        win = None
        for j in order:
            if a[j] > b[j]:
                win = 0
                break
            if b[j] > a[j]:
                win = 1
                break
        if win is None:
            continue  # no discriminating cue (does not occur here)

        # Evidence relative to the TTB winner.
        s = 1.0 if win == 0 else -1.0
        Erel = E * s

        r_val = int(r)
        chose_winner = 1.0 if r_val == win else 0.0

        if Erel > 3.0:
            highs.append(chose_winner)
        elif Erel < -0.5:
            lows.append(chose_winner)

    if not highs or not lows:
        return 0.0

    return float(np.mean(highs) - np.mean(lows))
```

**Observed (real) value:** -0.5467 (var=0.0421)
**Previous candidate values (this loop):**
  - iter 1: -0.6342 (var=0.0092) (Δ vs real -0.0875)
  - iter 2: -0.5646 (var=0.0093) (Δ vs real -0.0179)
  - iter 3: -0.5862 (var=0.0113) (Δ vs real -0.0396)
  - iter 4 (most recent): -0.5929 (var=0.0107) (Δ vs real -0.0463)
**Other theories' values on this metric (for reference):**
- pi_1: 0.0108 (var=0.0045)
- pi_3: 0.4433 (var=0.0115)
- pi_2: 0.5433 (var=0.0293)
- pi_4: -0.4146 (var=0.0116)
- pi_5: -0.5708 (var=0.0133)
- pi_6: -0.4858 (var=0.0140)
- pi_7: -0.5546 (var=0.0132)
- pi_8: -0.5946 (var=0.0135)
- pi_8_1: -0.5054 (var=0.0118)
- pi_9: -0.5383 (var=0.0227)
- pi_10: -0.5125 (var=0.0166)

### Experiment 4
**Design**
  A=[1, 0, 1, 1, 1, 1, 1, 1, 1]  B=[0, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 1, 1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0, 1, 1, 1, 1]  B=[1, 0, 1, 1, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 1, 1, 1, 1, 1]  B=[1, 0, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 1, 1, 1, 1, 1]  B=[0, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[0, 0, 0, 1, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """
    Signed-evidence slope.

    For every trial we compute the VWEI evidence
        E = sum_j w_j * sign(a_j - b_j),  w_j = logit(v_j)^3
    and the TTB winner (first discriminating cue in validity order;
    validities are strictly descending so cue order = feature order).

    Define the signed regressor  x = +E if TTB's winner is A, x = -E if
    TTB's winner is B, and the outcome y = 1 iff the subject chose TTB's
    winner.  Return the OLS slope of y on x.

    TTB's probability of choosing its own winner is a single constant
    (softmax(beta) mixed with a lapse) on EVERY trial, so its expected
    slope is exactly 0.  VWEI's probability of choosing TTB's winner is
    sigmoid(beta * x) on every trial, giving a clearly positive slope
    (~0.05 at the design center, sign-stable over the whole parameter
    box).  The two theories are maximally separated on this statistic.
    """
    if data is None or len(data) == 0:
        return 0.0

    validities = np.array([0.74, 0.73, 0.70, 0.69, 0.68,
                           0.67, 0.66, 0.65, 0.64], dtype=float)
    v = np.clip(validities, 0.5 + 1e-9, 1.0 - 1e-6)
    w = np.log(v / (1.0 - v)) ** 3.0

    def _to_vec(cell):
        if isinstance(cell, str):
            return [float(ch) for ch in cell if ch in '01']
        return [float(val) for val in cell]

    a = np.array([_to_vec(r) for r in data['option_a_ratings']], dtype=float)
    b = np.array([_to_vec(r) for r in data['option_b_ratings']], dtype=float)
    if a.ndim != 2 or a.shape[0] == 0 or a.shape[1] != len(w):
        return 0.0

    resp = data['response'].to_numpy(dtype=float)

    d = np.sign(a - b)                     # +1 favors A, -1 favors B
    E = d @ w                              # VWEI evidence for A

    disc = d != 0
    keep = disc.any(axis=1)                # drop degenerate all-tie rows
    d, E, resp, disc = d[keep], E[keep], resp[keep], disc[keep]
    if d.shape[0] == 0:
        return 0.0

    # First discriminating cue (validities strictly descending -> order 0..8)
    first_idx = disc.argmax(axis=1)
    rows = np.arange(d.shape[0])
    d_first = d[rows, first_idx]
    winner_a = d_first > 0                  # TTB's winner is option A

    # y = 1 iff subject chose TTB's winner; x = evidence signed toward winner
    y = np.where(winner_a, 1.0 - resp, resp)
    x = np.where(winner_a, E, -E)

    xc = x - x.mean()
    denom = float(np.dot(xc, xc))
    if denom <= 1e-12:
        return 0.0
    yc = y - y.mean()
    slope = float(np.dot(xc, yc)) / denom
    return slope
```

**Observed (real) value:** -0.1938 (var=0.0027)
**Previous candidate values (this loop):**
  - iter 1: -0.2181 (var=0.0005) (Δ vs real -0.0243)
  - iter 2: -0.2013 (var=0.0006) (Δ vs real -0.0075)
  - iter 3: -0.2065 (var=0.0005) (Δ vs real -0.0127)
  - iter 4 (most recent): -0.2057 (var=0.0005) (Δ vs real -0.0119)
**Other theories' values on this metric (for reference):**
- pi_3: 0.0475 (var=0.0011)
- pi_1: 0.0002 (var=0.0008)
- pi_2: 0.1895 (var=0.0024)
- pi_4: -0.2020 (var=0.0005)
- pi_5: -0.2142 (var=0.0004)
- pi_6: -0.1987 (var=0.0006)
- pi_7: -0.1995 (var=0.0005)
- pi_8: -0.2078 (var=0.0006)
- pi_8_1: -0.1963 (var=0.0008)
- pi_9: -0.1995 (var=0.0006)
- pi_10: -0.1950 (var=0.0004)

### Experiment 5
**Design**
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Top-cue allegiance under endorsement-majority conflict.

    Selected trials: the 95%-validity expert (feature index 0) endorses
    exactly one option, AND that option carries strictly MORE total
    endorsements (sum of ratings) than its rival.  On these trials the
    metric is the empirical rate of choosing the option endorsed by the
    top expert.

    VWEI (any gamma, beta, epsilon) must follow the top cue at ~0.98
    here: the amplified log-odds weight of v=.95 dominates every
    possible opposing coalition of the remaining cues, and 50%-expert
    endorsements contribute exactly zero weight.
    SDI must AVOID the top-cue option here (~0.15-0.25): every
    endorsement is a liability, and the top-cue option is also the
    endorsement-majority option.
    """
    df = data.reset_index(drop=True)

    a = np.array([list(x) for x in df['option_a_ratings']], dtype=float)
    b = np.array([list(x) for x in df['option_b_ratings']], dtype=float)
    resp = df['response'].to_numpy(dtype=float)

    if a.ndim != 2 or a.shape[0] == 0:
        return 0.5

    chose_a = resp < 0.5

    # Which option does the top (95%) expert endorse?
    top_a = a[:, 0] > 0.5
    top_b = b[:, 0] > 0.5
    # Keep only trials where exactly one option gets the top expert's
    # endorsement (guards against degenerate rows).
    xor_top = np.logical_xor(top_a, top_b)

    # Total endorsement counts per option.
    cnt_a = a.sum(axis=1)
    cnt_b = b.sum(axis=1)

    # Is the top-cue-endorsed option also the endorsement-majority
    # option (strictly more endorsements)?
    top_option_more = np.where(top_a, cnt_a > cnt_b, cnt_b > cnt_a)

    sel = xor_top & top_option_more
    if not np.any(sel):
        return 0.5

    # Did the subject choose the option endorsed by the top expert?
    followed = np.where(top_a[sel], chose_a[sel], ~chose_a[sel])
    return float(np.mean(followed))
```

**Observed (real) value:** 0.1143 (var=0.0077)
**Previous candidate values (this loop):**
  - iter 1: 0.0924 (var=0.0028) (Δ vs real -0.0219)
  - iter 2: 0.1090 (var=0.0032) (Δ vs real -0.0052)
  - iter 3: 0.1005 (var=0.0030) (Δ vs real -0.0138)
  - iter 4 (most recent): 0.1205 (var=0.0022) (Δ vs real +0.0062)
**Other theories' values on this metric (for reference):**
- pi_4: 0.1348 (var=0.0038)
- pi_3: 0.9867 (var=0.0003)
- pi_1: 0.8433 (var=0.0110)
- pi_2: 0.9057 (var=0.0054)
- pi_5: 0.0852 (var=0.0016)
- pi_6: 0.1043 (var=0.0024)
- pi_7: 0.1000 (var=0.0018)
- pi_8: 0.0829 (var=0.0023)
- pi_8_1: 0.1390 (var=0.0031)
- pi_9: 0.1300 (var=0.0057)
- pi_10: 0.1424 (var=0.0064)

### Experiment 6
**Design**
  A=[0, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 0, 1, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 0]
  A=[0, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0]  B=[0, 0, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1]
  A=[0, 0, 1, 0, 1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 1, 1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0]  B=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 0, 1, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Double-dissociation composite built on the two strongest contrasts
    # engineered into this design:
    #
    # COMPONENT 1 ("big-gap single endorsers", pairs 6/18, 8 trials/subject):
    #   both options carry exactly ONE endorsement; the endorsers' validities
    #   differ by >= 0.25 (0.90 vs 0.60).  VWEI overwhelmingly follows the
    #   higher-validity endorser (P ~ 0.89 across its whole parameter box);
    #   SDI is structurally near-blind at matched endorsement counts
    #   (P ~ 0.50-0.55 across its whole box).
    #
    # COMPONENT 2 ("ridge-crest coalition", pairs 10/22, 8 trials/subject):
    #   one option carries a single 0.80-validity endorsement, the other a
    #   coalition of four 0.75-validity endorsements.  Score +1 for choosing
    #   the COALITION.  VWEI favors the coalition (P ~ 0.62); SDI strongly
    #   favors the single endorser (coalition P ~ 0.10).
    #
    # Metric = mean of the two rates.  Expected: VWEI ~ 0.75, SDI ~ 0.31.
    # Both components use only 8 trials each but their gaps point the SAME
    # way after sign alignment, so the composite has a large mean gap and
    # modest binomial-only between-subject variance.

    V = np.array([0.90, 0.85, 0.80, 0.80, 0.75, 0.75, 0.75, 0.75, 0.65, 0.60])

    a_cells = data['option_a_ratings'].tolist()
    b_cells = data['option_b_ratings'].tolist()
    resp = data['response'].to_numpy()

    scores_gap = []    # 1 = chose the higher-validity single endorser
    scores_coal = []    # 1 = chose the 4x0.75 coalition over the single 0.80 endorser

    for a_raw, b_raw, r in zip(a_cells, b_cells, resp):
        a = np.asarray(a_raw, dtype=float).ravel()
        b = np.asarray(b_raw, dtype=float).ravel()
        if a.shape != V.shape or b.shape != V.shape:
            continue
        ca = int(round(a.sum()))
        cb = int(round(b.sum()))
        chose_a = (int(r) == 0)

        if ca == 1 and cb == 1:
            # Single endorsement on each side: who endorsed, and how good
            # is that expert?
            ia = int(np.argmax(a))
            ib = int(np.argmax(b))
            va = V[ia]
            vb = V[ib]
            if abs(va - vb) >= 0.25:
                hi_is_a = (va > vb)
                scores_gap.append(1.0 if (chose_a == hi_is_a) else 0.0)

        elif (ca == 1 and cb == 4) or (ca == 4 and cb == 1):
            # Ridge-crest conflict: verify it is exactly the designed cell
            # (single 0.80 expert vs four 0.75 experts) and score the
            # coalition choice.
            if ca == 1:
                single_vec, coal_vec = a, b
                single_is_a = True
            else:
                single_vec, coal_vec = b, a
                single_is_a = False
            i_single = int(np.argmax(single_vec))
            coal_idx = np.where(coal_vec > 0.5)[0]
            if (
                abs(V[i_single] - 0.80) < 1e-9
                and len(coal_idx) == 4
                and bool(np.all(np.abs(V[coal_idx] - 0.75) < 1e-9))
            ):
                # +1 when the subject chose the coalition side
                scores_coal.append(1.0 if (chose_a != single_is_a) else 0.0)

    r_gap = float(np.mean(scores_gap)) if len(scores_gap) > 0 else 0.5
    r_coal = float(np.mean(scores_coal)) if len(scores_coal) > 0 else 0.5
    return 0.5 * (r_gap + r_coal)
```

**Observed (real) value:** 0.1925 (var=0.0159)
**Previous candidate values (this loop):**
  - iter 1: 0.1800 (var=0.0093) (Δ vs real -0.0125)
  - iter 2: 0.2200 (var=0.0113) (Δ vs real +0.0275)
  - iter 3: 0.2350 (var=0.0146) (Δ vs real +0.0425)
  - iter 4 (most recent): 0.2150 (var=0.0081) (Δ vs real +0.0225)
**Other theories' values on this metric (for reference):**
- pi_3: 0.7625 (var=0.0125)
- pi_4: 0.3037 (var=0.0089)
- pi_1: 0.4863 (var=0.0079)
- pi_2: 0.6925 (var=0.0122)
- pi_5: 0.1862 (var=0.0087)
- pi_6: 0.2387 (var=0.0095)
- pi_7: 0.2312 (var=0.0144)
- pi_8: 0.2050 (var=0.0059)
- pi_8_1: 0.2350 (var=0.0077)
- pi_9: 0.2425 (var=0.0146)
- pi_10: 0.2375 (var=0.0123)

### Experiment 7
**Design**
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0]  B=[0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]  B=[0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0]  B=[0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0]  B=[0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0]  B=[0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # "Validity-following rate in theory-conflict cells"
    #
    # The 15 experts split into a HIGH-validity group (features 0-6:
    # validities 0.95, 0.90, 0.90, 0.90, 0.85, 0.80, 0.65) and a
    # LOW-validity group (features 7-14: validity 0.60). Every trial in
    # this design pits a "pure high" option against a "pure low"
    # option. Two families of cells separate SDI from VPS:
    #
    # Family 1 (matched endorsement counts, validity gap): SDI's
    #   penalty is a near-flat function of validity (delta ~ 0), so it
    #   is pinned at ~0.51 for the high-validity option (its weak
    #   alpha tie-break even pushes slightly ABOVE 0.5). VPS's
    #   penalty rises steeply in validity, so it systematically picks
    #   the LOW-validity option (~0.28).
    #
    # Family 2 (count conflict where the FEWER-endorsed option is the
    #   high-validity one): SDI follows the endorsement count and
    #   picks the high-validity option (~0.72). VPS's validity-scaled
    #   distrust makes the low-validity majority cheaper, so it picks
    #   the high-validity option only ~0.30 of the time.
    #
    # The metric is the average of P(choose the high-validity-group
    #   option) over these two families. SDI predicts ~0.62; VPS
    #   predicts ~0.29.

    V = np.array([0.95, 0.90, 0.90, 0.90, 0.85, 0.80, 0.65,
                  0.60, 0.60, 0.60, 0.60, 0.60, 0.60, 0.60, 0.60])

    f1_hits = 0.0
    f1_n = 0
    f2_hits = 0.0
    f2_n = 0

    for a_raw, b_raw, r in zip(data['option_a_ratings'],
                               data['option_b_ratings'],
                               data['response']):
        a = np.asarray(a_raw, dtype=float).ravel()
        b = np.asarray(b_raw, dtype=float).ravel()
        m = int(min(a.size, b.size, V.size))
        if m == 0:
            continue
        a = a[:m]
        b = b[:m]

        top = V[:m] >= 0.65  # high-validity expert group
        a_top = float(np.sum(a[top]))
        a_bot = float(np.sum(a[~top]))
        b_top = float(np.sum(b[top]))
        b_bot = float(np.sum(b[~top]))

        # Require each option to be endorsed purely by one group
        # (all trials in this design satisfy this; guards oddities).
        if (a_top > 0 and a_bot > 0) or (b_top > 0 and b_bot > 0):
            continue
        ca = a_top + a_bot
        cb = b_top + b_bot
        if ca == 0 or cb == 0:
            continue

        a_is_top = a_top > 0
        b_is_top = b_top > 0
        if a_is_top == b_is_top:
            continue

        chose_a = (int(round(float(r))) == 0)
        chose_top = chose_a if a_is_top else (not chose_a)

        if ca == cb:
            # Family 1: matched counts, validity gap.
            f1_n += 1
            f2_unused = None
            f1_hits += 1.0 if chose_top else 0.0
        else:
            # Family 2: count conflict; keep only cells where the
            # FEWER-endorsed option is the high-validity one
            # (the cells where SDI and VPS point in opposite
            # directions). Cells where the fewer-endorsed option is
            # the low-validity one are agreed upon by both theories
            # and are excluded.
            fewer_is_top = (a_is_top and ca < cb) or (b_is_top and cb < ca)
            if fewer_is_top:
                f2_n += 1
                f2_hits += 1.0 if chose_top else 0.0

    p1 = f1_hits / f1_n if f1_n > 0 else np.nan
    p2 = f2_hits / f2_n if f2_n > 0 else np.nan
    vals = [p for p in (p1, p2) if not np.isnan(p)]
    if not vals:
        return 0.5
    return float(np.mean(vals))
```

**Observed (real) value:** 0.3815 (var=0.0238)
**Previous candidate values (this loop):**
  - iter 1: 0.3412 (var=0.0155) (Δ vs real -0.0403)
  - iter 2: 0.3393 (var=0.0041) (Δ vs real -0.0422)
  - iter 3: 0.3802 (var=0.0087) (Δ vs real -0.0013)
  - iter 4 (most recent): 0.3580 (var=0.0104) (Δ vs real -0.0235)
**Other theories' values on this metric (for reference):**
- pi_4: 0.6227 (var=0.0042)
- pi_5: 0.2844 (var=0.0060)
- pi_1: 0.8411 (var=0.0121)
- pi_2: 0.3319 (var=0.0035)
- pi_3: 0.9332 (var=0.0008)
- pi_6: 0.3286 (var=0.0033)
- pi_7: 0.3960 (var=0.0030)
- pi_8: 0.3794 (var=0.0044)
- pi_8_1: 0.3931 (var=0.0044)
- pi_9: 0.3754 (var=0.0130)
- pi_10: 0.3841 (var=0.0089)

### Experiment 8
**Design**
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Matched-count validity-reversal index.
    #
    # On trials where A and B carry the SAME number of endorsements (k vs k),
    # the two theories make opposite-sign predictions:
    #   VPS: the coalition of LOWER-validity endorsers is preferred
    #        (a high-validity endorsement is a bigger suspected defect),
    #        with preference strengthening in k.
    #   SDI: at matched count its validity sensitivity has the wrong sign
    #        and is bounded, so it stays at or below chance for the
    #        low-validity coalition on every such trial.
    #
    # The metric is the empirical proportion of choices of the
    # LOW-validity coalition across all matched-count trials
    # (design pairs 1-6 and their A/B mirrors 13-18; 48 of the 96
    # trials per subject). VPS predicts ~0.85; SDI predicts ~0.45.
    # It is well-defined on a single subject's slice (48 Bernoulli
    # trials) and on the pooled data.

    v = np.array([
        0.95, 0.95, 0.95, 0.90, 0.90, 0.90, 0.90, 0.85, 0.85, 0.75,
        0.65, 0.65, 0.65, 0.60, 0.60, 0.60, 0.60, 0.65, 0.65, 0.65,
    ], dtype=float)

    hits = []
    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=float)
        b = np.asarray(row["option_b_ratings"], dtype=float)
        if a.shape[0] != v.shape[0] or b.shape[0] != v.shape[0]:
            continue

        ca = float(a.sum())
        cb = float(b.sum())
        # Keep only matched-count trials with at least one endorsement
        # on each side (the validity-reversal assay cells).
        if ca == 0.0 or cb == 0.0 or ca != cb:
            continue

        # Mean validity of the endorsing coalition on each side.
        va = float(np.mean(v[a > 0]))
        vb = float(np.mean(v[b > 0]))
        if va == vb:
            continue

        low_is_a = va < vb
        chose_a = (int(row["response"]) == 0)
        hits.append(1.0 if (chose_a == low_is_a) else 0.0)

    if len(hits) == 0:
        return 0.5
    return float(np.mean(hits))
```

**Observed (real) value:** 0.7808 (var=0.0201)
**Previous candidate values (this loop):**
  - iter 1: 0.7808 (var=0.0178) (Δ vs real +0.0000)
  - iter 2: 0.7725 (var=0.0196) (Δ vs real -0.0083)
  - iter 3: 0.7658 (var=0.0129) (Δ vs real -0.0150)
  - iter 4 (most recent): 0.7679 (var=0.0117) (Δ vs real -0.0129)
**Other theories' values on this metric (for reference):**
- pi_5: 0.8263 (var=0.0045)
- pi_4: 0.4600 (var=0.0059)
- pi_1: 0.1496 (var=0.0101)
- pi_2: 0.5108 (var=0.0054)
- pi_3: 0.0317 (var=0.0006)
- pi_6: 0.8054 (var=0.0034)
- pi_7: 0.7746 (var=0.0055)
- pi_8: 0.7825 (var=0.0049)
- pi_8_1: 0.7629 (var=0.0041)
- pi_9: 0.7767 (var=0.0076)
- pi_10: 0.7192 (var=0.0178)

### Experiment 9
**Design**
  A=[0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Weighted proportion of choosing the side whose endorsements come from
    # MORE VALID experts, on matched-endorsement-count trials.
    #
    # Design validities (n_features=20, fixed): indices 0-5 are 0.50,
    # indices 6-19 are 0.60. On every trial where both options carry the
    # SAME number of endorsements, the flat count terms (c0) of both
    # DCD and VPS cancel exactly, so the choice is driven purely by the
    # validity composition of the endorsers:
    #   - VPS: penalty strictly increasing in v  -> always avoids the
    #     0.60 experts -> weighted P(hi-validity side) well below 0.5
    #     (mid ~0.38, box <= ~0.45).
    #   - DCD: dampened distrust (2v-1)^kappa collapses near chance and
    #     is opposed by the residual trust term alpha*logit(v) ->
    #     essentially at/above chance (mid ~0.51, box >= ~0.49).
    # Trials are weighted by m = |#0.60-endorsements difference|, which
    # emphasizes the cells (m=2,3,4) where the two theories diverge most.
    V = np.array([0.5] * 6 + [0.6] * 14, dtype=float)
    hi = (V > 0.55).astype(float)  # indicator of the 0.60-validity experts

    if data is None or len(data) == 0:
        return 0.5

    a_col = data['option_a_ratings'].tolist()
    b_col = data['option_b_ratings'].tolist()
    resp = data['response'].to_numpy()

    num = 0.0
    den = 0.0
    for i in range(len(data)):
        a = np.asarray(a_col[i], dtype=float)
        b = np.asarray(b_col[i], dtype=float)
        if a.shape[0] != V.shape[0] or b.shape[0] != V.shape[0]:
            continue
        tA = float(np.sum(a))
        tB = float(np.sum(b))
        # Only matched-count trials: the flat c0 terms cancel and the
        # choice isolates the validity-composition sensitivity.
        if tA != tB:
            continue
        hA = float(np.dot(hi, a))  # number of 0.60-expert endorsements on A
        hB = float(np.dot(hi, b))
        if hA == hB:
            continue  # pure tie in validity composition
        m = abs(hA - hB)
        r = int(resp[i])
        chose_hi = (r == 0) if (hA > hB) else (r == 1)
        den += m
        if chose_hi:
            num += m

    if den <= 0:
        return 0.5
    return num / den
```

**Observed (real) value:** 0.3729 (var=0.0159)
**Previous candidate values (this loop):**
  - iter 1: 0.3461 (var=0.0059) (Δ vs real -0.0268)
  - iter 2: 0.3960 (var=0.0041) (Δ vs real +0.0231)
  - iter 3: 0.3970 (var=0.0042) (Δ vs real +0.0242)
  - iter 4 (most recent): 0.3710 (var=0.0048) (Δ vs real -0.0019)
**Other theories' values on this metric (for reference):**
- pi_6: 0.5269 (var=0.0032)
- pi_5: 0.3820 (var=0.0036)
- pi_1: 0.7308 (var=0.0072)
- pi_2: 0.5032 (var=0.0040)
- pi_3: 0.5099 (var=0.0041)
- pi_4: 0.4895 (var=0.0044)
- pi_7: 0.3889 (var=0.0038)
- pi_8: 0.3844 (var=0.0045)
- pi_8_1: 0.4000 (var=0.0040)
- pi_9: 0.3760 (var=0.0061)
- pi_10: 0.4242 (var=0.0058)

### Experiment 10
**Design**
  A=[0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0]  B=[0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # COIN-FLIP ENDORSEMENT TOLERANCE.
    #
    # For every trial, count how many endorsements each option receives
    # from the five chance-validity (v = 0.50) experts (feature indices
    # 15-19 in this experiment's fixed validity vector). Every one of the
    # 24 unique pairs pits an option carrying coin-flip endorsements
    # against an option carrying none, so the trial is scored:
    #   1.0  if the subject chose the option with MORE 0.50-expert
    #        endorsements (the 'coin-flip tolerant' choice),
    #   0.0  otherwise.
    # The metric is the mean of this score over all trials.
    #
    # This is a direct assay of the one structural difference between the
    # two confidence-distrust theories: the geometry of the per-endorsement
    # distrust charge. VPS charges c0 + c1*v^kappa, so a 0.50 endorsement
    # still costs a substantial c1*0.25-0.33 distrust units and the
    # internal exchange rate between mid-validity (0.75) endorsements and
    # coin-flips is ~1.9 coin-flips per 0.75. DCD charges
    # c0 + c1*(2v-1)^kappa, which collapses to the bare floor c0 at
    # v = 0.50 (and refunds part of the 0.75 charge via the residual trust
    # term), yielding an exchange rate of only ~1.3. Hence VPS subjects
    # are systematically MORE willing to accept coin-flip endorsements,
    # across every cell family in the design:
    #   composition cells (mixed {v_hi, 0.50} vs homogeneous mid): VPS
    #     picks the mixed side (0.53-0.59), DCD avoids it (0.33-0.45);
    #   exchange cells (0.75-coalition vs k coin-flips): VPS keeps
    #     choosing the coin-flip side through k=3-4, DCD abandons it;
    #   calibration cells ({0.90} vs {0.50}, {0.50,0.50} vs {0.90,0.90}):
    #     VPS 0.73/0.86 vs DCD 0.65/0.76.
    # Mid-parameter predictions: VPS ~0.59, DCD ~0.45 (disjoint across
    # their full parameter boxes), with per-subject SD ~0.05-0.06 from
    # 96 Bernoulli trials.

    validities = np.array([
        0.92, 0.90, 0.90, 0.90, 0.85, 0.77, 0.77,
        0.75, 0.75, 0.75, 0.75, 0.75, 0.75, 0.72, 0.72,
        0.50, 0.50, 0.50, 0.50, 0.50,
    ])
    coin_mask = np.isclose(validities, 0.5)

    responses = data["response"].to_numpy()
    ratings_a = data["option_a_ratings"].tolist()
    ratings_b = data["option_b_ratings"].tolist()

    scores = []
    for i in range(len(ratings_a)):
        a = np.asarray(ratings_a[i], dtype=float).ravel()
        b = np.asarray(ratings_b[i], dtype=float).ravel()
        n = min(a.shape[0], b.shape[0], validities.shape[0])
        mask = coin_mask[:n]
        ca = float(np.sum(a[:n][mask]))
        cb = float(np.sum(b[:n][mask]))
        if ca == cb:
            # No coin-flip asymmetry on this trial; skip defensively.
            continue
        chose_a = (int(responses[i]) == 0)
        c_chosen = ca if chose_a else cb
        c_other = cb if chose_a else ca
        scores.append(1.0 if c_chosen > c_other else 0.0)

    if len(scores) == 0:
        return 0.5
    return float(np.mean(scores))
```

**Observed (real) value:** 0.5096 (var=0.0121)
**Previous candidate values (this loop):**
  - iter 1: 0.5465 (var=0.0068) (Δ vs real +0.0369)
  - iter 2: 0.5460 (var=0.0051) (Δ vs real +0.0365)
  - iter 3: 0.5540 (var=0.0050) (Δ vs real +0.0444)
  - iter 4 (most recent): 0.5458 (var=0.0066) (Δ vs real +0.0362)
**Other theories' values on this metric (for reference):**
- pi_5: 0.6071 (var=0.0030)
- pi_6: 0.4429 (var=0.0037)
- pi_1: 0.4433 (var=0.0012)
- pi_2: 0.6129 (var=0.0030)
- pi_3: 0.5190 (var=0.0010)
- pi_4: 0.3810 (var=0.0022)
- pi_7: 0.5540 (var=0.0032)
- pi_8: 0.5610 (var=0.0028)
- pi_8_1: 0.5415 (var=0.0033)
- pi_9: 0.5469 (var=0.0057)
- pi_10: 0.5508 (var=0.0041)

### Experiment 11
**Design**
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Saturated-conflict compliance rate.
    #
    # Logic: using a FIXED reference parameterization of the shared skeptic
    # core (c0=0.10, c1=1.0, kappa=2.0 -> d_j = 0.10 + v_j^2), compute the
    # skeptic decision variable D = pen(B) - pen(A) for every trial, plus the
    # raw endorsement counts cnt_A, cnt_B.
    #
    # Keep only trials that are (i) SATURATED for the skeptic core
    # (|D| > 2.0, so any plausible beta in either theory's box drives the
    # sigmoid to ~1) and (ii) in CONFLICT: the skeptic-preferred side is the
    # side with MORE endorsements (the pure counter branch votes the other
    # way). In this fixed design these are exactly the count-parity-jump
    # cells pairs 3, 4 and their mirrors 15, 16 (16 trials per subject).
    #
    # On these cells the two theories make disjoint predictions:
    #   VPS:  P(pick skeptic side) = (1-eps)*~1 + eps/2  ~ 0.95 (box 0.92-0.98)
    #   SVD:  P = (1-eps)*(w*1 + (1-w)*0) + eps/2 = (1-eps)*w + eps/2
    #         ~ 0.80 (box 0.73-0.87, since the counter mixture drags the
    #         saturated response toward the fewer-endorsement side).
    # The metric is the observed fraction of choices that follow the
    # skeptic-preferred side on these cells.

    validities = [0.95] * 7 + [0.75] * 4 + [0.50] * 9
    d_ref = [0.10 + 1.0 * (v ** 2) for v in validities]

    hits = []
    for _, row in data.iterrows():
        a_raw = row["option_a_ratings"]
        b_raw = row["option_b_ratings"]
        a = [int(float(x)) for x in a_raw]
        b = [int(float(x)) for x in b_raw]

        pen_a = sum(di for di, xi in zip(d_ref, a) if xi == 1)
        pen_b = sum(di for di, xi in zip(d_ref, b) if xi == 1)
        D = pen_b - pen_a  # >0 favors A

        cnt_a = sum(1 for x in a if x == 1)
        cnt_b = sum(1 for x in b if x == 1)

        # (i) saturation for the skeptic core
        if abs(D) <= 2.0:
            continue
        # counter branch must be decisive (not indifferent)
        if cnt_a == cnt_b:
            continue

        skeptic_prefers_a = D > 0
        counter_prefers_a = cnt_a < cnt_b  # fewer endorsements preferred

        # (ii) conflict: counter branch votes AGAINST the saturated skeptic core
        if skeptic_prefers_a == counter_prefers_a:
            continue

        resp = int(row["response"])  # 0 = chose A, 1 = chose B
        followed_skeptic = (resp == 0) if skeptic_prefers_a else (resp == 1)
        hits.append(1.0 if followed_skeptic else 0.0)

    if len(hits) == 0:
        return 0.5
    return float(np.mean(hits))
```

**Observed (real) value:** 0.7875 (var=0.0537)
**Previous candidate values (this loop):**
  - iter 1: 0.7900 (var=0.0293) (Δ vs real +0.0025)
  - iter 2: 0.7712 (var=0.0328) (Δ vs real -0.0162)
  - iter 3: 0.8050 (var=0.0270) (Δ vs real +0.0175)
  - iter 4 (most recent): 0.7438 (var=0.0416) (Δ vs real -0.0437)
**Other theories' values on this metric (for reference):**
- pi_7: 0.7812 (var=0.0147)
- pi_5: 0.9525 (var=0.0034)
- pi_1: 0.1400 (var=0.0209)
- pi_2: 0.8375 (var=0.0163)
- pi_3: 0.0075 (var=0.0004)
- pi_4: 0.1500 (var=0.0081)
- pi_6: 0.9487 (var=0.0026)
- pi_8: 0.7937 (var=0.0289)
- pi_8_1: 0.7937 (var=0.0271)
- pi_9: 0.7500 (var=0.0405)
- pi_10: 0.7400 (var=0.0332)

### Experiment 12
**Design**
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 1, 1]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # COIN-SIDE CHOICE RATE ON SATURATED PERFECT-VS-COIN CELLS.
    #
    # Features 0..5 are the validity-1.0 ("perfect") experts; features
    # 6..14 are the coin-flip (v=0.5) experts.
    #
    # Selected cells: one option carries >= 4 perfect endorsements with
    # <= 7 total endorsements, the other carries 0 perfect and >= 5 coin
    # endorsements. This selects exactly the 10 saturated pairs
    # (1,2,3,4,6 and their A/B mirrors 13,14,15,16,18), i.e. 40 of the
    # 96 trials per subject. The staircase top rung (pairs 5/17) and the
    # exchange-locus pairs are deliberately excluded: there the two
    # theories overlap or the per-subject spread is maximal.
    #
    # The metric is the rate of CHOOSING THE COIN-ONLY SIDE (i.e. avoiding
    # the perfect-endorser side), pooled over floor trials and their
    # mirrors, which cancels any side bias.

    n_perf = 6
    df = data.reset_index(drop=True)

    hits = []
    for a_raw, b_raw, resp in zip(
        df["option_a_ratings"], df["option_b_ratings"], df["response"]
    ):
        a = [int(x) for x in a_raw]
        b = [int(x) for x in b_raw]

        perfA = sum([1 for i in range(len(a)) if a[i] == 1 and i < n_perf])
        coinA = sum([1 for i in range(len(a)) if a[i] == 1 and i >= n_perf])
        perfB = sum([1 for i in range(len(b)) if b[i] == 1 and i < n_perf])
        coinB = sum([1 for i in range(len(b)) if b[i] == 1 and i >= n_perf])

        a_heavy = (perfA >= 4) and ((perfA + coinA) <= 7)
        b_heavy = (perfB >= 4) and ((perfB + coinB) <= 7)
        a_coin = (perfA == 0) and (coinA >= 5)
        b_coin = (perfB == 0) and (coinB >= 5)

        if a_heavy and b_coin:
            # A is the perfect-heavy side, so the coin-only side is B.
            hits.append(1.0 if int(resp) == 1 else 0.0)
        elif b_heavy and a_coin:
            # B is the perfect-heavy side, so the coin-only side is A.
            hits.append(1.0 if int(resp) == 0 else 0.0)

    if len(hits) == 0:
        return 0.5
    return float(np.mean(hits))
```

**Observed (real) value:** 0.8320 (var=0.0438)
**Previous candidate values (this loop):**
  - iter 1: 0.8165 (var=0.0220) (Δ vs real -0.0155)
  - iter 2: 0.7865 (var=0.0293) (Δ vs real -0.0455)
  - iter 3: 0.8220 (var=0.0105) (Δ vs real -0.0100)
  - iter 4 (most recent): 0.7910 (var=0.0224) (Δ vs real -0.0410)
**Other theories' values on this metric (for reference):**
- pi_5: 0.9385 (var=0.0024)
- pi_7: 0.8175 (var=0.0049)
- pi_1: 0.1350 (var=0.0072)
- pi_2: 0.7165 (var=0.0069)
- pi_3: 0.0050 (var=0.0001)
- pi_4: 0.0885 (var=0.0040)
- pi_6: 0.0525 (var=0.0010)
- pi_8: 0.8385 (var=0.0089)
- pi_8_1: 0.8320 (var=0.0072)
- pi_9: 0.7725 (var=0.0315)
- pi_10: 0.7630 (var=0.0419)

### Experiment 13
**Design**
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd
    from ast import literal_eval

    # Fixed design: experts 0-5 have v=1.0, experts 6-7 have v=0.65,
    # experts 8-15 have v=0.5.
    PERF = (0, 1, 2, 3, 4, 5)
    MID = (6, 7)
    COIN = (8, 9, 10, 11, 12, 13, 14, 15)

    def _vec(cell):
        if isinstance(cell, str):
            cell = literal_eval(cell)
        return np.asarray(list(cell), dtype=float).ravel()

    def _saturation_side(a, b):
        """Saturation (pure lapse-assay) trials: one option carries only
        1-2 coin endorsements, the other carries only 4-5 perfect
        endorsements. Both routes of both theories saturate toward the
        coin-side option, so P(choose coin side) = 1 - epsilon/2.
        Returns 0 if A is the coin side, 1 if B is, else -1."""
        pa = int(round(sum(a[i] for i in PERF)))
        ma = int(round(sum(a[i] for i in MID)))
        ca = int(round(sum(a[i] for i in COIN)))
        pb = int(round(sum(b[i] for i in PERF)))
        mb = int(round(sum(b[i] for i in MID)))
        cb = int(round(sum(b[i] for i in COIN)))
        if ma == 0 and mb == 0:
            a_low = (pa == 0 and ca in (1, 2) and pb in (4, 5) and cb == 0)
            b_low = (pb == 0 and cb in (1, 2) and pa in (4, 5) and ca == 0)
            if a_low != b_low:
                return 0 if a_low else 1
        return -1

    def _rate(df):
        hits = []
        for a_cell, b_cell, resp in zip(
            df["option_a_ratings"].tolist(),
            df["option_b_ratings"].tolist(),
            df["response"].tolist(),
        ):
            side = _saturation_side(_vec(a_cell), _vec(b_cell))
            if side < 0:
                continue
            hits.append(1.0 if int(float(resp)) == side else 0.0)
        if not hits:
            return float("nan")
        return float(np.mean(hits))

    n_subj = int(pd.Series(data["subject_id"]).nunique())

    # Single subject's slice: that subject's saturation accuracy.
    if n_subj <= 1:
        return _rate(data)

    # Pooled sample: population-level prevalence of ceiling-level
    # saturation (the design's designated lapse falsification assay).
    rates = []
    for _, sdf in data.groupby("subject_id", sort=False):
        r = _rate(sdf)
        if np.isfinite(r):
            rates.append(r)
    if not rates:
        return float("nan")
    rates = np.asarray(rates, dtype=float)
    return float(np.mean(rates >= 0.95))
```

**Observed (real) value:** 0.2800 (var=0.0133)
**Previous candidate values (this loop):**
  - iter 1: 0.3000 (var=0.0106) (Δ vs real +0.0200)
  - iter 2: 0.3200 (var=0.0092) (Δ vs real +0.0400)
  - iter 3: 0.2200 (var=0.0091) (Δ vs real -0.0600)
  - iter 4 (most recent): 0.3600 (var=0.0137) (Δ vs real +0.0800)
**Other theories' values on this metric (for reference):**
- pi_7: 0.4000 (var=0.0038)
- pi_8: 0.5200 (var=0.0013)
- pi_1: 0.0000 (var=0.0135)
- pi_2: 0.0000 (var=0.0088)
- pi_3: 0.0000 (var=0.0004)
- pi_4: 0.0000 (var=0.0507)
- pi_5: 0.6600 (var=0.0033)
- pi_6: 0.0000 (var=0.0022)
- pi_8_1: 0.3200 (var=0.0029)
- pi_9: 0.2800 (var=0.0125)
- pi_10: 0.1800 (var=0.0084)

### Experiment 14
**Design**
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # ------------------------------------------------------------------
    # EXCESS-DISPERSION METRIC (conflict staircase + congruent asymptote)
    #
    # Per subject:
    #   x = P(choose the fewer-endorsement side | CONFLICT trials)
    #       Conflict trials: the option with FEWER endorsements carries the
    #       HIGHER total validity mass (the perfect-vs-coins staircase,
    #       8 pairs x 4 reps = 32 trials/subject).
    #   r = P(choose the fewer-endorsement side | SATURATED CONGRUENT
    #       trials) (fewer-endorsed side carries >= 3 LESS validity mass;
    #       8 pairs x 4 reps = 32 trials/subject).
    #   v = (x - 0.21)^2 - (r - 0.96)^2
    #
    # 0.21 = a priori conflict-rate reference (midpoint of the SVD
    # box-implied range [0.13, 0.29]); 0.96 = the asymptote ceiling
    # (1 - eps/2 at eps = 0.08), which sits above SVD's hard cap of
    # 0.94 (eps >= 0.12).
    #
    # v is each subject's squared conflict-rate deviation from the
    # reference that is NOT paid for by a lapse-driven asymptote
    # shortfall.  Under SVD, all between-subject conflict dispersion
    # comes from (w, eps) heterogeneity, and eps >= 0.12 forces
    # r <= 0.94, so the two squared terms cancel subject-by-subject
    # (E[v] ~ 0.001).  Under GDRD-B, the bimodal route-weight
    # population (12% counter mode at conflict 0.35-0.53, skeptic
    # majority at 0.12-0.23) generates conflict dispersion while the
    # asymptote stays at the ceiling (eps <= 0.18), so v > 0
    # (E[v] ~ 0.011).
    #
    # Population value: root-mean-square of v across subjects (the
    # excess dispersion in rate units).  Single subject: its own v
    # (its squared contribution to the population statistic).
    # ------------------------------------------------------------------
    VALIDITIES = np.array([1.0, 1.0, 1.0, 1.0, 1.0, 1.0, 0.86, 0.74,
                           0.5, 0.5, 0.5, 0.5, 0.5, 0.5, 0.5, 0.5, 0.5])
    CONFLICT_REF = 0.21
    ASYMPTOTE_REF = 0.96
    MASS_GAP_MIN = 3.0

    df = data.reset_index(drop=True)
    A = np.vstack([np.asarray(x, dtype=float).ravel()
                   for x in df["option_a_ratings"]])
    B = np.vstack([np.asarray(x, dtype=float).ravel()
                   for x in df["option_b_ratings"]])
    resp = df["response"].to_numpy(dtype=float)

    n_feat = A.shape[1]
    valid = VALIDITIES[:n_feat]

    cnt_a = A.sum(axis=1)
    cnt_b = B.sum(axis=1)
    mass_a = A @ valid
    mass_b = B @ valid

    unequal = cnt_a != cnt_b
    fewer_a = cnt_a < cnt_b
    mass_fewer = np.where(fewer_a, mass_a, mass_b)
    mass_more = np.where(fewer_a, mass_b, mass_a)

    conflict = unequal & (mass_fewer > mass_more)
    asymptote = (unequal & (mass_fewer < mass_more)
                 & ((mass_more - mass_fewer) >= MASS_GAP_MIN))

    chose_fewer = np.where(fewer_a, resp == 0.0, resp == 1.0).astype(float)

    tmp = pd.DataFrame({"sid": df["subject_id"].to_numpy(),
                        "conflict": conflict,
                        "asymptote": asymptote,
                        "cf": chose_fewer})

    sub_ids = pd.unique(tmp["sid"])
    x = tmp[tmp["conflict"]].groupby("sid")["cf"].mean().reindex(sub_ids)
    r = tmp[tmp["asymptote"]].groupby("sid")["cf"].mean().reindex(sub_ids)

    v = (x - CONFLICT_REF) ** 2 - (r - ASYMPTOTE_REF) ** 2
    v = v.dropna().to_numpy()
    if v.size == 0:
        return 0.0
    if v.size == 1:
        # single subject: its squared excess deviation (contribution
        # to the population dispersion statistic)
        return float(v[0])
    # population: root-mean-squared excess dispersion, in rate units
    return float(np.sqrt(max(0.0, float(np.mean(v)))))
```

**Observed (real) value:** 0.1152 (var=0.0110)
**Previous candidate values (this loop):**
  - iter 1: 0.1381 (var=0.0034) (Δ vs real +0.0229)
  - iter 2: 0.1145 (var=0.0019) (Δ vs real -0.0007)
  - iter 3: 0.1353 (var=0.0034) (Δ vs real +0.0201)
  - iter 4 (most recent): 0.1229 (var=0.0015) (Δ vs real +0.0077)
**Other theories' values on this metric (for reference):**
- pi_8: 0.1117 (var=0.0005)
- pi_7: 0.0387 (var=0.0001)
- pi_1: 0.0000 (var=0.0145)
- pi_2: 0.0000 (var=0.0239)
- pi_3: 0.0000 (var=0.0015)
- pi_4: 0.3730 (var=0.0446)
- pi_5: 0.1587 (var=0.0002)
- pi_6: 0.0000 (var=0.0107)
- pi_8_1: 0.0594 (var=0.0004)
- pi_9: 0.1489 (var=0.0031)
- pi_10: 0.1263 (var=0.0026)

### Experiment 15
**Design**
  A=[1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # EXTREME COUNTER-MODE ASSAY.
    # Per subject we form S = r_parity + r_conflict, where
    #   r_parity   = rate of choosing the PERFECT-ENDORSEMENT-HEAVY option
    #                on the count-matched parity trials (8v8 / 6v6),
    #   r_conflict = rate of choosing the 8-perfect (fewer-endorsement)
    #                option on the 8v9 conflict trials.
    # Algebra (lapse eps, skeptic weight w, count-route mass X=(1-eps)(1-w)):
    #   SVD:      S = 1.5*X + eps, X in [0.06,0.18] indep of eps in [0.12,0.24]
    #             -> true per-subject S confined to [0.23, 0.47] (w>=0.80 caps
    #                the count route at 0.20 of the core mixture).
    #   GDRD-B skeptics (87%): X = 0.25 - eps (neutrality coupling)
    #             -> S = 0.375 - 0.5*eps in [0.26, 0.30]: pinned LOW.
    #   GDRD-B counters (13%): w in [0.42,0.56] -> X in [0.34,0.51]
    #             -> S in [0.74, 0.89]: DISJOINT from SVD's entire box.
    # The two theories' pooled means on these cells are matched by
    # construction, so the dissociation lives in the tail: only GDRD-B
    # produces subjects whose (parity, conflict) pair lands above the
    # 0.47 ceiling of SVD's box. We map S through a logistic centered
    # in the empty moat (0.72, scale 0.12) and take the POPULATION
    # MAXIMUM of this bounded membership score. Under SVD the maximum
    # is a noise draw from the low zone (m ~ 0.2-0.45); under GDRD-B
    # the ~13% counter mode puts at least one subject deep in the high
    # zone (m ~ 0.6-1.0). This directly operationalises the design's
    # own falsifier ("any subject with conflict rate >= 0.40 falsifies
    # SVD outright") while pooling the parity and conflict readouts to
    # cut per-subject binomial noise.
    df = data.reset_index(drop=True)

    def _vec(x):
        if isinstance(x, np.ndarray):
            return x.astype(float)
        return np.asarray(list(x), dtype=float)

    a_list = [_vec(x) for x in df["option_a_ratings"]]
    b_list = [_vec(x) for x in df["option_b_ratings"]]

    n_perf = 8  # experts 0-7 are the perfect (v=1.0) experts in this design
    pA = np.array([v[:n_perf].sum() for v in a_list], dtype=float)
    pB = np.array([v[:n_perf].sum() for v in b_list], dtype=float)
    nA = np.array([v.sum() for v in a_list], dtype=float)
    nB = np.array([v.sum() for v in b_list], dtype=float)

    resp = df["response"].to_numpy(dtype=float)  # 0 = chose A, 1 = chose B
    chose_A = resp < 0.5
    ph_is_A = pA > pB  # option with more perfect-expert endorsements
    chose_ph = np.where(ph_is_A, chose_A, ~chose_A)

    parity_mask = (nA == nB)           # trials 1-4: 8v8 and 6v6
    conflict_mask = ((nA + nB) == 17)  # trials 5-6: 8v9

    sid = df["subject_id"].to_numpy()

    def _m(S):
        z = (S - 0.72) / 0.12
        return 1.0 / (1.0 + np.exp(-z))

    scores = []
    for s in pd.unique(sid):
        m_sub = (sid == s)
        pm = parity_mask & m_sub
        cm = conflict_mask & m_sub
        r_p = float(chose_ph[pm].mean()) if pm.sum() > 0 else 0.15
        r_c = float(chose_ph[cm].mean()) if cm.sum() > 0 else 0.205
        scores.append(float(_m(r_p + r_c)))

    # pooled: the most counter-like subject in the sample;
    # single-subject slice: that subject's own membership score.
    return float(np.max(scores))
```

**Observed (real) value:** 0.9846 (var=0.0914)
**Previous candidate values (this loop):**
  - iter 1: 0.9993 (var=0.0591) (Δ vs real +0.0147)
  - iter 2: 0.9981 (var=0.0632) (Δ vs real +0.0135)
  - iter 3: 0.8597 (var=0.0288) (Δ vs real -0.1249)
  - iter 4 (most recent): 0.9985 (var=0.0528) (Δ vs real +0.0139)
**Other theories' values on this metric (for reference):**
- pi_7: 0.3118 (var=0.0035)
- pi_8_1: 0.7372 (var=0.0287)
- pi_1: 1.0000 (var=0.0000)
- pi_2: 0.9305 (var=0.0600)
- pi_3: 1.0000 (var=0.0000)
- pi_4: 1.0000 (var=0.0000)
- pi_5: 0.0324 (var=0.0000)
- pi_6: 1.0000 (var=0.0000)
- pi_8: 0.4974 (var=0.0098)
- pi_9: 0.9995 (var=0.0592)
- pi_10: 0.9991 (var=0.0833)

### Experiment 16
**Design**
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
import numpy as np
import pandas as pd


def metric(data: pd.DataFrame) -> float:
    # Population dispersion of the per-subject PERFECT-SIDE INDEX.
    # Diagnostic trials are identified structurally from the rating
    # vectors using the design validity layout: features 0-5 are the
    # six perfect experts (v = 1.0), features 6-11 are mid-validity
    # experts, features 12-19 are the eight coin experts (v = 0.5).
    # A diagnostic trial has one option carrying exactly the six
    # perfect endorsements and nothing else, while the other option
    # carries only coin endorsements (6, 7 or 8 of them) and no
    # mid-validity or perfect endorsements. On these trials the
    # analytic distrust route is saturated toward the coin side under
    # BOTH theories, so the rate of choosing the 6-perfect option
    # isolates the count-route transmission plus lapse.
    # Per-subject predictions:
    #   GDRD-B skeptics (about 87 percent): index near 0.16
    #   GDRD-B counters (about 13 percent): index near 0.42
    #   SVD subjects (all): index confined to about 0.18 - 0.24
    # The pooled statistic is the between-subject standard deviation
    # of this index: about 0.12 under GDRD-B (bimodal population,
    # super-binomial dispersion) versus about 0.085 under SVD
    # (binomial noise plus a tiny true spread). On a single
    # subject's slice the dispersion collapses to a small strictly
    # positive scale floor (1e-3 times the subject's own index), so
    # the statistic is well defined at both the pooled and the
    # per-subject level and is nearly constant across subjects.
    n_feat = 20
    indices = []
    for sid in pd.unique(data['subject_id']):
        sdf = data[data['subject_id'] == sid]
        a_cells = sdf['option_a_ratings'].values
        b_cells = sdf['option_b_ratings'].values
        r_cells = sdf['response'].values
        hits = 0
        n = 0
        for i in range(len(sdf)):
            xa = a_cells[i]
            xb = b_cells[i]
            if isinstance(xa, str):
                xa = [float(t) for t in xa.strip('[]() ').split(',') if t.strip() != '']
            if isinstance(xb, str):
                xb = [float(t) for t in xb.strip('[]() ').split(',') if t.strip() != '']
            try:
                av = np.asarray(list(xa), dtype=float).ravel()
                bv = np.asarray(list(xb), dtype=float).ravel()
            except Exception:
                continue
            if av.shape[0] != n_feat or bv.shape[0] != n_feat:
                continue
            try:
                r = int(round(float(r_cells[i])))
            except Exception:
                continue
            ap = float(av[0:6].sum())
            am = float(av[6:12].sum())
            ac = float(av[12:20].sum())
            bp = float(bv[0:6].sum())
            bm = float(bv[6:12].sum())
            bc = float(bv[12:20].sum())
            a_perf = (ap == 6.0) and (am == 0.0) and (ac == 0.0)
            b_perf = (bp == 6.0) and (bm == 0.0) and (bc == 0.0)
            if a_perf == b_perf:
                continue
            if a_perf:
                om = bm
                op = bp
                oc = bc
            else:
                om = am
                op = ap
                oc = ac
            if om != 0.0 or op != 0.0:
                continue
            if oc != 6.0 and oc != 7.0 and oc != 8.0:
                continue
            chose_perf = (r == 0 and a_perf) or (r == 1 and b_perf)
            if chose_perf:
                hits += 1
            n += 1
        if n > 0:
            indices.append(hits / float(n))
    if len(indices) == 0:
        return 0.0
    vals = np.asarray(indices, dtype=float)
    m = float(np.mean(vals))
    v = float(np.var(vals, ddof=0))
    fl = 1e-3 * m
    return float(np.sqrt(v + fl * fl))
```

**Observed (real) value:** 0.1433 (var=0.0000)
**Previous candidate values (this loop):**
  - iter 1: 0.1689 (var=0.0000) (Δ vs real +0.0256)
  - iter 2: 0.1505 (var=0.0000) (Δ vs real +0.0072)
  - iter 3: 0.1463 (var=0.0000) (Δ vs real +0.0030)
  - iter 4 (most recent): 0.2154 (var=0.0000) (Δ vs real +0.0721)
**Other theories' values on this metric (for reference):**
- pi_8_1: 0.1323 (var=0.0000)
- pi_7: 0.0816 (var=0.0000)
- pi_1: 0.1275 (var=0.0000)
- pi_2: 0.0956 (var=0.0000)
- pi_3: 0.0181 (var=0.0000)
- pi_4: 0.0529 (var=0.0000)
- pi_5: 0.0484 (var=0.0000)
- pi_6: 0.0523 (var=0.0000)
- pi_8: 0.1187 (var=0.0000)
- pi_9: 0.1873 (var=0.0000)
- pi_10: 0.1711 (var=0.0000)

### Experiment 17
**Design**
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    # Design constants for this experiment (fixed validities):
    # features 0-5: perfect experts (v=1.0); 6-11: mid-validity (0.85/0.75/0.65);
    # 12-17: coin experts (v=0.5).
    V = np.array([1.0]*6 + [0.85, 0.85, 0.75, 0.75, 0.65, 0.65] + [0.5]*6)
    PERF = np.where(V >= 0.99)[0]
    COIN = np.where(V <= 0.51)[0]
    MID = np.array([i for i in range(len(V)) if (V[i] < 0.99 and V[i] > 0.51)])

    subj = np.asarray(data['subject_id'].values)
    resp = np.asarray(data['response'].values).astype(int)

    A = np.array([np.asarray(r, dtype=float).ravel() for r in data['option_a_ratings']])
    B = np.array([np.asarray(r, dtype=float).ravel() for r in data['option_b_ratings']])
    if A.ndim != 2 or A.shape[1] != len(V) or B.shape != A.shape:
        return 0.0

    pa = A[:, PERF].sum(axis=1); ca = A[:, COIN].sum(axis=1); ma = A[:, MID].sum(axis=1)
    pb = B[:, PERF].sum(axis=1); cb = B[:, COIN].sum(axis=1); mb = B[:, MID].sum(axis=1)

    # Structured perfect-vs-coin cells: no mid-validity endorsements,
    # each option endorsed by exactly one expert class.
    struct = (ma + mb == 0) & (pa + pb >= 1) & (ca + cb >= 1) & ((pa == 0) | (pb == 0))

    # Asymptote cells: 6 perfects vs 1-2 coins (trials 19-22).
    asy = struct & (
        ((pa == 6) & (ca == 0) & (pb == 0) & ((cb == 1) | (cb == 2))) |
        ((pb == 6) & (cb == 0) & (pa == 0) & ((ca == 1) | (ca == 2)))
    )
    # Trust-signal cells: T-family, conflict, parity, convergence
    # (perfect-endorsement side vs coin side, 56 trials).
    ycell = struct & (~asy)

    rf = resp.astype(float)
    # Asymptote cells: 1 if the subject chose the COIN-endorsed option.
    x_val = np.where(pa == 6, rf, 1.0 - rf)
    # Trust-signal cells: 1 if the subject chose the PERFECT-endorsed option.
    y_val = np.where(pa > 0, 1.0 - rf, rf)

    tmp = pd.DataFrame({
        'subj': subj,
        'asy': np.asarray(asy),
        'x': x_val,
        'yc': np.asarray(ycell),
        'y': y_val,
    })
    a_df = tmp[tmp['asy']]
    y_df = tmp[tmp['yc']]
    xg = a_df.groupby('subj')['x'].mean() if len(a_df) else pd.Series(dtype=float)
    yg = y_df.groupby('subj')['y'].mean() if len(y_df) else pd.Series(dtype=float)

    ids = np.unique(subj)
    if len(ids) >= 2:
        common = xg.index.intersection(yg.index)
        if len(common) >= 2:
            xs = xg.loc[common].to_numpy(dtype=float)
            ys = yg.loc[common].to_numpy(dtype=float)
            xc = xs - xs.mean()
            ycm = ys - ys.mean()
            denom = float(np.dot(xc, xc))
            if denom > 1e-12:
                # Cross-subject OLS slope of perfect-side preference (y)
                # on asymptote coin-side compliance (x).
                return float(np.dot(xc, ycm) / denom)
    # Single-subject (or degenerate) fallback: the subject's own
    # dissociation score  y - x  (perfect-side preference on the
    # trust-signal cells minus asymptote coin-side compliance).
    common = xg.index.intersection(yg.index)
    if len(common) > 0:
        return float(np.mean(yg.loc[common].to_numpy(dtype=float)
                             - xg.loc[common].to_numpy(dtype=float)))
    if len(yg) > 0:
        return float(np.mean(yg.to_numpy(dtype=float)))
    if len(xg) > 0:
        return float(np.mean(xg.to_numpy(dtype=float)))
    return 0.0
```

**Observed (real) value:** -0.5985 (var=0.0503)
**Previous candidate values (this loop):**
  - iter 1: -0.8016 (var=0.0434) (Δ vs real -0.2031)
  - iter 2: -0.8478 (var=0.0531) (Δ vs real -0.2493)
  - iter 3: -0.7160 (var=0.0513) (Δ vs real -0.1175)
  - iter 4 (most recent): -0.8445 (var=0.0844) (Δ vs real -0.2460)
**Other theories' values on this metric (for reference):**
- pi_9: -0.8020 (var=0.0877)
- pi_8_1: 0.2631 (var=0.0122)
- pi_1: -0.4701 (var=0.0544)
- pi_2: 0.1738 (var=0.0101)
- pi_3: -0.2083 (var=0.0003)
- pi_4: -0.1650 (var=0.0798)
- pi_5: -0.2434 (var=0.0063)
- pi_6: -0.0690 (var=0.0074)
- pi_7: 0.0234 (var=0.0090)
- pi_8: 0.3328 (var=0.0051)
- pi_10: -0.8137 (var=0.0548)

### Experiment 18
**Design**
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    df = data.reset_index(drop=True)
    n = len(df)
    if n == 0:
        return 0.0

    # ---- responses: 0 = chose A, 1 = chose B ----
    resp = np.empty(n, dtype=float)
    for i in range(n):
        r = df['response'].iloc[i]
        try:
            resp[i] = float(r)
        except (TypeError, ValueError):
            resp[i] = 0.0 if str(r).strip().upper() in ('A', '0') else 1.0

    # ---- per-trial endorsement counts by validity class ----
    # feature indices 0-7: perfect experts (v=1.0)
    # 8-16: coin experts (v=0.5); 17-24: graded experts (v>.5)
    a_perf = np.zeros(n); a_coin = np.zeros(n); a_grad = np.zeros(n)
    b_perf = np.zeros(n); b_coin = np.zeros(n); b_grad = np.zeros(n)
    for i in range(n):
        va = [float(x) for x in list(df['option_a_ratings'].iloc[i])]
        vb = [float(x) for x in list(df['option_b_ratings'].iloc[i])]
        a_perf[i] = sum(va[0:8]);  a_coin[i] = sum(va[8:17]);  a_grad[i] = sum(va[17:])
        b_perf[i] = sum(vb[0:8]);  b_coin[i] = sum(vb[8:17]);  b_grad[i] = sum(vb[17:])

    # ---- family masks (content-based, order-independent) ----
    # Asymptote: one option = 8 perfect endorsements, other = 1-2 coin.
    asym_A = ((a_perf == 0) & (a_grad == 0) & (a_coin >= 1) & (a_coin <= 2) &
              (b_perf == 8) & (b_grad == 0) & (b_coin == 0))
    asym_B = ((b_perf == 0) & (b_grad == 0) & (b_coin >= 1) & (b_coin <= 2) &
              (a_perf == 8) & (a_grad == 0) & (a_coin == 0))
    # Conflict: one option = 6-7 perfect, other = 8-9 coin.
    conf_A = ((a_perf == 0) & (a_grad == 0) & (a_coin >= 8) & (a_coin <= 9) &
              (b_perf >= 6) & (b_perf <= 7) & (b_grad == 0) & (b_coin == 0))
    conf_B = ((b_perf == 0) & (b_grad == 0) & (b_coin >= 8) & (b_coin <= 9) &
              (a_perf >= 6) & (a_perf <= 7) & (a_grad == 0) & (a_coin == 0))
    # Parity: equal counts, one all-perfect vs one all-coin (6-6 or 8-8).
    par_A = ((a_perf == 0) & (a_grad == 0) & ((a_coin == 6) | (a_coin == 8)) &
             (b_perf == a_coin) & (b_grad == 0) & (b_coin == 0))
    par_B = ((b_perf == 0) & (b_grad == 0) & ((b_coin == 6) | (b_coin == 8)) &
             (a_perf == b_coin) & (a_grad == 0) & (a_coin == 0))

    # coin-side choice indicators (1 = chose the all-coin option)
    coin_asym = np.where(asym_A, 1.0 - resp, resp)
    coin_conf = np.where(conf_A, 1.0 - resp, resp)
    coin_par = np.where(par_A, 1.0 - resp, resp)

    subj = df['subject_id'].values
    subjects = pd.unique(subj)

    # ---- per-subject family rates ----
    a_list, c_list, p_list = [], [], []
    for s in subjects:
        m = (subj == s)
        ma = m & (asym_A | asym_B)
        mc = m & (conf_A | conf_B)
        mp = m & (par_A | par_B)
        if ma.sum() > 0 and mc.sum() > 0 and mp.sum() > 0:
            a_list.append(float(np.mean(coin_asym[ma])))
            c_list.append(float(np.mean(coin_conf[mc])))
            p_list.append(float(np.mean(coin_par[mp])))

    if len(a_list) == 0:
        return 0.0

    a = np.asarray(a_list, dtype=float)
    c = np.asarray(c_list, dtype=float)
    p = np.asarray(p_list, dtype=float)

    if len(a) == 1:
        # single-subject slice: the subject's own coupling residual,
        # (conflict + parity)/2 - asymptote, i.e. how far the subject sits
        # from the GDRD-B neutrality relation c = a - 0.75, p = 0.125.
        return float((c[0] + p[0]) / 2.0 - a[0])

    # ---- pooled statistic: cross-subject coupling signature ----
    y = c + p
    ybar = float(np.mean(y))
    x = a
    if len(x) < 3:
        return ybar
    vx = float(np.var(x, ddof=1))
    if vx < 1e-12:
        return ybar
    cxy = float(np.cov(x, y, ddof=1)[0, 1])
    slope = cxy / vx
    return slope + ybar
```

**Observed (real) value:** 1.8844 (var=0.0249)
**Previous candidate values (this loop):**
  - iter 1: 3.5996 (var=0.0111) (Δ vs real +1.7152)
  - iter 2: 3.0066 (var=0.0101) (Δ vs real +1.1221)
  - iter 3: 3.1575 (var=0.0114) (Δ vs real +1.2730)
  - iter 4 (most recent): 3.1899 (var=0.0299) (Δ vs real +1.3055)
**Other theories' values on this metric (for reference):**
- pi_8_1: 1.5470 (var=0.0163)
- pi_9: 2.4428 (var=0.0181)
- pi_1: 1.1837 (var=0.0100)
- pi_2: 0.7872 (var=0.0199)
- pi_3: -0.2254 (var=0.0006)
- pi_4: 0.1827 (var=0.0838)
- pi_5: 2.1163 (var=0.0030)
- pi_6: 0.0006 (var=0.0066)
- pi_7: 1.9108 (var=0.0069)
- pi_8: 2.1134 (var=0.0126)
- pi_10: 3.0879 (var=0.0215)

### Experiment 19
**Design**
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # ------------------------------------------------------------------
    # Population "validity-gradient steepness" theta = beta * c1 of the
    # analytic distrust route, estimated from the matched-count validity
    # ladder (Family L rungs + the parity cell), with trust-mode subjects
    # screened out via the saturated cells, reported as a precision-
    # weighted (shrinkage) estimate of the population value.
    #
    # Identification: on matched-count cells c0 cancels exactly and the
    # graded count route sits at exactly 0.5, so the coin-side rate is
    #   r_rung = 0.5 + V * (sigmoid(theta * g_rung) - 0.5),
    # with g_rung = m*(v^kappa - 0.5^kappa).  Both theories share the
    # same distrust core, so the population compliance V_eff is the same
    # (~0.67) for both; V is fixed and theta is the only free parameter.
    # theta = beta*c1 is exactly the dimension on which the two theories'
    # boxes are disjoint-ish: HT beta in [1.8, 3.0], c1 in [1.0, 1.35]
    # (theta in [1.8, 4.05], mean ~2.8); T3 beta in [1.5, 2.6], c1 in
    # [1.0, 1.3] (theta in [1.5, 3.38], mean ~2.36).
    #
    # Trust screening: cells pitting 1-2 coin experts against 3 or 6
    # perfect experts saturate every non-trust mode to the coin side
    # (~0.9) while the trust mode sits at ~0.5; subjects below 0.70 are
    # dropped (their ladder preferences are reversed and would bias the
    # steepness fit).
    #
    # Regularization: the estimate is shrunk toward the mid-point prior
    # (MU0, SD S0) with weight S0^2 / (S0^2 + SE^2), where SE is the
    # analytic binomial standard error of the fit.  A single subject's 48
    # ladder trials identify theta only weakly (SE ~ 1.6), so
    # single-subject values are strongly regularized and stable; the
    # pooled estimate's SE falls as 1/sqrt(N) and the metric converges to
    # the population steepness.
    # ------------------------------------------------------------------
    KAPPA = 1.85      # fixed charge curvature for the rung design matrix
    V_FIX = 0.67      # fixed population compliance (shared-core value)
    MU0 = 2.60        # shrinkage prior centre (mid-point of the theta boxes)
    S0 = 0.15         # shrinkage prior SD
    TRUST_CUT = 0.70  # saturated-cell coin-rate cut for trust screening
    VALID = np.array([1.0] * 6 + [0.5] * 7 + [0.85] * 2 + [0.75] * 2 + [0.65] * 2)

    df = data.reset_index(drop=True)
    if len(df) == 0:
        return float(MU0)

    A = np.vstack([np.asarray(r, dtype=float).ravel() for r in df["option_a_ratings"]])
    B = np.vstack([np.asarray(r, dtype=float).ravel() for r in df["option_b_ratings"]])
    resp = np.asarray(df["response"], dtype=float).ravel()

    n_feat = A.shape[1]
    if n_feat != VALID.shape[0]:
        VALID = np.full(n_feat, 0.75)  # defensive fallback; design is fixed
    v = np.clip(VALID, 0.5, 1.0)
    vk = np.power(v, KAPPA)

    sa = A.dot(vk)
    sb = B.dot(vk)
    ca = A.sum(axis=1)
    cb = B.sum(axis=1)

    # coin side = side with the smaller total power-charge
    coin_is_b = sb < sa
    chose_coin = np.where(coin_is_b, resp == 1, resp == 0).astype(float)

    is_coin = (v == 0.5).astype(float)
    is_perf = (v == 1.0).astype(float)
    coin_a = A.dot(is_coin)
    coin_b = B.dot(is_coin)
    perf_a = A.dot(is_perf)
    perf_b = B.dot(is_perf)
    oth_a = ca - coin_a - perf_a
    oth_b = cb - coin_b - perf_b

    # saturated screening cells: (1-2 coin experts) vs (3 or 6 perfect experts)
    sat = (
        ((coin_a >= 1) & (coin_a <= 2) & (perf_a == 0) & (oth_a == 0)
         & (perf_b >= 3) & (perf_b <= 6) & (coin_b == 0) & (oth_b == 0))
        | ((coin_b >= 1) & (coin_b <= 2) & (perf_b == 0) & (oth_b == 0)
           & (perf_a >= 3) & (perf_a <= 6) & (coin_a == 0) & (oth_a == 0))
    )

    codes, uniq = pd.factorize(df["subject_id"].values)
    sat_rate = np.ones(len(uniq))
    if sat.any():
        sat_df = pd.DataFrame({"c": codes[sat], "y": chose_coin[sat]})
        gm = sat_df.groupby("c")["y"].mean()
        sat_rate[gm.index.values] = gm.values
    keep_row = sat_rate[codes] >= TRUST_CUT

    # matched-count cells only (c0 cancels, count route at exactly 0.5)
    sel = keep_row & (ca == cb)
    if sel.sum() < 8:
        return float(MU0)

    gv = np.round(np.abs(sa[sel] - sb[sel]), 3)
    yv = chose_coin[sel]
    ugr, inv = np.unique(gv, return_inverse=True)
    n_list = np.bincount(inv).astype(float)
    r_list = np.bincount(inv, weights=yv) / n_list
    g_list = ugr.astype(float)

    def sse_of(tau):
        x = 1.0 / (1.0 + np.exp(-tau * g_list)) - 0.5
        var = np.maximum(r_list * (1.0 - r_list), 1.0 / (4.0 * np.maximum(n_list, 1.0)))
        var = np.maximum(var, 0.02)
        w = n_list / var
        return float(np.sum(w * (r_list - 0.5 - V_FIX * x) ** 2))

    taus = np.linspace(0.4, 6.0, 281)
    sses = np.array([sse_of(t) for t in taus])
    tau_hat = float(taus[int(np.argmin(sses))])

    # analytic standard error of the 1-parameter fit
    s = 1.0 / (1.0 + np.exp(-tau_hat * g_list))
    p = 0.5 + V_FIX * (s - 0.5)
    varp = np.maximum(p * (1.0 - p), 1.0 / (4.0 * np.maximum(n_list, 1.0)))
    varp = np.maximum(varp, 0.02)
    J1 = V_FIX * s * (1.0 - s) * g_list
    F11 = float(np.sum((n_list / varp) * J1 ** 2))
    se = 5.0 if (not np.isfinite(F11)) or F11 <= 1e-12 else float(np.sqrt(1.0 / F11))

    w_shr = (S0 * S0) / (S0 * S0 + se * se)
    return float(MU0 + w_shr * (tau_hat - MU0))
```

**Observed (real) value:** 2.7176 (var=0.0000)
**Previous candidate values (this loop):**
  - iter 1: 2.8014 (var=0.0018) (Δ vs real +0.0838)
  - iter 2: 2.5519 (var=0.0055) (Δ vs real -0.1657)
  - iter 3: 2.5865 (var=0.0037) (Δ vs real -0.1311)
  - iter 4 (most recent): 2.6123 (var=0.0035) (Δ vs real -0.1053)
**Other theories' values on this metric (for reference):**
- pi_9: 2.4050 (var=0.0054)
- pi_10: 2.2250 (var=0.0064)
- pi_1: 2.6000 (var=0.0000)
- pi_2: 2.6000 (var=0.0000)
- pi_3: 2.6000 (var=0.0000)
- pi_4: 1.2528 (var=0.0133)
- pi_5: 2.5648 (var=0.0020)
- pi_6: 2.6000 (var=0.0000)
- pi_7: 2.3525 (var=0.0031)
- pi_8: 2.4219 (var=0.0051)
- pi_8_1: 2.3929 (var=0.0062)

### Experiment 20
**Design**
  A=[0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]

**Metric**
```python
import numpy as np
import pandas as pd


def metric(data: pd.DataFrame) -> float:
    """
    Discriminative evidence score: the total log-likelihood ratio
    (log Bayes factor) of every observed choice under the advocated
    GDRD-T3 population model versus the competing HT-GDRD population
    model.

    For each of the 16 unique stimulus pairs, the marginal probability
    of choosing A is computed for each theory by Monte-Carlo integration
    over that theory's FULL parameter box (uniform draws of c0, c1,
    kappa, beta, alpha, u_pop, u_w, w_spread, with the exact trimodal
    mode-branch code of each theory's predict function, including the
    mode masses, lapse bands, and route weights).  The metric then sums,
    over all trials in `data`, log( P_T3(choice) / P_HT(choice) ).

    Positive values => choices are more probable under GDRD-T3;
    negative values => more probable under HT-GDRD.  Applied to a single
    subject's slice it returns that subject's evidence contribution
    (the score is exactly additive over trials, so the pooled value is
    the sum of the per-subject values).
    """
    VALIDITIES = np.array([1.0] * 6 + [0.5] * 9 + [0.85] * 2)

    if data is None or len(data) == 0:
        return 0.0

    df = data.reset_index(drop=True)
    keys = [
        (tuple([int(x) for x in a]), tuple([int(x) for x in b]))
        for a, b in zip(
            df["option_a_ratings"].tolist(), df["option_b_ratings"].tolist()
        )
    ]
    resp = np.asarray(df["response"].to_numpy())
    unique = sorted(set(keys))
    idx = {k: i for i, k in enumerate(unique)}

    ck = tuple(unique)
    cache = getattr(metric, "_cache", None)
    if cache is not None and cache[0] == ck:
        lrA, lrB = cache[1], cache[2]
    else:
        rng = np.random.default_rng(987654321)
        S = 30000
        v = VALIDITIES
        v_pow = np.clip(v, 0.5, 1.0)
        v_tr = np.clip(v, 0.5, 1.0 - 1e-6)
        lg = np.clip(np.log(v_tr / (1.0 - v_tr)), 0.0, 3.0)
        A = np.array([np.asarray(k[0], dtype=float) for k in unique])
        B = np.array([np.asarray(k[1], dtype=float) for k in unique])

        def population(kind):
            # Monte-Carlo marginal P(choose A) for every unique pair,
            # integrating the theory's own predict() over its parameter box.
            if kind == "T3":
                c0 = rng.uniform(0.05, 0.14, S)
                c1 = rng.uniform(1.00, 1.30, S)
                kap = rng.uniform(1.6, 2.0, S)
                beta = rng.uniform(1.5, 2.6, S)
                fc, ft = 0.13, 0.96
            else:
                c0 = rng.uniform(0.06, 0.13, S)
                c1 = rng.uniform(1.00, 1.35, S)
                kap = rng.uniform(1.6, 2.1, S)
                beta = rng.uniform(1.8, 3.0, S)
                fc, ft = 0.16, 0.94
            u = rng.uniform(0.0, 1.0, S)
            u_w = rng.uniform(0.0, 1.0, S)
            wsp = rng.uniform(-0.02, 0.02, S)
            alph = rng.uniform(0.0, 0.05, S)

            w_mix = np.zeros(S)
            eps = np.zeros(S)
            gam = np.zeros(S)
            amode = alph.copy()

            ic = u < fc
            it = u >= ft
            isk = ~(ic | it)
            tc = u[ic] / fc
            ts = (u[isk] - fc) / (ft - fc)
            tt = (u[it] - ft) / (1.0 - ft)

            if kind == "T3":
                # counter minority (13%), compressed
                w_mix[ic] = 0.46 + 0.08 * tc
                eps[ic] = 0.14 + 0.04 * tc
                gam[ic] = 2.0 + 1.5 * tc
                # skeptic majority (83%), independent w draw
                eps[isk] = 0.14 + 0.10 * np.power(ts, 0.8)
                w_mix[isk] = np.clip(
                    0.83 + 0.12 * np.clip(u_w[isk], 0.0, 1.0) + wsp[isk], 0.83, 0.95
                )
                gam[isk] = 1.5 + 2.0 * ts
                # trust residual (4%), homogenized
                amode[it] = 0.47 + 0.10 * tt
                w_mix[it] = 0.47 + 0.06 * tt
                eps[it] = 0.18 + 0.04 * tt
                gam[it] = 1.9 + 0.7 * tt
            else:
                # counter minority (16%), wide w band
                w_mix[ic] = 0.46 + 0.24 * tc
                eps[ic] = 0.13 + 0.10 * tc
                gam[ic] = 2.5 + 1.5 * tc
                # skeptic majority (78%), heavy-tailed lapse
                eps[isk] = 0.13 + 0.14 * np.power(ts, 0.8)
                w_mix[isk] = np.clip(0.86 + 0.08 * ts + wsp[isk], 0.82, 0.96)
                gam[isk] = 1.5 + 2.0 * ts
                # trust residual (6%), dominant micro-trust, high lapse
                amode[it] = 0.50 + 0.18 * tt
                w_mix[it] = 0.44 + 0.12 * tt
                eps[it] = 0.26 + 0.08 * tt
                gam[it] = 1.5 + 1.5 * tt
            eps = np.clip(eps, 0.02, 0.45)

            # Route 1 charges d_j = c0 + c1 * v^kappa
            d = c0[:, None] + c1[:, None] * np.power(v_pow[None, :], kap[:, None])
            pA = np.zeros(len(unique))
            for j in range(len(unique)):
                a = A[j]
                b = B[j]
                pen_a = d @ a
                pen_b = d @ b
                D = pen_b - pen_a + amode * float(lg @ (a - b))
                P1 = 0.5 * (1.0 + np.tanh(0.5 * beta * D))
                P2 = 0.5 * (1.0 + np.tanh(0.5 * gam * float(b.sum() - a.sum())))
                pcore = w_mix * P1 + (1.0 - w_mix) * P2
                pA[j] = float(np.mean((1.0 - eps) * pcore + 0.5 * eps))
            return pA

        pT = np.clip(population("T3"), 1e-6, 1.0 - 1e-6)
        pH = np.clip(population("HT"), 1e-6, 1.0 - 1e-6)
        lrA = np.log(pT) - np.log(pH)
        lrB = np.log(1.0 - pT) - np.log(1.0 - pH)
        metric._cache = (ck, lrA, lrB)

    total = 0.0
    for k, r in zip(keys, resp):
        j = idx[k]
        if int(r) == 0:
            total += lrA[j]
        else:
            total += lrB[j]
    return float(total)
```

**Observed (real) value:** 21.6467 (var=2.4113)
**Previous candidate values (this loop):**
  - iter 1: -12.1652 (var=0.3696) (Δ vs real -33.8119)
  - iter 2: -0.2646 (var=0.2852) (Δ vs real -21.9113)
  - iter 3: -3.4136 (var=0.5880) (Δ vs real -25.0603)
  - iter 4 (most recent): -8.8536 (var=0.3096) (Δ vs real -30.5003)
**Other theories' values on this metric (for reference):**
- pi_10: 9.2931 (var=0.5515)
- pi_9: -6.8217 (var=0.2698)
- pi_1: -17.1770 (var=0.1567)
- pi_2: -173.3419 (var=0.6130)
- pi_3: -10.5679 (var=0.0082)
- pi_4: 42.7141 (var=0.4126)
- pi_5: -25.0411 (var=0.3065)
- pi_6: -34.8084 (var=0.0806)
- pi_7: -0.5596 (var=0.2575)
- pi_8: 2.4806 (var=0.2447)
- pi_8_1: 6.0620 (var=0.8500)

## PREVIOUS CANDIDATE (this loop)
The RUNNING-BEST (last ACCEPTED) candidate in this critique loop — i.e. the source the loop's accept gate kept as the best base so far. If your most recent attempt was REJECTED by the gate, this is NOT that attempt; it is the previously-accepted base the gate rolled back to. Iterate on this source — the next critic feedback should be applied on top of it.

**Description**
ISC-GDRD (recalibrated): a trimodal, three-independent-quantile dual-route distrust population whose analytic core keeps the arbiter-demanded steepness theta = beta*c1 ~ 2.6-3.0 but achieves it with a T3-range beta ([1.9, 2.6]) and a heavier charge c1 ([1.15, 1.40]), so the choice pattern stays inside the region the Exp-20 likelihood ratio scores as T3-like rather than HT-like; a moderate skeptic lapse band (eps = 0.13 + 0.10*t^0.85 over [0.13, 0.23]) restores between-subject variance in the asymptote rate (the direct lever on the Exp-18 coupling slope) and the T3-like lapse profile that the Exp-20 Bayes factor rewards; and a softened counter minority (w in [0.50, 0.56], gamma in [1.8, 2.6], mass held at 12%) pulls the counter-mode perfect-side index down toward ~0.35, shrinking the Exp-16 dispersion toward 0.143 while preserving the counter mode's Exp-15 maximum-membership signature.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    # ISC-GDRD, iter-2: RECALIBRATED steep core, moderate lapse band,
    # softened counter mode -- per the iter-1 critique, which diagnosed
    # three interacting failures of the accepted iter-1 box:
    #   (a) Exp 20's Bayes factor went catastrophically wrong-signed
    #       (-12.2 vs the demanded +15): beta in [2.4, 3.4] pushed the
    #       choice pattern beyond even HT's high-beta box. FIX: keep
    #       theta = beta*c1 in the arbiter-demanded [2.6, 3.0]-ish band
    #       but reach it with beta pulled back to T3's range [1.9, 2.6]
    #       and c1 raised to [1.15, 1.40]. This also pulls Exps 1/2/3
    #       back from their too-deterministic overshoots.
    #   (b) The 'lighter lapse tail' (eps in [0.12, 0.21]) failed all
    #       three of its promised targets: it collapsed between-subject
    #       variance in the asymptote rate, which MECHANICALLY inflated
    #       the Exp-18 slope (slope = cov/var; shrinking var(a) while
    #       the w-driven covariance survives blows the slope up to 3.6),
    #       and it made the simulated choices less T3-like. FIX: restore
    #       a moderate band, eps = 0.13 + 0.10*t^0.85 over [0.13, 0.23]
    #       (mean ~0.18), slightly lighter than T3's own band.
    #   (c) Exp 16 dispersion (0.169 vs 0.143) is driven by the mode
    #       mixture, not the lapse. FIX: soften the counter minority's
    #       count route -- w in [0.50, 0.56] (up from [0.47, 0.53]) and
    #       gamma in [1.8, 2.6] (down from [2.2, 3.2]) -- pulling the
    #       counter perfect-side index from ~0.42 toward ~0.35 while
    #       HOLDING the counter mass at 12% (Exp 15's max-membership
    #       ~0.99 must be preserved).
    # Everything else -- the three independent quantiles (u_mode, u_w,
    # u_eps), the compressed trust mode, the skeptic w band [0.85, 0.95]
    # and skeptic gamma [1.4, 2.8] -- is unchanged from iter 1.
    if isinstance(state, dict):
        a_vec = np.asarray(state["option_a_ratings"], dtype=float).ravel()
        b_vec = np.asarray(state["option_b_ratings"], dtype=float).ravel()
        stim = np.vstack([a_vec, b_vec])
    else:
        stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"ISC-GDRD expects a (2, n_features) stimulus; got shape {stim.shape}."
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
    u_mode = float(parameters["u_mode"])
    u_w = float(parameters["u_w"])
    u_eps = float(parameters["u_eps"])

    # --- Fully decoupled trimodal population mixture (recalibrated) ---
    # u_mode  -> mode membership (and within-mode position for gamma)
    # u_w     -> skeptic route weight (independent of lapse)
    # u_eps   -> skeptic lapse (independent of route weight)
    f_counter = 0.12
    f_trust_lo = 0.96
    u = min(max(u_mode, 0.0), 1.0)
    if u < f_counter:
        # Counter minority (12%, mass held): near-balanced routes, low-
        # moderate lapse, SOFTENED count slope (gamma in [1.8, 2.6]) and
        # a slightly higher w band ([0.50, 0.56]) so the counter-mode
        # perfect-side index drops toward ~0.35 (Exp 16 dispersion)
        # without eliminating the mode (Exp 15 maximum preserved).
        t = u / f_counter
        w_mix = 0.50 + 0.06 * t          # [0.50, 0.56]
        epsilon = 0.14 + 0.04 * t       # [0.14, 0.18]
        gamma = 1.8 + 0.8 * t            # [1.8, 2.6]
        alpha_mode = alpha_base
    elif u < f_trust_lo:
        # Skeptic majority (84%): analytic distrust dominant. Route
        # weight and lapse drawn from INDEPENDENT quantiles. The lapse
        # band is MODERATE again: eps = 0.13 + 0.09... no --
        # eps = 0.13 + 0.10 * u_eps^0.85 over [0.13, 0.23] (mean ~0.18):
        # wide enough to restore between-subject variance in the
        # asymptote rate (the direct lever on the Exp-18 coupling
        # slope) and to make the lapse profile T3-like for the Exp-20
        # likelihood ratio, while still sitting slightly below HT's
        # heavy-tailed [0.13, 0.27].
        t = (u - f_counter) / (f_trust_lo - f_counter)
        te = min(max(u_eps, 0.0), 1.0)
        epsilon = 0.13 + 0.10 * (te ** 0.85)   # [0.13, 0.23]
        tw = min(max(u_w, 0.0), 1.0)
        w_mix = 0.85 + 0.10 * tw              # [0.85, 0.95], indep of eps
        gamma = 1.4 + 1.4 * t                 # [1.4, 2.8]
        alpha_mode = alpha_base
    else:
        # Trust-leaning residual mode (4%, homogenized): the positive
        # micro-trust term is DOMINANT, so high-validity endorsers act
        # as net assets; the route weight is count-leaning and the lapse
        # is moderate. UNCHANGED from iter 1.
        t = (u - f_trust_lo) / (1.0 - f_trust_lo)
        alpha_mode = 0.48 + 0.10 * t     # [0.48, 0.58]
        w_mix = 0.47 + 0.06 * t          # [0.47, 0.53]
        epsilon = 0.17 + 0.04 * t        # [0.17, 0.21]
        gamma = 1.8 + 0.8 * t            # [1.8, 2.6]
    epsilon = float(min(max(epsilon, 0.02), 0.45))

    # --- Route 1: steep validity-proportional charge + micro-trust edge ---
    d = c0 + c1 * np.power(v_pow, kappa)
    pen_a = float(np.dot(d, a))
    pen_b = float(np.dot(d, b))

    # Micro-trust: logit(0.5) = 0 (coin-flip experts contribute nothing);
    # capped at 3 so perfect experts exert a bounded pull.
    lg = np.clip(np.log(v_tr / (1.0 - v_tr)), 0.0, 3.0)
    trust_edge = float(np.dot(lg, a - b))

    # D > 0 favors A (B carries more accumulated suspicion, net of the
    # trust edge).
    D = (pen_b - pen_a) + alpha_mode * trust_edge
    p_route1_a = 0.5 * (1.0 + np.tanh(0.5 * beta * D))  # stable sigmoid

    # --- Route 2: soft graded endorsement-count preference ---
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

`policy(probs) -> int`:
def policy(probabilities):
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()  # Ensure valid probabilities.
    return np.random.choice(len(probabilities), p=probabilities)

`parameters`:
- c0: [0.05, 0.13]
- c1: [1.15, 1.40]
- kappa: [1.6, 2.0]
- beta: [1.9, 2.6]
- alpha: [0.0, 0.05]
- u_mode: [0, 1]
- u_w: [0, 1]
- u_eps: [0, 1]
- validities: validities

`rationale`: This is a minimal-diff recalibration of the accepted ISC-GDRD base, applying exactly the three knob changes the iter-1 critique prescribed while keeping the arbiter-mandated mechanism family (trimodal mixture, dual route, three independent quantiles) fully intact. (1) REBALANCED STEEP CORE: the iter-1 box (beta [2.4, 3.4], c1 [1.05, 1.30]) hit the theta target but pushed the choice pattern past HT's own high-beta box, which is precisely why the Exp-20 log-Bayes-factor flipped to -12.2 (worse than pi_9's -6.8) and why Exps 1/2/3 overshot to 0.809/-0.303/-0.634. Holding theta ~ beta*c1 at the same level with beta back in T3's range [1.9, 2.6] and c1 raised to [1.15, 1.40] preserves the Exp-19 steepness register (~2.7-2.9) while moving the saturated/soft-cell choice probabilities back inside the region the fixed T3-vs-HT likelihood ratio scores as T3-like -- the single most important fix, since Exp 20 alone carried roughly a third of the iter-1 loss. Lower beta also directly softens the Exps 1/2/3 determinism toward the observed 0.71/-0.26/-0.55. (2) MODERATE LAPSE BAND: the iter-1 'light tail' (eps [0.12, 0.21]) failed on all three of its promised targets; the critique correctly identified the mechanism -- compressing skeptic eps collapsed between-subject variance in the asymptote rate, and since the Exp-18 slope is cov/var, shrinking var(a) while the w-driven covariance survives mechanically inflated the slope to 3.60. Restoring eps = 0.13 + 0.10*t^0.85 over [0.13, 0.23] (mean ~0.18, slightly below T3's own band) re-inflates the asymptote-rate variance, pulling the slope toward the observed 1.88, and the heavier lapse is itself part of what the Exp-20 ratio rewards as T3-like. (3) TAMED COUNTER MODE: since lapse compression did not reduce Exp 16's dispersion (0.169 vs 0.143), the excess lives in the mode mixture; raising the counter w band to [0.50, 0.56] and softening counter gamma to [1.8, 2.6] pulls the counter-mode perfect-side index from ~0.42 toward ~0.35, shrinking the between-subject SD toward 0.143, while the counter mass is held at 12% so the Exp-15 population-maximum membership (~0.99) is preserved. No further decoupling or compression was introduced, per the critique's explicit instruction. The theory remains falsifiable on the same axes: theta-hat near 2.7 (Exp 19), a positive-to-large BF vs HT (Exp 20), coupling slope near 1.9 (Exp 18), dispersion near 0.14 (Exps 14/16), and Exps 1/2/3 pulled back inside the sibling envelope.

## PRIOR FEEDBACK ITERATIONS
The critic's verdicts on each previous in-loop candidate, in order. Each block ends with an **Outcome of this advice** line saying whether the candidate the proposer produced AFTER this advice was ACCEPTED (loss strictly beat the running best) or REJECTED (the gate discarded it). Address the most recent iteration's feedback in your next edit, but down-weight past advice whose candidates were REJECTED.

### Iteration 1
Verdict: regenerate
Interpretation: The candidate was accepted by the loss gate, but graded against the arbiter's own falsifiability axes it fails on most of them. Where it succeeds: Exp 19's steepness (2.80 vs observed 2.72 — the steep core worked, and both siblings undershot at 2.41/2.23), Exp 8 (exact 0.7808), Exps 11/12 ceilings (0.79/0.817 vs 0.7875/0.832), Exps 5/6/7/9/13/15 are all within reasonable tolerance. Where it fails badly: (1) Exp 20 — the arbiter demanded a BF vs HT of +15 or more; the candidate produces -12.17, i.e. its simulated choices are more HT-like than T3-like, WORSE than pi_9 (-6.8) and dramatically worse than pi_10 (+9.3) and the observed +21.6. (2) Exp 18 — the arbiter demanded the conflict-on-asymptote coupling slope be attenuated toward 1.88; the candidate produces 3.60, worse than both pi_9 (2.44) and pi_10 (3.09). The 'softer count route' (gamma [1.4,2.8]) did NOT attenuate the slope, so the driver is elsewhere. (3) Dispersion targets: Exp 16 gives 0.169 vs observed 0.143, Exp 14 gives 0.138 vs 0.115 — the 'lighter lapse tail' did not shrink dispersion as promised. (4) The steep core overshot the TTB-compliance registers: Exp 1 (0.809 vs 0.712), Exp 2 (-0.303 vs -0.256), Exp 3 (-0.634 vs -0.547) — the candidate is now the most extreme theory on all three, worse than both siblings. Diagnosis: the four 'repairs' interact pathologically. Raising beta to [2.4,3.4] pushes the choice pattern beyond even HT's high-beta box, which is exactly why the Exp 20 likelihood ratio flips negative — the data look HT-like, not T3-like. Meanwhile compressing the skeptic lapse band collapsed between-subject variance in the asymptote rate, which mechanically inflates the Exp 18 regression slope (slope = cov/var; shrinking var(a) while the w-driven covariance survives blows the slope up), and the lighter eps did not reduce the mode-mixture-driven dispersion that actually drives Exp 16.
Rationale: Keep the ISC-GDRD family (trimodal mixture, dual route, three independent quantiles — all faithful to the arbiter recommendation) but recalibrate three knobs. (1) REBALANCE THE STEEP CORE: keep theta = beta*c1 in [2.6, 3.0] (to hold Exp 19 at ~2.7-2.8) but achieve it with beta pulled back to [1.9, 2.6] (T3's range) and c1 raised to [1.15, 1.40]. This preserves the steepness the arbiter wanted while moving the choice pattern back inside T3's likelihood — the single most important fix for Exp 20's Bayes factor, which is currently catastrophically wrong-signed (-12 vs +21.6). It will also pull Exps 1/2/3 back from their too-deterministic overshoots toward the observed 0.71/-0.26/-0.55. (2) RESTORE A MODERATE LAPSE BAND: the lighter tail (eps = 0.12 + 0.09*t^0.9) failed on all three of its promised targets — dispersion is still over-produced, the Exp 18 slope got worse, and the BF went negative. Move back toward T3's band but slightly lighter, e.g. eps = 0.13 + 0.10*t^0.85 over [0.13, 0.23] (mean ~0.18). The wider band restores between-subject variance in the asymptote rate, which is the direct lever to bring the Exp 18 coupling slope from 3.60 down toward the observed 1.88, and heavier lapse is part of what makes real choices T3-like in the Exp 20 likelihood ratio. (3) TAME THE COUNTER MODE FOR DISPERSION: since lapse compression did not reduce Exp 16's dispersion (0.169 vs 0.143), the excess must come from the mode mixture itself — slightly soften the counter minority's count-route (e.g. counter w in [0.50, 0.56] or counter gamma in [1.8, 2.6]) to pull the counter-mode perfect-side index down from ~0.42 toward ~0.35, shrinking the between-subject SD toward 0.143 without eliminating the mode (Exp 15's max-membership of ~0.99 must be preserved — do not shrink the counter mass below ~10%). Do NOT further decouple or further compress the population — the current level of decoupling is already past what the data support; iterate on the parameter bands above instead.

**Outcome of this advice:** iter 1 candidate loss=0.0894 -> iter 2 candidate loss=0.0745 -> the gate marked it ACCEPTED.

### Iteration 2
Verdict: regenerate
Interpretation: The iter-2 recalibration worked exactly as the iter-1 critique predicted on three of four axes, and the gate accepted it (loss 0.0894 -> 0.0745). Confirmed improvements: Exp 20's Bayes factor moved from -12.17 to -0.26 (the beta/c1 rebalance at constant theta was indeed the right lever — theta was ~3.0 in both iterations, so the BF flip confirms the likelihood ratio keys on beta's position relative to HT's 1.8 floor, not on theta itself); Exp 18's coupling slope dropped 3.60 -> 3.01 (restoring lapse-band variance in the asymptote rate worked as diagnosed); Exp 16 dispersion dropped 0.169 -> 0.1505 (observed 0.143); Exps 2/3 came back to near-perfect (-0.274/-0.565 vs -0.256/-0.547); Exp 14 is essentially exact (0.1145 vs 0.1152). Remaining failures, in order of severity: (1) Exp 20 is still ~neutral (-0.26 vs observed +21.6 and the arbiter's +15 demand; pi_10 achieved +9.3) — the candidate's beta band [1.9, 2.6] sits almost entirely inside HT's [1.8, 3.0] overlap region, so its choices are still not discriminably T3-like. (2) Exp 18 slope is still 3.01 vs 1.88 — the variance restoration helped but one more step of var(a) is needed. (3) Exp 19's theta-hat fell to 2.55 vs 2.72 (arbiter demanded >= 2.65) — this drop was caused by the heavier lapse MEAN (0.18) flattening the ladder, not by theta itself. (4) Exp 12's saturated ceiling slipped to 0.787 vs 0.832 (arbiter demanded >= 0.80) — also the heavier lapse mean. (5) Exp 17 worsened slightly (-0.848 vs -0.599), again lapse-mean-sensitive. (6) Exp 1 is still the most TTB-extreme theory in the pool (0.805 vs 0.712) — needs a softer beta floor. The pattern across failures 3-6 is coherent: they all want the lapse MEAN back down toward ~0.17 while failure 2 wants the lapse VARIANCE up — these are separable knobs.
Rationale: verdict regenerate because the arbiter's flagship falsifiability axes (Exp 20 BF >= +15, Exp 18 slope ~1.9, Exp 19 theta >= 2.65, Exp 12 ceiling >= 0.80) still fail, and the iter-1->iter-2 trajectory gives a clean, empirically validated direction for each. Keep the ISC-GDRD family, mode masses (12/84/4), counter w [0.50,0.56], three independent quantiles, and all coupling structure EXACTLY as-is; change only three things. (1) LOWER THE BETA FLOOR INTO T3-ONLY TERRITORY: beta [1.6, 2.4] instead of [1.9, 2.6]. The iter-1->2 comparison proved the Exp 20 likelihood ratio discriminates on beta's position relative to HT's 1.8 floor (theta held constant, BF moved +12 points); the current band has essentially no mass below 1.8, so the candidate cannot score as T3-like. This also directly softens Exp 1's TTB compliance (0.805 -> toward the 0.71-0.77 sibling envelope) and helps Exp 17. If Exp 19's theta-hat falls below ~2.4, recover steepness by raising the c1 CEILING (to ~1.45) rather than raising beta — c1 barely discriminates T3 from HT (1.30 vs 1.35 ceilings) whereas beta does. (2) WIDEN THE SKEPTIC LAPSE BAND ASYMMETRICALLY, KEEPING THE MEAN NEAR 0.17: e.g. eps = 0.12 + 0.11*t^0.85 over [0.12, 0.23], or floor 0.11 with ceiling 0.24. The iter-2 fix showed var(a) is the direct lever on the Exp 18 slope (3.60 -> 3.01 with a modest widening); one more widening step should reach ~2.3-2.6. Crucially, do NOT raise the mean: the heavier 0.18 mean is what simultaneously depressed Exp 19's steepness readout (2.80 -> 2.55 at similar theta), Exp 12's ceiling (0.817 -> 0.787), and Exp 17 (-0.80 -> -0.85). Holding the mean at ~0.17 while widening the spread addresses Exp 18 without re-breaking 12/17/19. (3) GUARD Exp 14: it is currently exact (0.1145 vs 0.1152) and its statistic subtracts asymptote shortfall, so if the wider band pushes it below ~0.10, narrow the eps ceiling back to 0.22 rather than narrowing the spread. Do not touch the counter mode, trust mode, mode masses, or decoupling — the iter-1 advice to freeze those was accepted and Exp 16 (0.1505 vs 0.143), Exp 15 (0.998), Exp 8 (0.773), and Exp 14 all confirm they are calibrated.

**Outcome of this advice:** iter 2 candidate loss=0.0745 -> iter 3 candidate loss=0.0777 -> the gate marked it REJECTED.

### Iteration 3
Verdict: regenerate
Interpretation: The gate rejected iter-3 (loss 0.0777 vs the accepted iter-2 base at 0.0745), so the candidate is discarded and the next attempt builds on iter-2. Attribution of the three knob changes is now informative because the gains and losses dissociate. What iter-3's changes bought: Exp 7 is essentially fixed (0.339 -> 0.380 vs observed 0.382), Exp 12 recovered to 0.822 (observed 0.832, arbiter floor 0.80), Exp 17 improved (-0.848 -> -0.716), Exp 1 moved toward the envelope (0.805 -> 0.777), Exp 16 improved (0.1505 -> 0.1463 vs 0.143). What they cost: the Exp-20 Bayes factor regressed from -0.26 to -3.41 (observed +21.6), the Exp-18 coupling slope regressed from 3.01 to 3.16 (observed 1.88), Exp 15 dropped from 0.998 to 0.860, and Exp 14 worsened (0.1145 -> 0.1353). The two flagship failures are the ones that matter; Exp 13 (0.32 -> 0.22) and Exp 6 (0.22 -> 0.235) moved by less than their binomial standard errors and should not be chased. The critical empirical pattern across all three iterations of this loop: with beta/c1 configurations varying, BOTH flagship metrics order monotonically in the skeptic lapse MEAN and nothing else. Lapse means 0.167 / 0.170 / 0.184 give Exp-20 BF of -12.17 / -3.41 / -0.26 and Exp-18 slopes of 3.60 / 3.16 / 3.01. Heavier skeptic lapse mean -> more T3-like likelihood AND lower coupling slope, exactly the two directions the arbiter demands. This falsifies my iter-2 hypothesis that the BF keys on beta's position relative to HT's 1.8 floor: iter-3 put half its beta mass below 1.8 and the BF got MORE negative, not less. It also falsifies the iter-2 hypothesis that widening the lapse SPREAD lowers the Exp-18 slope: iter-3 widened the spread to 0.13 and the slope went up, because the mean simultaneously fell. The mean is the lever on both; the spread is not. The one iter-3 change that appears safe-to-beneficial is the c1 ceiling raise ([1.20, 1.45]): it coincided with the Exp 7/12/17 improvements and is not implicated in the BF/Exp-18 damage, and it is the natural compensator for steepness (theta = beta*c1 stays ~2.65) once the lapse mean rises again.
Rationale: Verdict regenerate (the gate already discarded this candidate; a 'continue' would be downgraded). Build on the accepted iter-2 base and change the lapse direction — my iter-2 push (lower beta floor, lower lapse mean, wider spread) was rejected by the gate, so do not repeat it; instead extend the iter-1 direction that was accepted (heavier skeptic lapse), one step further. Concretely: (1) LEAVE BETA AT THE BASE [1.9, 2.6]. The beta-floor hypothesis is now empirically dead: lowering the floor from 1.9 to 1.6 moved the Exp-20 BF from -0.26 to -3.41, the opposite of the prediction. (2) RAISE THE SKEPTIC LAPSE MEAN TO ~0.20, matching T3's reference band (0.14 + 0.10*t^0.8, mean ~0.196): e.g. eps = 0.14 + 0.11*t^0.8 over [0.14, 0.25] (mean ~0.199), keeping a wide spread. Justification: across the three iterations the Exp-20 BF is monotone increasing in this mean (-12.2 at 0.167, -3.4 at 0.170, -0.26 at 0.184) and the Exp-18 slope is monotone decreasing in it (3.60, 3.16, 3.01). Extrapolating the observed sensitivity (~+12 BF and ~-0.6 slope per +0.017 of mean), a mean near 0.20 should push the BF toward +5 to +12 and the slope toward ~2.4-2.6 — the largest available movement on both flagship axes simultaneously. Do not exceed ~0.21: HT's reference mean is 0.208, and if the BF keys on closeness to T3 rather than monotone heaviness, overshooting toward HT's band could reverse the gain. (3) KEEP THE C1 CEILING RAISE from iter-3 ([1.20, 1.45]) as the compensating knob: the heavier lapse will flatten the Exp-19 ladder and depress the Exp-12 ceiling (both lapse-mean-sensitive per the iter-1/2/3 trajectories), and holding theta = beta*c1 near 2.65 through c1 rather than beta is the validated way to protect Exp 19 (>= 2.65 demanded) — c1 barely discriminates T3 from HT in the likelihood ratio whereas the lapse does. (4) FREEZE everything else exactly as in the accepted base: mode masses 12/84/4, counter mode (w [0.50,0.56], gamma [1.8,2.6]), trust mode, the three independent quantiles, skeptic w [0.85,0.95]. The iter-3 drops on Exps 13 and 6 are within binomial noise (prevalence/rate metrics with SE ~0.06), and the Exp-15 drop (0.998 -> 0.860) is a max-over-subjects statistic that is fragile to resampling — with the counter mode frozen it should recover; if it does not, that is a signal the counter-mode gamma floor of 1.8 is too soft, and the minimal fix is raising counter gamma to [2.0, 2.8] (toward T3's own counter band), not restructuring the mode. (5) GUARDS: if Exp 12 falls below ~0.78 under the heavier lapse, trim the lapse ceiling from 0.25 to 0.24 rather than narrowing the spread or lowering the mean — the mean is doing the work on Exps 18/20 and must not be sacrificed; if the Exp-19 readout falls below ~2.5 despite the c1 raise, extend the c1 ceiling to 1.50 before touching beta.

**Outcome of this advice:** iter 3 candidate loss=0.0777 -> iter 4 candidate loss=0.0947 -> the gate marked it REJECTED.

### Iteration 4 (most recent — address this)
Verdict: regenerate
Interpretation: The gate REJECTED iter-4 (loss 0.0947 vs the accepted iter-2 base at 0.0745), and the rejection is informative in a way that requires me to correct my own prior analysis. Iter-4 implemented my iter-3 prescription exactly (skeptic lapse mean raised to ~0.199 via eps = 0.14 + 0.11*t^0.8, c1 ceiling to 1.45, everything else frozen), and BOTH extrapolations failed decisively: the Exp-20 Bayes factor moved from -0.26 to -8.85 (I predicted +5..+12) and the Exp-18 coupling slope moved from 3.01 to 3.19 (I predicted 2.4-2.6). The 'both flagship metrics order monotonically in the lapse mean' claim I made in iter-3 was wrong: I had mis-ordered the iter-2/iter-3 (mean, BF, slope) triples. The true sequence over lapse means 0.165 / ~0.18 / ~0.17 / 0.199 is BF -12.2 / -0.26 / -3.4 / -8.85 and slope 3.60 / 3.01 / 3.16 / 3.19 — non-monotone in the mean, with the optimum at iter-2's ~0.18. The mean lever is now exhausted in BOTH directions (0.17 rejected in iter-3, 0.199 rejected in iter-4). The heavier tail also did collateral damage exactly opposite to its rationale: Exp-16 between-subject dispersion blew up from 0.1505 to 0.2154 (observed 0.1433) — a heavier lapse tail INFLATES dispersion rather than shrinking it — and Exp 11 fell to 0.744 (observed 0.7875) while Exp 13 overshot to 0.36 (observed 0.28). The few things that did move well confirm earlier attributions: Exp 19 rose to 2.61 (the c1 ceiling raise protects steepness, as intended), Exp 1 eased to 0.788, Exp 15 recovered to 0.9985 with the counter mode frozen (as predicted), and Exps 5/9/14 remain essentially exact. Net reading: the lapse/beta/c1 region around the iter-2 base is a local optimum whose flagship residuals (Exp-20 BF ~0 vs +21.6 observed; Exp-18 slope ~3.0 vs 1.88 observed) cannot be moved by further lapse or beta excursions — every such excursion has been rejected. The one major structural knob never varied in this loop is the graded count route (skeptic gamma [1.4,2.8], counter gamma [1.8,2.6]), frozen since iter-1 and sitting well below T3's reference bands ([1.5,3.5] and [2.0,3.5] in the Exp-20 likelihood's own T3 population).
Rationale: Verdict regenerate (the gate already discarded iter-4; a 'continue' would be downgraded). Build on the unchanged iter-2 base and this time attack the two flagship residuals through the COUNT ROUTE, not the lapse or beta — those levers are empirically dead in both directions and must not be retried. (1) REVERT the lapse band to the iter-2 values exactly (eps = 0.13 + 0.10*t^0.85 over [0.13,0.23], mean ~0.18): the four-iteration trajectory now shows this is the empirical optimum for the Exp-20 BF, the Exp-18 slope, AND the Exp-16 dispersion simultaneously; both neighbors (mean ~0.17 and ~0.199) were rejected by the gate. Likewise revert c1 to [1.15,1.40] and keep beta [1.9,2.6] — the c1 raise to 1.45 was confounded with the failed lapse change and its solo effect on the loss is unproven, so revert to the accepted configuration for clean attribution. (2) PRIMARY CHANGE — STEEPEN THE COUNT ROUTE toward T3's reference box: skeptic gamma [1.4,2.8] -> [1.6,3.2] and counter gamma [1.8,2.6] -> [2.0,3.0]. Mechanistic rationale on both flagship axes at once: on Exp 18's conflict cells the coin side carries MORE endorsements, so a steeper count route votes more decisively for the fewer-endorsement (perfect) side, lowering the conflict coin-rate c — which lowers both the mean term and the lapse-coupled covariance in the Exp-18 statistic (target 1.88, currently 3.01); and in the Exp-20 likelihood the soft gamma is the largest remaining deviation from T3's own population (T3 skeptic gamma [1.5,3.5], counter [2.0,3.5]), so moving into that range should shift the marginal choice probabilities toward T3 and push the BF off its ~0 ceiling. Critically, Exp 19 is immune to this change (matched-count cells pin the count route at exactly 0.5), so the steepness readout is protected. (3) SECONDARY CHANGE (add only if you prefer a single simultaneous step; otherwise hold for the next iteration): lower the skeptic w floor from 0.85 to 0.83 — T3's own floor — which adds route-weight variance independent of lapse, further diluting the cov(a, c+p)/var(a) coupling that inflates the Exp-18 slope. (4) FREEZE everything else: mode masses 12/84/4, counter w [0.50,0.56], trust mode, the three independent quantiles, all decoupling structure. (5) GUARDS: if Exp 11's saturated compliance falls below ~0.74 (observed 0.7875), cap the skeptic gamma ceiling at 3.0; if Exps 6/7 move more than ~2 binomial SE, back the counter gamma off to [1.9,2.8]; do NOT compensate any Exp-19 slippage by touching beta — use the c1 ceiling (extend to 1.45) only, per the established pattern. (6) HONEST CAVEAT for the proposer: four iterations of in-family knob tuning have left the Exp-20 BF at best ~0 against a +21.6 target and the arbiter's +15 demand. If the gamma steepening (with or without the w-floor alignment) still leaves the BF materially negative, report that residual rather than launching further large parameter excursions — the gate has now rejected every such excursion, and the remaining gap may be a property of the prescribed box rather than a miscalibration this loop can tune away.

**Outcome of this advice:** iter 4 candidate loss=0.0947 -> next candidate accept-status=PENDING (this is the advice you are addressing now).


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
  "theory": "ISC-GDRD (Independent-quantile Steep-Core Graded Dual-Route Distrust): subjects evaluate expert endorsements through two concurrent, history-free routes. ROUTE 1 (analytic distrust): every endorsement is a liability whose magnitude grows with the endorser's raw claimed validity, d_j = c0 + c1*v_j^kappa; D = pen(B) - pen(A) + alpha_mode*sum_j clip(logit(v_j),0,3)*(a_j-b_j); P1(A) = sigmoid(beta*D). ROUTE 2 (graded counting): P2(A) = sigmoid(gamma*(cnt_B-cnt_A)). Mixture p = w*P1 + (1-w)*P2 plus independent lapse eps. The population is TRIMODAL via three independent uniform quantiles (u_mode for mode membership, u_w for the skeptic route weight, u_eps for the skeptic lapse): a skeptic majority (~84%) with w in [0.83, 0.95] independent of eps in [0.13, 0.23]; a counter minority (~12%) with near-balanced routes (w in [0.50, 0.56]), low-moderate lapse, and a decisively steep count slope gamma in [2.0, 3.0]; and a small trust-leaning mode (~4%) with a dominant micro-trust term. This iteration's single mechanistic claim: the two flagship residuals (the Exp-20 Bayes factor pinned at ~0 and the Exp-18 conflict-on-asymptote coupling slope stuck at ~3.0) are properties of the COUNT ROUTE's softness, not of the lapse or analytic steepness — every lapse/beta excursion in this loop was gate-rejected, and the count route is the one structural knob never varied. A steeper count route votes more decisively for the fewer-endorsement side on Exp-18's conflict cells (lowering the conflict coin-rate and hence both the mean term and the lapse-coupled covariance of the slope statistic), and it is the largest remaining deviation from the T3 reference population that the Exp-20 likelihood ratio integrates against.",
  "predict": "def predict(parameters, state, history):\n    # ISC-GDRD, iter-3: STEEPENED COUNT ROUTE on the accepted iter-2\n    # base, per the iter-4 critique. Four iterations established that\n    # the lapse/beta/c1 region around the iter-2 base is a local\n    # optimum whose flagship residuals (Exp-20 BF ~0 vs +21.6 observed;\n    # Exp-18 slope ~3.0 vs 1.88 observed) cannot be moved by further\n    # lapse or beta excursions -- every such excursion (iters 3 and 4)\n    # was gate-rejected. The one structural knob never varied is the\n    # graded count route. This edit changes ONLY the gamma bands and\n    # the skeptic w floor:\n    #   (1) skeptic gamma [1.4, 2.8] -> [1.6, 3.2]\n    #       (T3's reference band is [1.5, 3.5])\n    #   (2) counter gamma  [1.8, 2.6] -> [2.0, 3.0]\n    #       (T3's reference band is [2.0, 3.5])\n    #   (3) skeptic w floor 0.85 -> 0.83 (T3's own floor), i.e.\n    #       w_mix = 0.83 + 0.12*tw over [0.83, 0.95] -- adds\n    #       route-weight variance independent of the lapse, diluting\n    #       the cov(a, c+p)/var(a) coupling that inflates the Exp-18\n    #       slope, and aligns the band with the T3 reference\n    #       population the Exp-20 likelihood integrates against.\n    # Mechanistic rationale: on Exp-18's conflict cells the coin side\n    # carries MORE endorsements, so a steeper count route votes more\n    # decisively for the fewer-endorsement (perfect) side, lowering the\n    # conflict coin-rate c and hence both the mean term and the\n    # lapse-coupled covariance of the slope statistic. In the Exp-20\n    # likelihood the soft gamma is the largest remaining deviation\n    # from T3's own population. Exp 19 is immune (matched-count cells\n    # pin the count route at exactly 0.5), so the steepness readout is\n    # protected. Everything else -- lapse band eps = 0.13 +\n    # 0.10*t^0.85 over [0.13, 0.23], beta [1.9, 2.6], c1 [1.15, 1.40],\n    # mode masses 12/84/4, counter w [0.50, 0.56], trust mode, the\n    # three independent quantiles -- is byte-identical to the\n    # accepted iter-2 base.\n    if isinstance(state, dict):\n        a_vec = np.asarray(state[\"option_a_ratings\"], dtype=float).ravel()\n        b_vec = np.asarray(state[\"option_b_ratings\"], dtype=float).ravel()\n        stim = np.vstack([a_vec, b_vec])\n    else:\n        stim = np.asarray(state, dtype=float)\n    if stim.ndim != 2 or stim.shape[0] != 2:\n        raise ValueError(\n            f\"ISC-GDRD expects a (2, n_features) stimulus; got shape {stim.shape}.\"\n        )\n    a, b = stim[0], stim[1]\n    n_features = stim.shape[1]\n\n    v = np.asarray(parameters[\"validities\"], dtype=float)\n    if v.shape[0] != n_features:\n        raise ValueError(\n            f\"validities length {v.shape[0]} != n_features {n_features}.\"\n        )\n    v_pow = np.clip(v, 0.5, 1.0)          # power route: v=1 harmless\n    v_tr = np.clip(v, 0.5, 1.0 - 1e-6)     # guard the logit\n\n    kappa = float(parameters[\"kappa\"])\n    beta = float(parameters[\"beta\"])\n    c0 = float(parameters[\"c0\"])\n    c1 = float(parameters[\"c1\"])\n    alpha_base = float(parameters[\"alpha\"])\n    u_mode = float(parameters[\"u_mode\"])\n    u_w = float(parameters[\"u_w\"])\n    u_eps = float(parameters[\"u_eps\"])\n\n    # --- Fully decoupled trimodal population mixture ---\n    # u_mode  -> mode membership (and within-mode position for gamma)\n    # u_w     -> skeptic route weight (independent of lapse)\n    # u_eps   -> skeptic lapse (independent of route weight)\n    f_counter = 0.12\n    f_trust_lo = 0.96\n    u = min(max(u_mode, 0.0), 1.0)\n    if u < f_counter:\n        # Counter minority (12%, mass held): near-balanced routes, low-\n        # moderate lapse, STEEPENED count slope (gamma in [2.0, 3.0],\n        # toward T3's own counter band [2.0, 3.5]) so the mode stays\n        # decisively count-following on the conflict cells.\n        t = u / f_counter\n        w_mix = 0.50 + 0.06 * t          # [0.50, 0.56]\n        epsilon = 0.14 + 0.04 * t       # [0.14, 0.18]\n        gamma = 2.0 + 1.0 * t            # [2.0, 3.0]  (steepened)\n        alpha_mode = alpha_base\n    elif u < f_trust_lo:\n        # Skeptic majority (84%): analytic distrust dominant. Route\n        # weight and lapse drawn from INDEPENDENT quantiles. Lapse band\n        # UNCHANGED from the accepted base: eps = 0.13 + 0.10*u_eps^0.85\n        # over [0.13, 0.23] (mean ~0.18) -- the empirical optimum for\n        # the Exp-20 BF, Exp-18 slope, and Exp-16 dispersion\n        # simultaneously. The w floor is LOWERED to T3's own 0.83\n        # (w in [0.83, 0.95]), adding route-weight variance independent\n        # of the lapse. The count slope is STEEPENED to [1.6, 3.2].\n        t = (u - f_counter) / (f_trust_lo - f_counter)\n        te = min(max(u_eps, 0.0), 1.0)\n        epsilon = 0.13 + 0.10 * (te ** 0.85)   # [0.13, 0.23]\n        tw = min(max(u_w, 0.0), 1.0)\n        w_mix = 0.83 + 0.12 * tw              # [0.83, 0.95], indep of eps\n        gamma = 1.6 + 1.6 * t                 # [1.6, 3.2]  (steepened)\n        alpha_mode = alpha_base\n    else:\n        # Trust-leaning residual mode (4%, homogenized): the positive\n        # micro-trust term is DOMINANT, so high-validity endorsers act\n        # as net assets; the route weight is count-leaning and the lapse\n        # is moderate. UNCHANGED from the accepted base.\n        t = (u - f_trust_lo) / (1.0 - f_trust_lo)\n        alpha_mode = 0.48 + 0.10 * t     # [0.48, 0.58]\n        w_mix = 0.47 + 0.06 * t          # [0.47, 0.53]\n        epsilon = 0.17 + 0.04 * t        # [0.17, 0.21]\n        gamma = 1.8 + 0.8 * t            # [1.8, 2.6]\n    epsilon = float(min(max(epsilon, 0.02), 0.45))\n\n    # --- Route 1: steep validity-proportional charge + micro-trust edge ---\n    d = c0 + c1 * np.power(v_pow, kappa)\n    pen_a = float(np.dot(d, a))\n    pen_b = float(np.dot(d, b))\n\n    # Micro-trust: logit(0.5) = 0 (coin-flip experts contribute nothing);\n    # capped at 3 so perfect experts exert a bounded pull.\n    lg = np.clip(np.log(v_tr / (1.0 - v_tr)), 0.0, 3.0)\n    trust_edge = float(np.dot(lg, a - b))\n\n    # D > 0 favors A (B carries more accumulated suspicion, net of the\n    # trust edge).\n    D = (pen_b - pen_a) + alpha_mode * trust_edge\n    p_route1_a = 0.5 * (1.0 + np.tanh(0.5 * beta * D))  # stable sigmoid\n\n    # --- Route 2: graded endorsement-count preference (steepened) ---\n    cnt_a = float(np.sum(a))\n    cnt_b = float(np.sum(b))\n    p_route2_a = 0.5 * (1.0 + np.tanh(0.5 * gamma * (cnt_b - cnt_a)))\n\n    # --- Dual-route mixture ---\n    p_a = w_mix * p_route1_a + (1.0 - w_mix) * p_route2_a\n    p_a = float(min(max(p_a, 0.0), 1.0))\n    p_core = np.array([p_a, 1.0 - p_a], dtype=float)\n\n    # Independent lapse: with probability epsilon pick uniformly.\n    n_opts = p_core.shape[0]\n    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)",
  "policy": "def policy(probabilities):\n    probabilities = np.asarray(probabilities, dtype=np.float64)\n    probabilities = probabilities / probabilities.sum()  # Ensure valid probabilities.\n    return np.random.choice(len(probabilities), p=probabilities)",
  "parameters": {
    "c0": "[0.05, 0.13]",
    "c1": "[1.15, 1.40]",
    "kappa": "[1.6, 2.0]",
    "beta": "[1.9, 2.6]",
    "alpha": "[0.0, 0.05]",
    "u_mode": "[0, 1]",
    "u_w": "[0, 1]",
    "u_eps": "[0, 1]",
    "validities": "validities"
  },
  "rationale": "This is a minimal-diff edit of the accepted iter-2 base that implements the iter-4 critique's prescription exactly, touching only the one structural knob never varied in this loop: the graded count route. The four-iteration trajectory established empirically that the lapse/beta/c1 region around the iter-2 base is a local optimum -- lapse means of ~0.17 (iter 3) and ~0.199 (iter 4) were both gate-rejected, and the beta-floor hypothesis was falsified (lowering beta's floor moved the Exp-20 BF MORE negative, not less). So lapse, beta, and c1 are reverted to / kept at the accepted iter-2 values (eps = 0.13 + 0.10*t^0.85 over [0.13, 0.23], beta [1.9, 2.6], c1 [1.15, 1.40]) for clean attribution. The changes: (1) skeptic gamma [1.4, 2.8] -> [1.6, 3.2] and counter gamma [1.8, 2.6] -> [2.0, 3.0], moving both into the neighborhood of T3's reference bands ([1.5, 3.5] and [2.0, 3.5]). On Exp-18's conflict cells the coin side carries MORE endorsements, so a steeper count route votes more decisively for the fewer-endorsement (perfect) side, lowering the conflict coin-rate and hence both the mean term and the lapse-coupled covariance of the cov/var slope statistic (target 1.88, currently 3.01); and in the Exp-20 likelihood the soft gamma is the largest remaining deviation from T3's own population, so aligning it should shift the marginal choice probabilities toward T3 and push the BF off its ~0 ceiling. Exp 19 is structurally immune (matched-count cells pin the count route at exactly 0.5), so the steepness readout is protected. (2) The critic's secondary change, the skeptic w floor lowered from 0.85 to T3's own 0.83 (w in [0.83, 0.95], via w_mix = 0.83 + 0.12*tw), is included because it is a one-line change that attacks the same two flagship axes by an independent mechanism: it adds route-weight variance independent of the lapse, diluting the cov(a, c+p)/var(a) coupling that inflates the Exp-18 slope, and it aligns the skeptic w band with the exact T3 reference band the Exp-20 likelihood integrates against. Everything else -- mode masses 12/84/4, counter w [0.50, 0.56], the trust mode, the three independent quantiles, all decoupling structure -- is byte-identical to the accepted base, per the standing instruction to freeze those. Guards from the critique are respected implicitly: the skeptic gamma ceiling stays at 3.2 (below the 3.0-cap trigger's threshold would only bind if Exp 11 fell below 0.74, which the modest steepening and unchanged lapse make unlikely), and no beta or lapse compensation is introduced. Honest caveat, per the critique's own instruction: if this edit still leaves the Exp-20 BF materially negative, that residual should be reported rather than attacked with further large parameter excursions -- the gate has rejected every such excursion, and the remaining gap may be a property of the prescribed box rather than a miscalibration this loop can tune away."
}
```
```

## Usage

```json
{
  "input_tokens": 94097,
  "output_tokens": 4492,
  "reasoning_tokens": 758,
  "provider": "Sail Research"
}
```
