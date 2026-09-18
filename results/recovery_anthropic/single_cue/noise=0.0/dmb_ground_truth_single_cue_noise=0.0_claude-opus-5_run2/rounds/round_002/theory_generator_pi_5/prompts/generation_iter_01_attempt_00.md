# generation_iter_01_attempt_00

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
- THEORY 1 = `pi_3`
- THEORY 2 = `pi_4`
- The recommendation below acts on THEORY 1 (= `pi_3`).

Replace pi_3 (LSNC) with a theory built around ONE-REASON OVERRIDE ON A NOISY TALLY BASELINE with subjectively (mis)assigned cue weights. Sketch:

1) Weighted evidence, not raw counting. On each trial the subject computes a weighted difference E = sum_j w_j * (a_j - b_j) and chooses via a softmax/logistic on E with a lapse term. Because the w_j are unequal, a single strongly weighted cue CAN outvote a numeric majority \u2014 i.e. adherence to the feature-count winner is allowed to fall BELOW 0.5. This is the crucial capability both incumbents lack (exp1 coherent cells ~0.15, exp2 D1 ~ -0.8).

2) The subjective weights are only weakly and imperfectly bound to the STATED validities. Model w_j = exp(alpha*(v_j - vbar)/s_v + phi_j), where alpha is a free validity-sensitivity coefficient that is allowed to be near zero or NEGATIVE, and phi_j is a display-position salience profile (free, e.g. a small primacy/serial-position vector). Motivation: when the validity list is scrambled relative to display order (exps 1, 2, 4) subjects mis-bind validity values to expert positions, so the cue they treat as decisive need not be the objectively most valid one; when validities are presented in descending order (exp3) binding is coherent. This single mechanism can produce (a) chance on tally-tied, mirrored profiles when the weighted evidence approximately cancels (exp3 = 0.474), (b) ~0.75-0.80 adherence on generic/near-dominance profiles where all weightings agree with the count (exps 5, 6), (c) intermediate ~0.65 tally adherence on TTB-conflict trials with large margins (exp4), and (d) strongly sub-chance count adherence in exps 1/2 where, by construction, the count winner owns f0/f2 while the option that subjects actually chose owns f1/f3.

3) Add a mixture/override component if useful: with probability lambda the decision follows the single highest-subjective-weight discriminating cue (one-reason), otherwise the weighted sum; plus a lapse epsilon. Ties in the weighted evidence -> exact coin flip, preserving the exp3 chance result.

Parameter ranges should let alpha span negative-through-positive values, keep the position profile small but non-degenerate, and keep the softmax slope high enough to reach 0.9+ adherence on dominance trials (exps 5, 6) while a lapse caps it below 1. The decisive novel prediction versus pi_4 is that adherence to the count winner can go BELOW 0.5 whenever a single subjectively-dominant cue opposes the count \u2014 exactly the pattern in exps 1 and 2 \u2014 while pi_4 remains floored at chance.

## THEORY LEADERBOARD
A small set of prior picked theories shown for reference. Overall score is in `[0, 1]`, higher = better, computed as `1 - L2_norm(normalized_per_experiment_distances) / max_L2_norm`. 1.0 means closest to the real value on every experiment+metric pair; 0.0 means farthest. Each entry below carries the same depth of detail as the PREVIOUS MODEL INSTANCE above so you can borrow concrete mechanisms when useful.

### `pi_4` (overall score: 0.842)

**Description**
**Count-Direction with Conflict-Graded Confidence (CDCC).**

When people compare two multi-attribute options described by binary expert ratings, the *direction* of their preference and the *confidence* with which they execute it are computed by two functionally separate processes.

1. **Direction is purely count-based.** The comparator registers, for each attribute, only which option is rated higher, and the option that wins on more attributes becomes the candidate response. Validities never enter this stage: they cannot promote a minority-supported option to candidate status. When the two win-counts are equal, the comparator returns no candidate at all, and the subject flips a mental coin — exactly 0.5, with **no** validity-ordered tie-break. This is a hard, parameter-free prediction: on tally-tied, side-counterbalanced profiles CDCC predicts chance adherence to the most-valid discriminating cue, regardless of any parameter setting.

2. **Confidence, not direction, carries the validity information, and it is graded by evidence dilution and by cue conflict.** The probability of actually executing the count-winner is a saturating (tanh) function of a scalar confidence signal built from three ingredients: (i) the raw win margin M = |nA − nB|; (ii) *dilution* — the margin is discounted by the total number of discriminating cues raised to a power gamma, so that a 6-vs-2 split feels much weaker than a 4-vs-0 split even though both have M = 4 (evidence spread thin across many mutually contradicting attributes is subjectively less compelling than a clean, sparse, unanimous split); and (iii) *coherence* — the signed, normalised balance of validity weight between the cues the count-winner wins and the cues the loser wins, where the subjective weight of a cue is a convex (super-linear) function of its stated validity advantage, w_j = (v_j − 0.5)^rho. Convexity means the coherence signal is dominated by the few high-validity cues: when the best cue points *with* the count the subject feels certain, when it points *against* the count the subject feels torn even though the count itself is unambiguous.

3. **Conflict erodes confidence but never reverses direction.** The confidence argument is floored at zero, so validity conflict can drive behaviour arbitrarily close to guessing but never below chance: CDCC never makes systematic one-reason (Take-The-Best) choices. This is what separates it from any Tallying+TTB mixture: on high-margin trials where the top cue opposes the tally, people move toward 0.5 from above, not past it.

4. **Lapses.** With probability epsilon the entire decision is replaced by a coin flip (attention lapse), which caps adherence below 1 even on maximally coherent trials.

The theory therefore predicts a specific cross-design signature: chance performance on tally-tied profiles; high but sub-ceiling adherence on sparse, coherent, unanimous profiles; noticeably lower adherence on dense profiles where the loser also wins several cues even when the raw margin is larger; and the lowest (but still above-chance) adherence when the most valid cue opposes the count.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np

    stim = np.asarray(state, dtype=float)
    if stim.ndim == 1:
        stim = stim.reshape(2, -1)
    if stim.ndim != 2 or stim.shape[0] != 2:
        stim = stim.reshape(2, -1)
    a = stim[0]
    b = stim[1]
    n = int(a.shape[0])

    if n == 0:
        return np.array([0.5, 0.5], dtype=float)

    a_win = a > b
    b_win = b > a
    nA = int(np.sum(a_win))
    nB = int(np.sum(b_win))
    D = nA + nB

    # --- Commitment 1: direction is purely count-based; ties -> exact guess ---
    if D == 0 or nA == nB:
        return np.array([0.5, 0.5], dtype=float)

    winner = 0 if nA > nB else 1
    M = float(abs(nA - nB))

    # --- parameters -----------------------------------------------------
    beta = float(parameters.get("beta", 2.6))
    gamma = float(parameters.get("gamma", 1.5))
    kappa = float(parameters.get("kappa", 0.7))
    rho = float(parameters.get("rho", 3.0))
    eps = float(parameters.get("epsilon", 0.10))

    beta = min(max(beta, 0.0), 20.0)
    gamma = min(max(gamma, 0.0), 3.0)
    kappa = min(max(kappa, 0.0), 5.0)
    rho = min(max(rho, 0.5), 8.0)
    eps = min(max(eps, 0.0), 0.6)

    # --- validity weights (convex in validity advantage) ------------------
    v_raw = parameters.get("validities", None)
    v = None
    if v_raw is not None:
        try:
            v = np.asarray(v_raw, dtype=float).ravel()
        except Exception:
            v = None
    if v is None or v.shape[0] != n:
        # fallback: assume features are ordered by descending validity
        v = np.linspace(0.95, 0.55, n) if n > 1 else np.array([0.75])

    w = np.clip(v - 0.5, 1e-9, None) ** rho

    if winner == 0:
        W_win = float(np.sum(w[a_win]))
        W_lose = float(np.sum(w[b_win]))
    else:
        W_win = float(np.sum(w[b_win]))
        W_lose = float(np.sum(w[a_win]))

    tot = W_win + W_lose
    C = 0.0 if tot <= 0.0 else (W_win - W_lose) / tot   # in [-1, 1]

    # --- Commitment 2: dilution-discounted margin, coherence-gated --------
    S = M / (float(D) ** gamma)
    gate = (1.0 + kappa * C) / (1.0 + kappa)             # 1.0 when fully coherent
    arg = beta * S * gate

    # --- Commitment 3: conflict erodes confidence, never reverses it ------
    if arg < 0.0:
        arg = 0.0
    if arg > 30.0:
        arg = 30.0

    conf = float(np.tanh(arg))

    # --- Commitment 4: lapse ---------------------------------------------
    p_winner = 0.5 + 0.5 * (1.0 - eps) * conf
    p_winner = float(min(max(p_winner, 0.5), 1.0 - 1e-9))

    p = np.empty(2, dtype=float)
    p[winner] = p_winner
    p[1 - winner] = 1.0 - p_winner

    p = np.clip(p, 1e-12, 1.0)
    return p / p.sum()

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    s = probs.sum()
    if not np.isfinite(s) or s <= 0:
        probs = np.ones_like(probs) / len(probs)
    else:
        probs = probs / s
    return int(np.random.choice(len(probs), p=probs))

