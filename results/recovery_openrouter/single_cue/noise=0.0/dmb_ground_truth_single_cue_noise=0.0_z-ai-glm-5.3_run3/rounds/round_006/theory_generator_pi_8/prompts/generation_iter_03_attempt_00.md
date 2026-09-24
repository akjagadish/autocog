# generation_iter_03_attempt_00

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
- THEORY 1 = `pi_7`
- THEORY 2 = `pi_6`
- The recommendation below acts on THEORY 2 (= `pi_6`).

Replace PW-IVC with POSITION-RECOVERED DISTRUST TALLYING (PRDT). Core mechanism, differing from both current theories in one targeted way: (1) Keep the distrust-inversion kernel exactly as in the shared kernel: inv_j ∝ ((1-v_j) - c·min_k(1-v_k))^γ / Z, with γ ∈ [2, 5], c ∈ [0, 0.3]. (2) Replace the CONSTANT trust floor (1-tau)/n with a POSITION-GROWING trust residue: t_j = t0 + (t1 - t0)·(j/(n-1))^κ, with t0 ∈ [0.0, 0.15], t1 ∈ [0.30, 1.00], κ ∈ [1, 4]. Interpretation: subjects anchor in total skepticism toward early-communicated high-validity claims (so a position-1 95% expert is worth almost nothing — driving Exp 2's rescue rate down from 0.43 toward the observed 0.13) but progressively concede credibility to high-validity experts as they appear later (so a position-7 0.90 expert regains enough weight to lift Exp 10's final-expert following from ~0.28 toward the observed ~0.40, and Exp 8's recency-consistency from 0.30 toward 0.37). (3) Combine MULTIPLICATIVELY (the architecture validated by Exp 1): w_j ∝ g_j · [t_j·(1-tau)/n + tau·inv_j], with the floored convex primacy gate g_j = delta + (1-delta)·((n-j)/(n-1))^eta, delta ∈ [0.15, 0.45], eta ∈ [3.5, 7], tau ∈ [0.90, 0.97]. (4) De-attenuate commitment: beta ∈ [3.5, 10], epsilon ∈ [0.04, 0.12], to close the systematic magnitude under-shoot on Exp 1 (1.19 → toward 1.84), Exp 5 (-0.44 → toward -0.58), and the Exp 13/14 primacy slopes (0.23/0.47 → toward 0.31/0.54). Evidence integration stays additive over discriminating cues, d = Σ w_j·sign(A_j - B_j), with logistic choice in beta·d. Why this beats both incumbents: on Exp 1 it reproduces PGDT's sign-guaranteed validity-amplified crossover at larger magnitude (the growing trust residue further steepens the low-vs-high duel contrast); on Exp 2 it drives the position-1 trusted expert's effective weight toward zero, reaching rescue rates PGDT's box cannot; on Exp 10/8 it is the only architecture whose trusted-expert weight rises with position; on Exps 7, 9, 11, 12 it inherits the validated anti-validity and primacy-gate signatures. The single new degree of freedom (the t0→t1 trust-recovery ramp) is pinned by two independent joint failures of the incumbent theories, so it is not free curve-fitting — it is the minimal structural repair demanded by the pooled data.

## THEORY LEADERBOARD
A small set of prior picked theories shown for reference. Overall score is in `[0, 1]`, higher = better, computed as `1 - L2_norm(normalized_per_experiment_distances) / max_L2_norm`. 1.0 means closest to the real value on every experiment+metric pair; 0.0 means farthest. Each entry below carries the same depth of detail as the PREVIOUS MODEL INSTANCE above so you can borrow concrete mechanisms when useful.

### `pi_7` (overall score: 0.822)

**Description**
PRIMACY-GATED DISTRUST TALLYING (PGDT), floored-gate edition with a rebalanced distrust share. Subjects scan the expert ratings in presentation order and attention is deployed through a steep convex primacy gate with a substantial nonzero floor: g_j = delta + (1-delta)*((n-j)/(n-1))^eta, so the first one or two experts carry the dominant share of attention but late experts retain a meaningful attention residue. Independently, the communicated validities are distrust-inverted exactly as in the shared kernel: subjects act as if each stated validity were the expert's error rate, inv_j = ((1-v_j) - c*min_k(1-v_k))^gamma / Z. The two kernels combine MULTIPLICATIVELY: w_j proportional to g_j * [(1-tau)/n + tau*inv_j], normalized. The refinement this iteration is a rebalanced distrust share: tau is lowered to [0.82, 0.92] so the flat component (1-tau)/n of the multiplicative bracket grows from ~1.5% to ~4-5% per cue. This directly feeds trusted high-validity LATE experts (whose bracket value is structurally pinned at the flat share regardless of gate shape), softens the distrust-driven allegiance contrasts that overshoot their targets, and pulls the effective weights off pure anti-validity where that overshoots. A modestly raised gate floor delta in [0.20, 0.45] compensates on decreasing-validity layouts by further concentrating the product weights onto the back-loaded low-validity experts, protecting the anti-validity regression. Evidence is integrated additively over all discriminating cues, d = sum_j w_j * sign(A_j - B_j), and choice is logistic in beta*d with a small uniform lapse epsilon.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    # PGDT: Primacy-Gated Distrust Tallying, FLOORED-GATE edition,
    # REBALANCED-DISTRUST-SHARE variant.
    # iter-4 minimal-diff edit per critic's iter-3 directive:
    #   (1) PRIMARY KNOB: LOWER TAU. Range moved from [0.90, 0.97] to
    #       [0.82, 0.92] (still inside the arbiter's prescribed
    #       [0.80, 0.97]). This grows the flat share (1-tau)/n of the
    #       multiplicative bracket from ~1.5% to ~4-5% per cue, which is
    #       the ONLY lever that can move Exp8's final 0.90-validity
    #       expert (its weight is structurally pinned at the flat share
    #       regardless of gate shape), and simultaneously softens the
    #       over-committed distrust allegiances on Exp2/Exp4/Exp7.
    #   (2) COMPENSATING KNOB: RAISE DELTA CEILING. Range moved from
    #       [0.15, 0.40] to [0.20, 0.45] so the iter-2->3 trajectory's
    #       verified leverage on Exp3's back-loading (stronger
    #       anti-validity as the early-gate flattens) compensates the
    #       Exp3 weakening that the tau drop would otherwise cause.
    #   (3) Everything else frozen: eta, gamma, c, beta, epsilon.
    # Mechanism structure unchanged from the accepted iter-3 base.
    # Stimulus: array of shape (2, n_features); row 0 = option A, row 1 = B.
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"PGDT expects a (2, n_features) stimulus; got shape {stim.shape}."
        )
    a, b = stim[0], stim[1]
    n = int(stim.shape[1])

    v = np.asarray(parameters["validities"], dtype=float).ravel()
    if v.shape[0] != n:
        # Graceful fallback: strictly decreasing validities.
        v = np.linspace(0.95, 0.55, n)
    v = np.clip(v, 0.0, 1.0)

    tau = float(parameters["tau"])      # trust in the distrust kernel
    eta = float(parameters["eta"])       # convexity of the primacy gate
    delta = float(parameters["delta"])  # floor of the primacy gate
    gamma = float(parameters["gamma"])   # steepness of distrust inversion
    c = float(parameters["c"])           # partial centering of error rates
    beta = float(parameters["beta"])     # choice consistency
    eps = float(parameters["epsilon"])  # uniform lapse

    # (1) DISTRUST INVERSION with partial centering: treat the stated
    # validity as an error rate; subtract a fraction c of the smallest
    # error rate before raising to the gamma power, then normalize.
    err = 1.0 - v
    centered = np.maximum(err - c * float(err.min()), 0.0)
    inv = np.power(centered, gamma)
    Z_v = float(inv.sum())
    if Z_v > 1e-12:
        w_inv = inv / Z_v
    else:
        # Degenerate design (all validities tied at the extreme): the
        # distrust kernel is flat and the gate alone carries position.
        w_inv = np.full(n, 1.0 / n)

    # (2) STEEP CONVEX PRIMACY GATE WITH RAISED FLOOR over presentation
    # positions. Cue j (0-indexed) gets gate mass
    #     g_j = delta + (1-delta) * ((n - j)/(n - 1))^eta
    # with delta now in [0.20, 0.45]: the FIRST position still carries
    # the dominant share, but every late position retains a substantial
    # attention residue, so the multiplicative product never approaches
    # a pure primacy gradient and late low-validity (maximum-distrust)
    # cues keep enough weight to carry the anti-validity signature.
    # The raised ceiling further back-loads the product on decreasing-
    # validity layouts, compensating the tau drop for Exp3/Exp5.
    if n > 1:
        pos = np.arange(n, dtype=float)
        g = delta + (1.0 - delta) * np.power((n - pos) / (n - 1.0), eta)
    else:
        g = np.ones(1)

    # (3) MULTIPLICATIVE combination: the gate scales the distrust
    # bracket cue-by-cue. Where the bracket is flat (tied validities)
    # this reduces to the (floored) primacy gradient; where the bracket
    # nearly vanishes (trusted high-validity early experts) the gate
    # multiplies almost nothing and the distrust kernel decides where
    # the remaining weight mass sits. With tau lowered, the flat share
    # (1-tau)/n is large enough that trusted high-validity LATE experts
    # retain meaningful weight through the gate's floor residue -- the
    # structural fix for the under-weighted late-cue cluster (Exp6/8)
    # that no amount of gate flattening could rescue at tau >= 0.90.
    bracket = (1.0 - tau) / n + tau * w_inv
    raw = g * bracket
    Z_t = float(raw.sum())
    if Z_t > 1e-12:
        w = raw / Z_t
    else:
        w = np.full(n, 1.0 / n)

    # (4) Deterministic attention: every discriminating cue is always
    # attended; no capacity interference, beta is design-independent.
    s = np.sign(a - b)

    # (5) Additive integration of all discriminating cues.
    d = float(np.dot(w, s))

    # Numerically stable logistic choice rule.
    p_a = 0.5 * (1.0 + np.tanh(0.5 * beta * d))
    probs = np.array([p_a, 1.0 - p_a], dtype=float)

    # (6) Small uniform lapse; kept below IVC's range because the gate
    # itself supplies response dilution on late-cue trials.
    probs = (1.0 - eps) * probs + eps * 0.5
    return probs

`policy(probs) -> int`:
def policy(probs):
    probs = np.asarray(probs, dtype=np.float64)
    probs = probs / probs.sum()  # guard against float drift
    return int(np.random.choice(len(probs), p=probs))

`parameters`:
- tau: [0.82, 0.92]
- eta: [4.0, 6.0]
- delta: [0.20, 0.45]
- gamma: [2.8, 3.5]
- c: [0.10, 0.25]
- beta: [2.5, 6.0]
- epsilon: [0.06, 0.15]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.2080 (var=0.0060) vs this=0.1637 (var=0.0053)
- Experiment 2: real=0.1583 (var=0.0053) vs this=0.2996 (var=0.0066)
- Experiment 3: real=-0.5756 (var=0.0186) vs this=-0.4381 (var=0.0264)
- Experiment 4: real=0.8433 (var=0.0152) vs this=0.8925 (var=0.0035)
- Experiment 5: real=0.2313 (var=0.0046) vs this=0.2334 (var=0.0055)
- Experiment 6: real=0.3739 (var=0.0026) vs this=0.3028 (var=0.0052)
- Experiment 7: real=0.7878 (var=0.0086) vs this=0.8439 (var=0.0041)
- Experiment 8: real=0.3957 (var=0.0045) vs this=0.2832 (var=0.0037)
- Experiment 9: real=0.3414 (var=0.0042) vs this=0.2989 (var=0.0035)
- Experiment 10: real=-0.1729 (var=0.0118) vs this=-0.2325 (var=0.0136)
- Experiment 11: real=0.3148 (var=0.0095) vs this=0.2316 (var=0.0094)
- Experiment 12: real=0.5396 (var=0.0423) vs this=0.4678 (var=0.0344)
- Experiment 13: real=1.8356 (var=0.2112) vs this=1.1900 (var=0.2144)
- Experiment 14: real=0.1322 (var=0.0089) vs this=0.4311 (var=0.0074)


---

### `pi_6` (overall score: 0.636)