`parameters`:
- beta: [1.6, 3.6]
- gamma: [1.25, 1.75]
- kappa: [0.4, 1.0]
- rho: [2.2, 3.8]
- epsilon: [0.02, 0.18]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.4738 (var=0.0073) vs this=0.4913 (var=0.0090)
- Experiment 2: real=0.6538 (var=0.0092) vs this=0.6469 (var=0.0093)
- Experiment 3: real=0.7937 (var=0.0071) vs this=0.7781 (var=0.0023)
- Experiment 4: real=0.7546 (var=0.0064) vs this=0.7438 (var=0.0061)
- Experiment 5: real=-0.7633 (var=0.0200) vs this=0.1438 (var=0.0077)
- Experiment 6: real=-0.9375 (var=0.0693) vs this=0.1587 (var=0.0237)


---

### `pi_2` (overall score: 0.528)

**Description**
People compare two options by counting, across all features, how often one option has a higher value than the other. The option that wins on more features is chosen. Tallying discards cardinal magnitudes — only the sign of each feature-wise comparison matters — so the heuristic is robust to monotone rescaling of individual features and cannot be swayed by a single large feature difference in the way Equal-Weight can. Ties on an individual feature contribute nothing to either count: that cue is simply treated as uninformative for the pair. No feature is privileged, in contrast to Take The Best; every cue contributes equally to the tally. When the two counts are equal the heuristic has no basis for preference and the learner must guess. Response noise enters through a softmax over the two tallies with inverse temperature beta (interpolating between fully deterministic choice at large beta and uniform guessing at beta = 0), plus an independent lapse that with probability epsilon replaces the softmax output with a uniform pick over the two options.


`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    # Paper-faithful Tallying heuristic (Dawes 1979; Gigerenzer &
    # Goldstein 1999). Stimulus is the pair of option feature vectors
    # for the current trial: array-like of shape (2, n_features),
    # with row 0 = option A, row 1 = option B. History is ignored.
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Tallying expects a (2, n_features) stimulus; got shape {stim.shape}."
        )

    a, b = stim[0], stim[1]
    # Count strict feature-wise wins; ties contribute to neither option.
    a_wins = float(np.sum(a > b))
    b_wins = float(np.sum(b > a))
    scores = np.array([a_wins, b_wins])

    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    # Softmax with max-subtraction for numerical stability. When
    # a_wins == b_wins the softmax is exactly uniform regardless of
    # beta, which is the correct behavior for an undiscriminating
    # tally.
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()

    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    probabilities = probabilities / probabilities.sum()  # Ensure valid probabilities.
    return np.random.choice(len(probabilities), p=probabilities)


`parameters`:
- beta: [0.1, 20.0]
- epsilon: [0.0, 0.5]

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.4738 (var=0.0073) vs this=0.4988 (var=0.0068)
- Experiment 2: real=0.6538 (var=0.0092) vs this=0.8525 (var=0.0139)
- Experiment 3: real=0.7937 (var=0.0071) vs this=0.8494 (var=0.0069)
- Experiment 4: real=0.7546 (var=0.0064) vs this=0.8538 (var=0.0068)
- Experiment 5: real=-0.7633 (var=0.0200) vs this=0.0062 (var=0.0039)
- Experiment 6: real=-0.9375 (var=0.0693) vs this=-0.0038 (var=0.0345)


---

### `pi_3` (overall score: 0.394)

**Description**
**Limited-Sample Noisy Cue Counting (LSNC).** People neither integrate all cues (Tallying) nor consult a single best cue (Take-The-Best). Instead, on each choice they inspect only a *limited, randomly selected subset* of the presented expert ratings, tally feature-wise wins **within that sample only**, and pick the option that is ahead in the sample; a within-sample tie (including a sample containing no discriminating cue) forces a guess.

Three commitments define the theory:
1. **Equal-probability sampling.** The inspected subset is drawn uniformly at random from the whole profile — it is *not* validity-ordered and *not* validity-weighted. Stated validities are too weakly represented to steer the search order, so no cue enjoys priority. Consequently, on globally tally-tied, side-counterbalanced profiles the process is exactly symmetric and choice is 50/50, with no tendency to follow the most valid discriminating cue.
2. **Sample-size limitation with tie dilution.** The number of cues actually inspected, K, is a random variable with mean k < n (implemented as K = 1 + Binomial(n−1, q), so at least one cue is always read). Because the subset is drawn from *all* features, non-discriminating (tied) features occupy sampling slots and dilute the evidence: two profiles with the same raw tally margin M produce different adherence depending on how many uninformative cues pad the profile, and on the proportion (not the raw count) of informative cues won. This is the signature that dissociates LSNC from softmax Tallying, whose predictions depend only on M.
3. **Encoding noise + lapse.** Each inspected feature-wise comparison is registered with the wrong sign with probability nu (attention/encoding noise), and with probability epsilon the whole decision is replaced by a coin flip.

Because a small, noisy sample can easily reverse the sign of a large global margin, adherence to the full-tally winner is *capped well below 1* even on high-margin conflict trials — the systematic attenuation that full Tallying cannot produce without degenerate temperature — while symmetry guarantees exactly chance behaviour on tally-tied pairs.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    from math import comb

    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("LSNC expects a (2, n_features) stimulus; got shape %s." % (stim.shape,))
    a, b = stim[0], stim[1]
    n = int(a.shape[0])

    nA = int(np.sum(a > b))          # cues on which A wins
    nB = int(np.sum(b > a))          # cues on which B wins
    nT = n - nA - nB                 # uninformative (tied) cues

    k = float(parameters["k"])            # mean number of cues inspected
    nu = float(parameters["nu"])          # per-comparison encoding error
    eps = float(parameters["epsilon"])    # lapse rate
    nu = float(min(max(nu, 0.0), 0.5))
    eps = float(min(max(eps, 0.0), 1.0))

    if n == 0:
        return np.ones(2) / 2.0

    # ---- distribution of the inspected sample size K in {1..n} -------------
    if n == 1:
        pK = np.array([1.0])
    else:
        q = (k - 1.0) / (n - 1.0)
        q = float(min(max(q, 0.0), 1.0))
        pK = np.array([comb(n - 1, s - 1) * (q ** (s - 1)) * ((1.0 - q) ** (n - s))
                       for s in range(1, n + 1)], dtype=float)
        tot = pK.sum()
        pK = pK / tot if tot > 0 else np.ones(n) / float(n)

    # ---- exact enumeration over sample compositions ------------------------
    pA = 0.0
    for si, s in enumerate(range(1, n + 1)):
        w = float(pK[si])
        if w <= 0.0:
            continue
        denom = float(comb(n, s))
        for ai in range(0, min(nA, s) + 1):
            for bi in range(0, min(nB, s - ai) + 1):
                ti = s - ai - bi
                if ti < 0 or ti > nT:
                    continue
                cnt = comb(nA, ai) * comb(nB, bi) * comb(nT, ti)
                if cnt == 0:
                    continue
                ph = float(cnt) / denom          # multivariate hypergeometric
                m = ai + bi                      # informative cues in sample
                if m == 0:
                    pA += w * ph * 0.5           # nothing discriminates -> guess
                    continue
                # X = number of sampled comparisons REGISTERED as A-wins
                d1 = np.array([comb(ai, x) * ((1.0 - nu) ** x) * (nu ** (ai - x))
                               for x in range(ai + 1)], dtype=float)
                d2 = np.array([comb(bi, x) * (nu ** x) * ((1.0 - nu) ** (bi - x))
                               for x in range(bi + 1)], dtype=float)
                dist = np.convolve(d1, d2)
                xs = np.arange(m + 1)
                p_win = float(dist[2 * xs > m].sum())
                p_tie = float(dist[2 * xs == m].sum())
                pA += w * ph * (p_win + 0.5 * p_tie)

    pA = float(min(max(pA, 0.0), 1.0))
    p = np.array([pA, 1.0 - pA], dtype=float)
    p = (1.0 - eps) * p + eps * 0.5
    p = np.clip(p, 1e-12, 1.0)
    return p / p.sum()

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    probs = probs / probs.sum()
    return int(np.random.choice(len(probs), p=probs))

`parameters`:
- k: [1.5, 3.5]
- nu: [0.12, 0.32]
- epsilon: [0.0, 0.12]

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.4738 (var=0.0073) vs this=0.5125 (var=0.0055)
- Experiment 2: real=0.6538 (var=0.0092) vs this=0.6669 (var=0.0098)
- Experiment 3: real=0.7937 (var=0.0071) vs this=0.6379 (var=0.0030)
- Experiment 4: real=0.7546 (var=0.0064) vs this=0.6565 (var=0.0039)
- Experiment 5: real=-0.7633 (var=0.0200) vs this=-0.0042 (var=0.0075)
- Experiment 6: real=-0.9375 (var=0.0693) vs this=-0.0675 (var=0.0417)


## LOSS TRAJECTORY (this propose-loop)
Aggregate loss across iterations of THIS propose-loop (lower = better, 0 = perfect, `+inf` = unscorable). The ACCEPTED / REJECTED tag is the loop's programmatic accept-gate decision — only ACCEPTED candidates have ever been used as the base for a subsequent iteration. Use this together with PRIOR FEEDBACK ITERATIONS below to grade which past critic advice actually paid off.

- iter 1: loss=0.1938 -> ACCEPTED
Running-best (last ACCEPTED) base: iter 1 at loss=0.1938 — this is the source shown verbatim below under `## PREVIOUS CANDIDATE (this loop)`. Push the next edit's loss strictly below that floor or the gate will reject it.

## EXPERIMENTAL RESULTS
### Experiment 1
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 1]
  A=[0, 1, 1, 0, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    validities = [0.95, 0.85, 0.75, 0.62, 0.55]
    hits = []
    for a_raw, b_raw, r in zip(data['option_a_ratings'],
                               data['option_b_ratings'],
                               data['response']):
        a = np.asarray(list(a_raw), dtype=float)
        b = np.asarray(list(b_raw), dtype=float)
        n = a.shape[0]
        if b.shape[0] != n or n == 0:
            continue
        if n == len(validities):
            v = np.asarray(validities, dtype=float)
        else:
            # fall back: assume features already ordered by descending validity
            v = np.arange(n, 0, -1).astype(float)
        order = np.argsort(-v, kind='stable')

        a_wins = float(np.sum(a > b))
        b_wins = float(np.sum(b > a))
        if a_wins != b_wins:
            continue  # only tally-tie trials

        winner = None
        for j in order:
            if a[j] > b[j]:
                winner = 0
                break
            if b[j] > a[j]:
                winner = 1
                break
        if winner is None:
            continue  # no discriminating cue at all

        try:
            resp = int(r)
        except Exception:
            continue
        hits.append(1.0 if resp == winner else 0.0)

    if len(hits) == 0:
        return 0.5
    return float(np.mean(hits))
```

**Observed (real) value:** 0.4738 (var=0.0073)
**Previous candidate values (this loop):**
  - iter 1 (most recent): 0.4919 (var=0.0071) (Δ vs real +0.0181)
**Other theories' values on this metric (for reference):**
- pi_1: 0.8988 (var=0.0090)
- pi_2: 0.4988 (var=0.0068)
- pi_3: 0.5125 (var=0.0055)
- pi_4: 0.4913 (var=0.0090)

### Experiment 2
**Design**
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[0, 0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 1, 0, 1, 1, 1]
  A=[0, 1, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 1]  B=[0, 1, 0, 1, 1, 0]
  A=[0, 1, 0, 1, 1, 0]  B=[1, 0, 1, 0, 0, 1]
  A=[1, 0, 1, 0, 1, 1]  B=[0, 1, 0, 1, 0, 0]
  A=[0, 1, 0, 1, 0, 0]  B=[1, 0, 1, 0, 1, 1]
  A=[1, 1, 1, 0, 1, 1]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[1, 1, 1, 0, 1, 1]
  A=[1, 0, 1, 1, 0, 0]  B=[1, 1, 0, 1, 1, 1]
  A=[1, 1, 0, 1, 1, 1]  B=[1, 0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    val = np.array([0.93, 0.57, 0.79, 0.86, 0.62, 0.71], dtype=float)
    hits = []
    for a_raw, b_raw, r in zip(data['option_a_ratings'],
                               data['option_b_ratings'],
                               data['response']):
        a = np.asarray(list(a_raw), dtype=float)
        b = np.asarray(list(b_raw), dtype=float)
        n = a.shape[0]
        if b.shape[0] != n or n == 0:
            continue
        if val.shape[0] == n:
            order = np.argsort(-val, kind='stable')
        else:
            order = np.arange(n)
        # tally margin (A wins minus B wins)
        margin = int(np.sum(a > b) - np.sum(b > a))
        if abs(margin) < 2:
            continue
        tally_winner = 0 if margin > 0 else 1
        # take-the-best winner
        ttb_winner = None
        for j in order:
            if a[j] > b[j]:
                ttb_winner = 0
                break
            if b[j] > a[j]:
                ttb_winner = 1
                break
        if ttb_winner is None:
            continue
        if ttb_winner == tally_winner:
            continue  # keep only conflict trials
        try:
            resp = int(r)
        except Exception:
            continue
        hits.append(1.0 if resp == tally_winner else 0.0)
    if len(hits) == 0:
        return 0.5
    return float(np.mean(hits))
```

**Observed (real) value:** 0.6538 (var=0.0092)
**Previous candidate values (this loop):**
  - iter 1 (most recent): 0.9269 (var=0.0023) (Δ vs real +0.2731)
**Other theories' values on this metric (for reference):**
- pi_2: 0.8525 (var=0.0139)
- pi_1: 0.1431 (var=0.0111)
- pi_3: 0.6669 (var=0.0098)
- pi_4: 0.6469 (var=0.0093)

### Experiment 3
**Design**
  A=[1, 1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0, 1]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0, 1]
  A=[1, 1, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 1, 1, 0, 1, 0]
  A=[1, 0, 1, 0, 1, 1]  B=[0, 0, 1, 0, 0, 1]
  A=[0, 0, 1, 0, 0, 1]  B=[1, 0, 1, 0, 1, 1]
  A=[1, 1, 1, 0, 1, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[0, 0, 0, 1, 0, 1]  B=[1, 1, 1, 0, 1, 0]
  A=[1, 1, 1, 0, 1, 1]  B=[0, 0, 1, 0, 0, 1]
  A=[0, 0, 1, 0, 0, 1]  B=[1, 1, 1, 0, 1, 1]
  A=[1, 0, 0, 1, 1, 1]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[1, 0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    hits = []
    a_col = data['option_a_ratings'].tolist()
    b_col = data['option_b_ratings'].tolist()
    r_col = data['response'].tolist()
    for a, b, r in zip(a_col, b_col, r_col):
        av = np.asarray(a, dtype=float).ravel()
        bv = np.asarray(b, dtype=float).ravel()
        if av.size == 0 or av.size != bv.size:
            continue
        nA = float(np.sum(av > bv))
        nB = float(np.sum(bv > av))
        if nA == nB:
            continue
        winner = 0 if nA > nB else 1
        try:
            resp = int(r)
        except Exception:
            continue
        hits.append(1.0 if resp == winner else 0.0)
    if len(hits) == 0:
        return float('nan')
    return float(np.mean(hits))

```

**Observed (real) value:** 0.7937 (var=0.0071)
**Previous candidate values (this loop):**
  - iter 1 (most recent): 0.8125 (var=0.0019) (Δ vs real +0.0188)
**Other theories' values on this metric (for reference):**
- pi_3: 0.6379 (var=0.0030)
- pi_2: 0.8494 (var=0.0069)
- pi_1: 0.8731 (var=0.0059)
- pi_4: 0.7781 (var=0.0023)

### Experiment 4
**Design**
  A=[1, 1, 0, 1, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 0, 1, 0]
  A=[0, 1, 0, 1, 0, 0, 1, 0]  B=[1, 1, 0, 1, 1, 0, 1, 0]
  A=[1, 1, 0, 0, 1, 1, 0, 1]  B=[0, 0, 1, 0, 1, 1, 0, 0]
  A=[0, 0, 1, 0, 1, 1, 0, 0]  B=[1, 1, 0, 0, 1, 1, 0, 1]
  A=[1, 1, 1, 0, 0, 0, 1, 1]  B=[0, 0, 0, 1, 1, 1, 0, 0]
  A=[0, 0, 0, 1, 1, 1, 0, 0]  B=[1, 1, 1, 0, 0, 0, 1, 1]
  A=[1, 0, 1, 0, 1, 1, 1, 1]  B=[0, 0, 1, 0, 0, 0, 0, 1]
  A=[0, 0, 1, 0, 0, 0, 0, 1]  B=[1, 0, 1, 0, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 0, 1, 0]  B=[0, 0, 1, 0, 0, 1, 0, 0]
  A=[0, 0, 1, 0, 0, 1, 0, 0]  B=[1, 1, 1, 1, 1, 0, 1, 0]
  A=[1, 1, 1, 0, 1, 1, 0, 1]  B=[0, 0, 0, 1, 0, 0, 1, 0]
  A=[0, 0, 0, 1, 0, 0, 1, 0]  B=[1, 1, 1, 0, 1, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Adherence to the full-profile tally winner.

    For every trial we recompute the global feature-wise win counts
    nA = #(A > B) and nB = #(B > A) over ALL features, identify the
    option favoured by the complete tally, and score whether the subject
    chose it. The returned scalar is the proportion of such trials on
    which the subject followed the complete-tally winner.

    Works identically on the pooled DataFrame and on a single subject's
    slice.
    """
    a_col = data['option_a_ratings'].tolist()
    b_col = data['option_b_ratings'].tolist()
    r_col = data['response'].tolist()

    hits = []
    for a_raw, b_raw, r in zip(a_col, b_col, r_col):
        a = np.asarray(a_raw, dtype=float).ravel()
        b = np.asarray(b_raw, dtype=float).ravel()
        if a.shape[0] != b.shape[0] or a.shape[0] == 0:
            continue
        nA = float(np.sum(a > b))
        nB = float(np.sum(b > a))
        if nA == nB:
            continue  # undiagnostic (no complete-tally winner)
        winner = 0 if nA > nB else 1
        try:
            resp = int(r)
        except (TypeError, ValueError):
            continue
        if resp not in (0, 1):
            continue
        hits.append(1.0 if resp == winner else 0.0)

    if len(hits) == 0:
        return float('nan')
    return float(np.mean(hits))
```

**Observed (real) value:** 0.7546 (var=0.0064)
**Previous candidate values (this loop):**
  - iter 1 (most recent): 0.8919 (var=0.0014) (Δ vs real +0.1373)
**Other theories' values on this metric (for reference):**
- pi_2: 0.8538 (var=0.0068)
- pi_3: 0.6565 (var=0.0039)
- pi_1: 0.8571 (var=0.0084)
- pi_4: 0.7438 (var=0.0061)

### Experiment 5
**Design**
  A=[1, 0, 1, 1, 0, 1]  B=[0, 1, 0, 1, 0, 1]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 0, 1, 1, 0, 1]
  A=[0, 1, 0, 1, 1, 0]  B=[1, 0, 0, 0, 1, 0]
  A=[1, 0, 0, 0, 1, 0]  B=[0, 1, 0, 1, 1, 0]
  A=[1, 0, 1, 0, 1, 1]  B=[0, 1, 0, 0, 1, 0]
  A=[0, 1, 0, 0, 1, 0]  B=[1, 0, 1, 0, 1, 1]
  A=[0, 1, 1, 1, 1, 0]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 1, 1, 1, 0]
  A=[1, 0, 1, 0, 1, 1]  B=[0, 1, 0, 1, 0, 0]
  A=[0, 1, 0, 1, 0, 0]  B=[1, 0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 1, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    validities = np.array([0.94, 0.57, 0.86, 0.62, 0.70, 0.78], dtype=float)

    coh_hit = 0.0
    coh_n = 0.0
    con_hit = 0.0
    con_n = 0.0

    for a_raw, b_raw, resp in zip(data['option_a_ratings'],
                                  data['option_b_ratings'],
                                  data['response']):
        a = np.asarray(list(a_raw), dtype=float)
        b = np.asarray(list(b_raw), dtype=float)
        n = a.shape[0]
        if n == 0:
            continue
        if validities.shape[0] == n:
            v = validities
        else:
            v = np.linspace(0.95, 0.55, n) if n > 1 else np.array([0.75])

        a_win = a > b
        b_win = b > a
        nA = int(a_win.sum())
        nB = int(b_win.sum())
        if nA == nB:
            continue  # no count winner; excluded
        winner = 0 if nA > nB else 1

        disc = a_win | b_win
        if not disc.any():
            continue
        # highest-validity discriminating cue
        idx = int(np.argmax(np.where(disc, v, -np.inf)))
        top_owner = 0 if a_win[idx] else 1
        coherent = (top_owner == winner)

        try:
            r = int(resp)
        except Exception:
            continue
        hit = 1.0 if r == winner else 0.0

        if coherent:
            coh_hit += hit
            coh_n += 1.0
        else:
            con_hit += hit
            con_n += 1.0

    if coh_n == 0.0 or con_n == 0.0:
        return 0.0
    return float(coh_hit / coh_n - con_hit / con_n)

```

**Observed (real) value:** -0.7633 (var=0.0200)
**Previous candidate values (this loop):**
  - iter 1 (most recent): -0.7850 (var=0.0052) (Δ vs real -0.0217)
**Other theories' values on this metric (for reference):**
- pi_3: -0.0042 (var=0.0075)
- pi_4: 0.1438 (var=0.0077)
- pi_1: 0.6683 (var=0.0558)
- pi_2: 0.0062 (var=0.0039)

### Experiment 6
**Design**
  A=[1, 1, 1, 0, 1, 0, 0]  B=[0, 1, 0, 0, 1, 0, 1]
  A=[0, 1, 0, 0, 1, 0, 1]  B=[1, 1, 1, 0, 1, 0, 0]
  A=[0, 1, 1, 0, 0, 1, 1]  B=[1, 0, 1, 0, 0, 1, 0]
  A=[1, 0, 1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0, 1, 1]
  A=[1, 0, 1, 0, 1, 1, 1]  B=[0, 1, 0, 1, 0, 0, 1]
  A=[0, 1, 0, 1, 0, 0, 1]  B=[1, 0, 1, 0, 1, 1, 1]
  A=[0, 1, 0, 1, 1, 0, 1]  B=[1, 0, 1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0, 0]  B=[0, 1, 0, 1, 1, 0, 1]
  A=[1, 0, 1, 1, 1, 0, 1]  B=[1, 0, 0, 1, 0, 0, 1]
  A=[1, 0, 0, 1, 0, 0, 1]  B=[1, 0, 1, 1, 1, 0, 1]
  A=[1, 1, 1, 1, 0, 1, 1]  B=[0, 1, 1, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    V = np.array([0.94, 0.58, 0.86, 0.63, 0.72, 0.80, 0.55], dtype=float)

    coh_hit = 0.0; coh_n = 0
    con_hit = 0.0; con_n = 0
    us_hit = 0.0; us_n = 0
    ud_hit = 0.0; ud_n = 0

    a_col = data['option_a_ratings'].tolist()
    b_col = data['option_b_ratings'].tolist()
    r_col = data['response'].tolist()

    for a_raw, b_raw, resp in zip(a_col, b_col, r_col):
        try:
            a = np.asarray(a_raw, dtype=float).ravel()
            b = np.asarray(b_raw, dtype=float).ravel()
        except Exception:
            continue
        n = int(a.size)
        if n == 0 or int(b.size) != n:
            continue
        if n == int(V.size):
            w = V - 0.5
        elif n > 1:
            w = np.linspace(0.95, 0.55, n) - 0.5
        else:
            w = np.array([0.25])

        aw = a > b
        bw = b > a
        nA = int(np.sum(aw))
        nB = int(np.sum(bw))
        if nA == nB:
            continue
        winner = 0 if nA > nB else 1
        try:
            r = int(resp)
        except Exception:
            continue
        if r not in (0, 1):
            continue
        hit = 1.0 if r == winner else 0.0
        D = nA + nB
        if winner == 0:
            Ww = float(np.sum(w[aw])); Wl = float(np.sum(w[bw])); n_lose = nB
        else:
            Ww = float(np.sum(w[bw])); Wl = float(np.sum(w[aw])); n_lose = nA

        if n_lose == 0:
            # unanimous profiles: sparse (few discriminating cues) vs dense
            if D <= 2:
                us_hit += hit; us_n += 1
            else:
                ud_hit += hit; ud_n += 1
        else:
            if Ww > Wl:
                coh_hit += hit; coh_n += 1
            elif Ww < Wl:
                con_hit += hit; con_n += 1

    if coh_n > 0 and con_n > 0:
        d1 = coh_hit / coh_n - con_hit / con_n
    else:
        d1 = 0.0
    if us_n > 0 and ud_n > 0:
        d2 = us_hit / us_n - ud_hit / ud_n
    else:
        d2 = 0.0

    return float(d1 + d2)

```

**Observed (real) value:** -0.9375 (var=0.0693)
**Previous candidate values (this loop):**
  - iter 1 (most recent): -0.7819 (var=0.0169) (Δ vs real +0.1556)
**Other theories' values on this metric (for reference):**
- pi_4: 0.1587 (var=0.0237)
- pi_3: -0.0675 (var=0.0417)
- pi_1: 0.7206 (var=0.0361)
- pi_2: -0.0038 (var=0.0345)

## PREVIOUS CANDIDATE (this loop)
The RUNNING-BEST (last ACCEPTED) candidate in this critique loop — i.e. the source the loop's accept gate kept as the best base so far. If your most recent attempt was REJECTED by the gate, this is NOT that attempt; it is the previously-accepted base the gate rolled back to. Iterate on this source — the next critic feedback should be applied on top of it.

**Description**
**Redundancy-Discounted Tiered Integration (RDTI).**

When people are told how accurate each expert is, they do *not* convert those numbers into graded Bayesian cue weights. Two things happen instead, and together they can make choice run *against* both the feature count and the nominally most valid cue.

1. **Coarse credibility tiering (no graded map).** Stated validities are encoded only ordinally and only coarsely: the cue set is split at the median of the stated validities into a "star" tier (the top ⌊n/2⌋ experts) and a "marginal" tier (the rest). Fine gradations *within* a tier are not represented at all — a 0.95 expert and a 0.85 expert are simply both "the good ones".

2. **Redundancy discounting — the diagnosticity inversion.** The star experts are construed as merely re-reporting the obvious/consensus quality of the product ("if he is right 94% of the time he is just telling me what the quality is, which I can read off everything else"). Their ratings are therefore treated as *redundant* and enter the integration with only a small residual weight ε. The marginal experts, by contrast, are construed as idiosyncratic sources whose ratings carry distinctive, non-redundant information, and they get full weight. This is a mis-application of a normally adaptive policy — in natural environments the most valid cue is usually the one most redundant with the rest, so "look where the sources disagree with the obvious" is often useful — but here it inverts the objective diagnosticity ordering in a *step-like*, not graded, way.

3. **Additive integration with mild spread discounting.** The subject sums the tier-weighted signed feature differences, E = Σ_j w_j (a_j − b_j) with w_j ∈ {ε, 1}, and discounts the result by how thinly the evidence is spread over mutually contradicting cues (division by D^δ, D = number of discriminating cues). Choice is logistic in this scalar, plus an attention lapse.

4. **Exact indifference is possible and produces exact chance.** Because the weights take only two values, profiles in which the two options' supporting cues are *tier-matched* (e.g. each option supported by one star cue and one marginal cue) yield E = 0 exactly, and the subject flips a coin — there is no validity tie-break, no take-the-best fallback.

Signature predictions that separate RDTI from every count-based account: (i) **sub-chance** adherence to the feature-count winner whenever the winner's support is concentrated in the star tier while the loser's support lies in the marginal tier — the count and the most-valid cue lose *together*; (ii) **exactly chance** on tally-tied profiles whose supporting cues are tier-balanced, irrespective of how the validities are ordered; (iii) **high but sub-ceiling** adherence on unanimous or tier-coherent profiles, with sparse unanimous profiles slightly *less* compelling than dense ones when the sparse profile's discriminating cues happen to be star-tier (discounted) cues.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np

    # ---------- parse the stimulus into two rating vectors ----------
    a = None
    b = None
    try:
        if isinstance(state, dict):
            if 'option_a_ratings' in state and 'option_b_ratings' in state:
                a = np.asarray(list(state['option_a_ratings']), dtype=float).ravel()
                b = np.asarray(list(state['option_b_ratings']), dtype=float).ravel()
    except Exception:
        a = None
        b = None

    if a is None or b is None:
        stim = np.asarray(state, dtype=float)
        if stim.ndim == 1:
            stim = stim.reshape(2, -1)
        elif stim.ndim > 2:
            stim = stim.reshape(2, -1)
        if stim.shape[0] != 2:
            stim = stim.reshape(2, -1)
        a = np.asarray(stim[0], dtype=float).ravel()
        b = np.asarray(stim[1], dtype=float).ravel()

    n = int(a.shape[0])
    if n == 0 or int(b.shape[0]) != n:
        return np.array([0.5, 0.5], dtype=float)

    # ---------- parameters ----------
    def _get(name, default):
        try:
            return float(parameters.get(name, default))
        except Exception:
            return float(default)

    eps_w = _get('eps_w', 0.13)     # residual weight of the "star" (redundant) tier
    beta = _get('beta', 3.8)        # logistic slope
    delta = _get('delta', 0.10)     # evidence-spread discount exponent
    lapse = _get('lapse', 0.13)     # attention lapse

    eps_w = float(min(max(eps_w, 0.0), 1.0))
    beta = float(min(max(beta, 0.0), 20.0))
    delta = float(min(max(delta, -1.0), 2.0))
    lapse = float(min(max(lapse, 0.0), 0.6))

    # ---------- stated validities ----------
    v = None
    v_raw = parameters.get('validities', None) if hasattr(parameters, 'get') else None
    if v_raw is not None:
        try:
            v = np.asarray(v_raw, dtype=float).ravel()
        except Exception:
            v = None
    if v is None or v.shape[0] != n:
        # fallback: assume the display order is descending in validity
        v = np.linspace(0.95, 0.55, n) if n > 1 else np.array([0.75], dtype=float)

    # ---------- coarse credibility tiering + redundancy discount ----------
    k = int(n // 2)                                  # size of the "star" tier
    order = np.argsort(-v, kind='stable')            # most valid first
    w = np.ones(n, dtype=float)
    if k > 0:
        w[order[:k]] = eps_w                         # star tier == treated as redundant

    # ---------- tier-weighted additive evidence ----------
    diff = np.sign(a - b)                            # +1 A wins, -1 B wins, 0 tie
    D = int(np.sum(diff != 0))
    if D == 0:
        return np.array([0.5, 0.5], dtype=float)

    E = float(np.sum(w * diff))

    # spread discount: evidence thinly spread over many contradicting cues feels weaker
    denom = float(D) ** delta
    if not np.isfinite(denom) or denom <= 0.0:
        denom = 1.0
    z = beta * E / denom

    if z > 30.0:
        z = 30.0
    elif z < -30.0:
        z = -30.0

    p_a = 1.0 / (1.0 + np.exp(-z))

    # ---------- lapse ----------
    p_a = (1.0 - lapse) * p_a + lapse * 0.5
    p_a = float(min(max(p_a, 1e-9), 1.0 - 1e-9))

    p = np.array([p_a, 1.0 - p_a], dtype=float)
    p = np.clip(p, 1e-12, 1.0)
    return p / p.sum()

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    s = probs.sum()
    if not np.isfinite(s) or s <= 0:
        probs = np.ones_like(probs) / float(len(probs))
    else:
        probs = probs / s
    return int(np.random.choice(len(probs), p=probs))

`parameters`:
- eps_w: [0.05, 0.22]
- beta: [3.0, 5.0]
- delta: [-0.10, 0.25]
- lapse: [0.08, 0.20]
- validities: validities

`rationale`: **Why the incumbents fail.** pi_2/pi_3/pi_4 all make the count direction (or an unbiased sample of it) the only source of *direction*; validity can erode confidence but never reverse it, so adherence is floored at 0.5. Experiments 5 and 6 are exactly the cases where the humans go *below* the floor (−0.76 and −0.94 on coherent-minus-conflict), and this is why pi_4 (score 0.842) is off by ~0.9 and ~1.1 there while fitting exps 1–4 almost perfectly. Any fix must add a mechanism that can flip direction.

**What the data actually say.** I reverse-engineered the choices implied by the exp-5/exp-6 metrics. In every discriminating trial of exp 5 and exp 6 the option the subjects chose is the one that *loses* the highest-validity cue (and wins the low-validity cues): the count winner and the most valid cue lose together. So the subjective weights are not merely uninformed by validity — they are *inverted*. But exp 1 rules out a smoothly inverted weighting: there, on the tally-tied pairs {f0} vs {f1} and {f0,f2} vs {f1,f3}, behaviour is exactly at chance (0.474), which a graded anti-validity weight function cannot produce (it would predict clearly sub-chance). The reconciliation is a **step (tier) weight function**: with only two weight levels split at the validity median, exp 1's two tie profiles are tier-matched ({star} vs {star} and {star,marginal} vs {star,marginal}), giving evidence exactly zero → exact chance; whereas in exps 5 and 6 the count winner's support is concentrated in the star tier and the loser's in the marginal tier, giving strongly reversed evidence. That single, parameter-free structural fact is what the tiering buys.

**Quantitative check (hand-computed at the range midpoints, ε=0.14, β=3.8, δ=0.1, lapse=0.13):** exp 1 = 0.500 (real 0.474, both tie profiles cancel exactly); exp 3 ≈ 0.82 (real 0.794); exp 4 ≈ 0.81 (real 0.755); exp 5 ≈ −0.76 (real −0.763, coherent cells ≈ 0.12, conflict cells ≈ 0.99); exp 6 ≈ −0.80 (real −0.9375, with a small negative sparse-vs-dense unanimous term arising naturally because exp 6's sparse unanimous profile discriminates on a *star-tier* cue). Exp 2 is the one deliberate sacrifice (≈0.93 vs 0.654): its two metric trials are structurally identical to exp 5's conflict trials (one star cue against two marginal cues plus discounted extras) yet show much weaker tally adherence, so no monotone evidence model can satisfy both; I optimise the lapse to split the difference, which trades a ~0.28 error on exp 2 for ~0.85 and ~1.05 improvements on exps 5 and 6.

**Why this is the family the arbiter asked for, done right.** It implements weighted (not counted) evidence whose weights are only loosely — here negatively and step-wise — bound to the stated validities, so adherence to the count winner can fall well below 0.5 (exps 5, 6); ties in the weighted evidence give an exact coin flip (exp 1, exp 3-style symmetric profiles); a spread/dilution discount keeps dense conflict profiles sub-ceiling; and a lapse caps performance below 1 on dominance trials. Unlike the arbiter's exact sketch, I do not use a standardized-validity exponential weight or a serial-position profile: I verified that a graded weight in validity cannot simultaneously produce exp 1's exact chance and exp 5's near-total reversal (the required weight function is self-contradictory), while a position profile cannot be transported across n = 5, 6, 7, 8. The median-split tier weight is the minimal mechanism that does both and is fully experiment-invariant — it reads only `validities` and `n_features` and adapts to any feature count.

## PRIOR FEEDBACK ITERATIONS
The critic's verdicts on each previous in-loop candidate, in order. Each block ends with an **Outcome of this advice** line saying whether the candidate the proposer produced AFTER this advice was ACCEPTED (loss strictly beat the running best) or REJECTED (the gate discarded it). Address the most recent iteration's feedback in your next edit, but down-weight past advice whose candidates were REJECTED.

### Iteration 1 (most recent — address this)
Verdict: regenerate
Interpretation: RDTI is a genuine breakthrough on the two experiments that broke every incumbent: exp5 (-0.785 vs real -0.763) and exp6 (-0.782 vs real -0.938) are the first sub-chance, direction-reversing predictions in this loop, and they come from a structural fact (median-split tier weights with the high-validity tier discounted) rather than from a hand-tuned free parameter. Exp1 (0.492 vs 0.474) and exp3 (0.813 vs 0.794) are essentially exact, and the exact-tie-\u2192-coin-flip property does the work the arbiter asked for. The candidate is faithful to the prescribed family: weighted (not counted) evidence, weights only loosely/perversely bound to stated validities, logistic + lapse, exact indifference \u2192 chance. So the family question is settled; what remains is calibration.

The residuals are systematic and all point the same way: the model is too confident on DENSE, high-margin profiles. Exp2 = 0.927 vs 0.654 (error 0.27, the largest in the set) \u2014 its two retained trial-types are the fully-mirrored D=5 pair and the D=4 pair, exactly where marginal-tier cues pile up unopposed and z saturates. Exp4 = 0.892 vs 0.755 (error 0.14) \u2014 again n=8 profiles with D up to 8. Meanwhile exp6 is not extreme ENOUGH (-0.78 vs -0.94), i.e. the sparse/low-D contrasts need MORE separation, not less. A uniform lapse increase or beta decrease therefore cannot fix exp2/exp4 without further damaging exp6; the error is dimensioned by evidence density, which the current delta (division of E by D^delta, delta\u2208[-0.1,0.25]) is far too weak to capture because the logistic has already saturated by the time the discount bites.

Second systematic miss: between-subject variance is 3\u20134x too small everywhere (exp2 0.0023 vs 0.0092; exp4 0.0014 vs 0.0064; exp5 0.0052 vs 0.0200; exp6 0.0169 vs 0.0693). Human subjects are far more heterogeneous than the current narrow parameter ranges allow.
Rationale: The candidate was ACCEPTED and should be the base \u2014 keep the RDTI mechanism exactly as is (median-split star/marginal tiers, epsilon-discounted star tier, additive tier-weighted evidence, exact-zero \u2192 coin flip, logistic + lapse). Do NOT change family and do NOT abandon the tiering; the exp1/exp3/exp5 fits are earned by it. Three minor, in-family adjustments:

1) Make the softening density-dependent instead of uniform. The single biggest residual (exp2, +0.27; exp4, +0.14) comes from dense mirrored profiles where the logistic saturates. Replace/augment the weak D^delta discount with a dilution lapse that grows with the number of discriminating cues, e.g. lapse_eff = lapse0 + kappa * max(0, D - 2) / max(1, n - 2), with kappa \u2208 [0.0, 0.45] and lapse0 \u2208 [0.03, 0.15]. This pulls exp2's D=5/D=4 conflict trials and exp4's D=6\u20138 trials down toward 0.65\u20130.78 while leaving exp5's D=3 trials (which carry the -0.76 reversal) and exp1's exact ties untouched.

2) Compensate on the sharp end so exp6 gets MORE extreme, not less. With the dilution lapse absorbing the dense trials, you can raise beta (range ~[4, 8]) and lower base lapse; this should push exp6 from -0.78 toward -0.94 via a cleaner sparse-star-cue (discounted, near-chance) vs dense-unanimous (near-ceiling) contrast, and keep exp5 near -0.76 to -0.80.

3) Widen the ranges to generate realistic between-subject spread. Current simulated per-subject variance is 3\u20134x too low on exps 2, 4, 5, 6. Widen eps_w to roughly [0.02, 0.40] (a minority of subjects who barely discount the star tier), beta to [3, 8], lapse0 to [0.03, 0.22]. A little mass at high eps_w also nudges exp2/exp4 downward for free, since those subjects follow the star cue against the tally.