**Description**
PRIMACY-WEIGHTED INVERTED-VALIDITY COUNTING (PW-IVC). Subjects read the communicated validities but systematically distrust-invert them: they act as if each stated validity were the expert's error rate, so highly validated experts are discounted most (the anti-validity signature). Independently and additively, subjective attention is tilted toward EARLY-presented cues by a steep convex primacy gradient concentrated on the first one or two positions, at a small-to-moderate share of the subjective-weight mixture so the distrust kernel retains dominance wherever validity information varies. Each cue j carries weight w_j = (1-tau)/n + tau * [ (1-rho) * ((1-v_j) - c*min_k(1-v_k))^gamma / Z_v + rho * ((n-j)/(n-1))^eta / Z_p ]; evidence d = sum_j w_j * sign(A_j - B_j) is integrated additively over all discriminating cues; choice is logistic in beta*d with a small uniform lapse epsilon. On tied-validity designs the distrust kernel is exactly flat and the primacy kernel alone supplies the early-vs-late contrast, producing below-chance recency-following; on decreasing-validity layouts the distrust kernel dominates and reproduces the anti-validity regression signature.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    # PW-IVC: Primacy-Weighted Inverted-Validity Counting.
    # iter-4 minimal-diff edit per critic's iter-3 directive:
    #   (1) rho ceiling trimmed 0.34 -> 0.30 (restores distrust dominance in
    #       strictly-decreasing-validity layouts; the iter-3 ceiling raise is
    #       what regressed Exp3 from -0.434 to -0.372);
    #   (2) beta ceiling raised 6.5 -> 8.0 and epsilon floor lowered
    #       0.08 -> 0.06 (the commitment knobs that compensate the
    #       tied-validity experiments for the rho trim and de-attenuate the
    #       Exp3 OLS coefficient);
    #   (3) everything else frozen (tau, eta, gamma, c).
    # Mechanism structure unchanged from the accepted iter-3 base.
    # Stimulus: array of shape (2, n_features); row 0 = option A, row 1 = B.
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"PW-IVC expects a (2, n_features) stimulus; got shape {stim.shape}."
        )
    a, b = stim[0], stim[1]
    n = int(stim.shape[1])

    v = np.asarray(parameters["validities"], dtype=float).ravel()
    if v.shape[0] != n:
        # Graceful fallback: strictly decreasing validities.
        v = np.linspace(0.95, 0.55, n)
    v = np.clip(v, 0.0, 1.0)

    tau = float(parameters["tau"])      # trust in the non-flat kernel mixture
    rho = float(parameters["rho"])        # primacy share within the mixture
    eta = float(parameters["eta"])       # convexity of the primacy gradient
    gamma = float(parameters["gamma"])   # steepness of distrust inversion
    c = float(parameters["c"])           # partial centering of error rates
    beta = float(parameters["beta"])
    eps = float(parameters["epsilon"])

    # (1) DISTRUST INVERSION with partial centering: treat the stated
    # validity as an error rate; subtract a fraction c of the smallest
    # error rate before raising to the gamma power, then normalize.
    #     inv_j = ((1 - v_j) - c * min_k(1 - v_k))^gamma / Z_v
    # When all validities are tied this kernel is flat (or degenerate at
    # c -> 1, where we fall back to flat), so tied-validity designs are
    # carried entirely by the primacy kernel below.
    err = 1.0 - v
    centered = np.maximum(err - c * float(err.min()), 0.0)
    inv = np.power(centered, gamma)
    Z_v = float(inv.sum())
    if Z_v > 1e-12:
        w_inv = inv / Z_v
    else:
        w_inv = np.full(n, 1.0 / n)

    # (2) STEEP CONVEX PRIMACY GRADIENT over presentation positions: cue j
    # gets raw primacy mass ((n - j)/(n - 1))^eta with eta >= 3.5, so the
    # gradient is concentrated on the FIRST one or two positions. This
    # maximizes the early-vs-late weight CONTRAST per unit of mixture
    # share rho (what the anti-recency metrics score), while the small-to-
    # moderate rho keeps the primacy kernel from fighting the distrust
    # kernel on decreasing-validity layouts (Exps 3, 5, 8).
    if n > 1:
        pos = np.arange(n, dtype=float)
        prim = np.power((n - pos) / (n - 1.0), eta)
    else:
        prim = np.ones(1)
    Z_p = float(prim.sum())
    w_prim = prim / Z_p

    # (3) Subjective weights: mixture of flat counting, the partially
    # centered inverted-validity kernel, and the primacy kernel.
    # tau ~ 0.9+ keeps the non-flat kernels dominant; rho <= 0.30 keeps
    # the distrust kernel the dominant carrier of validity variance.
    w = (1.0 - tau) / n + tau * ((1.0 - rho) * w_inv + rho * w_prim)

    # (4) Deterministic attention: every discriminating cue is always
    # attended; no capacity interference, beta is design-independent.
    s = np.sign(a - b)

    # (5) Additive integration of all discriminating cues.
    d = float(np.dot(w, s))

    # Numerically stable logistic choice rule.
    p_a = 0.5 * (1.0 + np.tanh(0.5 * beta * d))
    probs = np.array([p_a, 1.0 - p_a], dtype=float)

    # (6) Small independent uniform lapse, capping anchor adherence.
    probs = (1.0 - eps) * probs + eps * 0.5
    return probs

`policy(probs) -> int`:
def policy(probs):
    probs = np.asarray(probs, dtype=np.float64)
    probs = probs / probs.sum()  # guard against float drift
    return int(np.random.choice(len(probs), p=probs))

`parameters`:
- tau: [0.88, 0.97]
- rho: [0.16, 0.30]
- eta: [3.5, 6.5]
- gamma: [2.9, 3.8]
- c: [0.0, 0.2]
- beta: [2.2, 8.0]
- epsilon: [0.06, 0.22]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.2080 (var=0.0060) vs this=0.1750 (var=0.0040)
- Experiment 2: real=0.1583 (var=0.0053) vs this=0.2408 (var=0.0082)
- Experiment 3: real=-0.5756 (var=0.0186) vs this=-0.4702 (var=0.0232)
- Experiment 4: real=0.8433 (var=0.0152) vs this=0.9058 (var=0.0060)
- Experiment 5: real=0.2313 (var=0.0046) vs this=0.2559 (var=0.0082)
- Experiment 6: real=0.3739 (var=0.0026) vs this=0.3361 (var=0.0034)
- Experiment 7: real=0.7878 (var=0.0086) vs this=0.7750 (var=0.0124)
- Experiment 8: real=0.3957 (var=0.0045) vs this=0.2818 (var=0.0035)
- Experiment 9: real=0.3414 (var=0.0042) vs this=0.4118 (var=0.0064)
- Experiment 10: real=-0.1729 (var=0.0118) vs this=-0.2233 (var=0.0216)
- Experiment 11: real=0.3148 (var=0.0095) vs this=0.1752 (var=0.0110)
- Experiment 12: real=0.5396 (var=0.0423) vs this=0.4027 (var=0.0731)
- Experiment 13: real=1.8356 (var=0.2112) vs this=-0.0794 (var=0.2347)
- Experiment 14: real=0.1322 (var=0.0089) vs this=0.6911 (var=0.0080)


---

### `pi_5` (overall score: 0.626)

**Description**
INVERTED-VALIDITY COUNTING (IVC) — distrust-weighted tallying. Subjects do read the communicated validities but map them through a systematic distrust inversion: they act as if each stated validity were the expert's error rate, so the most highly validated experts are discounted most. Every discriminating cue is attended deterministically (no attention lapses, no working-memory capacity interference — choice consistency is design-independent). Each cue j carries subjective weight w_j = (1-tau)/n + tau*(1-v_j)^kappa / Z, a mixture of flat counting and a normalized inverted-validity kernel; tau is the trust placed in the inversion, kappa its steepness (kappa=0, tau=0 recovers plain Tallying; large kappa approaches a worst-expert-first one-reason rule). Evidence is integrated additively, d = sum_j w_j * sign(A_j - B_j), and the choice is a logistic function of beta*d plus a small uniform lapse epsilon. Because the anti-validity signature is grounded in the communicated validity values rather than in cue position, it transfers across designs with different validity-position layouts — unlike SWC's recency gradient, which sign-failed the recency-consistency experiment.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    # IVC: Inverted-Validity Counting (distrust-weighted tallying).
    # Stimulus: array of shape (2, n_features); row 0 = option A, row 1 = B.
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"IVC expects a (2, n_features) stimulus; got shape {stim.shape}."
        )
    a, b = stim[0], stim[1]
    n = int(stim.shape[1])

    v = np.asarray(parameters["validities"], dtype=float).ravel()
    if v.shape[0] != n:
        # Graceful fallback: strictly decreasing validities.
        v = np.linspace(0.95, 0.55, n)
    v = np.clip(v, 0.0, 1.0)

    tau = float(parameters["tau"])
    kappa = float(parameters["kappa"])
    beta = float(parameters["beta"])
    eps = float(parameters["epsilon"])

    # (1) Distrust inversion: treat the communicated validity as if it
    # were the expert's error rate. (1 - v_j)^kappa is small for highly
    # validated experts and large for weakly validated ones; Z normalizes
    # the kernel so the mixture weights sum to one.
    inv = np.power(1.0 - v, kappa)
    Z = float(inv.sum())
    if Z > 1e-12:
        w_inv = inv / Z
    else:
        w_inv = np.full(n, 1.0 / n)

    # Subjective weights: mixture of flat counting and inverted validity.
    # tau = 0 recovers plain Tallying; tau = 1 with large kappa approaches
    # a 'worst-expert-first' one-reason rule.
    w = (1.0 - tau) / n + tau * w_inv

    # (2) Deterministic attention: every discriminating cue is always
    # attended. NO capacity interference: beta is design-independent
    # (anchor consistency stays high even at n = 8 features).
    s = np.sign(a - b)

    # (3) Additive integration of all discriminating cues.
    d = float(np.dot(w, s))

    # Numerically stable logistic choice rule.
    p_a = 0.5 * (1.0 + np.tanh(0.5 * beta * d))
    probs = np.array([p_a, 1.0 - p_a], dtype=float)

    # (4) Small independent uniform lapse.
    probs = (1.0 - eps) * probs + eps * 0.5
    return probs

`policy(probs) -> int`:
def policy(probs):
    probs = np.asarray(probs, dtype=np.float64)
    probs = probs / probs.sum()  # guard against float drift
    return int(np.random.choice(len(probs), p=probs))

`parameters`:
- tau: [0.85, 1.0]
- kappa: [2.4, 3.0]
- beta: [1.8, 2.5]
- epsilon: [0.03, 0.07]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.2080 (var=0.0060) vs this=0.1807 (var=0.0022)
- Experiment 2: real=0.1583 (var=0.0053) vs this=0.2308 (var=0.0086)
- Experiment 3: real=-0.5756 (var=0.0186) vs this=-0.5397 (var=0.0203)
- Experiment 4: real=0.8433 (var=0.0152) vs this=0.8083 (var=0.0061)
- Experiment 5: real=0.2313 (var=0.0046) vs this=0.2544 (var=0.0025)
- Experiment 6: real=0.3739 (var=0.0026) vs this=0.4408 (var=0.0038)
- Experiment 7: real=0.7878 (var=0.0086) vs this=0.6389 (var=0.0060)
- Experiment 8: real=0.3957 (var=0.0045) vs this=0.3561 (var=0.0033)
- Experiment 9: real=0.3414 (var=0.0042) vs this=0.5043 (var=0.0045)
- Experiment 10: real=-0.1729 (var=0.0118) vs this=-0.0563 (var=0.0178)
- Experiment 11: real=0.3148 (var=0.0095) vs this=-0.0209 (var=0.0151)
- Experiment 12: real=0.5396 (var=0.0423) vs this=0.0254 (var=0.0512)
- Experiment 13: real=1.8356 (var=0.2112) vs this=0.0650 (var=0.2219)
- Experiment 14: real=0.1322 (var=0.0089) vs this=0.5822 (var=0.0076)


## LOSS TRAJECTORY (this propose-loop)
Aggregate loss across iterations of THIS propose-loop (lower = better, 0 = perfect, `+inf` = unscorable). The ACCEPTED / REJECTED tag is the loop's programmatic accept-gate decision — only ACCEPTED candidates have ever been used as the base for a subsequent iteration. Use this together with PRIOR FEEDBACK ITERATIONS below to grade which past critic advice actually paid off.

- iter 1: loss=0.1754 -> ACCEPTED
- iter 2: loss=0.1630 -> ACCEPTED
- iter 3: loss=0.1659 -> REJECTED
Running-best (last ACCEPTED) base: iter 2 at loss=0.1630 — this is the source shown verbatim below under `## PREVIOUS CANDIDATE (this loop)`. Push the next edit's loss strictly below that floor or the gate will reject it.

## EXPERIMENTAL RESULTS
### Experiment 1
**Design**
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  A=[1, 1, 0, 1, 1]  B=[1, 1, 1, 0, 0]

**Metric**
```python
import numpy as np
import pandas as pd


def metric(data: pd.DataFrame) -> float:
    # Design validities (fixed by experiment): strictly decreasing,
    # so the TTB cue order is simply feature 0,1,2,3,4.
    validities = np.array([0.95, 0.85, 0.75, 0.65, 0.5])
    cue_order = np.argsort(-validities, kind="stable")

    def _to_vec(x):
        if isinstance(x, str):
            return np.array(
                [int(v) for v in x.strip("[]()").replace(",", " ").split()]
            )
        return np.asarray(x, dtype=float)

    hits = []
    a_col = data["option_a_ratings"].tolist()
    b_col = data["option_b_ratings"].tolist()
    r_col = data["response"].tolist()

    for a_cell, b_cell, resp in zip(a_col, b_col, r_col):
        a = _to_vec(a_cell)
        b = _to_vec(b_cell)
        if a.size == 0 or a.shape != b.shape:
            continue

        # --- TTB winner: first discriminating cue in validity order ---
        ttb_winner = None
        for j in cue_order:
            if j >= a.size:
                continue
            if a[j] > b[j]:
                ttb_winner = 0
                break
            if b[j] > a[j]:
                ttb_winner = 1
                break
        if ttb_winner is None:
            continue  # no discriminating cue: TTB guesses, uninformative

        # --- Tallying winner: strict feature-wise win counts ---
        a_wins = int(np.sum(a > b))
        b_wins = int(np.sum(b > a))
        if a_wins == b_wins:
            continue  # tally ties -> Tallying guesses at 0.5, dilutes contrast
        tally_winner = 0 if a_wins > b_wins else 1

        if tally_winner == ttb_winner:
            continue  # heuristics agree: uninformative

        # Pure conflict trial: TTB's option vs the tally majority's option.
        hits.append(1.0 if int(resp) == ttb_winner else 0.0)

    if not hits:
        return 0.5
    return float(np.mean(hits))
```

**Observed (real) value:** 0.2080 (var=0.0060)
**Previous candidate values (this loop):**
  - iter 1: 0.0650 (var=0.0015) (Δ vs real -0.1430)
  - iter 2: 0.1027 (var=0.0015) (Δ vs real -0.1053)
  - iter 3 (most recent): 0.0703 (var=0.0014) (Δ vs real -0.1377)
**Other theories' values on this metric (for reference):**
- pi_1: 0.8443 (var=0.0128)
- pi_2: 0.1357 (var=0.0112)
- pi_3: 0.2377 (var=0.0050)
- pi_4: 0.2197 (var=0.0050)
- pi_5: 0.1807 (var=0.0022)
- pi_5_1: 0.1870 (var=0.0059)
- pi_6: 0.1750 (var=0.0040)
- pi_7: 0.1637 (var=0.0053)

### Experiment 2
**Design**
  A=[0, 1, 0, 0, 1, 1]  B=[0, 0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 0, 1]  B=[0, 1, 0, 0, 1, 0]
  A=[0, 0, 1, 1, 0, 0]  B=[0, 1, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 1, 0]  B=[0, 0, 1, 1, 0, 1]
  A=[1, 0, 0, 1, 1, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 1, 1, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1]  B=[0, 0, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 1, 0]  B=[0, 1, 1, 1, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Tally-vs-TTB choice-allegiance contrast.

    For every trial we determine (i) the TALLYING winner (option with more
    strict feature-wise wins) and (ii) the TAKE-THE-BEST winner (winner on
    the highest-validity discriminating cue, validities fixed by design as
    [0.95, 0.9, 0.85, 0.65, 0.6, 0.5]).  The metric is

        mean( response == tally winner ) - mean( response == TTB winner )

    On the 4 trial types where both heuristics pick the same option
    (trials 1, 3, 5, 7 and mirrors) the two indicators are identical and
    cancel.  On the 12 conflict trial types they are exact complements, so
    the metric reduces to 0.75 * (2*P(tally winner | conflict) - 1): strongly
    positive under Tallying, strongly negative under TTB.
    """
    validities = np.array([0.95, 0.9, 0.85, 0.65, 0.6, 0.5])
    cue_order = np.argsort(-validities, kind="stable")

    a_col = data["option_a_ratings"].tolist()
    b_col = data["option_b_ratings"].tolist()
    r_col = data["response"].tolist()

    tally_match = []
    ttb_match = []

    for ca, cb, cr in zip(a_col, b_col, r_col):
        a = np.asarray(ca, dtype=float).ravel()
        b = np.asarray(cb, dtype=float).ravel()
        r = int(cr)

        # Tallying winner: more strict feature-wise wins (ties on a feature
        # contribute to neither side).
        a_wins = float(np.sum(a > b))
        b_wins = float(np.sum(b > a))
        if a_wins > b_wins:
            tally_winner = 0
        elif b_wins > a_wins:
            tally_winner = 1
        else:
            tally_winner = -1  # undiscriminating tally -> excluded

        # TTB winner: first discriminating cue in descending-validity order.
        ttb_winner = -1
        for j in cue_order:
            if a[j] > b[j]:
                ttb_winner = 0
                break
            if b[j] > a[j]:
                ttb_winner = 1
                break

        if tally_winner >= 0:
            tally_match.append(1.0 if r == tally_winner else 0.0)
        if ttb_winner >= 0:
            ttb_match.append(1.0 if r == ttb_winner else 0.0)

    if len(tally_match) == 0 or len(ttb_match) == 0:
        return 0.0

    return float(np.mean(tally_match) - np.mean(ttb_match))
```

**Observed (real) value:** 0.1583 (var=0.0053)
**Previous candidate values (this loop):**
  - iter 1: 0.3750 (var=0.0124) (Δ vs real +0.2167)
  - iter 2: 0.3429 (var=0.0061) (Δ vs real +0.1846)
  - iter 3 (most recent): 0.4200 (var=0.0069) (Δ vs real +0.2617)
**Other theories' values on this metric (for reference):**
- pi_2: 0.5479 (var=0.0187)
- pi_1: -0.4837 (var=0.0228)
- pi_3: 0.1658 (var=0.0093)
- pi_4: 0.2079 (var=0.0051)
- pi_5: 0.2308 (var=0.0086)
- pi_5_1: 0.2875 (var=0.0062)
- pi_6: 0.2408 (var=0.0082)
- pi_7: 0.2996 (var=0.0066)

### Experiment 3
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[1, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[0, 1, 1, 0, 1]  B=[1, 0, 0, 1, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 1]  B=[1, 0, 0, 1, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[0, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 1]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 0]  B=[1, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1]

**Metric**
```python
import numpy as np
import pandas as pd


def _to_vec(x):
    """Robustly convert a cell (list/tuple/ndarray/str) to a float 1-D array."""
    if isinstance(x, np.ndarray):
        return x.astype(float)
    if isinstance(x, (list, tuple)):
        return np.asarray(list(x), dtype=float)
    s = str(x).strip().replace("[", " ").replace("]", " ").replace(",", " ")
    return np.asarray(s.split(), dtype=float)


def metric(data: pd.DataFrame) -> float:
    df = data.reset_index(drop=True)
    n_rows = len(df)
    if n_rows == 0:
        return 0.0

    A = np.vstack([_to_vec(x) for x in df["option_a_ratings"]])
    B = np.vstack([_to_vec(x) for x in df["option_b_ratings"]])
    n_feat = A.shape[1]

    # Design validities [0.95, 0.85, 0.75, 0.65, 0.60]; fall back gracefully.
    v = np.array([0.95, 0.85, 0.75, 0.65, 0.60], dtype=float)
    if v.shape[0] != n_feat:
        v = np.linspace(0.95, 0.60, n_feat)

    # Chose-A indicator (response: 0 = A, 1 = B).
    y = (np.asarray(df["response"], dtype=float) == 0.0).astype(float)

    a_win = A > B
    b_win = B > A

    # Signed tally margin (Tallying's ONLY explanatory variable).
    margin = a_win.sum(axis=1).astype(float) - b_win.sum(axis=1).astype(float)

    # Validity-weighted evidence difference (NVW's driving quantity).
    d = (a_win * v).sum(axis=1) - (b_win * v).sum(axis=1)

    # OLS: y ~ 1 + margin + d. Return the partial coefficient on d.
    X = np.column_stack([np.ones(n_rows), margin, d])
    beta, _, _, _ = np.linalg.lstsq(X, y, rcond=None)
    return float(beta[2])
```

**Observed (real) value:** -0.5756 (var=0.0186)
**Previous candidate values (this loop):**
  - iter 1: -0.8191 (var=0.0207) (Δ vs real -0.2435)
  - iter 2: -0.7293 (var=0.0113) (Δ vs real -0.1537)
  - iter 3 (most recent): -0.7080 (var=0.0193) (Δ vs real -0.1324)
**Other theories' values on this metric (for reference):**
- pi_3: 0.2763 (var=0.0165)
- pi_2: -0.0069 (var=0.0141)
- pi_1: 0.7613 (var=0.0601)
- pi_4: -0.4120 (var=0.0294)
- pi_5: -0.5397 (var=0.0203)
- pi_5_1: -0.5621 (var=0.0241)
- pi_6: -0.4702 (var=0.0232)
- pi_7: -0.4381 (var=0.0264)

### Experiment 4
**Design**
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 0, 0]  B=[1, 1, 1, 1, 1, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 1, 1, 0]
  A=[1, 0, 0, 0, 0, 1, 1, 0]  B=[0, 1, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 1, 0, 1]
  A=[0, 1, 0, 1, 0, 1, 0, 1]  B=[1, 0, 1, 0, 1, 0, 1, 0]
  A=[0, 1, 1, 0, 0, 0, 1, 1]  B=[1, 0, 0, 1, 1, 1, 0, 0]
  A=[1, 0, 0, 1, 1, 1, 0, 0]  B=[0, 1, 1, 0, 0, 0, 1, 1]
  A=[1, 1, 1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Anchor-allegiance: proportion of trials with a large tally margin
    (|a_wins - b_wins| >= 6) on which the subject chose the option that
    wins on more features (the tally winner).

    Under Tallying, these are the unambiguous anchors (8-0 and 7-1 splits:
    design trials 7, 8, 21, 22, 23, 24 and their 4 repetitions = 24 trials
    per subject), where the softmax over tallies predicts near-deterministic
    choice for any non-trivial beta. Under NVW, the capacity-interference
    factor delta^4 crushes the effective inverse temperature to
    beta_eff <= 11 * 0.30^4 ~ 0.09, so even the maximum validity-weighted
    evidence difference (~6) yields P ~ sigmoid(0.5) <= 0.64; attention
    lapses and the uniform-mixing epsilon only pull this further toward
    0.5. The two theories therefore make sharply separated predictions on
    this proportion, and the A/B-mirrored anchors cancel side bias.
    """
    a_col = data['option_a_ratings']
    b_col = data['option_b_ratings']
    r_col = data['response']

    n_anchor = 0
    n_hit = 0

    for ra, rb, resp in zip(a_col, b_col, r_col):
        va = np.asarray(ra, dtype=float)
        vb = np.asarray(rb, dtype=float)
        if va.shape != vb.shape:
            continue

        a_wins = float(np.sum(va > vb))
        b_wins = float(np.sum(vb > va))
        margin = a_wins - b_wins

        if abs(margin) >= 6:
            n_anchor += 1
            winner_is_a = margin > 0
            chose_a = (int(resp) == 0)
            if chose_a == winner_is_a:
                n_hit += 1

    if n_anchor == 0:
        return 0.5
    return float(n_hit) / float(n_anchor)

```

**Observed (real) value:** 0.8433 (var=0.0152)
**Previous candidate values (this loop):**
  - iter 1: 0.9217 (var=0.0042) (Δ vs real +0.0783)
  - iter 2: 0.8917 (var=0.0031) (Δ vs real +0.0483)
  - iter 3 (most recent): 0.9167 (var=0.0035) (Δ vs real +0.0733)
**Other theories' values on this metric (for reference):**
- pi_2: 0.8808 (var=0.0089)
- pi_3: 0.5300 (var=0.0122)
- pi_1: 0.6133 (var=0.0060)
- pi_4: 0.8133 (var=0.0065)
- pi_5: 0.8083 (var=0.0061)
- pi_5_1: 0.8217 (var=0.0065)
- pi_6: 0.9058 (var=0.0060)
- pi_7: 0.8925 (var=0.0035)

### Experiment 5
**Design**
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 1, 1]  B=[0, 1, 1, 1, 0, 0]
  A=[0, 1, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1, 1]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Validity-adherence rate on VALIDITY-vs-RECENCY conflict trials.
    #
    # For every trial we compute two decision variables from the presented
    # cue patterns:
    #   d_v = sum_j v_j * sign(A_j - B_j)   (validity-weighted evidence for A)
    #   d_r = sum_j (j/(n-1))^3 * sign(A_j - B_j)  (convex cue-order recency
    #                                              evidence for A)
    # A trial is a CONFLICT trial when the two point in opposite directions
    # and both are non-trivial in magnitude. On those trials the metric is
    # the proportion of choices that follow the VALIDITY-implied option.
    #
    # NVW (validity-weighted integration) predicts adherence clearly above
    # chance (~0.6); SWC (recency-dominated subjective weights) predicts
    # adherence well below chance (~0.3), because on these trials its
    # recency gradient favors the opposite option.

    validities = np.array([0.95, 0.90, 0.85, 0.62, 0.50, 0.50], dtype=float)
    n = int(validities.shape[0])
    # Convex recency profile over presentation positions (eta ~ 3).
    recency = (np.arange(n, dtype=float) / float(n - 1)) ** 3.0

    a_col = data["option_a_ratings"]
    b_col = data["option_b_ratings"]
    r_col = data["response"]

    hits = []
    for a_raw, b_raw, resp in zip(a_col, b_col, r_col):
        a = np.asarray(a_raw, dtype=float).ravel()
        b = np.asarray(b_raw, dtype=float).ravel()
        if a.shape[0] != n or b.shape[0] != n:
            continue
        s = np.sign(a - b)
        if not np.any(s != 0):
            continue

        d_v = float(np.dot(validities, s))
        d_r = float(np.dot(recency, s))

        # Need a real conflict with non-trivial evidence on both axes.
        if abs(d_v) < 0.30 or abs(d_r) < 0.50:
            continue
        if np.sign(d_v) == np.sign(d_r):
            continue

        validity_winner_is_a = (d_v > 0.0)
        chose_a = (int(resp) == 0)
        hits.append(1.0 if (chose_a == validity_winner_is_a) else 0.0)

    if len(hits) == 0:
        return 0.0
    return float(np.mean(hits))
```

**Observed (real) value:** 0.2313 (var=0.0046)
**Previous candidate values (this loop):**
  - iter 1: 0.0803 (var=0.0023) (Δ vs real -0.1509)
  - iter 2: 0.1531 (var=0.0025) (Δ vs real -0.0781)
  - iter 3 (most recent): 0.1037 (var=0.0017) (Δ vs real -0.1275)
**Other theories' values on this metric (for reference):**
- pi_3: 0.5988 (var=0.0039)
- pi_4: 0.2816 (var=0.0052)
- pi_1: 0.7519 (var=0.0061)
- pi_2: 0.5803 (var=0.0046)
- pi_5: 0.2544 (var=0.0025)
- pi_5_1: 0.2369 (var=0.0070)
- pi_6: 0.2559 (var=0.0082)
- pi_7: 0.2334 (var=0.0055)

### Experiment 6
**Design**
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 1, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 1, 0]  B=[1, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 1, 0]  B=[0, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1]  B=[0, 1, 0, 1, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 1, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 1, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 1, 1, 1, 1, 0]
  A=[0, 0, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 1, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Recency-consistency rate: fraction of choices aligned with a convex
    # cue-order recency gradient, restricted to trials where that gradient
    # is strong and its direction is unambiguous across SWC's eta range.
    #
    # SWC (advocated): late cues dominate via convex recency -> rate well
    #   above 0.5 (predicted ~0.65-0.85 across its parameter box).
    # NVW (competing): validity-weighted integration with capacity
    #   interference (beta_eff = beta*delta^3 <= ~0.30 at n=7) -> choices
    #   near chance on nearly every trial, and anti-recency or neutral on
    #   the conflict trials -> rate ~0.50.
    df = data.reset_index(drop=True)
    if len(df) == 0:
        return 0.5

    a_arrs = [np.asarray(list(x), dtype=float) for x in df['option_a_ratings']]
    b_arrs = [np.asarray(list(x), dtype=float) for x in df['option_b_ratings']]
    resp = pd.to_numeric(df['response'], errors='coerce').to_numpy()

    if len(a_arrs) == 0 or a_arrs[0].ndim != 1:
        return 0.5
    n = int(a_arrs[0].shape[0])
    if n < 2:
        return 0.5

    pos = np.arange(n, dtype=float) / (n - 1.0)
    w_lo = pos ** 2.5   # SWC's eta lower corner
    w_mid = pos ** 3.5  # SWC's eta midpoint
    w_hi = pos ** 4.5   # SWC's eta upper corner

    consistent = []
    for a, b, r in zip(a_arrs, b_arrs, resp):
        if a.shape[0] != n or b.shape[0] != n:
            continue
        if not np.isfinite(r):
            continue
        s = np.sign(a - b)
        if not np.any(s != 0):
            continue
        e_lo = float(np.dot(w_lo, s))
        e_mid = float(np.dot(w_mid, s))
        e_hi = float(np.dot(w_hi, s))
        # Require the recency gradient's direction to be invariant across
        # SWC's whole eta range (drops ambiguous trials, e.g. 1 late cue vs
        # 4 mid cues, where the sign flips with eta).
        if e_lo == 0.0 or e_hi == 0.0 or np.sign(e_lo) != np.sign(e_hi):
            continue
        # Require non-trivial gradient magnitude (drops near-degenerate
        # trials where even SWC predicts ~0.52).
        if abs(e_mid) < 0.25:
            continue
        fav_a = e_mid > 0.0
        chose_a = (int(r) == 0)  # response: 0 = chose A, 1 = chose B
        consistent.append(1.0 if (chose_a == fav_a) else 0.0)

    if len(consistent) == 0:
        return 0.5
    return float(np.mean(consistent))
```

**Observed (real) value:** 0.3739 (var=0.0026)
**Previous candidate values (this loop):**
  - iter 1: 0.2625 (var=0.0025) (Δ vs real -0.1114)
  - iter 2: 0.3153 (var=0.0028) (Δ vs real -0.0586)
  - iter 3 (most recent): 0.2681 (var=0.0035) (Δ vs real -0.1058)
**Other theories' values on this metric (for reference):**
- pi_4: 0.7261 (var=0.0028)
- pi_3: 0.4847 (var=0.0034)
- pi_1: 0.3794 (var=0.0022)
- pi_2: 0.3853 (var=0.0032)
- pi_5: 0.4408 (var=0.0038)
- pi_5_1: 0.4392 (var=0.0036)
- pi_6: 0.3361 (var=0.0034)
- pi_7: 0.3028 (var=0.0052)

### Experiment 7
**Design**
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 0, 1, 0, 1, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 1, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0, 0]  B=[1, 0, 1, 0, 1, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Anti-validity vs. recency disagreement score.

    On trials where IVC's distrust-inverted weights and SWC's recency-dominated
    weights point to OPPOSITE options, report the proportion of choices that
    follow the IVC-preferred option. IVC-simulated data -> well above 0.5;
    SWC-simulated data -> well below 0.5.
    """
    data = data.reset_index(drop=True)
    if len(data) == 0:
        return 0.5

    # Build stimulus matrices without hashing any list-valued cells.
    a = np.vstack([np.asarray(r, dtype=float) for r in data["option_a_ratings"]])
    b = np.vstack([np.asarray(r, dtype=float) for r in data["option_b_ratings"]])
    n = a.shape[1]

    # Design validities (fallback mirrors both theories' graceful degradation).
    v = np.array([0.5, 0.9, 0.6, 0.95, 0.5, 0.6], dtype=float)
    if v.shape[0] != n:
        v = np.linspace(0.95, 0.55, n)

    # --- IVC weights at mid-range parameters (tau=0.925, kappa=2.7) ---
    tau, kappa = 0.925, 2.7
    inv = np.power(1.0 - v, kappa)
    Z = float(inv.sum())
    w_inv = inv / Z if Z > 1e-12 else np.full(n, 1.0 / n)
    w_ivc = (1.0 - tau) / n + tau * w_inv

    # --- SWC weights at mid-range parameters (lam=0.9, rho=0.9, eta=3.5) ---
    lam, rho, eta = 0.9, 0.9, 3.5
    vspan = float(v.max() - v.min())
    if vspan > 1e-12:
        vnorm = (v - v.min()) / vspan
    else:
        vnorm = np.full(n, 0.5)
    if n > 1:
        pos = (np.arange(n, dtype=float) / (n - 1.0)) ** eta
    else:
        pos = np.full(n, 0.5)
    g = (1.0 - rho) * vnorm + rho * pos
    w_swc = (1.0 - lam) / n + lam * g

    # Signed discriminating-cue vector per trial.
    s = np.sign(a - b)
    d_ivc = s @ w_ivc
    d_swc = s @ w_swc

    # Keep only trials where the two theories STRICTLY disagree in sign.
    # (d_ivc == 0, e.g. the validity-matched EQ trials, is excluded.)
    mask = (d_ivc * d_swc) < 0.0
    if not np.any(mask):
        return 0.5

    resp = np.asarray(data["response"].to_numpy())
    r = resp[mask]
    ivc_prefers_a = d_ivc[mask] > 0.0
    chose_ivc_preferred = np.where(ivc_prefers_a, r == 0, r == 1)
    return float(chose_ivc_preferred.mean())
```

**Observed (real) value:** 0.7878 (var=0.0086)
**Previous candidate values (this loop):**
  - iter 1: 0.9017 (var=0.0031) (Δ vs real +0.1139)
  - iter 2: 0.8589 (var=0.0026) (Δ vs real +0.0711)
  - iter 3 (most recent): 0.8906 (var=0.0026) (Δ vs real +0.1028)
**Other theories' values on this metric (for reference):**
- pi_5: 0.6389 (var=0.0060)
- pi_4: 0.3622 (var=0.0067)
- pi_1: 0.1533 (var=0.0097)
- pi_2: 0.5167 (var=0.0064)
- pi_3: 0.4511 (var=0.0081)
- pi_5_1: 0.6478 (var=0.0070)
- pi_6: 0.7750 (var=0.0124)
- pi_7: 0.8439 (var=0.0041)

### Experiment 8
**Design**
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 1, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]