Guardrails: exp1 must stay at ~0.47\u20130.50 (the tier-matched cancellation must remain exact \u2014 do not add a validity tie-break or take-the-best fallback, which would push exp1 up toward 0.57+), and exp3 must stay near 0.79. Target profile: exp1 ~0.48, exp2 0.68\u20130.75, exp3 ~0.79, exp4 ~0.78, exp5 ~-0.77, exp6 ~-0.90.

**Outcome of this advice:** iter 1 candidate loss=0.1938 -> next candidate accept-status=PENDING (this is the advice you are addressing now).


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
{
  "theory": "**Redundancy-Discounted Tiered Integration with Majority Discounting (RDTI-M).**\n\nThe core claim of RDTI is retained unchanged: stated validities are encoded only *coarsely and ordinally* (a median split into a \"star\" tier and a \"marginal\" tier, with no gradations inside a tier), and the star tier is treated as **redundant** — the very accurate experts are construed as merely restating the obvious consensus quality of the product, so their ratings enter the integration with only a small residual weight \u03b5, while the idiosyncratic marginal experts get full weight. Evidence is the tier-weighted signed sum E = \u03a3_j w_j (a_j \u2212 b_j), w_j \u2208 {\u03b5, 1}, mildly discounted for how thinly it is spread over mutually contradicting cues (D^\u03b4), and choice is logistic in that scalar plus an attention lapse. Because the weights take only two values, tier-matched profiles cancel *exactly* and give an exact coin flip, with no validity tie-break and no take-the-best fallback.\n\nThe single new commitment is that the **same redundancy logic is applied one level up, to the majority itself**. A feature-count majority is the most \"obvious\" statistic in the display: if most experts already agree, that agreement is exactly the consensus signal the subject has decided is uninformative-because-redundant. Subjects therefore apply a *contrarian consensus discount*: the logit is shifted away from the count winner in proportion to the count margin, \u2212b\u00b7(nA \u2212 nB). Each additional majority cue adds one more increment of \"this is just the obvious answer\", so the discount grows with the margin, not merely with its sign.\n\nThis yields four signatures. (i) On tally-tied profiles the margin is zero and, if the supporting cues are tier-matched, E is exactly zero too: choice is exactly chance, irrespective of how the validities are ordered. (ii) On profiles where the count winner's support sits in the star tier and the loser's in the marginal tier, the tier discount and the majority discount *add*, producing strongly **sub-chance** adherence to the count winner \u2014 the count and the most valid cue lose together, and they lose harder the bigger the count margin. (iii) On dense, high-margin profiles where the tier-weighted evidence agrees with the count, the majority discount subtracts most (margin is large), so adherence saturates well below ceiling even though the raw evidence is overwhelming. (iv) Sparse unanimous profiles whose discriminating cues are star-tier cues are *less* compelling than dense unanimous ones, but the margin-scaled discount partly offsets this, keeping the sparse-minus-dense contrast small and negative.",
  "predict": "def predict(parameters, state, history):\n    import numpy as np\n\n    # ---------- parse the stimulus into two rating vectors ----------\n    a = None\n    b = None\n    try:\n        if isinstance(state, dict):\n            if 'option_a_ratings' in state and 'option_b_ratings' in state:\n                a = np.asarray(list(state['option_a_ratings']), dtype=float).ravel()\n                b = np.asarray(list(state['option_b_ratings']), dtype=float).ravel()\n    except Exception:\n        a = None\n        b = None\n\n    if a is None or b is None:\n        stim = np.asarray(state, dtype=float)\n        if stim.ndim == 1:\n            stim = stim.reshape(2, -1)\n        elif stim.ndim > 2:\n            stim = stim.reshape(2, -1)\n        if stim.shape[0] != 2:\n            stim = stim.reshape(2, -1)\n        a = np.asarray(stim[0], dtype=float).ravel()\n        b = np.asarray(stim[1], dtype=float).ravel()\n\n    n = int(a.shape[0])\n    if n == 0 or int(b.shape[0]) != n:\n        return np.array([0.5, 0.5], dtype=float)\n\n    # ---------- parameters ----------\n    def _get(name, default):\n        try:\n            return float(parameters.get(name, default))\n        except Exception:\n            return float(default)\n\n    eps_w = _get('eps_w', 0.17)          # residual weight of the \"star\" (redundant) tier\n    beta = _get('beta', 3.3)             # logistic slope\n    delta = _get('delta', 0.075)         # evidence-spread discount exponent\n    lapse = _get('lapse', 0.135)         # attention lapse\n    count_bias = _get('count_bias', 0.285)  # contrarian consensus (majority) discount\n\n    eps_w = float(min(max(eps_w, 0.0), 1.0))\n    beta = float(min(max(beta, 0.0), 20.0))\n    delta = float(min(max(delta, -1.0), 2.0))\n    lapse = float(min(max(lapse, 0.0), 0.6))\n    count_bias = float(min(max(count_bias, 0.0), 1.5))\n\n    # ---------- stated validities ----------\n    v = None\n    v_raw = parameters.get('validities', None) if hasattr(parameters, 'get') else None\n    if v_raw is not None:\n        try:\n            v = np.asarray(v_raw, dtype=float).ravel()\n        except Exception:\n            v = None\n    if v is None or v.shape[0] != n:\n        # fallback: assume the display order is descending in validity\n        v = np.linspace(0.95, 0.55, n) if n > 1 else np.array([0.75], dtype=float)\n\n    # ---------- coarse credibility tiering + redundancy discount ----------\n    k = int(n // 2)                                  # size of the \"star\" tier\n    order = np.argsort(-v, kind='stable')            # most valid first\n    w = np.ones(n, dtype=float)\n    if k > 0:\n        w[order[:k]] = eps_w                         # star tier == treated as redundant\n\n    # ---------- tier-weighted additive evidence ----------\n    diff = np.sign(a - b)                            # +1 A wins, -1 B wins, 0 tie\n    D = int(np.sum(diff != 0))\n    if D == 0:\n        return np.array([0.5, 0.5], dtype=float)\n\n    E = float(np.sum(w * diff))\n\n    # spread discount: evidence thinly spread over many contradicting cues feels weaker\n    denom = float(D) ** delta\n    if not np.isfinite(denom) or denom <= 0.0:\n        denom = 1.0\n    z = beta * E / denom\n\n    # ---------- contrarian consensus (majority-redundancy) discount ----------\n    # the feature-count majority is the \"obvious\" signal; it is discounted in\n    # proportion to how large it is, shifting choice toward the count loser.\n    nA = int(np.sum(diff > 0))\n    nB = int(np.sum(diff < 0))\n    margin = float(np.clip(nA - nB, -6, 6))\n    z = z - count_bias * margin\n\n    if z > 30.0:\n        z = 30.0\n    elif z < -30.0:\n        z = -30.0\n\n    p_a = 1.0 / (1.0 + np.exp(-z))\n\n    # ---------- lapse ----------\n    p_a = (1.0 - lapse) * p_a + lapse * 0.5\n    p_a = float(min(max(p_a, 1e-9), 1.0 - 1e-9))\n\n    p = np.array([p_a, 1.0 - p_a], dtype=float)\n    p = np.clip(p, 1e-12, 1.0)\n    return p / p.sum()",
  "policy": "def policy(probs):\n    import numpy as np\n    probs = np.asarray(probs, dtype=np.float64)\n    probs = np.clip(probs, 0.0, None)\n    s = probs.sum()\n    if not np.isfinite(s) or s <= 0:\n        probs = np.ones_like(probs) / float(len(probs))\n    else:\n        probs = probs / s\n    return int(np.random.choice(len(probs), p=probs))",
  "parameters": {
    "eps_w": "[0.04, 0.30]",
    "beta": "[2.4, 4.2]",
    "delta": "[-0.10, 0.25]",
    "lapse": "[0.06, 0.21]",
    "count_bias": "[0.12, 0.45]",
    "validities": "validities"
  },
  "rationale": "**Minimal edit.** The RDTI base is re-emitted verbatim except for four lines in `predict` (compute nA, nB, margin; subtract `count_bias * margin` from the logit) plus widened parameter ranges. Mechanism family, tiering, exact-zero-\u2192-coin-flip and lapse are untouched, so the earned exp1/exp3/exp5 fits are preserved.\n\n**Why I did NOT implement the critic's literal suggestion (D-dependent dilution lapse).** I hand-computed it. The dense trials that need softening in exp2 (D=5, D=4) and exp4 (D=6\u20138) are *not* separable by D from the trials that carry exp5's and exp6's reversal: exp5's coherent cells include D=4 and D=6 profiles and exp6's conflict cells are D=6. With lapse_eff = lapse0 + \u03ba(D\u22122)/(n\u22122), \u03ba=0.45, exp5 degrades from \u22120.785 to \u22120.57 and exp6 from \u22120.78 to \u22120.62 \u2014 losing far more than the ~0.06/0.07 gained on exp2/exp4. Raising \u03b2 to compensate cannot recover it, because the coherent cells' |E| (\u22480.5\u20130.7) is *smaller* than the conflict cells' (\u22482\u20133), so any density-blind sharpening helps the wrong cell first.\n\n**The margin-scaled consensus discount does the same job with the right selectivity.** It is subtractive in the direction of the count winner, so (i) on count-aligned dense/high-margin trials (all of exp4, both retained exp2 trial types, exp3's strong trials) it *reduces* adherence, exactly where the model was over-confident; (ii) on exp5/exp6 coherent cells, where the tier-weighted evidence already opposes the count, it *adds* to the reversal, pushing those cells from ~0.17 to ~0.15 and making the reversal robust even for subjects with large \u03b5 (where E alone would nearly cancel); (iii) on exp6's dense unanimous profile (M=4) it subtracts twice as much as on the sparse one (M=2), sharpening the negative d2 term; (iv) on exp1's tally-tied metric trials M=0 *and* E=0 by tier-matching, so the exact-chance guardrail (0.47\u20130.50) is untouched by construction. Hand-computed midpoint predictions: exp1 0.49 (real 0.474), exp2 0.93 (0.654), exp3 0.792 (0.794), exp4 \u22480.87 (0.755), exp5 \u22120.77 (\u22120.763), exp6 \u22120.81 (\u22120.938) \u2014 an RMS improvement over the accepted base on every experiment except exp2, which is provably unreachable in this family (its two retained trial types are structurally identical to exp5's conflict trials \u2014 one 0.93/0.94 star cue against 2\u20133 marginal cues \u2014 yet the humans show 0.65 there and ~0.9 in exp5, so no monotone evidence model can satisfy both; I keep the compromise the accepted base already struck).\n\n**Theoretical gain, not just fit.** The new term is not a free knob bolted on: it is the *same* redundancy principle the theory already applies to high-validity experts, applied to the majority statistic. That makes the theory more experiment-invariant in the sense that matters here \u2014 sub-chance adherence to the count winner is now produced by two independent, mutually reinforcing discounts rather than by a delicate cancellation of \u03b5 against 1.\n\n**Variance.** Per the critic, ranges are widened (\u03b5 0.04\u20130.30, \u03b2 2.4\u20134.2, lapse 0.06\u20130.21, bias 0.12\u20130.45). At \u03b5\u22480.30 a minority of subjects barely discount the star tier and are nearly count-following on 3-vs-1 profiles, while at \u03b5\u22480.04 subjects are near-total reversers; combined with the \u03b2/lapse spread this should lift the between-subject variance on exps 2, 4, 5, 6 toward the observed 0.009\u20130.07 without moving the pooled point estimates, since the widening is symmetric about the midpoints used above."
}
```

## Usage

```json
{
  "input_tokens": 26053,
  "output_tokens": 59262
}
```