**Metric**
```python
import numpy as np
import pandas as pd


def metric(data: pd.DataFrame) -> float:
    """Final-Expert Dominance Index (FEDI).

    Among trials where the LAST-presented expert (feature position n-1) is the
    ONLY cue favoring one option (i.e., that option's rating vector is all
    zeros except a 1 in the final position), compute the proportion of
    choices that follow the final expert's recommendation.

    A convex-recency weighting (SWC) predicts adherence well above 0.5
    (the last cue carries the largest subjective weight at every corner of
    its parameter box). A distrust-inverted validity weighting (IVC)
    predicts adherence below 0.5, because the final expert here has a high
    stated validity (0.90) and is therefore heavily discounted.
    """
    df = data.reset_index(drop=True)

    A = np.array(
        [list(map(int, x)) for x in df['option_a_ratings']], dtype=int
    )
    B = np.array(
        [list(map(int, x)) for x in df['option_b_ratings']], dtype=int
    )
    r = df['response'].to_numpy(dtype=int)

    if A.ndim != 2 or A.shape[0] == 0:
        return float('nan')

    n_feat = A.shape[1]
    last = n_feat - 1

    a_last = A[:, last]
    b_last = B[:, last]

    # Last expert discriminates between the options.
    disc = a_last != b_last

    # The option endorsed by the final expert wins ONLY that final cue
    # (its rating vector sums to 1). This selects the single-cue and
    # multi-cue 'ladder' duels against the last expert (trials 1-14 and
    # their mirrors) and excludes trials where the last-cue option also
    # wins other cues.
    a_sel = disc & (a_last == 1) & (A.sum(axis=1) == 1)
    b_sel = disc & (b_last == 1) & (B.sum(axis=1) == 1)
    sel = a_sel | b_sel

    if not np.any(sel):
        return float('nan')

    # response: 0 = chose A, 1 = chose B.
    # Did the subject follow the final expert's endorsed option?
    followed = np.where(a_sel[sel], r[sel] == 0, r[sel] == 1)

    return float(np.mean(followed))
```

**Observed (real) value:** 0.3957 (var=0.0045)
**Previous candidate values (this loop):**
  - iter 1: 0.2464 (var=0.0034) (Δ vs real -0.1493)
  - iter 2: 0.2696 (var=0.0036) (Δ vs real -0.1261)
  - iter 3 (most recent): 0.2321 (var=0.0024) (Δ vs real -0.1636)
**Other theories' values on this metric (for reference):**
- pi_4: 0.6796 (var=0.0044)
- pi_5: 0.3561 (var=0.0033)
- pi_1: 0.5529 (var=0.0024)
- pi_2: 0.4039 (var=0.0053)
- pi_3: 0.4300 (var=0.0036)
- pi_5_1: 0.3393 (var=0.0058)
- pi_6: 0.2818 (var=0.0035)
- pi_7: 0.2832 (var=0.0037)

### Experiment 9
**Design**
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 1, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Recency-following rate on count-neutral trials.
    #
    # With all six validities equal (0.95), IVC's weight vector is EXACTLY
    # flat for every admissible parameter combination (the distrust kernel
    # is constant across features, so w_j = 1/n identically). Hence on any
    # trial where the two options win an equal number of discriminating
    # cues (count difference = 0), IVC's evidence d = 0 and P(choose A) =
    # 0.50 exactly -- the lapse preserves 0.5. This is parameter-free.
    #
    # SWC, in contrast, has strictly increasing weights in cue position
    # (lambda >= 0.8, rho >= 0.8, convex recency), and on count-neutral
    # trials its evidence reduces EXACTLY to d = lambda*rho*sum_j pos_j*s_j,
    # so it must prefer the option supported by the LATER cues, with
    # subject-level choice rates roughly in [0.60, 0.79].
    #
    # The metric: among count-neutral trials, the fraction of choices that
    # go to the option favored by the later (more recent) discriminating
    # cues. IVC -> 0.50 for every subject; SWC -> well above 0.50.

    def _mat(col):
        return np.array(
            [np.asarray(v, dtype=float).ravel() for v in list(col)],
            dtype=float,
        )

    A = _mat(data['option_a_ratings'])
    B = _mat(data['option_b_ratings'])
    resp = np.asarray(pd.Series(data['response']).to_numpy(), dtype=float)

    if A.size == 0 or A.ndim != 2 or A.shape[0] == 0 or B.shape[0] != A.shape[0]:
        return 0.5
    n = int(A.shape[1])
    if n < 2:
        return 0.5

    # Convex recency profile over cue positions (any strictly increasing
    # profile gives the same favored direction on count-neutral trials;
    # 3.5 matches SWC's mid-gradient). Direction is what matters here.
    pos = (np.arange(n, dtype=float) / (n - 1.0)) ** 3.5

    S = np.sign(A - B)            # +1: cue favors A, -1: favors B, 0: tie
    count = S.sum(axis=1)         # IVC's evidence direction (flat weights)
    rec = S @ pos                 # recency evidence for A

    neutral = (np.abs(count) < 1e-9) & (np.abs(rec) > 1e-9)
    if not np.any(neutral):
        return 0.5

    chose_a = resp[neutral] == 0
    fav_a = rec[neutral] > 0      # option supported by the later cues
    followed = np.where(fav_a, chose_a, ~chose_a)
    return float(np.mean(followed))
```

**Observed (real) value:** 0.3414 (var=0.0042)
**Previous candidate values (this loop):**
  - iter 1: 0.2571 (var=0.0046) (Δ vs real -0.0843)
  - iter 2: 0.3489 (var=0.0066) (Δ vs real +0.0075)
  - iter 3 (most recent): 0.2375 (var=0.0039) (Δ vs real -0.1039)
**Other theories' values on this metric (for reference):**
- pi_5_1: 0.5043 (var=0.0036)
- pi_4: 0.6693 (var=0.0058)
- pi_1: 0.1557 (var=0.0121)
- pi_2: 0.4986 (var=0.0044)
- pi_3: 0.4986 (var=0.0040)
- pi_5: 0.5043 (var=0.0045)
- pi_6: 0.4118 (var=0.0064)
- pi_7: 0.2989 (var=0.0035)

### Experiment 10
**Design**
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[0, 0, 0, 1, 0, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 1, 1, 0]  B=[0, 1, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 0, 1, 0, 0, 1]
  A=[0, 0, 1, 0, 0, 1]  B=[1, 0, 0, 1, 0, 0]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 0, 1, 0, 1, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Recency-gradient choice score on theory-divergent trials.
    #
    # Design validities: experts at positions 1 and 4 (0-indexed 0 and 3)
    # have validity 0.95; the other four experts have validity 0.75.
    #
    # Per trial:
    #   s_j = sign(A_j - B_j)   which option expert j favors
    #   x   = sum_j p_j * s_j   recency evidence for A, with convex
    #                           position weights p_j = (j/5)^3.5
    #   y   = +1 if A chosen, -1 if B chosen
    #
    # Scored trial families (48 of the 96 trials per subject):
    # (1) VALIDITY-MATCHED trials (types 3/4, 9/10, 13/14, 17/18, 25/26
    #     plus mirrors): the two options' discriminating experts carry
    #     identical validity multisets. Any validity-only weighting (IVC)
    #     yields exactly zero evidence, so E[x*y] = 0 for EVERY parameter
    #     combination (the uniform lapse preserves 0.5). SWC's convex
    #     recency gradient makes E[x*y] strongly positive.
    # (2) VALIDITY-CONFOUNDED trials (types 5/6, 11/12, 23/24 plus
    #     mirrors): the option whose experts sit LATER also carries
    #     strictly more 0.95 experts. IVC's distrust inversion favors
    #     the EARLY option, so E[x*y] < 0; SWC's recency gradient still
    #     favors the LATE option, so E[x*y] > 0.
    #
    # Metric = mean of x*y over these trials.
    # SWC: strongly positive (~ +0.28 across its box, range ~ +0.17..+0.41).
    # IVC: zero on the matched family for all parameters, slightly
    # negative overall (~ -0.03).

    n = 6
    V = np.array([0.95, 0.75, 0.75, 0.95, 0.75, 0.75])
    P = (np.arange(n, dtype=float) / float(n - 1)) ** 3.5
    hi = V >= 0.9

    def to_arr(cell):
        if isinstance(cell, np.ndarray):
            return np.asarray(cell, dtype=float).ravel()
        if isinstance(cell, (list, tuple)):
            return np.asarray(list(cell), dtype=float).ravel()
        txt = str(cell).strip().strip('[]()')
        parts = txt.replace(',', ' ').split()
        return np.asarray([float(t) for t in parts], dtype=float).ravel()

    a_cells = data['option_a_ratings'].tolist()
    b_cells = data['option_b_ratings'].tolist()
    r_cells = data['response'].tolist()

    scores = []
    for i in range(len(a_cells)):
        try:
            a = to_arr(a_cells[i])
            b = to_arr(b_cells[i])
        except Exception:
            continue
        if a.shape[0] != n or b.shape[0] != n:
            continue
        try:
            resp = int(r_cells[i])
        except Exception:
            continue
        if resp != 0 and resp != 1:
            continue

        s = np.sign(a - b)
        ia = np.where(s > 0)[0]
        ib = np.where(s < 0)[0]
        if ia.size == 0 or ib.size == 0:
            continue

        va = sorted(V[ia].tolist())
        vb = sorted(V[ib].tolist())
        matched = (va == vb)

        x = float(np.dot(P, s))
        if not matched:
            if x == 0:
                continue
            late_a = x > 0
            late_hi = int(hi[ia].sum()) if late_a else int(hi[ib].sum())
            early_hi = int(hi[ib].sum()) if late_a else int(hi[ia].sum())
            if late_hi <= early_hi:
                continue

        y = 1.0 if resp == 0 else -1.0
        scores.append(x * y)

    if len(scores) == 0:
        return 0.0
    return float(np.mean(scores))
```

**Observed (real) value:** -0.1729 (var=0.0118)
**Previous candidate values (this loop):**
  - iter 1: -0.3051 (var=0.0100) (Δ vs real -0.1322)
  - iter 2: -0.2338 (var=0.0090) (Δ vs real -0.0610)
  - iter 3 (most recent): -0.2842 (var=0.0066) (Δ vs real -0.1113)
**Other theories' values on this metric (for reference):**
- pi_4: 0.2647 (var=0.0159)
- pi_5_1: -0.0459 (var=0.0117)
- pi_1: -0.3350 (var=0.0112)
- pi_2: 0.0242 (var=0.0128)
- pi_3: 0.0443 (var=0.0150)
- pi_5: -0.0563 (var=0.0178)
- pi_6: -0.2233 (var=0.0216)
- pi_7: -0.2325 (var=0.0136)

### Experiment 11
**Design**
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 1, 0]  B=[0, 1, 0, 0, 0, 1]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[0, 0, 1, 0, 1, 0]  B=[1, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 0, 1, 0, 1, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 1, 0, 1, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 0, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 1, 0]  B=[1, 0, 0, 1, 0, 1]
  A=[1, 0, 0, 1, 0, 1]  B=[0, 1, 1, 0, 1, 0]
  A=[1, 0, 0, 1, 0, 1]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 0, 0, 1, 0, 1]

**Metric**
```python
import numpy as np
import pandas as pd

def metric(data: pd.DataFrame) -> float:
    # Within-allegiance-cell OLS slope of choice on reference primacy evidence.
    #
    # Identification: group every trial by (c1, c2) where
    #   c1 = number of 0.60-expert wins for A minus for B (positions 2,3,5),
    #   c2 = total signed cue count.
    # Any position-INVARIANT validity-weighted model (IVC at ANY parameter
    # combo, plain tallying, any lapse/transform) makes P(choose A) a function
    # of (c1, c2) ONLY. Demeaning the primacy regressor within these cells
    # therefore makes the population OLS slope EXACTLY 0 under IVC,
    # parameter-free, for every subject. PW-IVC's primacy gradient breaks the
    # cell-conditional independence, producing a strictly positive slope.

    ratings_a = data['option_a_ratings']
    ratings_b = data['option_b_ratings']
    A = np.array([np.asarray(r, dtype=float) for r in ratings_a], dtype=float)
    B = np.array([np.asarray(r, dtype=float) for r in ratings_b], dtype=float)
    if A.ndim != 2 or A.shape[0] == 0:
        return 0.0
    n = A.shape[1]

    # Reference primacy kernel, eta = 5 (middle of PW-IVC's eta range [3.5, 6.5]).
    if n > 1:
        pos = np.arange(n, dtype=float)
        wp = ((n - pos) / (n - 1.0)) ** 5.0
        wp = wp / wp.sum()
    else:
        wp = np.ones(1)

    S = np.sign(A - B)
    y = 1.0 - np.asarray(data['response'], dtype=float)  # 1 = chose A

    x1 = S.dot(wp)  # primacy evidence favoring A

    # Allegiance cell for this design: validities [0.95, 0.6, 0.6, 0.95, 0.6, 0.95]
    # -> 0.60 experts at 0-indexed positions 1, 2, 4.
    if n == 6:
        c1 = S[:, 1] + S[:, 2] + S[:, 4]
    else:
        c1 = np.zeros(A.shape[0])
    c2 = S.sum(axis=1)

    g = c1.astype(int).astype(str) + "_" + c2.astype(int).astype(str)
    df = pd.DataFrame({'x1': x1, 'y': y, 'g': g})

    # Demean primacy evidence within allegiance cell: removes ALL validity-based
    # mean structure (distrust kernel at any gamma/c/tau, flat counting, lapse).
    df['x1c'] = df['x1'] - df.groupby('g')['x1'].transform('mean')
    ssx = float((df['x1c'] ** 2).sum())
    if ssx <= 1e-12:
        return 0.0
    ybar = float(df['y'].mean())
    slope = float((df['x1c'] * (df['y'] - ybar)).sum() / ssx)
    return slope
```

**Observed (real) value:** 0.3148 (var=0.0095)
**Previous candidate values (this loop):**
  - iter 1: 0.2471 (var=0.0095) (Δ vs real -0.0677)
  - iter 2: 0.1651 (var=0.0072) (Δ vs real -0.1497)
  - iter 3 (most recent): 0.2991 (var=0.0040) (Δ vs real -0.0157)
**Other theories' values on this metric (for reference):**
- pi_5_1: -0.0034 (var=0.0097)
- pi_6: 0.1752 (var=0.0110)
- pi_1: 0.4129 (var=0.0077)
- pi_2: -0.0132 (var=0.0118)
- pi_3: 0.0021 (var=0.0076)
- pi_4: -0.3642 (var=0.0070)
- pi_5: -0.0209 (var=0.0151)
- pi_7: 0.2316 (var=0.0094)

### Experiment 12
**Design**
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 1, 0]  B=[0, 0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 0, 0]  B=[0, 1, 0, 0, 1, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 1, 1, 0]  B=[0, 1, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 1, 0]  B=[0, 1, 0, 0, 0, 1]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 0, 0, 0, 1, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 1, 1, 0]  B=[0, 1, 1, 0, 0, 1]
  A=[0, 1, 1, 0, 0, 1]  B=[1, 0, 0, 1, 1, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 1, 0]  B=[0, 1, 0, 1, 0, 0]
  A=[0, 1, 0, 1, 0, 0]  B=[1, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """
    Primacy-slope metric on validity-matched cells (with X2-family
    orientation absorbed by a dummy).

    Logic: on every trial where the two options' winning-cue validity
    multisets are IDENTICAL (the 20 matched cells: D0,Z1,D1,W1,W2,D2,
    D2b,D3,D4,D5 + mirrors), the distrust kernel and the flat counting
    kernel cancel EXACTLY, so IVC predicts P(A)=0.500 parameter-free
    (the lapse preserves 0.5). PW-IVC predicts a systematic deviation
    graded by the primacy contrast C = w_prim . sign(A-B), with a
    steep convex reference gradient (eta=5).

    We also include the six X2-family cells (2 wins per side, unequal
    validity multisets). Under IVC all X2 cells share ONE probability
    that depends only on orientation (A-won-the-0.9 vs mirror), so a
    single +-1 orientation dummy Z absorbs IVC's entire mean structure
    there; the within-family position spread then loads on C.

    Metric = OLS coefficient of C in y ~ 1 + C + Z, with y = +1 (chose
    A) / -1 (chose B). Under IVC this coefficient is EXACTLY 0 in
    expectation for every admissible parameter. Under PW-IVC it is
    strictly positive (roughly 2*(1-eps)*beta*tau*rho scale), typically
    0.15-0.8.
    """
    import numpy as np
    import pandas as pd

    n = 6
    v = np.array([0.9, 0.6, 0.6, 0.6, 0.6, 0.9], dtype=float)

    # Reference primacy kernel (eta = 5): convex, front-loaded.
    pos = np.arange(n, dtype=float)
    prim = ((n - pos) / (n - 1.0)) ** 5.0
    w_prim = prim / prim.sum()

    # Reference inverted-validity kernel (gamma = 3, c = 0.1).
    # Only the SIGN of its dot product with s is used (orientation).
    err = 1.0 - v
    cent = np.maximum(err - 0.1 * float(err.min()), 0.0)
    u = cent ** 3.0
    u = u / u.sum()

    a = np.array([[float(t) for t in r] for r in data['option_a_ratings']], dtype=float)
    b = np.array([[float(t) for t in r] for r in data['option_b_ratings']], dtype=float)
    y = 1.0 - 2.0 * np.asarray(data['response'], dtype=float).ravel()  # +1 = A

    m = a.shape[0]
    if m == 0:
        return 0.0

    s = np.sign(a - b)
    aWin = a > b
    bWin = b > a

    C = np.zeros(m)
    Z = np.zeros(m)
    keep = np.zeros(m, dtype=bool)

    for i in range(m):
        ka = tuple(sorted(v[aWin[i]].tolist()))
        kb = tuple(sorted(v[bWin[i]].tolist()))
        nA = int(aWin[i].sum())
        nB = int(bWin[i].sum())
        if ka == kb and nA > 0:
            # Matched-validity cell: distrust+flat kernels cancel exactly.
            keep[i] = True
            C[i] = float(np.dot(w_prim, s[i]))
        elif nA == 2 and nB == 2 and ka != kb:
            # X2-family cell: orientation dummy absorbs IVC's constant
            # allegiance effect; position spread loads on C.
            keep[i] = True
            C[i] = float(np.dot(w_prim, s[i]))
            Z[i] = float(np.sign(np.dot(u, s[i])))

    if int(keep.sum()) < 12:
        return 0.0

    Ck = C[keep]
    Zk = Z[keep]
    yk = y[keep]

    X = np.column_stack([np.ones_like(Ck), Ck, Zk])
    try:
        coef, _, _, _ = np.linalg.lstsq(X, yk, rcond=None)
        return float(coef[1])
    except Exception:
        return 0.0
```

**Observed (real) value:** 0.5396 (var=0.0423)
**Previous candidate values (this loop):**
  - iter 1: 0.6192 (var=0.0436) (Δ vs real +0.0796)
  - iter 2: 0.3544 (var=0.0388) (Δ vs real -0.1851)
  - iter 3 (most recent): 0.6811 (var=0.0328) (Δ vs real +0.1415)
**Other theories' values on this metric (for reference):**
- pi_6: 0.4027 (var=0.0731)
- pi_5_1: 0.0336 (var=0.0381)
- pi_1: 0.8316 (var=0.0733)
- pi_2: -0.0087 (var=0.0294)
- pi_3: -0.0421 (var=0.0393)
- pi_4: -0.6945 (var=0.0377)
- pi_5: 0.0254 (var=0.0512)
- pi_7: 0.4678 (var=0.0344)

### Experiment 13
**Design**
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 1, 0, 0]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 1, 1, 0]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 0, 1, 0, 1, 0]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 0, 1, 0, 1, 0]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 0, 0, 1]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    # Trial specification keyed by (A ratings, B ratings) -> (family, aligned response).
    # Families (validities = [0.95, 0.5, 0.95, 0.5, 0.95, 0.5]; experts 1,3,5 are 95%, experts 2,4,6 are 50%):
    #   "H" : high-validity (95%) duels (trials 1-4); aligned = product winning the LATER expert (anti-primacy)
    #   "L" : low-validity (50%) duels (trials 7-10); aligned = product winning the EARLIER expert (primacy)
    #   "M" : distrust-neutralized position cells (trials 13-18); aligned = product winning expert 2
    #   "C" : count/validity-balanced coalition cells (trials 21-24); aligned = product winning experts {2,3}
    spec = {
        ((1, 0, 0, 0, 0, 0), (0, 0, 0, 0, 1, 0)): ("H", 1),
        ((0, 0, 0, 0, 1, 0), (1, 0, 0, 0, 0, 0)): ("H", 0),
        ((1, 0, 0, 0, 0, 0), (0, 0, 1, 0, 0, 0)): ("H", 1),
        ((0, 0, 1, 0, 0, 0), (1, 0, 0, 0, 0, 0)): ("H", 0),
        ((0, 1, 0, 0, 0, 0), (0, 0, 0, 0, 0, 1)): ("L", 0),
        ((0, 0, 0, 0, 0, 1), (0, 1, 0, 0, 0, 0)): ("L", 1),
        ((0, 1, 0, 0, 0, 0), (0, 0, 0, 1, 0, 0)): ("L", 0),
        ((0, 0, 0, 1, 0, 0), (0, 1, 0, 0, 0, 0)): ("L", 1),
        ((0, 1, 0, 0, 0, 0), (1, 0, 0, 0, 0, 1)): ("M", 0),
        ((1, 0, 0, 0, 0, 1), (0, 1, 0, 0, 0, 0)): ("M", 1),
        ((0, 1, 0, 0, 0, 0), (1, 0, 0, 1, 0, 0)): ("M", 0),
        ((1, 0, 0, 1, 0, 0), (0, 1, 0, 0, 0, 0)): ("M", 1),
        ((0, 1, 1, 0, 0, 0), (1, 0, 0, 0, 0, 1)): ("M", 0),
        ((1, 0, 0, 0, 0, 1), (0, 1, 1, 0, 0, 0)): ("M", 1),
        ((0, 1, 1, 0, 0, 0), (0, 0, 0, 1, 1, 0)): ("C", 0),
        ((0, 0, 0, 1, 1, 0), (0, 1, 1, 0, 0, 0)): ("C", 1),
        ((0, 1, 1, 0, 0, 0), (0, 0, 0, 0, 1, 1)): ("C", 0),
        ((0, 0, 0, 0, 1, 1), (0, 1, 1, 0, 0, 0)): ("C", 1),
    }

    hits = {"H": 0, "L": 0, "M": 0, "C": 0}
    tots = {"H": 0, "L": 0, "M": 0, "C": 0}

    a_cells = data["option_a_ratings"].tolist()
    b_cells = data["option_b_ratings"].tolist()
    r_vals = data["response"].tolist()

    for a_cell, b_cell, r in zip(a_cells, b_cells, r_vals):
        try:
            ka = tuple([int(x) for x in a_cell])
            kb = tuple([int(x) for x in b_cell])
            ri = int(r)
        except Exception:
            continue
        entry = spec.get((ka, kb))
        if entry is None:
            continue
        fam, al = entry
        tots[fam] += 1
        if ri == al:
            hits[fam] += 1

    def prop(fam):
        if tots[fam] == 0:
            return 0.5
        return hits[fam] / float(tots[fam])

    p_l = prop("L")  # P(earlier-expert product | low-validity duel)
    p_h = prop("H")  # P(later-expert product  | high-validity duel)
    p_m = prop("M")  # P(expert-2 product | distrust-neutralized cells)
    p_c = prop("C")  # P({2,3}-coalition product | balanced coalition cells)

    # (1) Validity-scaled position crossover: C = P(early|low duel) - P(early|high duel)
    #     = p_l + p_h - 1. Strictly positive under PGDT, strictly negative under PW-IVC
    #     at every corner of both parameter boxes (position effects are validity-
    #     AMPLIFIED under PGDT's multiplicative kernel, validity-INVARIANT under
    #     PW-IVC's additive kernel, where the position-1 expert always dominates).
    # (2) M-family: distrust terms cancel exactly in BOTH theories, leaving opposite-
    #     signed position architecture (PGDT: d>0 at every corner; PW-IVC: d<0 at every
    #     corner). Double-weighted because this is the only sign-DISJOINT family.
    # (3) Coalition cells: counting and distrust both cancel; only position varies.
    #     PGDT separates the coalition strongly (d in [0.08, 0.39]); PW-IVC caps at
    #     d <= 0.11. Double-weighted to use the 12 trials efficiently.
    crossover = p_l + p_h - 1.0
    m_term = 2.0 * (p_m - 0.5)
    c_term = 2.0 * (p_c - 0.5)

    return float(crossover + m_term + c_term)
```

**Observed (real) value:** 1.8356 (var=0.2112)
**Previous candidate values (this loop):**
  - iter 1: 1.9594 (var=0.1127) (Δ vs real +0.1239)
  - iter 2: 1.2356 (var=0.1399) (Δ vs real -0.6000)
  - iter 3 (most recent): 2.0078 (var=0.0856) (Δ vs real +0.1722)
**Other theories' values on this metric (for reference):**
- pi_7: 1.1900 (var=0.2144)
- pi_6: -0.0794 (var=0.2347)
- pi_1: 0.0389 (var=0.0856)
- pi_2: -0.4917 (var=0.1577)
- pi_3: -0.2350 (var=0.2168)
- pi_4: -0.8106 (var=0.2217)
- pi_5: 0.0650 (var=0.2219)
- pi_5_1: 0.0894 (var=0.1646)

### Experiment 14
**Design**
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 1, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 1, 1]
  A=[1, 0, 1, 0, 1, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 1, 0, 1, 1]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 1, 0, 0]
  A=[1, 0, 1, 1, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 1, 0]  B=[0, 1, 0, 1, 0, 0]
  A=[0, 1, 0, 1, 0, 0]  B=[1, 0, 0, 0, 1, 0]
  A=[1, 0, 0, 1, 0, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 1, 0, 1]
  A=[0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 1, 1]  B=[1, 0, 0, 1, 0, 0]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 1, 1, 0, 1, 1]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    # Critical "primacy-rescue" trial family: exactly one option carries the
    # position-1 trusted (0.95) expert, the opposing option carries only
    # early low-validity (0.50) experts. Six f1-side patterns (option that
    # holds the position-1 trusted expert) x two counterpart patterns.
    P = {
        (1, 0, 0, 0, 0, 1),  # {95%@1, 50%@6}          (L1 rung)
        (1, 0, 0, 0, 1, 1),  # {95%@1, 50%@5, 50%@6}   (L2 rung)
        (1, 0, 1, 0, 1, 1),  # {95%@1, 50%@3,5,6}     (L3 rung)
        (1, 0, 1, 0, 0, 0),  # {95%@1, 50%@3}          (L1e early helper)
        (1, 0, 1, 1, 0, 0),  # {95%@1, 50%@3, 95%@4}   (TB+ cell)
        (1, 0, 0, 0, 1, 0),  # {95%@1, 50%@5}          (FL cell)
    }
    Q = {
        (0, 1, 0, 0, 0, 0),  # {50%@2}
        (0, 1, 0, 1, 0, 0),  # {50%@2, 95%@4}
    }

    def to_key(x):
        return tuple(int(v) for v in x)

    hits = []
    a_col = data["option_a_ratings"]
    b_col = data["option_b_ratings"]
    r_col = data["response"]
    for a_raw, b_raw, r_raw in zip(a_col, b_col, r_col):
        a = to_key(a_raw)
        b = to_key(b_raw)
        r = int(r_raw)
        if a in P and b in Q:
            # trusted-early product is option A
            hits.append(1.0 if r == 0 else 0.0)
        elif b in P and a in Q:
            # trusted-early product is option B
            hits.append(1.0 if r == 1 else 0.0)

    if len(hits) == 0:
        return 0.5
    return float(np.mean(hits))
```

**Observed (real) value:** 0.1322 (var=0.0089)
**Previous candidate values (this loop):**
  - iter 1: 0.2572 (var=0.0123) (Δ vs real +0.1250)
  - iter 2: 0.4094 (var=0.0060) (Δ vs real +0.2772)
  - iter 3 (most recent): 0.2144 (var=0.0071) (Δ vs real +0.0822)
**Other theories' values on this metric (for reference):**
- pi_6: 0.6911 (var=0.0080)
- pi_7: 0.4311 (var=0.0074)
- pi_1: 0.8344 (var=0.0128)
- pi_2: 0.7878 (var=0.0063)
- pi_3: 0.6217 (var=0.0047)
- pi_4: 0.6733 (var=0.0080)
- pi_5: 0.5822 (var=0.0076)
- pi_5_1: 0.5911 (var=0.0082)

## PREVIOUS CANDIDATE (this loop)
The RUNNING-BEST (last ACCEPTED) candidate in this critique loop — i.e. the source the loop's accept gate kept as the best base so far. If your most recent attempt was REJECTED by the gate, this is NOT that attempt; it is the previously-accepted base the gate rolled back to. Iterate on this source — the next critic feedback should be applied on top of it.

**Description**
POSITION-RECOVERED DISTRUST TALLYING (PRDT), calibration-pass edition. Subjects scan expert ratings in presentation order through a floored convex primacy gate g_j = delta + (1-delta)*((n-j)/(n-1))^eta. Communicated validities are distrust-inverted (subjects act as if stated validity were the expert's error rate): inv_j = ((1-v_j) - c*min_k(1-v_k))^gamma / Z. Trust itself recovers with position: t_j = t0 + (t1-t0)*(j/(n-1))^kappa, with t0 pinned at ~0 — total skepticism toward early-communicated high-validity claims — ramping to a strong late-position residue. Weights combine multiplicatively: w_j ∝ g_j * [t_j*(1-tau)/n + tau*inv_j]; evidence d = Σ w_j*sign(A_j - B_j); choice is logistic in beta*d with uniform lapse epsilon. This iteration keeps the accepted architecture exactly and re-calibrates only: softer commitment (beta in the lower half of its box, epsilon in the upper half), a stronger delayed trust ramp (t1 up to 1.0, t0 ~ 0, kappa 2-4), a softer gate (eta 3.5-4.5, delta 0.35-0.45) so late positions are not crushed, and slightly reduced distrust dominance (tau 0.90-0.93, gamma 2.0-3.5) to soften the anti-validity over-shoots without breaking the early-trusted-expert suppression carried by t0≈0.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    # PRDT: Position-Recovered Distrust Tallying.
    # iter-2 CALIBRATION PASS per the critic's iter-1 directive.
    # Architecture UNCHANGED from the accepted iter-1 base (distrust
    # inversion + position-growing trust residue + floored primacy gate,
    # multiplicative combination, additive integration, logistic choice).
    # Only the parameter RANGES are re-calibrated:
    #   (1) DE-ESCALATE COMMITMENT: beta moved from [3.5, 10] to
    #       [3.5, 5.5] (lower half of the box) and epsilon from
    #       [0.04, 0.12] to [0.08, 0.12] (upper half). The iter-1
    #       over-execution of the de-attenuation made choices too
    #       deterministic, amplifying every weight imbalance to near-1/0
    #       (Exps 1, 2, 3, 4, 7, 10 all over-shot in the distrust /
    #       anti-validity direction). Softer commitment pulls those back
    #       toward their observed values, and simultaneously moves Exps
    #       5/6/8/9 (all between the iter-1 simulation and 0.5) toward
    #       their targets.
    #   (2) STRENGTHEN THE TRUST-RECOVERY RAMP: t1 raised to [0.70, 1.00],
    #       t0 pinned to [0.0, 0.02] (~exactly zero: the position-1
    #       trusted expert's bracket must vanish so the Exp 14 rescue
    #       rate falls from 0.26 toward 0.13), kappa kept in [2, 4] so
       #       trust recovery stays delayed.
    #   (3) SOFTEN THE GATE so g_j's decay stops crushing the late
       #       positions that t_j is trying to rescue: eta narrowed to
    #       [3.5, 4.5], delta raised to [0.35, 0.45].
    #   (4) REDUCE DISTRUST DOMINANCE slightly: tau narrowed to
    #       [0.90, 0.93], gamma to [2.0, 3.5], softening the anti-validity
    #       over-shoots (Exps 3, 7, 10) without touching the Exp 14
    #       suppression (carried by t0 ~ 0, not by gamma).
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"PRDT expects a (2, n_features) stimulus; got shape {stim.shape}."
        )
    a, b = stim[0], stim[1]
    n = int(stim.shape[1])

    v = np.asarray(parameters["validities"], dtype=float).ravel()
    if v.shape[0] != n:
        # Graceful fallback: strictly decreasing validities.
        v = np.linspace(0.95, 0.55, n)
    v = np.clip(v, 0.0, 1.0)

    tau = float(parameters["tau"])        # distrust share of the bracket
    eta = float(parameters["eta"])         # convexity of the primacy gate
    delta = float(parameters["delta"])    # floor of the primacy gate
    gamma = float(parameters["gamma"])    # steepness of distrust inversion
    c = float(parameters["c"])             # partial centering of error rates
    t0 = float(parameters["t0"])           # trust residue at position 1 (~0)
    t1 = float(parameters["t1"])           # trust residue at the last position
    kappa = float(parameters["kappa"])    # convexity of the trust ramp
    beta = float(parameters["beta"])      # choice consistency (softened)
    eps = float(parameters["epsilon"])   # uniform lapse (raised)

    # (1) DISTRUST INVERSION with partial centering: treat the stated
    # validity as an error rate; subtract a fraction c of the smallest
    # error rate before raising to the gamma power, then normalize.
    err = 1.0 - v
    centered = np.maximum(err - c * float(err.min()), 0.0)
    inv = np.power(centered, gamma)
    Z_v = float(inv.sum())
    if Z_v > 1e-12:
        w_inv = inv / Z_v
    else:
        # Degenerate design (all validities tied at the extreme): the
        # distrust kernel is flat and position alone carries structure.
        w_inv = np.full(n, 1.0 / n)

    if n > 1:
        pos = np.arange(n, dtype=float)
        # (2) POSITION-GROWING TRUST RESIDUE: near-total skepticism toward
        # early-communicated trusted claims, progressive credibility
        # concession as trusted experts appear later.
        t = t0 + (t1 - t0) * np.power(pos / (n - 1.0), kappa)
        # (3) STEEP CONVEX PRIMACY GATE WITH FLOOR over presentation order.
        g = delta + (1.0 - delta) * np.power((n - pos) / (n - 1.0), eta)
    else:
        t = np.array([1.0])
        g = np.array([1.0])

    # (4) MULTIPLICATIVE combination: the gate scales the bracket cue-by-cue.
    # The bracket's trusted channel is modulated by the position-growing
    # trust residue, so an early trusted expert's bracket nearly vanishes
    # (t0 ~ 0) while a late trusted expert regains up to the full flat
    # share (t1 up to 1).
    bracket = t * (1.0 - tau) / n + tau * w_inv
    raw = g * bracket
    Z_t = float(raw.sum())
    if Z_t > 1e-12:
        w = raw / Z_t
    else:
        w = np.full(n, 1.0 / n)

    # (5) Deterministic attention: every discriminating cue is attended;
    # no capacity interference, beta is design-independent.
    s = np.sign(a - b)

    # Additive integration of all discriminating cues.
    d = float(np.dot(w, s))

    # Numerically stable logistic choice rule.
    p_a = 0.5 * (1.0 + np.tanh(0.5 * beta * d))
    probs = np.array([p_a, 1.0 - p_a], dtype=float)

    # Uniform lapse.
    probs = (1.0 - eps) * probs + eps * 0.5
    return probs

`policy(probs) -> int`:
def policy(probs):
    probs = np.asarray(probs, dtype=np.float64)
    probs = probs / probs.sum()  # guard against float drift
    return int(np.random.choice(len(probs), p=probs))

`parameters`:
- tau: [0.90, 0.93]
- eta: [3.5, 4.5]
- delta: [0.35, 0.45]
- gamma: [2.0, 3.5]
- c: [0.0, 0.3]
- t0: [0.0, 0.02]
- t1: [0.70, 1.00]
- kappa: [2.0, 4.0]
- beta: [3.5, 5.5]
- epsilon: [0.08, 0.12]
- validities: validities

`rationale`: This is the calibration pass the critic explicitly requested — the PRDT architecture is kept byte-for-byte identical to the accepted iter-1 base and only the parameter ranges are re-tuned, because every pooled residual was diagnosed as a monotone, in-box parameter away from its target. (A) Over-commitment fix: the iter-1 de-attenuation (beta up to 10, epsilon down to 0.04) over-executed the arbiter's prescription, making choices too deterministic and amplifying every weight imbalance to near-1/0 — the source of the distrust-direction over-shoots on Exps 1 (0.065 vs 0.208), 2 (0.375 vs 0.158), 3 (-0.82 vs -0.58), 4 (0.92 vs 0.84), 7 (0.90 vs 0.79) and 10 (-0.31 vs -0.17). Moving beta to [3.5, 5.5] and epsilon to [0.08, 0.12] softens determinism, which pulls all six back toward their observed values, and — because the observed values on Exps 5 (0.23), 6 (0.37), 8 (0.40) and 9 (0.34) all lie between the iter-1 simulation and 0.5 — the same softening simultaneously lifts the under-shot recency metrics. (B) Trust-ramp strengthening: the iter-1 fit let the multiplicative gate g_j decay with position faster than t_j rose, so late trusted experts were still crushed — Exp 8 fell to 0.246 vs the observed 0.396. Raising t1 to [0.70, 1.00], pinning t0 at ~0 (so the position-1 trusted expert's bracket vanishes completely, pushing Exp 14's rescue rate from 0.26 toward 0.13), keeping kappa in [2, 4] for delayed recovery, and softening the gate (eta to [3.5, 4.5], delta to [0.35, 0.45]) lets the late-position trusted channel actually regain weight. (C) Distrust-dominance trim: tau to [0.90, 0.93] and gamma to [2.0, 3.5] soften the anti-validity over-shoots on Exps 3, 7 and 10 without touching the Exp 14 suppression, which is carried by t0 ≈ 0 rather than by gamma. No kernel, no combination rule, no integration rule was altered: the sign-guaranteed validity-amplified crossover (Exp 13, 1.96 vs observed 1.84) and the early-trusted rescue suppression (Exp 14) — the two structural successes that got iter-1 accepted — are preserved by construction, while every remaining residual is addressed by a monotone in-box adjustment.

## PRIOR FEEDBACK ITERATIONS
The critic's verdicts on each previous in-loop candidate, in order. Each block ends with an **Outcome of this advice** line saying whether the candidate the proposer produced AFTER this advice was ACCEPTED (loss strictly beat the running best) or REJECTED (the gate discarded it). Address the most recent iteration's feedback in your next edit, but down-weight past advice whose candidates were REJECTED.

### Iteration 1
Verdict: regenerate
Interpretation: PRDT is a genuine structural success on the two joint failures that motivated it: Exp 13 (validity-amplified crossover composite) jumps from pi_7's 1.19 to 1.96 against an observed 1.84, and Exp 14 (early-trusted-expert rescue) drops from 0.43 to 0.26 against an observed 0.13 — by far the best of any theory on both. The gate correctly accepted it (loss 0.1754). However, the pooled residuals show two systematic, opposite-signed calibration errors. (A) OVER-COMMITMENT / over-dominant distrust channel: Exp 1 (0.065 vs 0.208, far too anti-TTB), Exp 2 (0.375 vs 0.158, too tally-aligned), Exp 3 (-0.82 vs -0.58, anti-validity slope too steep), Exp 4 (0.92 vs 0.84), Exp 7 (0.90 vs 0.79), Exp 10 (-0.31 vs -0.17) all over-shoot in the distrust/anti-validity direction. The arbiter's 'de-attenuation' prescription (beta up to 10) was over-executed: choices are too deterministic, amplifying every weight imbalance to near-1/0. (B) The trust-recovery ramp UNDER-delivered on recency: Exp 8 final-expert following actually FELL to 0.246 (vs pi_7's 0.283, observed 0.396), and Exps 5 (0.08 vs 0.23), 6 (0.26 vs 0.37), 9 (0.26 vs 0.34) all under-shoot. Mechanistically, the multiplicative primacy gate g_j decays faster with position than the trust ramp t_j rises, so the product still crushes late-cue weight — the fitted t1/kappa combination is too weak (and/or eta too steep, delta too low) to let a late trusted expert regain weight. Note that many of the (B) failures would also be partially corrected simply by reducing determinism, since observed values on Exps 5/6/8/9 all lie between the candidate's value and 0.5. The architecture is right; the calibration is not.
Rationale: Keep the PRDT architecture exactly as prescribed (distrust-inversion kernel, position-growing trust residue, multiplicative floored primacy gate, additive integration, logistic choice) — it is the first candidate to simultaneously produce the Exp 13 crossover magnitude and the Exp 14 rescue suppression. But it was accepted with systematic residuals, so keep tuning on this base with in-family parameter adjustments only: (1) DE-ESCALATE the de-attenuation: move beta to the lower half of its box (≈3.5–5.5) and epsilon to the upper half (≈0.08–0.12). This alone pulls Exp 1 up toward 0.21, Exp 2 down toward 0.16, Exp 3 up toward -0.58, Exp 7 down toward 0.79, Exp 10 toward -0.17, and Exp 4 toward 0.84, and moves Exps 5/6/8/9 toward their observed values (all between the current simulation and 0.5). (2) STRENGTHEN the trust-recovery ramp so late trusted experts actually regain weight: push t1 to 0.7–1.0, keep t0 pinned at exactly 0.0 (Exp 14 is still 2x the observed rescue rate; the position-1 trusted expert's bracket must vanish completely), and keep kappa in 2–4 so trust stays delayed. If Exp 8 remains under-shot after the beta correction, soften the gate: eta toward 3.5–4.5 and delta toward 0.35–0.45, so g_j's floor stops crushing the late positions that t_j is trying to rescue. (3) Slightly reduce distrust dominance: tau toward 0.90–0.93 and gamma toward 2–3.5 to soften the anti-validity over-shoots (Exps 3, 7, 10) without breaking the Exp 14 suppression (which is carried by t0≈0, not by gamma). Do NOT restructure the kernel or switch families — every residual is a monotone, in-box parameter away from the observed value, so this is a calibration pass, not a redesign.

**Outcome of this advice:** iter 1 candidate loss=0.1754 -> iter 2 candidate loss=0.1630 -> the gate marked it ACCEPTED.

### Iteration 2
Verdict: regenerate
Interpretation: The iter-2 calibration pass was a net gain (loss 0.1754 -> 0.1630, accepted) and my iter-1 diagnosis was partially validated: softening commitment and trimming distrust dominance improved ten experiments, several substantially (Exp 9 is now essentially perfect at 0.349 vs 0.341; Exps 5, 6, 10 nearly closed). However, the pass over-corrected and gave away exactly the two signature phenomena that justified PRDT over the incumbents in the first place. Exp 13 (validity-amplified crossover) fell from 1.96 to 1.236 — statistically indistinguishable from pi_7's 1.19, i.e. the candidate no longer beats the incumbent the arbiter wanted to replace. Exp 14 (early-trusted-expert rescue) ROSE from 0.257 to 0.409 against an observed 0.132 — again no better than pi_7's 0.431. The primacy slopes also collapsed: Exp 11 (0.247 -> 0.165 vs observed 0.315), Exp 12 (0.619 -> 0.354 vs observed 0.540). Diagnosis of the mechanism: (a) the beta reduction to [3.5, 5.5] shrank every slope-like metric (11, 12, 13) toward zero; (b) the gate softening (eta 3.5-4.5, delta 0.35-0.45) was the wrong lever — it bought only +0.023 on Exp 8 (0.246 -> 0.270, still 0.13 under observed) while directly sabotaging Exps 13/14/11/12. The Exp 14 failure is instructive: in that design the rescue option's supporting cues are LOW-validity (0.50) experts at late positions, so they carry large distrust-inverted weight, and the softened gate (plus the stronger t1 ramp) let them regain exactly that weight. The only discriminator between the opposing early 0.50 expert and the rescue option's late 0.50 helpers is gate steepness — so the steep gate IS the Exp 14 mechanism, and flattening it destroys the rescue suppression. Meanwhile Exp 8's residual under-shot is capped structurally: the final expert's trust channel is bounded by (1-tau)/n ≈ 0.017 at tau >= 0.90, so gate-flattening was never going to close it anyway. The tau/gamma trim (Exps 3, 7, 10 all improved) is the part of iter 2 that worked and should be kept; the beta/gate/delta changes are the parts that broke the primacy family.
Rationale: verdict: regenerate

**Outcome of this advice:** iter 2 candidate loss=0.1630 -> iter 3 candidate loss=0.1659 -> the gate marked it REJECTED.

### Iteration 3 (most recent — address this)
Verdict: regenerate
Interpretation: The iter-3 'steep-gate restore' was a partial success that still lost to the gate: it recovered the primacy family almost perfectly (Exp 13: 2.01 vs observed 1.84, a huge rebound from iter-2's 1.24; Exp 11: 0.299 vs 0.315, essentially exact; Exp 14: 0.214, the best value any theory in this pool has produced against the observed 0.132), but it re-broke everything my iter-1 critique flagged as over-commitment and re-crushed the recency family: Exp 1 fell back to 0.070 (vs 0.208), Exp 2 rose to 0.420 (vs 0.158), Exp 5 to 0.104 (vs 0.231), Exp 6 to 0.268 (vs 0.374), Exp 8 to 0.232 (vs 0.396), Exp 9 to 0.238 (vs 0.341 — iter-2 had this at 0.349, essentially perfect), and Exp 10 to -0.284 (vs -0.173). Exp 12 also over-shot (0.681 vs 0.540), confirming beta at [4.5, 8.0] is too hot even for the metrics it was raised to serve. The loss trajectory (0.1754 → 0.1630 → 0.1659) plus my own critique history shows a clean oscillation: iter-1/iter-3 at the steep/high-beta corner win the primacy family and lose the recency/anti-commitment family; iter-2 at the soft/low-beta corner does the reverse. Neither corner is right — the observed data sit between the two flanks on essentially every metric (Exps 5, 6, 8, 9 observed values all lie between the iter-2 and iter-3 simulations or between candidate and 0.5; Exp 13's 1.84 lies between iter-2's 1.24 and iter-3's 2.01; Exp 12's 0.54 lies between 0.35 and 0.68). The fix is not another full swing but an interpolation, plus one genuinely new in-family lever that decouples the two families rather than trading them off: the trust-ramp convexity kappa.
Rationale: Verdict regenerate — and this time the directive is explicitly INTERPOLATE, do not re-swing. My iter-2 advice ('restore the steep gate and beta') was rejected by the gate, and the iter-3 result confirms why: the gate/beta axis is a single coupled dial that trades the primacy family (Exps 11-14) against the recency/anti-commitment family (Exps 1, 2, 5, 6, 8, 9, 10), and both corners have now been tried. Working from the accepted iter-2 base, make these changes: (1) BETA AT THE MIDPOINT: [4.0, 5.5] — above iter-2's [3.5, 5.5] to recover slope magnitude on Exps 11/12/13, well below iter-3's [4.5, 8.0] which re-blew up Exps 1/2/4/7/12. (2) GATE HALF-STEP: eta [4.5, 5.5] and delta [0.25, 0.35] — steeper than iter-2's softened gate (which destroyed Exp 14 rescue suppression and the Exp 13 crossover), gentler than iter-3's (which crushed Exps 5/6/8/9). Exp 13 should land near 1.6-1.8 and Exp 14 near 0.25-0.30. (3) NEW LEVER — LOWER KAPPA to [1.5, 3.0]: this is the change that breaks the oscillation. The current kappa ∈ [2, 4] is so convex that trust arrives only at the very last position, so mid-late positions get neither gate weight nor trust weight — that is why the recency family under-shoots whenever the gate is steep. Lowering kappa lets trust recover earlier across positions 3-5, lifting Exps 5/6/9 toward their observed values WITHOUT flattening the gate, and it barely touches Exp 14 because the rescue option's late helpers are 0.50-validity experts whose brackets are dominated by the distrust channel (tau·inv_j), not the trust channel (t_j·(1-tau)/n ≤ ~0.017). It also leaves Exp 8's final expert (which gets t1 regardless of kappa) unaffected, so Exp 8's residual under-shot must instead be addressed by the delta floor within the new range and epsilon held at [0.08, 0.12]. (4) KEEP the validated iter-2 trims byte-for-byte: tau [0.90, 0.93], gamma [2.0, 3.5], t0 ∈ [0, 0.02] (Exp 14 still needs the position-1 trusted bracket at ~zero), t1 [0.70, 1.00], c [0, 0.3]. Do NOT restructure the kernel, combination rule, or integration rule — the architecture is sound; the calibration has simply been ping-ponging between two corners of a box whose interior has never been sampled. Expected trade: most of iter-3's primacy gains retained at ~60-70% strength, with the recency family giving back only ~0.03-0.05 per experiment instead of the 0.08-0.13 iter-3 gave back — a clear net improvement over the 0.1630 floor.

**Outcome of this advice:** iter 3 candidate loss=0.1659 -> next candidate accept-status=PENDING (this is the advice you are addressing now).


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
  "theory": "POSITION-RECOVERED DISTRUST TALLYING (PRDT), interpolated-calibration edition. Subjects scan expert ratings in presentation order through a floored convex primacy gate g_j = delta + (1-delta)*((n-j)/(n-1))^eta. Communicated validities are distrust-inverted (subjects act as if the stated validity were the expert's error rate): inv_j = ((1-v_j) - c*min_k(1-v_k))^gamma / Z. Trust itself recovers with presentation position: t_j = t0 + (t1-t0)*(j/(n-1))^kappa, with t0 pinned near zero — total skepticism toward early-communicated high-validity claims — ramping to a strong late-position residue, with the ramp's convexity kappa now LOW so credibility returns across the mid-late positions rather than only at the final slot. Weights combine multiplicatively: w_j proportional to g_j * [t_j*(1-tau)/n + tau*inv_j]; evidence d = sum_j w_j*sign(A_j - B_j) is integrated additively over discriminating cues; choice is logistic in beta*d with a uniform lapse epsilon. The claim: the primacy family (Exps 11-14) and the recency/anti-commitment family (Exps 1, 2, 5, 6, 8, 9, 10) are not traded off by a single gate/beta dial — the trust-recovery convexity kappa is the independent lever that lets mid-late trusted cues regain weight without flattening the early gate that suppresses the position-1 trusted expert.",
  "predict": "def predict(parameters, state, history):\n    # PRDT: Position-Recovered Distrust Tallying.\n    # iter-4 INTERPOLATION PASS per the critic's iter-3 directive.\n    # Architecture UNCHANGED from the accepted iter-2 base (distrust\n    # inversion + position-growing trust residue + floored primacy gate,\n    # multiplicative combination, additive integration, logistic choice).\n    # The iter-1/iter-3 oscillation showed the gate/beta axis is a single\n    # coupled dial trading the primacy family against the recency family;\n    # this pass samples the box INTERIOR and adds one new in-family lever\n    # (lower kappa) that decouples the two families:\n    #   (1) BETA AT THE MIDPOINT: [4.0, 5.5] -- above iter-2's [3.5, 5.5]\n    #       to recover slope magnitude on Exps 11/12/13, well below\n    #       iter-3's [4.5, 8.0] which re-blew up Exps 1/2/4/7/12.\n    #   (2) GATE HALF-STEP: eta [4.5, 5.5], delta [0.25, 0.35] -- steeper\n    #       than iter-2's softened gate (which destroyed Exp 14 rescue\n    #       suppression and the Exp 13 crossover), gentler than iter-3's\n    #       (which crushed Exps 5/6/8/9).\n    #   (3) NEW LEVER -- LOWER KAPPA to [1.5, 3.0]: trust now recovers\n    #       earlier across positions 3-5, lifting Exps 5/6/9 toward their\n    #       observed values WITHOUT flattening the gate; barely touches\n    #       Exp 14 (whose late helpers' brackets are distrust-dominated,\n    #       not trust-dominated) and leaves Exp 8's final expert (which\n    #       gets t1 regardless of kappa) unaffected.\n    #   (4) KEEP the validated iter-2 trims byte-for-byte: tau [0.90, 0.93],\n    #       gamma [2.0, 3.5], t0 [0.0, 0.02], t1 [0.70, 1.00], c [0.0, 0.3],\n    #       epsilon [0.08, 0.12].\n    stim = np.asarray(state, dtype=float)\n    if stim.ndim != 2 or stim.shape[0] != 2:\n        raise ValueError(\n            f\"PRDT expects a (2, n_features) stimulus; got shape {stim.shape}.\"\n        )\n    a, b = stim[0], stim[1]\n    n = int(stim.shape[1])\n\n    v = np.asarray(parameters[\"validities\"], dtype=float).ravel()\n    if v.shape[0] != n:\n        # Graceful fallback: strictly decreasing validities.\n        v = np.linspace(0.95, 0.55, n)\n    v = np.clip(v, 0.0, 1.0)\n\n    tau = float(parameters[\"tau\"])        # distrust share of the bracket\n    eta = float(parameters[\"eta\"])         # convexity of the primacy gate\n    delta = float(parameters[\"delta\"])    # floor of the primacy gate\n    gamma = float(parameters[\"gamma\"])    # steepness of distrust inversion\n    c = float(parameters[\"c\"])             # partial centering of error rates\n    t0 = float(parameters[\"t0\"])           # trust residue at position 1 (~0)\n    t1 = float(parameters[\"t1\"])           # trust residue at the last position\n    kappa = float(parameters[\"kappa\"])    # convexity of the trust ramp (LOW)\n    beta = float(parameters[\"beta\"])      # choice consistency (midpoint)\n    eps = float(parameters[\"epsilon\"])   # uniform lapse\n\n    # (1) DISTRUST INVERSION with partial centering: treat the stated\n    # validity as an error rate; subtract a fraction c of the smallest\n    # error rate before raising to the gamma power, then normalize.\n    err = 1.0 - v\n    centered = np.maximum(err - c * float(err.min()), 0.0)\n    inv = np.power(centered, gamma)\n    Z_v = float(inv.sum())\n    if Z_v > 1e-12:\n        w_inv = inv / Z_v\n    else:\n        # Degenerate design (all validities tied at the extreme): the\n        # distrust kernel is flat and position alone carries structure.\n        w_inv = np.full(n, 1.0 / n)\n\n    if n > 1:\n        pos = np.arange(n, dtype=float)\n        # (2) POSITION-GROWING TRUST RESIDUE: near-total skepticism toward\n        # early-communicated trusted claims, progressive credibility\n        # concession as trusted experts appear later. kappa now LOW\n        # ([1.5, 3.0]) so trust returns across mid-late positions, not\n        # only at the very last slot.\n        t = t0 + (t1 - t0) * np.power(pos / (n - 1.0), kappa)\n        # (3) STEEP CONVEX PRIMACY GATE WITH FLOOR over presentation order.\n        g = delta + (1.0 - delta) * np.power((n - pos) / (n - 1.0), eta)\n    else:\n        t = np.array([1.0])\n        g = np.array([1.0])\n\n    # (4) MULTIPLICATIVE combination: the gate scales the bracket cue-by-cue.\n    # The bracket's trusted channel is modulated by the position-growing\n    # trust residue, so an early trusted expert's bracket nearly vanishes\n    # (t0 ~ 0) while a late trusted expert regains up to the full flat\n    # share (t1 up to 1).\n    bracket = t * (1.0 - tau) / n + tau * w_inv\n    raw = g * bracket\n    Z_t = float(raw.sum())\n    if Z_t > 1e-12:\n        w = raw / Z_t\n    else:\n        w = np.full(n, 1.0 / n)\n\n    # (5) Deterministic attention: every discriminating cue is attended;\n    # no capacity interference, beta is design-independent.\n    s = np.sign(a - b)\n\n    # Additive integration of all discriminating cues.\n    d = float(np.dot(w, s))\n\n    # Numerically stable logistic choice rule.\n    p_a = 0.5 * (1.0 + np.tanh(0.5 * beta * d))\n    probs = np.array([p_a, 1.0 - p_a], dtype=float)\n\n    # Uniform lapse.\n    probs = (1.0 - eps) * probs + eps * 0.5\n    return probs",
  "policy": "def policy(probs):\n    probs = np.asarray(probs, dtype=np.float64)\n    probs = probs / probs.sum()  # guard against float drift\n    return int(np.random.choice(len(probs), p=probs))",
  "parameters": {
    "tau": "[0.90, 0.93]",
    "eta": "[4.5, 5.5]",
    "delta": "[0.25, 0.35]",
    "gamma": "[2.0, 3.5]",
    "c": "[0.0, 0.3]",
    "t0": "[0.0, 0.02]",
    "t1": "[0.70, 1.00]",
    "kappa": "[1.5, 3.0]",
    "beta": "[4.0, 5.5]",
    "epsilon": "[0.08, 0.12]",
    "validities": "validities"
  },
  "rationale": "This is the interpolation pass the iter-3 critique explicitly requested — the PRDT architecture is kept byte-for-byte identical to the accepted iter-2 base and only the parameter ranges move, because the loss trajectory (0.1754 -> 0.1630 -> 0.1659, REJECTED) plus the critic's own diagnosis show a clean oscillation between two corners of the parameter box whose interior has never been sampled: the steep-gate/high-beta corner (iter-1, iter-3) wins the primacy family (Exps 11-14) and loses the recency/anti-commitment family (Exps 1, 2, 5, 6, 8, 9, 10); the soft-gate/low-beta corner (iter-2) does the reverse. The observed values sit between the two flanks on essentially every metric (Exp 13's 1.84 between 1.24 and 2.01; Exp 12's 0.54 between 0.35 and 0.68; Exps 5/6/8/9 between iter-3's values and 0.5 or between the two simulations). The minimal edits: (1) BETA at the midpoint [4.0, 5.5] — above iter-2 to recover slope magnitude on Exps 11/12/13, well below iter-3's hot [4.5, 8.0] which re-blew up Exps 1/2/4/7/12. (2) GATE HALF-STEP: eta [4.5, 5.5], delta [0.25, 0.35] — steeper than iter-2's softened gate (which destroyed the Exp 14 rescue suppression and the Exp 13 crossover), gentler than iter-3's (which crushed Exps 5/6/8/9). The steep gate IS the Exp 14 mechanism (the only discriminator between the opposing early 0.50 expert and the rescue option's late 0.50 helpers is gate steepness), so it must stay steep — but not maximal. (3) THE NEW LEVER — kappa lowered to [1.5, 3.0]. This is the change that breaks the oscillation rather than trading within it: at kappa in [2, 4], trust arrives only at the very last position, so mid-late positions get neither gate weight nor trust weight — which is exactly why the recency family under-shoots whenever the gate is steep. Lower kappa lets trust recover across positions 3-5, lifting Exps 5/6/9 toward their observed values WITHOUT flattening the gate; it barely touches Exp 14 (the rescue option's late helpers are 0.50-validity experts whose brackets are dominated by the distrust channel tau*inv_j, not the trust channel t_j*(1-tau)/n <= ~0.017) and leaves Exp 8's final expert (which receives t1 regardless of kappa) unaffected. (4) Everything the iter-2 pass validated is kept byte-for-byte: tau [0.90, 0.93], gamma [2.0, 3.5], t0 [0.0, 0.02], t1 [0.70, 1.00], c [0.0, 0.3], epsilon [0.08, 0.12]. No kernel, combination rule, or integration rule was altered. Expected trade per the critic's own accounting: most of iter-3's primacy gains retained at ~60-70% strength (Exp 13 near 1.6-1.8, Exp 14 near 0.25-0.30, Exp 11 near 0.30), with the recency family giving back only ~0.03-0.05 per experiment instead of the 0.08-0.13 iter-3 gave back — a clear net improvement over the 0.1630 floor."
}
```
```

## Usage

```json
{
  "input_tokens": 45608,
  "output_tokens": 3412,
  "reasoning_tokens": 361,
  "provider": "Sail Research"
}
```
