# improvement_iter_03_attempt_00

## System Prompt

You are a renowned cognitive scientist and an expert Python programmer.

Your job is to propose a NEW model instantiation of an EXISTING theory, given arbiter feedback on the previous instantiation. The theory's prose claim is fixed — you are NOT redefining the theory. You are regenerating only the runnable bits: the `predict` function, the `policy` function, and the `parameters` ranges. The newly proposed model should display human-like behavior when simulated on experiments in the Decision Making (Binary Features) domain.

The goal of the model improvement process is to SURFACE theories that are EXPERIMENT-INVARIANT: that is,theories that explain data across multiple experiments. 
If your model fails to compile or behaves badly, you may receive feedback and have to propose another instantiation. Iterate until accepted.

If you think the failure to capture human behavior is due to arbiter feedback that is inaccurate or unhelpful, you can propose a new model instance that ignores the feedback, but you must provide rationale for why you are ignoring it and how your proposal overcomes the identified mechanistic failures.

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

## ROUND THEORIES
The arbiter compared the two theories below this round. Your job is to regenerate ONLY the runnable bits (`predict`, `policy`, `parameters`) of the one tagged **TO REVISE**, keeping its description verbatim. The other theory is shown for context — it is NOT being changed.

### THEORY 1 — `pi_6` (other theory — context only, NOT revised)

**Description:**
People choose between two products through a stable, subject-level mixture of three routes: a weak forward lexicographic scan, a moderate backward/recency lexicographic scan, and feature-win tallying. Choice is modulated by a context-sensitive amplification of a higher-precision backward lexicographic route. The decision maker monitors the trailing 24-trial frequency of fully diagnostic, near-tied-tally comparisons, ignores isolated occurrences via a minimum qualifying count, and maps the qualifying fraction through a band-limited trapezoidal sensitivity curve. Moderate densities of such trials produce the strongest backward amplification, which generates the strong negative top-cue effects seen in dense complementary designs; very high densities attenuate to a lower floor, protecting all-complementary blocks from over-reversal. Sparse designs that never contain fully diagnostic near-tied trials keep the trigger at exactly zero, so their behavior stays governed by the pi_4-like baseline mixture, preserving the near-zero active-inactive contrasts in those experiments.

**Model instance (shown for context):**

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np

    stim = np.asarray(state, dtype=float)
    if stim.ndim == 3 and stim.shape[0] == 1:
        stim = stim[0]
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f'Expected a (2, n_features) stimulus, got {stim.shape}.')

    a = stim[0]
    b = stim[1]
    n = int(stim.shape[1])

    validities = parameters.get('validities')
    if validities is None:
        validities = list(np.linspace(0.9, 0.5, n))
    validities = np.asarray(validities, dtype=float)
    if validities.ndim == 0 or validities.shape[0] != n:
        validities = np.linspace(0.9, 0.5, n)

    descending = np.argsort(-validities, kind='stable')
    ascending = np.argsort(validities, kind='stable')

    def lex_probabilities(order, beta):
        winner = None
        for j in order:
            if a[j] > b[j]:
                winner = 0
                break
            if b[j] > a[j]:
                winner = 1
                break
        if winner is None:
            return np.full(2, 0.5, dtype=float)
        z = float(beta) if winner == 0 else -float(beta)
        p_a = 1.0 / (1.0 + np.exp(-z))
        return np.array([p_a, 1.0 - p_a], dtype=float)

    tie_margin = float(parameters['tie_margin'])

    def complementarity_signal(x, y):
        x = np.asarray(x, dtype=float)
        y = np.asarray(y, dtype=float)
        d = x - y
        n_discrim = int(np.sum(d != 0.0))
        tally = float(np.sum(d > 0.0) - np.sum(d < 0.0))
        return 1.0 if (n_discrim >= n and abs(tally) <= tie_margin) else 0.0

    signals = []
    past_a = history.get('option_a_ratings', [])
    past_b = history.get('option_b_ratings', [])
    n_past = min(len(past_a), len(past_b))
    for i in range(n_past):
        signals.append(complementarity_signal(past_a[i], past_b[i]))
    signals.append(complementarity_signal(a, b))

    context_window = int(parameters['context_window'])
    if len(signals) > context_window:
        signals = signals[-context_window:]

    n_recent = max(1, len(signals))
    n_qual = float(np.sum(signals))
    frac = n_qual / n_recent

    min_count = int(parameters['min_qualifying_count'])
    rise_start = float(parameters['rise_start_frac'])
    peak_start = float(parameters['peak_start_frac'])
    peak_end = float(parameters['peak_end_frac'])
    fall_end = float(parameters['fall_end_frac'])
    s_max = float(parameters['s_max'])
    s_floor = min(float(parameters['s_floor']), s_max)

    if n_qual < min_count:
        s = 0.0
    else:
        if frac <= rise_start:
            s = 0.0
        elif frac <= peak_start:
            s = s_max * (frac - rise_start) / (peak_start - rise_start + 1e-9)
        elif frac <= peak_end:
            s = s_max
        elif frac <= fall_end:
            s = s_max - (s_max - s_floor) * (frac - peak_end) / (fall_end - peak_end + 1e-9)
        else:
            s = s_floor
    s = float(np.clip(s, 0.0, 1.0))

    beta_forward = float(parameters['beta_forward'])
    beta_backward = float(parameters['beta_backward'])
    beta_backward_strong = float(parameters['beta_backward_strong'])

    p_forward = lex_probabilities(descending, beta_forward)
    p_backward = lex_probabilities(ascending, beta_backward)
    p_backward_strong = lex_probabilities(ascending, beta_backward_strong)

    a_wins = float(np.sum(a > b))
    b_wins = float(np.sum(b > a))
    tally_scores = np.array([a_wins, b_wins], dtype=float)
    beta_tally = float(parameters['beta_tally'])
    z = beta_tally * (tally_scores - np.max(tally_scores))
    e = np.exp(z)
    p_tally = e / np.sum(e)

    w_forward = float(parameters['w_forward'])
    w_backward = float(parameters['w_backward'])
    w_tally = 1.0 - w_forward - w_backward
    if w_tally < 0.0:
        w_tally = 0.0
    weights = np.array([w_forward, w_backward, w_tally], dtype=float)
    weights = weights / np.sum(weights)

    p_base = weights[0] * p_forward + weights[1] * p_backward + weights[2] * p_tally
    p = (1.0 - s) * p_base + s * p_backward_strong
    p = np.clip(p, 0.0, None)
    return p / np.sum(p)


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=float)
    if probs.size == 0:
        return 0
    probs = probs / probs.sum()
    return int(np.random.choice(probs.size, p=probs))


`parameters`:
- w_forward: [0.22, 0.32]
- w_backward: [0.42, 0.54]
- beta_forward: [0.08, 0.20]
- beta_backward: [1.30, 1.70]
- beta_tally: [1.80, 2.60]
- beta_backward_strong: [2.50, 4.00]
- context_window: {24}
- tie_margin: [2.0, 3.0]
- min_qualifying_count: {2, 3}
- rise_start_frac: [0.03, 0.06]
- peak_start_frac: [0.08, 0.14]
- peak_end_frac: [0.26, 0.34]
- fall_end_frac: [0.40, 0.48]
- s_max: [0.84, 0.92]
- s_floor: [0.40, 0.50]
- validities: validities

---

### THEORY 2 — `pi_7_2` **TO REVISE**

**Description (PRESERVE VERBATIM — do not rewrite the prose):**
People choose between two products through a baseline mixture of a weak forward lexicographic scan, a moderate lowest-validity-first lexicographic scan, and feature-win tallying. Decision makers continuously accumulate local evidence about cue reliability from recent discriminating trials. Evidence is graded by discrimination density: near-tied trials with only a few discriminating features contribute little or nothing, while dense five-of-six or fully discriminating trials drive a leaky accumulator. The accumulator has asymmetric rise and decay, a minimum qualifying count, hysteresis, and smooth activation of a strengthened lowest-validity-first route. When fully discriminating trials dominate the local evidence stream, the reversed route is gently capped below its maximum so strongly complementary designs reverse strongly but not excessively. When dense conflict is sparse, evidence decays back to baseline mixture weights, preserving near-zero active-inactive contrasts in sparse designs.

**Previous model instance — REGENERATE `predict`, `policy`, and `parameters` ranges:**

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np

    stim = np.asarray(state, dtype=float)
    if stim.ndim == 3 and stim.shape[0] == 1:
        stim = stim[0]
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError('Expected a (2, n_features) stimulus.')

    a = stim[0]
    b = stim[1]
    n_features = int(stim.shape[1])

    validities = parameters.get('validities')
    if validities is None:
        validities = list(np.linspace(0.9, 0.5, n_features))
    validities = np.asarray(validities, dtype=float)
    if validities.ndim == 0 or validities.shape[0] != n_features:
        validities = np.linspace(0.9, 0.5, n_features)

    descending = np.argsort(-validities, kind='stable')
    ascending = np.argsort(validities, kind='stable')

    def lex_probabilities(x, y, order, beta):
        winner = None
        for j in order:
            if x[j] > y[j]:
                winner = 0
                break
            if y[j] > x[j]:
                winner = 1
                break
        if winner is None:
            return np.full(2, 0.5, dtype=float)
        z = float(beta) if winner == 0 else -float(beta)
        p_a = 1.0 / (1.0 + np.exp(-z))
        return np.array([p_a, 1.0 - p_a], dtype=float)

    beta_forward = float(parameters['beta_forward'])
    beta_backward = float(parameters['beta_backward'])
    beta_backward_strong = float(parameters['beta_backward_strong'])
    beta_tally = float(parameters['beta_tally'])

    p_forward = lex_probabilities(a, b, descending, beta_forward)
    p_backward = lex_probabilities(a, b, ascending, beta_backward)
    p_shift = lex_probabilities(a, b, ascending, beta_backward_strong)

    a_wins = float(np.sum(a > b))
    b_wins = float(np.sum(b > a))
    tally_scores = np.array([a_wins, b_wins], dtype=float)
    z = beta_tally * (tally_scores - np.max(tally_scores))
    e = np.exp(z)
    p_tally = e / np.sum(e)

    w_forward = float(parameters['w_forward'])
    w_backward = float(parameters['w_backward'])
    w_tally = 1.0 - w_forward - w_backward
    if w_tally < 0.0:
        w_tally = 0.0
    weights = np.array([w_forward, w_backward, w_tally], dtype=float)
    weights = weights / np.sum(weights)
    p_base = weights[0] * p_forward + weights[1] * p_backward + weights[2] * p_tally

    tie_margin = float(parameters['tie_margin'])
    hi_idx = int(descending[0])
    lo_idx = int(ascending[0])

    if n_features == 6:
        min_discrim_count = 5
    elif n_features == 5:
        min_discrim_count = 4
    else:
        min_discrim_count = int(np.ceil(0.75 * max(1, n_features)))

    base_evidence = float(parameters['base_evidence'])
    hi_lo_bonus = float(parameters['hi_lo_bonus'])
    near_full_evidence_scale = float(parameters['near_full_evidence_scale'])
    opposing_evidence_scale = float(parameters['opposing_evidence_scale'])

    def trial_evidence(x, y):
        x = np.asarray(x, dtype=float)
        y = np.asarray(y, dtype=float)
        d = x - y
        n_discrim = int(np.sum(d != 0.0))
        if n_discrim < min_discrim_count:
            return 0.0
        tally = float(np.sum(d))
        hi_dir = int(np.sign(d[hi_idx]))
        lo_dir = int(np.sign(d[lo_idx]))
        if hi_dir == 0 or lo_dir == 0 or hi_dir == lo_dir:
            return 0.0

        # Narrow special branch for six-feature 5-of-6 trials where the
        # highest and lowest cues disagree but the tally mildly opposes the
        # highest cue (e.g. E17 target patterns).  Exclude strong opposition
        # such as E1 patterns with tally +-3.
        if (n_features == 6 and n_discrim == 5 and abs(tally) <= 2.0
                and tally * hi_dir < 0.0):
            return float(min(1.0, opposing_evidence_scale * (base_evidence + hi_lo_bonus)))

        if abs(tally) > tie_margin:
            return 0.0
        if tally * hi_dir < 0.0:
            return 0.0

        if n_discrim == n_features:
            density_gain = 1.0
        else:
            density_gain = near_full_evidence_scale
        return float(min(1.0, (base_evidence + hi_lo_bonus) * density_gain))

    evidence_seq = []
    full_flags = []
    past_a = history.get('option_a_ratings', [])
    past_b = history.get('option_b_ratings', [])
    n_past = min(len(past_a), len(past_b))
    for i in range(n_past):
        x = np.asarray(past_a[i], dtype=float)
        y = np.asarray(past_b[i], dtype=float)
        evidence_seq.append(trial_evidence(x, y))
        full_flags.append(1.0 if np.all((x - y) != 0.0) else 0.0)
    evidence_seq.append(trial_evidence(a, b))
    full_flags.append(1.0 if np.all((a - b) != 0.0) else 0.0)

    evidence_rise = float(parameters['evidence_rise'])
    evidence_decay = float(parameters['evidence_decay'])
    zero_decay_boost = float(parameters['zero_decay_boost'])
    threshold = float(parameters['conflict_threshold'])
    saturation = float(parameters['saturation_evidence'])
    hysteresis = float(parameters['hysteresis'])
    activation_rise = float(parameters['activation_rise'])
    activation_decay = float(parameters['activation_decay'])
    min_qual = int(parameters['min_qualifying_count'])
    qualifying_window = int(parameters['qualifying_window'])
    full_frac_window = int(parameters['full_frac_window'])
    s_max = float(parameters['s_max'])
    full_penalty_start = float(parameters['full_penalty_start'])
    full_penalty_depth = float(parameters['full_penalty_depth'])
    full_penalty_width = float(parameters['full_penalty_width'])
    full_penalty_floor = float(parameters['full_penalty_floor'])

    X = 0.0
    S = 0.0

    for idx, u in enumerate(evidence_seq):
        if u >= X:
            X += evidence_rise * (u - X)
        else:
            decay_mult = zero_decay_boost if u <= 0.0 else 1.0
            X -= evidence_decay * decay_mult * (X - u)
        X = float(np.clip(X, 0.0, 1.0))

        q_start = max(0, idx - qualifying_window + 1)
        recent_q = np.asarray(evidence_seq[q_start:idx + 1], dtype=float)
        n_recent_qual = int(np.sum(recent_q > 0.0))

        f_start = max(0, idx - full_frac_window + 1)
        recent_flags = np.asarray(full_flags[f_start:idx + 1], dtype=float)
        window_len = idx - f_start + 1
        full_frac = float(np.sum(recent_flags > 0.5)) / max(1, window_len)

        center = full_penalty_start + full_penalty_width
        if full_frac <= full_penalty_start:
            full_penalty = 0.0
        elif full_frac <= center:
            full_penalty = full_penalty_depth * (full_frac - full_penalty_start) / full_penalty_width
        else:
            fall_end = center + full_penalty_width
            if full_frac >= fall_end:
                full_penalty = full_penalty_floor
            else:
                full_penalty = full_penalty_depth - (full_penalty_depth - full_penalty_floor) * (full_frac - center) / full_penalty_width
        full_penalty = float(np.clip(full_penalty, 0.0, 1.0))
        s_max_eff = s_max * (1.0 - full_penalty)

        if n_recent_qual < min_qual:
            target = 0.0
        else:
            threshold_eff = threshold - hysteresis if S > 0.5 else threshold
            if X <= threshold_eff:
                target = 0.0
            elif X >= saturation:
                target = s_max_eff
            else:
                target = s_max_eff * ((X - threshold_eff) / (saturation - threshold_eff + 1e-9))

        target = float(np.clip(target, 0.0, max(s_max_eff, 1e-9)))
        if target > S:
            S += activation_rise * (target - S)
        else:
            S -= activation_decay * (S - target)
        S = float(np.clip(S, 0.0, s_max_eff))

    s = float(np.clip(S, 0.0, s_max))
    p = (1.0 - s) * p_base + s * p_shift

    epsilon = float(parameters.get('epsilon', 0.0))
    if epsilon > 0.0:
        p = (1.0 - epsilon) * p + epsilon * np.full(2, 0.5, dtype=float)

    p = np.clip(p, 0.0, None)
    return p / np.sum(p)


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=float)
    if probs.size == 0:
        return 0
    probs = probs / probs.sum()
    return int(np.random.choice(probs.size, p=probs))


`parameters`:
- w_forward: [0.24, 0.32]
- w_backward: [0.40, 0.48]
- beta_forward: [0.12, 0.20]
- beta_backward: [1.30, 1.55]
- beta_tally: [2.00, 2.50]
- beta_backward_strong: [3.00, 3.40]
- tie_margin: {3}
- base_evidence: [0.60, 0.72]
- hi_lo_bonus: [0.20, 0.32]
- near_full_evidence_scale: [0.82, 0.90]
- opposing_evidence_scale: [0.20, 0.35]
- evidence_rise: [0.30, 0.42]
- evidence_decay: [0.06, 0.12]
- zero_decay_boost: [1.40, 2.40]
- conflict_threshold: [0.03, 0.05]
- saturation_evidence: [0.22, 0.32]
- hysteresis: [0.02, 0.05]
- activation_rise: [0.20, 0.30]
- activation_decay: [0.04, 0.08]
- min_qualifying_count: {3, 4}
- qualifying_window: {16}
- full_frac_window: {16}
- s_max: [0.80, 0.88]
- full_penalty_start: [0.28, 0.40]
- full_penalty_depth: [0.38, 0.50]
- full_penalty_width: [0.12, 0.20]
- full_penalty_floor: [0.20, 0.30]
- epsilon: {0}
- validities: validities


## ARBITER GUIDE
The arbiter labelled this round's two theories in its recommendation as follows:
- THEORY 1 = `pi_6`
- THEORY 2 = `pi_7_2`
- The recommendation below acts on THEORY 2 (= `pi_7_2`).

Keep the pi_7_2 theory description and regenerate its predict function and parameter ranges. First, replace the hard zero for fully discriminating trials whose tally opposes the highest cue with a graded positive contribution, e.g. evidence = min(1.0, opposing_full_evidence_scale * (base_evidence + hi_lo_bonus)) with opposing_full_evidence_scale around 0.30-0.65, so E1 moves from about 0.75 toward the observed 0.823 without reaching pi_6's excessive 0.90. Second, weaken the existing special 5-of-6 opposing branch by lowering opposing_evidence_scale to roughly 0.25-0.50 or capping its output below aligned-evidence saturation, bringing E19 down from about 0.67 toward 0.55-0.60. Third, relax the full-diagnostic penalty slightly, e.g. lower full_penalty_depth or full_penalty_floor and/or raise s_max modestly, to lift the low-cue agreement in E15/E16 from about 0.81 toward the observed 0.84 while keeping E7/E8 near -0.66 to -0.67. Fourth, widen subject-level ranges for evidence_rise, evidence_decay, threshold, s_max, beta_backward_strong, and the mixture weights so between-subject variance better matches the observed values, especially E1 var 0.0143 and E2 var 0.0460 versus simulated variances near 0.002-0.005. Preserve the hysteresis, minimum qualifying count, activation rise/decay, and cap logic that already produce near-zero sparse-design contrasts and the small E17 dynamic effect.

## THEORY LEADERBOARD
A small set of prior picked theories shown for reference. Overall score is in `[0, 1]`, higher = better, computed as `1 - L2_norm(normalized_per_experiment_distances) / max_L2_norm`. 1.0 means closest to the real value on every experiment+metric pair; 0.0 means farthest. Each entry below carries the same depth of detail as the PREVIOUS MODEL INSTANCE above so you can borrow concrete mechanisms when useful.

### `pi_7` (overall score: 0.861)

**Description**
People choose between two products through a baseline mixture of a weak forward lexicographic scan, a moderate lowest-validity-first lexicographic scan, and feature-win tallying. Decision makers continuously accumulate local evidence about cue reliability from recent discriminating trials. Evidence is graded by discrimination density: near-tied trials with only a few discriminating features contribute little or nothing, while dense five-of-six or fully discriminating trials drive a leaky accumulator. The accumulator has asymmetric rise and decay, a minimum qualifying count, hysteresis, and smooth activation of a strengthened lowest-validity-first route. When fully discriminating trials dominate the local evidence stream, the reversed route is gently capped below its maximum so strongly complementary designs reverse strongly but not excessively. When dense conflict is sparse, evidence decays back to baseline mixture weights, preserving near-zero active-inactive contrasts in sparse designs.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np

    stim = np.asarray(state, dtype=float)
    if stim.ndim == 3 and stim.shape[0] == 1:
        stim = stim[0]
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError('Expected a (2, n_features) stimulus.')

    a = stim[0]
    b = stim[1]
    n_features = int(stim.shape[1])

    validities = parameters.get('validities')
    if validities is None:
        validities = list(np.linspace(0.9, 0.5, n_features))
    validities = np.asarray(validities, dtype=float)
    if validities.ndim == 0 or validities.shape[0] != n_features:
        validities = np.linspace(0.9, 0.5, n_features)

    descending = np.argsort(-validities, kind='stable')
    ascending = np.argsort(validities, kind='stable')

    def lex_probabilities(x, y, order, beta):
        winner = None
        for j in order:
            if x[j] > y[j]:
                winner = 0
                break
            if y[j] > x[j]:
                winner = 1
                break
        if winner is None:
            return np.full(2, 0.5, dtype=float)
        z = float(beta) if winner == 0 else -float(beta)
        p_a = 1.0 / (1.0 + np.exp(-z))
        return np.array([p_a, 1.0 - p_a], dtype=float)

    beta_forward = float(parameters['beta_forward'])
    beta_backward = float(parameters['beta_backward'])
    beta_backward_strong = float(parameters['beta_backward_strong'])
    beta_tally = float(parameters['beta_tally'])

    p_forward = lex_probabilities(a, b, descending, beta_forward)
    p_backward = lex_probabilities(a, b, ascending, beta_backward)
    p_shift = lex_probabilities(a, b, ascending, beta_backward_strong)

    a_wins = float(np.sum(a > b))
    b_wins = float(np.sum(b > a))
    tally_scores = np.array([a_wins, b_wins], dtype=float)
    z = beta_tally * (tally_scores - np.max(tally_scores))
    e = np.exp(z)
    p_tally = e / np.sum(e)

    w_forward = float(parameters['w_forward'])
    w_backward = float(parameters['w_backward'])
    w_tally = 1.0 - w_forward - w_backward
    if w_tally < 0.0:
        w_tally = 0.0
    weights = np.array([w_forward, w_backward, w_tally], dtype=float)
    weights = weights / np.sum(weights)
    p_base = weights[0] * p_forward + weights[1] * p_backward + weights[2] * p_tally

    tie_margin = float(parameters['tie_margin'])
    hi_lo_bonus = float(parameters['hi_lo_bonus'])
    base_evidence = float(parameters['base_evidence'])
    tied_top_evidence = float(parameters['tied_top_evidence'])
    density_floor = float(parameters['density_floor'])
    hi_idx = int(descending[0])
    lo_idx = int(ascending[0])

    def trial_evidence(x, y):
        x = np.asarray(x, dtype=float)
        y = np.asarray(y, dtype=float)
        d = x - y
        n_discrim = int(np.sum(d != 0.0))
        density = n_discrim / max(1, n_features)
        tally = float(np.sum(d))
        near = 1.0 if abs(tally) <= tie_margin else 0.0
        if near <= 0.0 or density <= density_floor:
            return 0.0

        density_gain = (density - density_floor) / (1.0 - density_floor)
        hi_dir = np.sign(d[hi_idx])
        lo_dir = np.sign(d[lo_idx])
        disagree = 1.0 if (hi_dir != 0.0 and lo_dir != 0.0 and hi_dir == -lo_dir) else 0.0

        if hi_dir == 0.0:
            base = tied_top_evidence
        else:
            base = base_evidence + hi_lo_bonus * disagree

        return float(min(1.0, base * density_gain))

    evidence_seq = []
    full_flags = []
    past_a = history.get('option_a_ratings', [])
    past_b = history.get('option_b_ratings', [])
    n_past = min(len(past_a), len(past_b))
    for i in range(n_past):
        x = np.asarray(past_a[i], dtype=float)
        y = np.asarray(past_b[i], dtype=float)
        evidence_seq.append(trial_evidence(x, y))
        full_flags.append(1.0 if np.all((x - y) != 0.0) else 0.0)
    evidence_seq.append(trial_evidence(a, b))
    full_flags.append(1.0 if np.all((a - b) != 0.0) else 0.0)

    evidence_rise = float(parameters['evidence_rise'])
    evidence_decay = float(parameters['evidence_decay'])
    zero_decay_boost = float(parameters['zero_decay_boost'])
    threshold = float(parameters['conflict_threshold'])
    hysteresis = float(parameters['hysteresis'])
    activation_rise = float(parameters['activation_rise'])
    activation_decay = float(parameters['activation_decay'])
    min_qual = int(parameters['min_qualifying_count'])
    s_max = float(parameters['s_max'])
    full_penalty_threshold = float(parameters['full_penalty_threshold'])
    full_penalty_depth = float(parameters['full_penalty_depth'])

    X = 0.0
    S = 0.0
    n_seen = 0
    for idx, u in enumerate(evidence_seq):
        if u >= X:
            X += evidence_rise * (u - X)
        else:
            decay_mult = zero_decay_boost if u <= 0.0 else 1.0
            X -= evidence_decay * decay_mult * (X - u)

        if u > 0.0:
            n_seen += 1

        n_evidence = 0
        n_full = 0
        for k in range(idx + 1):
            if evidence_seq[k] > 0.0:
                n_evidence += 1
                if full_flags[k] > 0.5:
                    n_full += 1
        full_frac = (n_full / max(1, n_evidence)) if n_evidence > 0 else 0.0

        if full_frac > full_penalty_threshold:
            full_penalty = full_penalty_depth * ((full_frac - full_penalty_threshold) / (1.0 - full_penalty_threshold + 1e-9))
        else:
            full_penalty = 0.0
        s_max_eff = s_max * (1.0 - full_penalty)

        if n_seen < min_qual:
            target = 0.0
        else:
            threshold_eff = threshold - hysteresis if S > 0.5 else threshold
            target = s_max_eff if X >= threshold_eff else 0.0

        if target > S:
            S += activation_rise * (target - S)
        else:
            S -= activation_decay * (S - target)

    s = float(np.clip(S, 0.0, s_max))
    p = (1.0 - s) * p_base + s * p_shift

    epsilon = float(parameters['epsilon'])
    if epsilon > 0.0:
        p = (1.0 - epsilon) * p + epsilon * np.full(2, 0.5, dtype=float)

    p = np.clip(p, 0.0, None)
    return p / np.sum(p)


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=float)
    if probs.size == 0:
        return 0
    probs = probs / probs.sum()
    return int(np.random.choice(probs.size, p=probs))


`parameters`:
- w_forward: [0.22, 0.32]
- w_backward: [0.42, 0.54]
- beta_forward: [0.08, 0.20]
- beta_backward: [1.30, 1.70]
- beta_tally: [1.80, 2.60]
- beta_backward_strong: [2.40, 4.00]
- tie_margin: [2.0, 3.0]
- hi_lo_bonus: [0.30, 0.55]
- base_evidence: [0.62, 0.78]
- tied_top_evidence: [0.50, 0.72]
- density_floor: {0.80}
- evidence_rise: [0.22, 0.42]
- evidence_decay: [0.02, 0.12]
- zero_decay_boost: [1.20, 2.50]
- conflict_threshold: [0.03, 0.05]
- hysteresis: [0.02, 0.05]
- activation_rise: [0.08, 0.30]
- activation_decay: [0.01, 0.08]
- min_qualifying_count: {2, 3}
- s_max: [0.75, 0.85]
- full_penalty_threshold: [0.85, 0.95]
- full_penalty_depth: [0.10, 0.18]
- epsilon: [0.0, 0.02]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.2487 (var=0.0065) vs this=0.2331 (var=0.0017)
- Experiment 2: real=0.4196 (var=0.0128) vs this=0.4373 (var=0.0096)
- Experiment 3: real=-0.1300 (var=0.0159) vs this=-0.1158 (var=0.0055)
- Experiment 4: real=-0.2742 (var=0.0069) vs this=-0.2704 (var=0.0106)
- Experiment 5: real=-0.6583 (var=0.0598) vs this=-0.6529 (var=0.0087)
- Experiment 6: real=-0.6711 (var=0.0489) vs this=-0.5633 (var=0.0084)
- Experiment 7: real=0.1553 (var=0.0159) vs this=0.1667 (var=0.0021)
- Experiment 8: real=0.0150 (var=0.0027) vs this=0.0208 (var=0.0062)
- Experiment 9: real=-0.0283 (var=0.0032) vs this=-0.0013 (var=0.0043)
- Experiment 10: real=-0.0008 (var=0.0091) vs this=-0.0071 (var=0.0128)
- Experiment 11: real=-0.0050 (var=0.0198) vs this=0.0408 (var=0.0280)
- Experiment 12: real=-0.0178 (var=0.0089) vs this=-0.0200 (var=0.0134)
- Experiment 13: real=0.8425 (var=0.0101) vs this=0.7425 (var=0.0023)
- Experiment 14: real=0.8413 (var=0.0122) vs this=0.8350 (var=0.0017)
- Experiment 15: real=0.0553 (var=0.0224) vs this=0.0339 (var=0.0118)
- Experiment 16: real=0.6412 (var=0.0315) vs this=0.7974 (var=0.0100)
- Experiment 17: real=0.5710 (var=0.0228) vs this=0.7837 (var=0.0089)
- Experiment 18: real=0.6942 (var=0.0025) vs this=0.6952 (var=0.0018)
- Experiment 19: real=0.8229 (var=0.0143) vs this=0.8817 (var=0.0013)
- Experiment 20: real=0.7500 (var=0.0460) vs this=0.1779 (var=0.0155)


---

### `pi_7_1` (overall score: 0.808)

**Description**
People choose between two products through a baseline mixture of a weak forward lexicographic scan, a moderate lowest-validity-first lexicographic scan, and feature-win tallying. Decision makers continuously accumulate local evidence about cue reliability from recent discriminating trials. Evidence is graded by discrimination density: near-tied trials with only a few discriminating features contribute little or nothing, while dense five-of-six or fully discriminating trials drive a leaky accumulator. The accumulator has asymmetric rise and decay, a minimum qualifying count, hysteresis, and smooth activation of a strengthened lowest-validity-first route. When fully discriminating trials dominate the local evidence stream, the reversed route is gently capped below its maximum so strongly complementary designs reverse strongly but not excessively. When dense conflict is sparse, evidence decays back to baseline mixture weights, preserving near-zero active-inactive contrasts in sparse designs.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np

    stim = np.asarray(state, dtype=float)
    if stim.ndim == 3 and stim.shape[0] == 1:
        stim = stim[0]
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError('Expected a (2, n_features) stimulus.')

    a = stim[0]
    b = stim[1]
    n_features = int(stim.shape[1])

    validities = parameters.get('validities')
    if validities is None:
        validities = list(np.linspace(0.9, 0.5, n_features))
    validities = np.asarray(validities, dtype=float)
    if validities.ndim == 0 or validities.shape[0] != n_features:
        validities = np.linspace(0.9, 0.5, n_features)

    descending = np.argsort(-validities, kind='stable')
    ascending = np.argsort(validities, kind='stable')

    def lex_probabilities(x, y, order, beta):
        winner = None
        for j in order:
            if x[j] > y[j]:
                winner = 0
                break
            if y[j] > x[j]:
                winner = 1
                break
        if winner is None:
            return np.full(2, 0.5, dtype=float)
        z = float(beta) if winner == 0 else -float(beta)
        p_a = 1.0 / (1.0 + np.exp(-z))
        return np.array([p_a, 1.0 - p_a], dtype=float)

    beta_forward = float(parameters['beta_forward'])
    beta_backward = float(parameters['beta_backward'])
    beta_backward_strong = float(parameters['beta_backward_strong'])
    beta_tally = float(parameters['beta_tally'])

    p_forward = lex_probabilities(a, b, descending, beta_forward)
    p_backward = lex_probabilities(a, b, ascending, beta_backward)
    p_shift = lex_probabilities(a, b, ascending, beta_backward_strong)

    a_wins = float(np.sum(a > b))
    b_wins = float(np.sum(b > a))
    tally_scores = np.array([a_wins, b_wins], dtype=float)
    z = beta_tally * (tally_scores - np.max(tally_scores))
    e = np.exp(z)
    p_tally = e / np.sum(e)

    w_forward = float(parameters['w_forward'])
    w_backward = float(parameters['w_backward'])
    w_tally = 1.0 - w_forward - w_backward
    if w_tally < 0.0:
        w_tally = 0.0
    weights = np.array([w_forward, w_backward, w_tally], dtype=float)
    weights = weights / np.sum(weights)
    p_base = weights[0] * p_forward + weights[1] * p_backward + weights[2] * p_tally

    tie_margin = float(parameters['tie_margin'])
    hi_lo_bonus = float(parameters['hi_lo_bonus'])
    base_evidence = float(parameters['base_evidence'])
    tied_top_evidence = float(parameters['tied_top_evidence'])
    density_floor = float(parameters['density_floor'])
    near_full_boost = float(parameters['near_full_boost'])
    top_tied_tally_min = float(parameters['top_tied_tally_min'])
    top_tied_bonus = float(parameters['top_tied_bonus'])
    hi_idx = int(descending[0])
    lo_idx = int(ascending[0])

    def trial_evidence(x, y):
        x = np.asarray(x, dtype=float)
        y = np.asarray(y, dtype=float)
        d = x - y
        n_discrim = int(np.sum(d != 0.0))
        density = n_discrim / max(1, n_features)
        tally = float(np.sum(d))
        near = 1.0 if abs(tally) <= tie_margin else 0.0
        full = 1.0 if n_discrim >= n_features else 0.0
        if near <= 0.0:
            return 0.0

        hi_dir = np.sign(d[hi_idx])
        lo_dir = np.sign(d[lo_idx])
        disagree = 1.0 if (hi_dir != 0.0 and lo_dir != 0.0 and hi_dir == -lo_dir) else 0.0
        tally_align = 1.0 if (hi_dir == 0.0 or float(tally) * hi_dir >= 0.0) else 0.0

        if full > 0.5:
            density_gain = 1.0
            if hi_dir == 0.0:
                base = tied_top_evidence
            else:
                base = base_evidence + hi_lo_bonus * disagree
            return float(min(1.0, base * density_gain))

        # Non-full branch: top-tied fallback is narrowly gated by tally
        # magnitude so marginal top-tied sparse conflicts (e.g. E11) stay blocked,
        # while E13-style dense top-tied 5/6 conflicts can still emit evidence.
        if hi_dir == 0.0:
            fallback_hi_dir = 0.0
            for j in descending:
                if d[j] != 0.0:
                    fallback_hi_dir = float(np.sign(d[j]))
                    break
            if fallback_hi_dir == 0.0:
                return 0.0
            if abs(tally) < top_tied_tally_min:
                return 0.0
            disagree_t = 1.0 if (lo_dir != 0.0 and fallback_hi_dir != 0.0 and fallback_hi_dir == -lo_dir) else 0.0
            tally_align_t = 1.0 if (fallback_hi_dir != 0.0 and float(tally) * fallback_hi_dir >= 0.0) else 0.0
            if density <= density_floor or disagree_t <= 0.0 or tally_align_t <= 0.0:
                return 0.0
            density_gain = float(np.sqrt(max(0.0, (density - density_floor) / (1.0 - density_floor + 1e-9))))
            density_gain *= near_full_boost
            base = base_evidence + hi_lo_bonus + top_tied_bonus
            return float(min(1.0, base * density_gain))

        if density <= density_floor or disagree <= 0.0 or tally_align <= 0.0:
            return 0.0
        density_gain = float(np.sqrt(max(0.0, (density - density_floor) / (1.0 - density_floor + 1e-9))))
        density_gain *= near_full_boost
        base = base_evidence + hi_lo_bonus * disagree
        return float(min(1.0, base * density_gain))

    evidence_seq = []
    full_flags = []
    past_a = history.get('option_a_ratings', [])
    past_b = history.get('option_b_ratings', [])
    n_past = min(len(past_a), len(past_b))
    for i in range(n_past):
        x = np.asarray(past_a[i], dtype=float)
        y = np.asarray(past_b[i], dtype=float)
        evidence_seq.append(trial_evidence(x, y))
        full_flags.append(1.0 if np.all((x - y) != 0.0) else 0.0)
    evidence_seq.append(trial_evidence(a, b))
    full_flags.append(1.0 if np.all((a - b) != 0.0) else 0.0)

    evidence_rise = float(parameters['evidence_rise'])
    evidence_decay = float(parameters['evidence_decay'])
    zero_decay_boost = float(parameters['zero_decay_boost'])
    threshold = float(parameters['conflict_threshold'])
    saturation = float(parameters['saturation_evidence'])
    hysteresis = float(parameters['hysteresis'])
    activation_rise = float(parameters['activation_rise'])
    activation_decay = float(parameters['activation_decay'])
    min_qual = int(parameters['min_qualifying_count'])
    qualifying_window = int(parameters['qualifying_window'])
    full_frac_window = int(parameters['full_frac_window'])
    s_max = float(parameters['s_max'])
    full_penalty_center = float(parameters['full_penalty_threshold'])
    full_penalty_depth = float(parameters['full_penalty_depth'])
    full_penalty_width = float(parameters['full_penalty_width'])
    full_penalty_floor = float(parameters['full_penalty_floor'])

    X = 0.0
    S = 0.0

    for idx, u in enumerate(evidence_seq):
        if u >= X:
            X += evidence_rise * (u - X)
        else:
            decay_mult = zero_decay_boost if u <= 0.0 else 1.0
            X -= evidence_decay * decay_mult * (X - u)
        X = float(np.clip(X, 0.0, 1.0))

        q_start = max(0, idx - qualifying_window + 1)
        recent_q = np.asarray(evidence_seq[q_start:idx + 1], dtype=float)
        n_recent_qual = int(np.sum(recent_q > 0.0))

        f_start = max(0, idx - full_frac_window + 1)
        recent_flags = np.asarray(full_flags[f_start:idx + 1], dtype=float)
        window_len = idx - f_start + 1
        n_full = int(np.sum(recent_flags > 0.5))
        full_frac = n_full / max(1, window_len)

        width = max(full_penalty_width, 1e-9)
        rise_start = full_penalty_center - width
        fall_end = full_penalty_center + width
        if full_frac <= rise_start:
            full_penalty = 0.0
        elif full_frac < full_penalty_center:
            full_penalty = full_penalty_depth * max(0.0, (full_frac - rise_start)) / width
        elif full_frac < fall_end:
            full_penalty = full_penalty_floor + max(0.0, (full_penalty_depth - full_penalty_floor)) * max(0.0, (fall_end - full_frac)) / width
        else:
            full_penalty = full_penalty_floor
        full_penalty = float(np.clip(full_penalty, 0.0, 1.0))
        s_max_eff = s_max * (1.0 - full_penalty)

        if n_recent_qual < min_qual:
            target = 0.0
        else:
            threshold_eff = threshold - hysteresis if S > 0.5 else threshold
            if X <= threshold_eff:
                target = 0.0
            elif X >= saturation:
                target = s_max_eff
            else:
                target = s_max_eff * ((X - threshold_eff) / (saturation - threshold_eff + 1e-9))

        target = float(np.clip(target, 0.0, s_max_eff))
        if target > S:
            S += activation_rise * (target - S)
        else:
            S -= activation_decay * (S - target)
        S = float(np.clip(S, 0.0, s_max_eff))

    s = float(np.clip(S, 0.0, s_max))
    p = (1.0 - s) * p_base + s * p_shift

    epsilon = float(parameters.get('epsilon', 0.0))
    if epsilon > 0.0:
        p = (1.0 - epsilon) * p + epsilon * np.full(2, 0.5, dtype=float)

    p = np.clip(p, 0.0, None)
    return p / np.sum(p)


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=float)
    if probs.size == 0:
        return 0
    probs = probs / probs.sum()
    return int(np.random.choice(probs.size, p=probs))


`parameters`:
- w_forward: [0.25, 0.28]
- w_backward: [0.44, 0.52]
- beta_forward: [0.12, 0.20]
- beta_backward: [1.40, 1.60]
- beta_tally: [1.90, 2.40]
- beta_backward_strong: [2.60, 2.90]
- tie_margin: [2.5, 3.0]
- hi_lo_bonus: [0.45, 0.55]
- base_evidence: [0.38, 0.50]
- tied_top_evidence: [0.34, 0.44]
- density_floor: [0.56, 0.62]
- near_full_boost: [1.05, 1.12]
- evidence_rise: [0.35, 0.45]
- evidence_decay: [0.05, 0.08]
- zero_decay_boost: [1.20, 2.20]
- conflict_threshold: [0.03, 0.05]
- saturation_evidence: [0.25, 0.35]
- hysteresis: [0.02, 0.05]
- activation_rise: [0.22, 0.30]
- activation_decay: [0.04, 0.07]
- min_qualifying_count: {4}
- qualifying_window: {16}
- full_frac_window: {16}
- s_max: [0.72, 0.78]
- full_penalty_threshold: [0.50, 0.60]
- full_penalty_depth: [0.15, 0.25]
- full_penalty_width: [0.15, 0.22]
- full_penalty_floor: [0.04, 0.10]
- top_tied_tally_min: {2, 3}
- top_tied_bonus: [0.10, 0.20]
- epsilon: {0}
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.2487 (var=0.0065) vs this=0.2379 (var=0.0032)
- Experiment 2: real=0.4196 (var=0.0128) vs this=0.4431 (var=0.0090)
- Experiment 3: real=-0.1300 (var=0.0159) vs this=-0.1113 (var=0.0052)
- Experiment 4: real=-0.2742 (var=0.0069) vs this=-0.2825 (var=0.0100)
- Experiment 5: real=-0.6583 (var=0.0598) vs this=-0.6750 (var=0.0079)
- Experiment 6: real=-0.6711 (var=0.0489) vs this=-0.5422 (var=0.0126)
- Experiment 7: real=0.1553 (var=0.0159) vs this=0.1767 (var=0.0022)
- Experiment 8: real=0.0150 (var=0.0027) vs this=0.0188 (var=0.0073)
- Experiment 9: real=-0.0283 (var=0.0032) vs this=0.0021 (var=0.0056)
- Experiment 10: real=-0.0008 (var=0.0091) vs this=0.0033 (var=0.0095)
- Experiment 11: real=-0.0050 (var=0.0198) vs this=0.0367 (var=0.0284)
- Experiment 12: real=-0.0178 (var=0.0089) vs this=-0.0478 (var=0.0131)
- Experiment 13: real=0.8425 (var=0.0101) vs this=0.7629 (var=0.0021)
- Experiment 14: real=0.8413 (var=0.0122) vs this=0.8244 (var=0.0014)
- Experiment 15: real=0.0553 (var=0.0224) vs this=0.0529 (var=0.0354)
- Experiment 16: real=0.6412 (var=0.0315) vs this=0.7112 (var=0.0135)
- Experiment 17: real=0.5710 (var=0.0228) vs this=0.5890 (var=0.0153)
- Experiment 18: real=0.6942 (var=0.0025) vs this=0.7494 (var=0.0014)
- Experiment 19: real=0.8229 (var=0.0143) vs this=0.8394 (var=0.0015)
- Experiment 20: real=0.7500 (var=0.0460) vs this=0.6825 (var=0.0041)


---

### `pi_4` (overall score: 0.745)

**Description**
People choose between two options through a stable, subject-level mixture of three comparison routes: (1) forward lexicographic scanning, inspecting cues in descending validity order and stopping at the first discriminating cue; (2) backward lexicographic scanning, inspecting cues in ascending validity order and stopping at the first discriminating cue in that reversed order; and (3) feature-win tallying, where each option receives one point per feature on which it strictly beats the other and ties contribute nothing. The forward and backward lexicographic weights jointly act as a subject-level polarity parameter for first-validity-cue effects: forward weight supports a positive first-discriminator effect, while backward weight supports a negative one. Each route's preferred option is passed through its own softmax choice rule, so responding is noisy but not controlled by a uniform lapse.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np

    stim = np.asarray(state, dtype=float)
    if stim.ndim == 3 and stim.shape[0] == 1:
        stim = stim[0]
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f'Expected a (2, n_features) stimulus, got {stim.shape}.')

    a = stim[0]
    b = stim[1]
    n_features = stim.shape[1]

    # Preferred validity vector comes from the experiment.  If the
    # parameter resolver ever leaves it unresolved, fall back to a
    # descending validity vector so the model is still scorable.
    validities = parameters.get('validities')
    if validities is None:
        validities = list(np.linspace(0.9, 0.5, n_features))
    validities = np.asarray(validities, dtype=float)
    if validities.ndim == 0 or validities.shape[0] != n_features:
        validities = np.linspace(0.9, 0.5, n_features)

    descending = np.argsort(-validities, kind='stable')
    ascending = np.argsort(validities, kind='stable')

    def lex_probabilities(order, beta):
        winner = None
        for j in order:
            if a[j] > b[j]:
                winner = 0
                break
            if b[j] > a[j]:
                winner = 1
                break
        if winner is None:
            return np.ones(2, dtype=float) / 2.0

        z = float(beta) if winner == 0 else -float(beta)
        p_a = 1.0 / (1.0 + np.exp(-z))
        return np.array([p_a, 1.0 - p_a], dtype=float)

    beta_forward = float(parameters['beta_forward'])
    beta_backward = float(parameters['beta_backward'])
    p_forward = lex_probabilities(descending, beta_forward)
    p_backward = lex_probabilities(ascending, beta_backward)

    a_wins = float(np.sum(a > b))
    b_wins = float(np.sum(b > a))
    tally_scores = np.array([a_wins, b_wins], dtype=float)
    beta_tally = float(parameters['beta_tally'])
    z = beta_tally * (tally_scores - np.max(tally_scores))
    e = np.exp(z)
    p_tally = e / np.sum(e)

    w_forward = float(parameters['w_forward'])
    w_backward = float(parameters['w_backward'])
    w_tally = 1.0 - w_forward - w_backward
    if w_tally < 0.0:
        w_tally = 0.0
    weights = np.array([w_forward, w_backward, w_tally], dtype=float)
    weights = weights / weights.sum()

    p = weights[0] * p_forward + weights[1] * p_backward + weights[2] * p_tally

    epsilon = float(parameters.get('epsilon', 0.0))
    if epsilon > 0.0:
        p = (1.0 - epsilon) * p + epsilon * np.ones(2, dtype=float) / 2.0

    p = np.clip(p, 0.0, None)
    return p / p.sum()


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=float)
    probs = probs / probs.sum()
    return int(np.random.choice(len(probs), p=probs))


`parameters`:
- w_forward: [0.22, 0.32]
- w_backward: [0.42, 0.54]
- beta_forward: [0.08, 0.20]
- beta_backward: [1.30, 1.70]
- beta_tally: [1.80, 2.60]
- epsilon: {0}
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.2487 (var=0.0065) vs this=0.2306 (var=0.0024)
- Experiment 2: real=0.4196 (var=0.0128) vs this=0.4335 (var=0.0093)
- Experiment 3: real=-0.1300 (var=0.0159) vs this=-0.1325 (var=0.0113)
- Experiment 4: real=-0.2742 (var=0.0069) vs this=-0.2879 (var=0.0081)
- Experiment 5: real=-0.6583 (var=0.0598) vs this=-0.2833 (var=0.0124)
- Experiment 6: real=-0.6711 (var=0.0489) vs this=-0.0722 (var=0.0187)
- Experiment 7: real=0.1553 (var=0.0159) vs this=0.4160 (var=0.0041)
- Experiment 8: real=0.0150 (var=0.0027) vs this=-0.0162 (var=0.0110)
- Experiment 9: real=-0.0283 (var=0.0032) vs this=-0.0012 (var=0.0120)
- Experiment 10: real=-0.0008 (var=0.0091) vs this=0.0100 (var=0.0111)
- Experiment 11: real=-0.0050 (var=0.0198) vs this=0.0250 (var=0.0283)
- Experiment 12: real=-0.0178 (var=0.0089) vs this=-0.0067 (var=0.0117)
- Experiment 13: real=0.8425 (var=0.0101) vs this=0.5792 (var=0.0037)
- Experiment 14: real=0.8413 (var=0.0122) vs this=0.6440 (var=0.0025)
- Experiment 15: real=0.0553 (var=0.0224) vs this=0.0258 (var=0.0268)
- Experiment 16: real=0.6412 (var=0.0315) vs this=0.3880 (var=0.0187)
- Experiment 17: real=0.5710 (var=0.0228) vs this=0.4962 (var=0.0247)
- Experiment 18: real=0.6942 (var=0.0025) vs this=0.7056 (var=0.0015)
- Experiment 19: real=0.8229 (var=0.0143) vs this=0.7377 (var=0.0020)
- Experiment 20: real=0.7500 (var=0.0460) vs this=0.2121 (var=0.0085)


## LOSS TRAJECTORY (this propose-loop)
Aggregate loss across iterations of THIS propose-loop (lower = better, 0 = perfect, `+inf` = unscorable). The ACCEPTED / REJECTED tag is the loop's programmatic accept-gate decision — only ACCEPTED candidates have ever been used as the base for a subsequent iteration. Use this together with PRIOR FEEDBACK ITERATIONS below to grade which past critic advice actually paid off.

- iter 1: loss=0.0415 -> ACCEPTED
- iter 2: loss=0.0513 -> REJECTED
- iter 3: loss=0.0539 -> REJECTED
Running-best (last ACCEPTED) base: iter 1 at loss=0.0415 — this is the source shown verbatim below under `## PREVIOUS CANDIDATE (this loop)`. Push the next edit's loss strictly below that floor or the gate will reject it.

## EXPERIMENTAL RESULTS
### Experiment 1
**Design**
  A=[1, 0, 0, 0, 1, 1]  B=[0, 1, 1, 1, 1, 1]
  A=[1, 0, 0, 1, 0, 1]  B=[0, 1, 1, 1, 1, 1]
  A=[1, 0, 0, 1, 1, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[1, 0, 1, 0, 0, 1]  B=[0, 1, 1, 1, 1, 1]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[1, 0, 1, 1, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 1, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 1, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 1, 1]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 0, 1, 0, 1]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 0, 1, 1, 0]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 1, 0, 0, 1]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 1, 0, 1, 0]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 1, 1, 0, 0]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0, 1]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 1, 0, 0, 1, 0]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 1]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 1, 0]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 0, 1, 0, 0]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    matches = []
    for a, b, r in zip(data['option_a_ratings'], data['option_b_ratings'], data['response']):
        pred = None
        # Cues are in descending-validity order, so the first discriminating
        # feature is the Take The Best cue.
        for j in range(len(a)):
            if a[j] > b[j]:
                pred = 0
                break
            if b[j] > a[j]:
                pred = 1
                break
        if pred is not None:
            matches.append(1.0 if r == pred else 0.0)
    if not matches:
        return 0.5
    return float(np.mean(matches))
```

**Observed (real) value:** 0.2487 (var=0.0065)
**Previous candidate values (this loop):**
  - iter 1: 0.2227 (var=0.0022) (Δ vs real -0.0260)
  - iter 2: 0.2515 (var=0.0063) (Δ vs real +0.0027)
  - iter 3 (most recent): 0.2242 (var=0.0032) (Δ vs real -0.0246)
**Other theories' values on this metric (for reference):**
- pi_1: 0.8723 (var=0.0096)
- pi_2: 0.1175 (var=0.0068)
- pi_3: 0.2483 (var=0.0023)
- pi_4: 0.2306 (var=0.0024)
- pi_5: 0.2258 (var=0.0024)
- pi_5_1: 0.2360 (var=0.0031)
- pi_5_2: 0.2146 (var=0.0032)
- pi_6: 0.2292 (var=0.0019)
- pi_7: 0.2331 (var=0.0017)
- pi_7_1: 0.2379 (var=0.0032)
- pi_7_2: 0.2244 (var=0.0022)

### Experiment 2
**Design**
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 1]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 1]  B=[0, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 1, 0]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 0, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 1]  B=[1, 0, 1, 1, 1]
  A=[1, 1, 0, 1, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 1, 1, 0]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 1]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 1, 0]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[1, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    scores = []
    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=float)
        b = np.asarray(row["option_b_ratings"], dtype=float)

        response_a = 1.0 if int(row["response"]) == 0 else 0.0

        # Take The Best style second-cue prediction.
        # By design, feature 0 is tied on every trial, so feature 1 is
        # the first discriminating cue.
        if a[1] > b[1]:
            second_wins_a = True
        elif b[1] > a[1]:
            second_wins_a = False
        else:
            second_wins_a = True

        second_score = response_a if second_wins_a else (1.0 - response_a)

        # Tallying total score. Feature-specific ties contribute zero.
        wins_a = float(np.sum(a > b))
        wins_b = float(np.sum(b > a))
        tally_d = wins_a - wins_b

        if tally_d > 0.0:
            tally_score = response_a
        elif tally_d < 0.0:
            tally_score = 1.0 - response_a
        else:
            # Tallying has no preference on a tied tally.
            tally_score = 0.5

        scores.append(tally_score - second_score)

    return float(np.mean(scores)) if scores else 0.0
```

**Observed (real) value:** 0.4196 (var=0.0128)
**Previous candidate values (this loop):**
  - iter 1: 0.4454 (var=0.0106) (Δ vs real +0.0258)
  - iter 2: 0.4231 (var=0.0155) (Δ vs real +0.0035)
  - iter 3 (most recent): 0.4367 (var=0.0115) (Δ vs real +0.0171)
**Other theories' values on this metric (for reference):**
- pi_2: 0.6304 (var=0.0462)
- pi_1: -0.6075 (var=0.0314)
- pi_3: 0.4169 (var=0.0101)
- pi_4: 0.4335 (var=0.0093)
- pi_5: 0.4321 (var=0.0103)
- pi_5_1: 0.4519 (var=0.0082)
- pi_5_2: 0.4796 (var=0.0123)
- pi_6: 0.4558 (var=0.0077)
- pi_7: 0.4373 (var=0.0096)
- pi_7_1: 0.4431 (var=0.0090)
- pi_7_2: 0.4354 (var=0.0065)

### Experiment 3
**Design**
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 1]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 1, 1]
  A=[0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 1, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 1, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 1, 1, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 1, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 1, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 1, 1]  B=[0, 1, 0, 0, 0, 0]

**Metric**
```python
def metric(data):
    a1 = data["option_a_ratings"].apply(lambda x: x[1])
    b1 = data["option_b_ratings"].apply(lambda x: x[1])
    f1_a = a1 > b1
    f1_b = b1 > a1
    chose_a = data["response"].astype(int) == 0
    if f1_a.sum() == 0 or f1_b.sum() == 0:
        return 0.0
    return float(chose_a[f1_a].mean() - chose_a[f1_b].mean())
```

**Observed (real) value:** -0.1300 (var=0.0159)
**Previous candidate values (this loop):**
  - iter 1: -0.1042 (var=0.0068) (Δ vs real +0.0258)
  - iter 2: -0.1325 (var=0.0080) (Δ vs real -0.0025)
  - iter 3 (most recent): -0.1013 (var=0.0074) (Δ vs real +0.0287)
**Other theories' values on this metric (for reference):**
- pi_3: 0.2375 (var=0.0045)
- pi_2: -0.0158 (var=0.0048)
- pi_1: 0.6592 (var=0.0472)
- pi_4: -0.1325 (var=0.0113)
- pi_5: -0.1446 (var=0.0066)
- pi_5_1: -0.1329 (var=0.0102)
- pi_5_2: -0.1471 (var=0.0086)
- pi_6: -0.1254 (var=0.0091)
- pi_7: -0.1158 (var=0.0055)
- pi_7_1: -0.1113 (var=0.0052)
- pi_7_2: -0.1204 (var=0.0097)

### Experiment 4
**Design**
  A=[0, 0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 0, 0, 0, 0]  B=[1, 1, 0, 0, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 1, 0, 0, 0]  B=[1, 1, 0, 0, 0, 1, 1, 1]
  A=[1, 1, 1, 0, 1, 1, 0, 0]  B=[1, 1, 0, 1, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 0, 0]  B=[0, 0, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 0]  B=[0, 0, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 1, 1, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0, 0, 0]
  A=[1, 1, 0, 1, 0, 0, 1, 1]  B=[1, 1, 1, 0, 1, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 0, 1, 1, 1]  B=[1, 1, 1, 0, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 0, 1, 1]  B=[1, 1, 1, 0, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1, 0, 1]  B=[1, 1, 1, 0, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1, 1, 0]  B=[1, 1, 1, 0, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0, 1, 1, 1]
  A=[1, 1, 1, 0, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0, 1, 1]
  A=[1, 1, 1, 0, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 0, 1]
  A=[1, 1, 1, 0, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 1, 0]

**Metric**
```python
import numpy as np
import pandas as pd

def metric(data: pd.DataFrame) -> float:
    validities = np.array([0.92, 0.88, 0.80, 0.72, 0.65, 0.60, 0.55, 0.52])
    order = np.argsort(-validities)
    pos = []
    neg = []
    for row in data.itertuples(index=False):
        a = np.asarray(row.option_a_ratings, dtype=float)
        b = np.asarray(row.option_b_ratings, dtype=float)
        first = 'A'
        found = False
        for j in order:
            if a[j] > b[j]:
                first = 'A'
                found = True
                break
            if b[j] > a[j]:
                first = 'B'
                found = True
                break
        if not found:
            continue
        chose_a = 1.0 if row.response == 0 else 0.0
        if first == 'A':
            pos.append(chose_a)
        else:
            neg.append(chose_a)
    if len(pos) == 0 or len(neg) == 0:
        return 0.0
    return float(np.mean(pos) - np.mean(neg))

```

**Observed (real) value:** -0.2742 (var=0.0069)
**Previous candidate values (this loop):**
  - iter 1: -0.2337 (var=0.0121) (Δ vs real +0.0404)
  - iter 2: -0.2625 (var=0.0124) (Δ vs real +0.0117)
  - iter 3 (most recent): -0.2379 (var=0.0120) (Δ vs real +0.0363)
**Other theories' values on this metric (for reference):**
- pi_2: 0.0075 (var=0.0109)
- pi_3: 0.2375 (var=0.0114)
- pi_1: 0.6925 (var=0.0418)
- pi_4: -0.2879 (var=0.0081)
- pi_5: -0.2883 (var=0.0135)
- pi_5_1: -0.3025 (var=0.0121)
- pi_5_2: -0.3025 (var=0.0138)
- pi_6: -0.2946 (var=0.0138)
- pi_7: -0.2704 (var=0.0106)
- pi_7_1: -0.2825 (var=0.0100)
- pi_7_2: -0.2617 (var=0.0109)

### Experiment 5
**Design**
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 0, 1, 0, 1, 1]
  A=[1, 1, 0, 0, 1, 0]  B=[0, 0, 1, 1, 0, 1]
  A=[1, 0, 1, 1, 0, 0]  B=[0, 1, 0, 0, 1, 1]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[1, 0, 0, 1, 1, 0]  B=[0, 1, 1, 0, 0, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 1]
  A=[1, 1, 0, 1, 1, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[1, 1, 1, 0, 1, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 0, 0, 1]
  A=[1, 0, 1, 1, 1, 0]  B=[0, 1, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[1, 1, 1, 0, 1, 0]  B=[0, 1, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0, 1]  B=[1, 0, 0, 1, 1, 0]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 0, 1, 0, 1, 0]
  A=[0, 1, 0, 0, 1, 1]  B=[1, 0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 0, 1]  B=[1, 1, 0, 0, 1, 0]
  A=[0, 0, 1, 0, 1, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[0, 1, 0, 1, 1, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 0, 0, 1, 0, 0]
  A=[0, 1, 1, 0, 1, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 0, 0, 0, 1, 0]
  A=[0, 1, 1, 1, 0, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[0, 0, 1, 0, 0, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 1, 1]  B=[1, 1, 0, 1, 1, 0]
  A=[0, 0, 1, 0, 0, 1]  B=[1, 0, 0, 1, 0, 0]
  A=[0, 1, 1, 0, 1, 1]  B=[1, 1, 0, 1, 1, 0]

**Metric**
```python
def metric(data):
    import numpy as np
    a0 = np.array([int(r[0]) for r in data['option_a_ratings']])
    b0 = np.array([int(r[0]) for r in data['option_b_ratings']])
    choose_a = (np.asarray(data['response'], dtype=int) == 0).astype(float)
    top_a = a0 > b0
    top_b = ~top_a
    if not np.any(top_a) or not np.any(top_b):
        return 0.0
    return float(choose_a[top_a].mean() - choose_a[top_b].mean())
```

**Observed (real) value:** -0.6583 (var=0.0598)
**Previous candidate values (this loop):**
  - iter 1: -0.6354 (var=0.0058) (Δ vs real +0.0229)
  - iter 2: -0.6450 (var=0.0133) (Δ vs real +0.0133)
  - iter 3 (most recent): -0.6754 (var=0.0066) (Δ vs real -0.0171)
**Other theories' values on this metric (for reference):**
- pi_3: 0.2613 (var=0.0080)
- pi_4: -0.2833 (var=0.0124)
- pi_1: 0.6971 (var=0.0436)
- pi_2: -0.0012 (var=0.0086)
- pi_5: -0.6717 (var=0.0368)
- pi_5_1: -0.5975 (var=0.0258)
- pi_5_2: -0.7096 (var=0.0160)
- pi_6: -0.6721 (var=0.0051)
- pi_7: -0.6529 (var=0.0087)
- pi_7_1: -0.6750 (var=0.0079)
- pi_7_2: -0.6533 (var=0.0076)

### Experiment 6
**Design**
  A=[1, 1, 0, 1, 0, 0]  B=[0, 0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 0, 1, 0, 1, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0, 1]  B=[1, 0, 0, 1, 1, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[0, 0, 1, 0, 0, 1]  B=[1, 0, 0, 1, 0, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 1, 1, 0, 1, 1]
  A=[0, 1, 1, 1, 0, 1]  B=[1, 1, 1, 0, 1, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 1, 0]  B=[0, 1, 0, 0, 1, 1]
  A=[0, 0, 1, 0, 0, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[0, 0, 1, 0, 0, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[1, 0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 1, 1, 1, 0, 0]
  A=[1, 1, 0, 1, 1, 0]  B=[0, 0, 1, 0, 1, 1]
  A=[0, 0, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 0, 1]  B=[1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 1, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 1, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 1, 0, 0, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 1, 0, 1, 1, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 1, 0, 0, 1]  B=[1, 1, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np

    if len(data) == 0:
        return 0.0

    a = np.array([list(x) for x in data['option_a_ratings']], dtype=int)
    b = np.array([list(x) for x in data['option_b_ratings']], dtype=int)
    diff = a - b

    top_cue = diff[:, 0]
    tally_diff = (diff > 0).sum(axis=1) - (diff < 0).sum(axis=1)

    chose_a = (data['response'].to_numpy() == 0).astype(float)

    top_a_plus = (top_cue > 0) & (tally_diff >= 1)
    top_b_minus = (top_cue < 0) & (tally_diff <= -1)

    mean_top_a = np.mean(chose_a[top_a_plus]) if np.any(top_a_plus) else 0.0
    mean_top_b = np.mean(chose_a[top_b_minus]) if np.any(top_b_minus) else 0.0

    return float(mean_top_a - mean_top_b)
```

**Observed (real) value:** -0.6711 (var=0.0489)
**Previous candidate values (this loop):**
  - iter 1: -0.6056 (var=0.0123) (Δ vs real +0.0656)
  - iter 2: -0.5228 (var=0.0279) (Δ vs real +0.1483)
  - iter 3 (most recent): -0.6183 (var=0.0116) (Δ vs real +0.0528)
**Other theories' values on this metric (for reference):**
- pi_4: -0.0722 (var=0.0187)
- pi_3: 0.9950 (var=0.0001)
- pi_1: 0.6939 (var=0.0333)
- pi_2: 0.7450 (var=0.0289)
- pi_5: -0.6683 (var=0.0378)
- pi_5_1: -0.6233 (var=0.0227)
- pi_5_2: -0.7394 (var=0.0104)
- pi_6: -0.6406 (var=0.0120)
- pi_7: -0.5633 (var=0.0084)
- pi_7_1: -0.5422 (var=0.0126)
- pi_7_2: -0.6228 (var=0.0073)

### Experiment 7
**Design**
  A=[1, 0, 0, 1, 0, 0]  B=[0, 1, 1, 1, 0, 1]
  A=[0, 0, 0, 1, 0, 1]  B=[1, 1, 1, 1, 0, 0]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 0, 1, 0, 1, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[1, 1, 0, 1, 1, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 1, 0, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[1, 1, 0, 0, 1, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 1, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[0, 0, 1, 0, 0, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[1, 1, 0, 1, 1, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[0, 1, 0, 1, 1, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0, 1]  B=[1, 0, 0, 1, 1, 0]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 0, 1, 1, 0, 1]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 0, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[1, 1, 1, 0, 1, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 1, 1]  B=[1, 0, 0, 1, 1, 0]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 0, 1, 0, 0, 1]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[0, 1, 1, 1, 0, 1]  B=[1, 0, 0, 1, 0, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 1, 1, 1, 0, 1]  B=[1, 0, 0, 0, 1, 0]
  A=[1, 1, 1, 0, 1, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 1, 1, 0, 1, 1]  B=[1, 0, 0, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    choices = []
    for _, row in data.iterrows():
        a = [int(x) for x in row['option_a_ratings']]
        b = [int(x) for x in row['option_b_ratings']]
        if a[0] == b[0]:
            continue
        top = 0 if a[0] > b[0] else 1
        top_vec = a if top == 0 else b
        other_vec = b if top == 0 else a
        d_top = 0
        for i in range(len(top_vec)):
            if top_vec[i] > other_vec[i]:
                d_top += 1
            elif other_vec[i] > top_vec[i]:
                d_top -= 1
        if d_top >= 0:
            choices.append(1.0 if int(row['response']) == top else 0.0)
    if not choices:
        return 0.5
    return float(np.mean(choices))
```

**Observed (real) value:** 0.1553 (var=0.0159)
**Previous candidate values (this loop):**
  - iter 1: 0.2203 (var=0.0025) (Δ vs real +0.0650)
  - iter 2: 0.2510 (var=0.0069) (Δ vs real +0.0957)
  - iter 3 (most recent): 0.2040 (var=0.0042) (Δ vs real +0.0487)
**Other theories' values on this metric (for reference):**
- pi_5: 0.1807 (var=0.0115)
- pi_4: 0.4160 (var=0.0041)
- pi_1: 0.8197 (var=0.0124)
- pi_2: 0.7093 (var=0.0045)
- pi_3: 0.8537 (var=0.0015)
- pi_5_1: 0.1960 (var=0.0071)
- pi_5_2: 0.1453 (var=0.0037)
- pi_6: 0.1447 (var=0.0028)
- pi_7: 0.1667 (var=0.0021)
- pi_7_1: 0.1767 (var=0.0022)
- pi_7_2: 0.1980 (var=0.0023)

### Experiment 8
**Design**
  A=[1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1]
  A=[1, 1, 0, 1, 0, 1, 0, 0]  B=[0, 0, 0, 0, 1, 0, 1, 1]
  A=[1, 1, 0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1]
  A=[1, 1, 0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 1, 0, 1]
  A=[0, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 0, 1, 0, 0]  B=[1, 0, 0, 0, 1, 0, 1, 1]
  A=[0, 1, 1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 0, 0, 0]  B=[1, 0, 0, 1, 0, 1, 0, 1]
  A=[1, 1, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1]
  A=[1, 1, 0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 0, 1]
  A=[1, 1, 0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0, 0, 1]
  A=[1, 1, 0, 1, 0, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1]
  A=[0, 1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 1, 0, 1]
  A=[0, 1, 1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 0, 1, 0, 0]  B=[1, 0, 0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 1]  B=[1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 1, 0, 1]  B=[1, 1, 1, 0, 1, 0, 1, 0]
  A=[0, 0, 0, 1, 1, 0, 0, 1]  B=[1, 1, 0, 0, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 1, 0, 0, 1]  B=[1, 1, 1, 1, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 1, 0, 1, 0, 1]  B=[1, 1, 1, 0, 1, 0, 1, 0]
  A=[0, 0, 0, 1, 1, 0, 0, 1]  B=[0, 1, 1, 0, 0, 1, 1, 0]
  A=[1, 0, 0, 1, 1, 0, 0, 1]  B=[1, 1, 1, 1, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1]  B=[1, 1, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 1, 0, 1]  B=[1, 1, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0, 0, 1]  B=[1, 1, 0, 1, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 1, 1]  B=[1, 1, 1, 1, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 1, 0, 1]  B=[1, 1, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 1, 1]  B=[1, 1, 1, 1, 0, 1, 0, 0]

**Metric**
```python
import numpy as np
import pandas as pd

def metric(data: pd.DataFrame) -> float:
    if data.empty:
        return 0.0
    validities = np.array([0.9, 0.9, 0.8, 0.7, 0.6, 0.55, 0.52, 0.5], dtype=float)
    j_hi = int(np.argmax(validities))
    j_lo = int(np.argmin(validities))

    a_arr = np.array([np.asarray(x, dtype=float) for x in data['option_a_ratings']])
    b_arr = np.array([np.asarray(x, dtype=float) for x in data['option_b_ratings']])
    resp = np.asarray(data['response'], dtype=float)

    hi_diff = a_arr[:, j_hi] - b_arr[:, j_hi]
    lo_diff = a_arr[:, j_lo] - b_arr[:, j_lo]
    d = (a_arr > b_arr).sum(axis=1) - (b_arr > a_arr).sum(axis=1)

    hi_dir = np.where(hi_diff > 0, 1, np.where(hi_diff < 0, -1, 0))
    lo_dir = np.where(lo_diff > 0, 1, np.where(lo_diff < 0, -1, 0))
    live = (hi_dir != 0) & (lo_dir != 0) & (hi_dir == -lo_dir) & (d * hi_dir >= 0)

    y = np.where(lo_dir > 0, (resp == 0).astype(float),
                 np.where(lo_dir < 0, (resp == 1).astype(float), 0.5))

    if np.sum(live) == 0 or np.sum(~live) == 0:
        return 0.0
    return float(np.mean(y[live]) - np.mean(y[~live]))
```

**Observed (real) value:** 0.0150 (var=0.0027)
**Previous candidate values (this loop):**
  - iter 1: -0.0229 (var=0.0073) (Δ vs real -0.0379)
  - iter 2: -0.0104 (var=0.0051) (Δ vs real -0.0254)
  - iter 3 (most recent): -0.0337 (var=0.0077) (Δ vs real -0.0487)
**Other theories' values on this metric (for reference):**
- pi_4: -0.0162 (var=0.0110)
- pi_5: 0.2750 (var=0.0251)
- pi_1: -0.0038 (var=0.0040)
- pi_2: 0.0008 (var=0.0059)
- pi_3: 0.0004 (var=0.0001)
- pi_5_1: -0.0021 (var=0.0064)
- pi_5_2: -0.0021 (var=0.0144)
- pi_6: 0.0238 (var=0.0106)
- pi_7: 0.0208 (var=0.0062)
- pi_7_1: 0.0188 (var=0.0073)
- pi_7_2: -0.0125 (var=0.0044)

### Experiment 9
**Design**
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 1, 0, 1, 1, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 1, 1, 0, 1, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 0, 1, 0, 1, 0]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 1, 0]
  A=[1, 1, 1, 1, 0, 1]  B=[0, 1, 1, 1, 1, 0]
  A=[1, 1, 0, 0, 0, 1]  B=[0, 0, 1, 0, 1, 0]
  A=[1, 1, 0, 1, 0, 1]  B=[0, 0, 1, 1, 1, 0]
  A=[1, 0, 1, 0, 0, 1]  B=[0, 1, 0, 0, 1, 0]
  A=[1, 0, 1, 1, 0, 1]  B=[0, 1, 0, 1, 1, 0]
  A=[1, 0, 1, 0, 0, 1]  B=[0, 0, 0, 1, 1, 0]
  A=[1, 1, 1, 0, 0, 1]  B=[0, 1, 0, 1, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 0, 0, 1, 0, 0]
  A=[0, 0, 1, 1, 1, 0]  B=[1, 1, 1, 1, 0, 0]
  A=[0, 1, 0, 1, 1, 0]  B=[1, 1, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 1, 0]  B=[1, 1, 1, 1, 0, 0]
  A=[0, 0, 0, 1, 1, 0]  B=[1, 1, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 1, 0]  B=[1, 1, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[0, 1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 0, 1]
  A=[0, 1, 0, 0, 1, 0]  B=[1, 0, 1, 0, 0, 1]
  A=[0, 1, 0, 1, 1, 0]  B=[1, 0, 1, 1, 0, 1]
  A=[0, 0, 1, 0, 1, 0]  B=[1, 1, 0, 0, 0, 1]
  A=[0, 0, 1, 1, 1, 0]  B=[1, 1, 0, 1, 0, 1]
  A=[0, 0, 1, 0, 1, 0]  B=[1, 0, 0, 1, 0, 1]
  A=[0, 1, 1, 0, 1, 0]  B=[1, 1, 0, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    validities = np.array([0.90, 0.78, 0.66, 0.58, 0.52, 0.52])
    top_idx = int(np.argmax(validities))
    low_idx = np.where(validities == np.min(validities))[0]

    subject_effects = []
    for sid, sub in data.groupby('subject_id'):
        groups = {1: {'active': [], 'inactive': []},
                  -1: {'active': [], 'inactive': []}}
        for _, row in sub.iterrows():
            a = np.asarray(row['option_a_ratings'], dtype=float)
            b = np.asarray(row['option_b_ratings'], dtype=float)
            top_dir = int(np.sign(a[top_idx] - b[top_idx]))
            if top_dir == 0:
                continue
            lows = [int(np.sign(a[j] - b[j])) for j in low_idx]
            nonzero = [d for d in lows if d != 0]
            if len(nonzero) > 0 and all(d == nonzero[0] for d in nonzero):
                low_dir = nonzero[0]
            else:
                low_dir = 0
            tally_d = int(np.sum(a - b))
            gate = (low_dir != 0 and top_dir == -low_dir and tally_d * top_dir >= 0)
            y_a = 1.0 - float(row['response'])
            signed_y = float(top_dir) * y_a
            groups[top_dir]['active' if gate else 'inactive'].append(signed_y)

        dir_effects = []
        for d in (1, -1):
            active = groups[d]['active']
            inactive = groups[d]['inactive']
            if len(active) > 0 and len(inactive) > 0:
                dir_effects.append(float(np.mean(inactive) - np.mean(active)))
        if dir_effects:
            subject_effects.append(float(np.mean(dir_effects)))

    if not subject_effects:
        return 0.0
    return float(np.mean(subject_effects))
```

**Observed (real) value:** -0.0283 (var=0.0032)
**Previous candidate values (this loop):**
  - iter 1: -0.0167 (var=0.0039) (Δ vs real +0.0117)
  - iter 2: 0.0171 (var=0.0167) (Δ vs real +0.0454)
  - iter 3 (most recent): 0.0025 (var=0.0042) (Δ vs real +0.0308)
**Other theories' values on this metric (for reference):**
- pi_5_1: 0.2417 (var=0.0120)
- pi_4: -0.0012 (var=0.0120)
- pi_1: -0.0150 (var=0.0031)
- pi_2: 0.0033 (var=0.0040)
- pi_3: -0.0004 (var=0.0002)
- pi_5: -0.0029 (var=0.0043)
- pi_5_2: 0.0038 (var=0.0084)
- pi_6: -0.0358 (var=0.0108)
- pi_7: -0.0013 (var=0.0043)
- pi_7_1: 0.0021 (var=0.0056)
- pi_7_2: -0.0008 (var=0.0049)

### Experiment 10
**Design**
  A=[1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 0]
  A=[1, 1, 1, 1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1, 0, 1, 0]
  A=[1, 0, 1, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0]  B=[0, 1, 0, 1, 1, 1, 1, 0]
  A=[1, 0, 0, 1, 0, 0, 0, 1]  B=[0, 0, 0, 0, 0, 0, 1, 1]
  A=[1, 1, 1, 1, 1, 0, 0, 1]  B=[0, 1, 1, 0, 1, 0, 1, 1]
  A=[1, 0, 0, 0, 1, 1, 0, 1]  B=[0, 0, 0, 0, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1, 0, 1]  B=[0, 1, 1, 1, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 0, 0, 1, 0]
  A=[1, 1, 1, 1, 1, 0, 0, 1]  B=[0, 1, 1, 1, 1, 0, 1, 0]
  A=[1, 1, 0, 0, 0, 1, 0, 1]  B=[0, 0, 1, 0, 0, 1, 1, 0]
  A=[1, 1, 0, 1, 1, 1, 0, 1]  B=[0, 0, 1, 1, 1, 1, 1, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0, 0, 1, 0]
  A=[1, 1, 1, 0, 1, 0, 0, 1]  B=[0, 0, 1, 1, 1, 0, 1, 0]
  A=[1, 1, 0, 0, 0, 1, 0, 1]  B=[0, 0, 0, 0, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 0, 1, 0, 1]  B=[0, 0, 1, 1, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 1, 0, 1, 0]  B=[1, 1, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 1, 0]  B=[1, 0, 1, 0, 0, 1, 0, 0]
  A=[0, 1, 0, 1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1]  B=[1, 0, 0, 1, 0, 0, 0, 1]
  A=[0, 1, 1, 0, 1, 0, 1, 1]  B=[1, 1, 1, 1, 1, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 1, 1, 0, 1]
  A=[0, 1, 1, 1, 0, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 1, 0]  B=[1, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 1, 1, 1, 1, 0, 1, 0]  B=[1, 1, 1, 1, 1, 0, 0, 1]
  A=[0, 1, 0, 0, 0, 1, 1, 0]  B=[1, 0, 1, 0, 0, 1, 0, 1]
  A=[0, 1, 0, 1, 1, 1, 1, 0]  B=[1, 0, 1, 1, 1, 1, 0, 1]
  A=[0, 1, 0, 0, 0, 0, 1, 0]  B=[1, 0, 0, 1, 0, 0, 0, 1]
  A=[0, 1, 1, 0, 1, 0, 1, 0]  B=[1, 0, 1, 1, 1, 0, 0, 1]
  A=[0, 1, 0, 0, 0, 1, 1, 0]  B=[1, 0, 0, 0, 1, 1, 0, 1]
  A=[0, 1, 1, 1, 0, 1, 1, 0]  B=[1, 0, 1, 1, 1, 1, 0, 1]

**Metric**
```python
import pandas as pd

def metric(data: pd.DataFrame) -> float:
    a0 = data['option_a_ratings'].apply(lambda x: x[0]).astype(int)
    b0 = data['option_b_ratings'].apply(lambda x: x[0]).astype(int)
    a7 = data['option_a_ratings'].apply(lambda x: x[7]).astype(int)
    b7 = data['option_b_ratings'].apply(lambda x: x[7]).astype(int)

    top_is_a = a0 > b0
    gate_active = a7 == b7

    choose_top = ((top_is_a & (data['response'] == 0)) |
                  (~top_is_a & (data['response'] == 1))).astype(float)

    if gate_active.sum() == 0 or (~gate_active).sum() == 0:
        return 0.0

    return float(choose_top[~gate_active].mean() - choose_top[gate_active].mean())

```

**Observed (real) value:** -0.0008 (var=0.0091)
**Previous candidate values (this loop):**
  - iter 1: -0.0017 (var=0.0080) (Δ vs real -0.0008)
  - iter 2: 0.0204 (var=0.0118) (Δ vs real +0.0213)
  - iter 3 (most recent): 0.0092 (var=0.0114) (Δ vs real +0.0100)
**Other theories' values on this metric (for reference):**
- pi_4: 0.0100 (var=0.0111)
- pi_5_1: 0.2717 (var=0.0167)
- pi_1: -0.0088 (var=0.0044)
- pi_2: -0.0075 (var=0.0048)
- pi_3: 0.0021 (var=0.0002)
- pi_5: -0.0029 (var=0.0062)
- pi_5_2: -0.0125 (var=0.0074)
- pi_6: 0.0096 (var=0.0118)
- pi_7: -0.0071 (var=0.0128)
- pi_7_1: 0.0033 (var=0.0095)
- pi_7_2: -0.0087 (var=0.0096)

### Experiment 11
**Design**
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[1, 1, 0, 1, 1, 0]  B=[0, 0, 1, 0, 1, 1]
  A=[1, 0, 1, 1, 0, 0]  B=[0, 1, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 1, 0, 1, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 1, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[1, 1, 1, 1, 1, 0]  B=[1, 0, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 0]  B=[1, 0, 1, 0, 1, 1]
  A=[1, 1, 1, 1, 1, 0]  B=[1, 0, 1, 1, 0, 1]
  A=[1, 1, 1, 0, 1, 0]  B=[1, 0, 0, 1, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 1, 0, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 1, 1]  B=[1, 1, 0, 1, 1, 0]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 0, 1, 1, 0, 0]
  A=[0, 0, 1, 0, 1, 1]  B=[1, 1, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 1, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 1]  B=[0, 1, 1, 1, 0, 0]
  A=[1, 0, 0, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[1, 0, 1, 0, 1, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[1, 0, 1, 1, 0, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[1, 0, 0, 1, 0, 1]  B=[1, 1, 1, 0, 1, 0]

**Metric**
```python
import numpy as np
import pandas as pd

def metric(data: pd.DataFrame) -> float:
    validities = np.array([0.9, 0.8, 0.7, 0.6, 0.55, 0.5], dtype=float)
    descending = np.argsort(-validities)

    A = np.asarray(data['option_a_ratings'].tolist(), dtype=float)
    B = np.asarray(data['option_b_ratings'].tolist(), dtype=float)
    R = np.asarray(data['response'].tolist(), dtype=float)
    chose_a = (R == 0).astype(float)

    n = A.shape[0]
    if n == 0:
        return 0.0

    top_dir = np.full(n, -1, dtype=int)
    for j in descending:
        mask = (top_dir == -1) & (A[:, j] != B[:, j])
        top_dir[mask] = (B[mask, j] > A[mask, j]).astype(int)

    gate_active = (A[:, 0] != B[:, 0])
    cond = np.full(n, -1, dtype=int)
    cond[(top_dir == 0) & gate_active] = 0
    cond[(top_dir == 0) & (~gate_active)] = 1
    cond[(top_dir == 1) & gate_active] = 2
    cond[(top_dir == 1) & (~gate_active)] = 3

    cell_means = []
    for k in range(4):
        rows = (cond == k)
        if rows.sum() == 0:
            return 0.0
        cell_means.append(float(chose_a[rows].mean()))

    return float(cell_means[1] - cell_means[0] + cell_means[2] - cell_means[3])
```

**Observed (real) value:** -0.0050 (var=0.0198)
**Previous candidate values (this loop):**
  - iter 1: -0.0667 (var=0.0233) (Δ vs real -0.0617)
  - iter 2: -0.0517 (var=0.0492) (Δ vs real -0.0467)
  - iter 3 (most recent): -0.0100 (var=0.0348) (Δ vs real -0.0050)
**Other theories' values on this metric (for reference):**
- pi_5_2: 0.6500 (var=0.0457)
- pi_4: 0.0250 (var=0.0283)
- pi_1: -0.0150 (var=0.0273)
- pi_2: 0.0342 (var=0.0199)
- pi_3: -0.0058 (var=0.0006)
- pi_5: 0.5325 (var=0.0892)
- pi_5_1: 0.5525 (var=0.0595)
- pi_6: 0.0367 (var=0.0440)
- pi_7: 0.0408 (var=0.0280)
- pi_7_1: 0.0367 (var=0.0284)
- pi_7_2: -0.0508 (var=0.0245)

### Experiment 12
**Design**
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[1, 0, 0, 1, 0, 1]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 1, 1, 0, 0, 0]  B=[1, 0, 0, 1, 0, 1]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 1, 0, 0, 0, 1]
  A=[0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 1, 0, 1, 0, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 1, 1, 0, 1, 0]  B=[0, 1, 0, 0, 0, 1]
  A=[0, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 1, 1, 0, 1, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 1, 1, 0, 0]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 1, 1, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0, 1]  B=[1, 1, 1, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[0, 0, 1, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 1, 0, 1]  B=[1, 1, 0, 0, 0, 0]

**Metric**
```python
import numpy as np

def metric(data):
    if data is None or len(data) == 0:
        return 0.0
    validities = np.array([0.9, 0.8, 0.72, 0.61, 0.55, 0.5])
    order = np.argsort(-validities, kind='stable')
    hi_idx = int(order[0])
    second_idx = int(order[1])
    lo_idx = int(order[-1])
    active_low = []
    inactive_low = []
    for row in data.itertuples(index=False):
        a = np.asarray(row.option_a_ratings, dtype=float)
        b = np.asarray(row.option_b_ratings, dtype=float)
        resp = row.response
        if a.shape != validities.shape or b.shape != validities.shape:
            continue
        if a[lo_idx] == b[lo_idx]:
            continue
        low_dir = 1 if a[lo_idx] > b[lo_idx] else -1
        low_chosen = 1.0 if ((low_dir == 1 and resp == 0) or (low_dir == -1 and resp == 1)) else 0.0
        tally_d = int(np.sum(a > b) - np.sum(b > a))
        if a[hi_idx] != b[hi_idx]:
            hi_dir = 1 if a[hi_idx] > b[hi_idx] else -1
            if hi_dir == -low_dir and tally_d * hi_dir >= 0:
                active_low.append(low_chosen)
        else:
            if a[second_idx] != b[second_idx]:
                hi_dir = 1 if a[second_idx] > b[second_idx] else -1
                if hi_dir == -low_dir and tally_d * hi_dir >= 0:
                    inactive_low.append(low_chosen)
    if not active_low or not inactive_low:
        return 0.0
    return float(np.mean(active_low) - np.mean(inactive_low))
```

**Observed (real) value:** -0.0178 (var=0.0089)
**Previous candidate values (this loop):**
  - iter 1: -0.0017 (var=0.0147) (Δ vs real +0.0161)
  - iter 2: 0.0017 (var=0.0150) (Δ vs real +0.0194)
  - iter 3 (most recent): 0.0178 (var=0.0135) (Δ vs real +0.0356)
**Other theories' values on this metric (for reference):**
- pi_4: -0.0067 (var=0.0117)
- pi_5_2: 0.2894 (var=0.0132)
- pi_1: -0.0050 (var=0.0090)
- pi_2: 0.0017 (var=0.0129)
- pi_3: -0.0067 (var=0.0049)
- pi_5: 0.2600 (var=0.0188)
- pi_5_1: 0.2211 (var=0.0170)
- pi_6: -0.0206 (var=0.0128)
- pi_7: -0.0200 (var=0.0134)
- pi_7_1: -0.0478 (var=0.0131)
- pi_7_2: -0.0056 (var=0.0095)

### Experiment 13
**Design**
  A=[0, 0, 0, 0, 0, 1]  B=[0, 1, 1, 1, 1, 0]
  A=[0, 0, 1, 0, 0, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 0, 1, 1, 1, 0]
  A=[1, 1, 0, 0, 0, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 1, 0, 1, 1, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 1, 0]
  A=[1, 1, 1, 0, 0, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[1, 0, 0, 1, 0, 1]  B=[1, 0, 1, 1, 0, 0]
  A=[0, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[1, 0, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 1, 0]  B=[1, 1, 0, 0, 0, 1]
  A=[1, 1, 0, 1, 1, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 1, 0]  B=[1, 1, 1, 0, 0, 1]
  A=[1, 0, 1, 1, 1, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 0, 1]
  A=[1, 0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 1, 1, 1, 0, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 1, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    validities = np.array([0.9, 0.8, 0.72, 0.62, 0.61, 0.6], dtype=float)
    low_idx = int(np.argmin(validities))
    a = np.array(data['option_a_ratings'].tolist(), dtype=float)
    b = np.array(data['option_b_ratings'].tolist(), dtype=float)
    if a.ndim != 2 or b.ndim != 2 or a.shape[0] == 0:
        return 0.5
    a_low = a[:, low_idx]
    b_low = b[:, low_idx]
    valid = np.not_equal(a_low, b_low)
    if not np.any(valid):
        return 0.5
    low_cue_choice = np.where(a_low > b_low, 0, 1)
    response = data['response'].to_numpy(dtype=float)
    match = np.equal(response, low_cue_choice).astype(float)
    return float(np.mean(match[valid]))
```

**Observed (real) value:** 0.8425 (var=0.0101)
**Previous candidate values (this loop):**
  - iter 1: 0.7810 (var=0.0025) (Δ vs real -0.0615)
  - iter 2: 0.8098 (var=0.0028) (Δ vs real -0.0327)
  - iter 3 (most recent): 0.7881 (var=0.0020) (Δ vs real -0.0544)
**Other theories' values on this metric (for reference):**
- pi_6: 0.8048 (var=0.0022)
- pi_4: 0.5792 (var=0.0037)
- pi_1: 0.1235 (var=0.0079)
- pi_2: 0.3046 (var=0.0038)
- pi_3: 0.1665 (var=0.0008)
- pi_5: 0.7015 (var=0.0047)
- pi_5_1: 0.6865 (var=0.0051)
- pi_5_2: 0.7231 (var=0.0028)
- pi_7: 0.7425 (var=0.0023)
- pi_7_1: 0.7629 (var=0.0021)
- pi_7_2: 0.8069 (var=0.0017)

### Experiment 14
**Design**
  A=[0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[0, 0, 1, 0, 0, 1]  B=[1, 1, 0, 1, 1, 0]
  A=[0, 0, 0, 1, 0, 1]  B=[1, 1, 1, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 1, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0, 1]  B=[1, 0, 0, 1, 1, 0]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 0, 1, 0, 1, 0]
  A=[0, 1, 0, 0, 1, 1]  B=[1, 0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 0, 1]  B=[1, 1, 0, 0, 1, 0]
  A=[0, 0, 1, 0, 1, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[0, 1, 1, 1, 0, 1]  B=[1, 0, 0, 0, 1, 0]
  A=[0, 1, 1, 0, 1, 1]  B=[1, 0, 0, 1, 0, 0]
  A=[0, 1, 0, 1, 1, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 1, 0]  B=[0, 1, 1, 1, 0, 1]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 1, 1, 0, 1, 1]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[1, 0, 0, 1, 1, 0]  B=[0, 1, 1, 0, 0, 1]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[1, 0, 1, 1, 0, 0]  B=[0, 1, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 1, 0]  B=[0, 0, 1, 1, 0, 1]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 0, 1, 0, 1, 1]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 1, 0]  B=[0, 1, 0, 0, 0, 1]
  A=[1, 1, 0, 1, 1, 0]  B=[0, 0, 1, 0, 0, 1]
  A=[1, 1, 1, 0, 1, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 1]

**Metric**
```python
def metric(data):
    import numpy as np

    # Feature index 5 is the unique lowest-validity expert and discriminates in every pair.
    a5 = data['option_a_ratings'].apply(lambda x: int(x[5])).to_numpy()
    resp = data['response'].to_numpy(dtype=float)

    # A choice is feature-5-consistent if it picks the option whose feature 5 equals 1.
    match = np.where(a5 == 1, 1.0 - resp, resp)
    return float(np.mean(match))

```

**Observed (real) value:** 0.8413 (var=0.0122)
**Previous candidate values (this loop):**
  - iter 1: 0.8450 (var=0.0016) (Δ vs real +0.0037)
  - iter 2: 0.8433 (var=0.0020) (Δ vs real +0.0021)
  - iter 3 (most recent): 0.8869 (var=0.0012) (Δ vs real +0.0456)
**Other theories' values on this metric (for reference):**
- pi_4: 0.6440 (var=0.0025)
- pi_6: 0.7856 (var=0.0023)
- pi_1: 0.1590 (var=0.0096)
- pi_2: 0.4971 (var=0.0017)
- pi_3: 0.3656 (var=0.0013)
- pi_5: 0.7935 (var=0.0075)
- pi_5_1: 0.7956 (var=0.0031)
- pi_5_2: 0.8431 (var=0.0024)
- pi_7: 0.8350 (var=0.0017)
- pi_7_1: 0.8244 (var=0.0014)
- pi_7_2: 0.8131 (var=0.0019)

### Experiment 15
**Design**
  A=[1, 0, 0, 1, 1, 0]  B=[0, 0, 1, 0, 0, 1]
  A=[1, 1, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 1, 1, 0, 1, 1]
  A=[1, 0, 0, 1, 1, 0]  B=[0, 1, 0, 0, 0, 1]
  A=[1, 1, 1, 0, 1, 0]  B=[0, 0, 1, 1, 0, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 0, 0]  B=[0, 1, 1, 0, 1, 1]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 0, 0, 1]
  A=[1, 1, 0, 1, 1, 0]  B=[0, 0, 1, 1, 0, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 1, 1]
  A=[1, 0, 1, 1, 0, 0]  B=[0, 1, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 0, 0]  B=[0, 1, 0, 0, 1, 1]
  A=[1, 1, 0, 1, 1, 0]  B=[0, 0, 1, 0, 1, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 1, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[0, 0, 1, 0, 0, 1]  B=[1, 0, 0, 1, 1, 0]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 1, 1, 0, 1, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 1, 1]  B=[1, 0, 1, 1, 0, 0]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 0, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 0, 1]  B=[1, 1, 1, 0, 1, 0]
  A=[0, 0, 1, 0, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 1, 1]  B=[1, 0, 1, 1, 0, 0]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 0, 1, 0, 1, 0]
  A=[0, 0, 1, 1, 0, 1]  B=[1, 1, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 0, 1]  B=[1, 1, 0, 0, 1, 0]
  A=[0, 1, 0, 1, 1, 1]  B=[1, 0, 1, 0, 1, 0]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[0, 0, 1, 0, 1, 1]  B=[1, 1, 0, 1, 1, 0]

**Metric**
```python
import numpy as np

def metric(data):
    validities = np.array([0.9, 0.8, 0.72, 0.61, 0.6, 0.6])
    ascending = np.argsort(validities, kind='stable')
    n_features = len(validities)
    window = 24
    low_cut = 2
    high_cut = 3
    min_trial = 30

    subject_scores = []
    for subject_id, subj in data.groupby('subject_id', sort=False):
        subj = subj.reset_index(drop=True)
        n = len(subj)
        if n <= min_trial:
            continue

        is_full = np.zeros(n, dtype=bool)
        back_cons = np.zeros(n, dtype=float)
        has_winner = np.zeros(n, dtype=bool)

        for i in range(n):
            a = np.asarray(subj.loc[i, 'option_a_ratings'], dtype=float)
            b = np.asarray(subj.loc[i, 'option_b_ratings'], dtype=float)
            diff = a - b
            n_disc = int(np.sum(diff != 0.0))
            tally = float(np.sum(diff))
            if n_disc >= n_features and abs(tally) <= 3.0:
                is_full[i] = True

            winner = -1
            for j in ascending:
                if a[j] > b[j]:
                    winner = 0
                    break
                if b[j] > a[j]:
                    winner = 1
                    break
            if winner < 0:
                continue
            has_winner[i] = True
            back_cons[i] = 1.0 if int(subj.loc[i, 'response']) == winner else 0.0

        prefix = np.concatenate((np.zeros(1), np.cumsum(is_full.astype(float))))
        low_mask = np.zeros(n, dtype=bool)
        high_mask = np.zeros(n, dtype=bool)
        eligible = np.zeros(n, dtype=bool)

        for i in range(n):
            if i < min_trial or i < window - 1:
                continue
            start = i - window + 1
            full_count = prefix[i + 1] - prefix[start]
            eligible[i] = True
            if full_count < low_cut:
                low_mask[i] = True
            elif full_count >= high_cut:
                high_mask[i] = True

        non_full = ~is_full
        low_sel = eligible & low_mask & non_full & has_winner
        high_sel = eligible & high_mask & non_full & has_winner

        if not low_sel.any() or not high_sel.any():
            continue

        low_mean = float(np.mean(back_cons[low_sel]))
        high_mean = float(np.mean(back_cons[high_sel]))
        subject_scores.append(high_mean - low_mean)

    if not subject_scores:
        return 0.0
    return float(np.mean(subject_scores))
```

**Observed (real) value:** 0.0553 (var=0.0224)
**Previous candidate values (this loop):**
  - iter 1: 0.0482 (var=0.0154) (Δ vs real -0.0070)
  - iter 2: 0.0320 (var=0.0162) (Δ vs real -0.0233)
  - iter 3 (most recent): 0.0794 (var=0.0217) (Δ vs real +0.0242)
**Other theories' values on this metric (for reference):**
- pi_6: 0.2099 (var=0.0205)
- pi_7: 0.0339 (var=0.0118)
- pi_1: 0.0181 (var=0.0166)
- pi_2: 0.1104 (var=0.0222)
- pi_3: 0.1243 (var=0.0156)
- pi_4: 0.0258 (var=0.0268)
- pi_5: 0.0293 (var=0.0291)
- pi_5_1: 0.0363 (var=0.0247)
- pi_5_2: 0.0421 (var=0.0316)
- pi_7_1: 0.0529 (var=0.0354)
- pi_7_2: 0.0482 (var=0.0137)

### Experiment 16
**Design**
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 0, 1, 0, 1, 1]
  A=[1, 1, 0, 0, 1, 0]  B=[0, 0, 1, 1, 0, 1]
  A=[1, 0, 1, 1, 0, 0]  B=[0, 1, 0, 0, 1, 1]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[1, 0, 0, 1, 1, 0]  B=[0, 1, 1, 0, 0, 1]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[0, 1, 1, 0, 0, 1]  B=[1, 0, 0, 1, 1, 0]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 0, 1, 0, 1, 0]
  A=[0, 1, 0, 0, 1, 1]  B=[1, 0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 0, 1]  B=[1, 1, 0, 0, 1, 0]
  A=[0, 0, 1, 0, 1, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[0, 1, 1, 1, 0, 1]  B=[1, 0, 0, 0, 1, 0]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[1, 0, 1, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[1, 0, 0, 1, 1, 0]  B=[0, 0, 1, 0, 0, 1]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 1, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 1, 0]  B=[0, 0, 1, 0, 0, 1]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[0, 1, 1, 0, 0, 1]  B=[1, 1, 0, 1, 1, 0]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 1, 1, 0, 1, 0]
  A=[0, 1, 0, 0, 1, 1]  B=[1, 1, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 0, 1]  B=[1, 1, 1, 0, 1, 0]
  A=[0, 0, 1, 0, 1, 1]  B=[1, 1, 1, 1, 0, 0]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0]
  A=[0, 1, 0, 0, 1, 1]  B=[1, 0, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    low_order = [3, 4, 5]
    burn = 24

    sub_diffs = []
    for _, sub in data.groupby('subject_id', sort=False):
        sub = sub.reset_index(drop=True)
        infos = []
        full_flags = []

        for _, row in sub.iterrows():
            a = np.asarray(row['option_a_ratings'], dtype=float)
            b = np.asarray(row['option_b_ratings'], dtype=float)
            d = a - b
            full_flags.append(1.0 if np.all(d != 0.0) else 0.0)

            if d[0] == 0:
                infos.append(None)
                continue

            top_dir = 1.0 if d[0] > 0 else -1.0
            low_dir = 0.0
            for j in low_order:
                if d[j] != 0.0:
                    low_dir = 1.0 if d[j] > 0 else -1.0
                    break

            if low_dir == 0.0:
                infos.append(None)
                continue

            top_choice = 0 if top_dir > 0 else 1
            matched = 1.0 if int(row['response']) == top_choice else 0.0
            aligned = top_dir * low_dir > 0
            infos.append((matched, aligned))

        aligned_vals = []
        conflict_vals = []

        for i in range(burn, len(sub)):
            window = full_flags[i - 23:i + 1]
            frac = float(np.mean(window))
            if frac < 0.5:
                continue

            info = infos[i]
            if info is None:
                continue

            matched, aligned = info
            if aligned:
                aligned_vals.append(matched)
            else:
                conflict_vals.append(matched)

        if len(aligned_vals) == 0 or len(conflict_vals) == 0:
            continue

        sub_diffs.append(float(np.mean(aligned_vals) - np.mean(conflict_vals)))

    if not sub_diffs:
        return 0.0
    return float(np.mean(sub_diffs))

```

**Observed (real) value:** 0.6412 (var=0.0315)
**Previous candidate values (this loop):**
  - iter 1: 0.6627 (var=0.0141) (Δ vs real +0.0215)
  - iter 2: 0.6093 (var=0.0275) (Δ vs real -0.0319)
  - iter 3 (most recent): 0.7073 (var=0.0179) (Δ vs real +0.0661)
**Other theories' values on this metric (for reference):**
- pi_7: 0.7974 (var=0.0100)
- pi_6: 0.6026 (var=0.0164)
- pi_1: -0.0026 (var=0.0106)
- pi_2: 0.2110 (var=0.0313)
- pi_3: 0.2314 (var=0.0135)
- pi_4: 0.3880 (var=0.0187)
- pi_5: 0.5215 (var=0.0194)
- pi_5_1: 0.4401 (var=0.0172)
- pi_5_2: 0.4013 (var=0.0236)
- pi_7_1: 0.7112 (var=0.0135)
- pi_7_2: 0.5998 (var=0.0119)

### Experiment 17
**Design**
  A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 1, 1, 1, 0]
  A=[1, 1, 0, 0, 0, 1]  B=[0, 0, 1, 1, 1, 0]
  A=[1, 1, 1, 0, 0, 1]  B=[0, 0, 0, 1, 1, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 1, 1, 1]
  A=[0, 1, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 1]  B=[0, 0, 0, 0, 1, 0]
  A=[1, 0, 1, 1, 1, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[1, 1, 0, 1, 1, 1]  B=[0, 0, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 1, 1]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 1, 1, 1, 1]
  A=[0, 0, 1, 0, 0, 0]  B=[1, 1, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 0, 0]  B=[1, 1, 1, 0, 1, 1]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 1, 1, 0, 1, 1]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 1, 0, 0, 1, 1]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 1, 1]
  A=[1, 0, 1, 1, 0, 0]  B=[0, 1, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 1]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 0, 1]  B=[1, 0, 0, 0, 1, 0]
  A=[0, 1, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 1, 1]  B=[1, 0, 1, 1, 0, 0]
  A=[0, 1, 0, 0, 1, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 1, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[0, 1, 1, 0, 0, 1]  B=[1, 0, 0, 1, 0, 0]
  A=[0, 1, 1, 0, 1, 1]  B=[1, 0, 0, 1, 1, 0]

**Metric**
```python
def metric(data):
    import numpy as np
    if data.empty:
        return 0.0
    A = np.asarray(data['option_a_ratings'].tolist(), dtype=float)
    B = np.asarray(data['option_b_ratings'].tolist(), dtype=float)
    y = data['response'].to_numpy(dtype=float)
    if A.ndim != 2 or A.shape[1] < 6:
        return 0.0
    d = A - B
    n_disc = np.sum(d != 0.0, axis=1)
    tally = np.sum(d, axis=1)
    d0 = d[:, 0]
    d4 = d[:, 4]
    d5 = d[:, 5]
    topA = (d0 > 0.0) & (d5 < 0.0) & (d4 <= 0.0) & (n_disc == 5) & (tally < 0.0)
    topB = (d0 < 0.0) & (d5 > 0.0) & (d4 >= 0.0) & (n_disc == 5) & (tally > 0.0)
    if topA.sum() == 0 or topB.sum() == 0:
        return 0.0
    pB_topA = float(np.mean(y[topA]))
    pB_topB = float(np.mean(y[topB]))
    return float(pB_topA - pB_topB)
```

**Observed (real) value:** 0.5710 (var=0.0228)
**Previous candidate values (this loop):**
  - iter 1: 0.6502 (var=0.0137) (Δ vs real +0.0793)
  - iter 2: 0.6107 (var=0.0340) (Δ vs real +0.0398)
  - iter 3 (most recent): 0.5942 (var=0.0287) (Δ vs real +0.0232)
**Other theories' values on this metric (for reference):**
- pi_6: 0.7742 (var=0.0080)
- pi_7_1: 0.5890 (var=0.0153)
- pi_1: -0.6544 (var=0.0529)
- pi_2: 0.7242 (var=0.0366)
- pi_3: 0.4645 (var=0.0136)
- pi_4: 0.4962 (var=0.0247)
- pi_5: 0.5211 (var=0.0189)
- pi_5_1: 0.5061 (var=0.0183)
- pi_5_2: 0.4869 (var=0.0207)
- pi_7: 0.7837 (var=0.0089)
- pi_7_2: 0.6696 (var=0.0158)

### Experiment 18
**Design**
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 0, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 1, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 1, 0, 1, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[1, 0, 1, 1, 1, 0]  B=[0, 1, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 1, 0]  B=[0, 1, 1, 0, 1, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 1, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 1, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[0, 0, 1, 0, 1, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 0, 0, 1, 0, 0]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 0, 0, 0, 1, 0]
  A=[0, 0, 1, 0, 0, 1]  B=[1, 0, 0, 1, 0, 0]
  A=[0, 0, 1, 0, 0, 1]  B=[1, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 1, 0, 1]  B=[1, 0, 0, 0, 1, 0]
  A=[0, 0, 1, 1, 1, 1]  B=[1, 1, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 1, 1]  B=[1, 1, 1, 0, 1, 0]

**Metric**
```python
def metric(data):
    import numpy as np
    validities = np.array([0.9, 0.8, 0.7, 0.6, 0.75, 0.73], dtype=float)
    ascending = np.argsort(validities, kind='stable')
    A = np.array(data['option_a_ratings'].tolist(), dtype=float)
    B = np.array(data['option_b_ratings'].tolist(), dtype=float)
    resp = data['response'].to_numpy()
    diff = A - B
    scores = []
    for i in range(diff.shape[0]):
        bwd = -1
        for j in ascending:
            if diff[i, j] > 0.0:
                bwd = 0
                break
            if diff[i, j] < 0.0:
                bwd = 1
                break
        if bwd != -1:
            scores.append(1.0 if int(resp[i]) == bwd else 0.0)
    if len(scores) == 0:
        return 0.5
    return float(np.mean(scores))
```

**Observed (real) value:** 0.6942 (var=0.0025)
**Previous candidate values (this loop):**
  - iter 1: 0.6969 (var=0.0023) (Δ vs real +0.0027)
  - iter 2: 0.6994 (var=0.0030) (Δ vs real +0.0052)
  - iter 3 (most recent): 0.7010 (var=0.0025) (Δ vs real +0.0069)
**Other theories' values on this metric (for reference):**
- pi_7_1: 0.7494 (var=0.0014)
- pi_6: 0.6875 (var=0.0016)
- pi_1: 0.6135 (var=0.0015)
- pi_2: 0.6225 (var=0.0032)
- pi_3: 0.6806 (var=0.0012)
- pi_4: 0.7056 (var=0.0015)
- pi_5: 0.7137 (var=0.0020)
- pi_5_1: 0.7254 (var=0.0025)
- pi_5_2: 0.7427 (var=0.0023)
- pi_7: 0.6952 (var=0.0018)
- pi_7_2: 0.6940 (var=0.0015)

### Experiment 19
**Design**
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 1, 1, 1]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 1, 1, 0, 1, 1]
  A=[1, 0, 0, 0, 1, 0]  B=[0, 1, 1, 1, 0, 1]
  A=[0, 0, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 1, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 1, 1]  B=[1, 0, 0, 1, 0, 0]
  A=[0, 1, 1, 1, 0, 1]  B=[1, 0, 0, 0, 1, 0]
  A=[1, 0, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 1, 0, 1, 0]
  A=[1, 0, 0, 0, 1, 1]  B=[0, 1, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 0, 1, 1, 1, 1]
  A=[0, 0, 1, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 0, 1, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[0, 1, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 0, 1, 1]
  A=[1, 0, 0, 0, 1, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 1, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 1, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[1, 0, 0, 1, 1, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 0, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    matches = []
    for a, b, r in zip(data['option_a_ratings'], data['option_b_ratings'], data['response']):
        a = np.asarray(a, dtype=int)
        b = np.asarray(b, dtype=int)
        n = len(a)
        predicted = None
        for j in range(n - 1, -1, -1):
            if a[j] > b[j]:
                predicted = 0
                break
            if b[j] > a[j]:
                predicted = 1
                break
        if predicted is None:
            continue
        matches.append(1.0 if int(r) == predicted else 0.0)
    if not matches:
        return 0.5
    return float(np.mean(matches))
```

**Observed (real) value:** 0.8229 (var=0.0143)
**Previous candidate values (this loop):**
  - iter 1: 0.8121 (var=0.0024) (Δ vs real -0.0108)
  - iter 2: 0.8010 (var=0.0024) (Δ vs real -0.0219)
  - iter 3 (most recent): 0.8221 (var=0.0031) (Δ vs real -0.0008)
**Other theories' values on this metric (for reference):**
- pi_6: 0.8956 (var=0.0010)
- pi_7_2: 0.7469 (var=0.0020)
- pi_1: 0.3421 (var=0.0038)
- pi_2: 0.7871 (var=0.0041)
- pi_3: 0.7315 (var=0.0017)
- pi_4: 0.7377 (var=0.0020)
- pi_5: 0.7367 (var=0.0025)
- pi_5_1: 0.7421 (var=0.0024)
- pi_5_2: 0.7667 (var=0.0025)
- pi_7: 0.8817 (var=0.0013)
- pi_7_1: 0.8394 (var=0.0015)

### Experiment 20
**Design**
  A=[1, 0, 1, 1, 0]  B=[0, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[1, 1, 0, 1, 0]  B=[0, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 1, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 0]  B=[0, 1, 1, 0, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 0, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 0, 1]
  A=[0, 0, 0, 0, 1]  B=[1, 0, 1, 1, 0]
  A=[0, 1, 0, 0, 1]  B=[1, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 1]  B=[1, 1, 0, 1, 0]
  A=[0, 0, 1, 0, 1]  B=[1, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 1]  B=[1, 1, 1, 0, 0]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 1, 0]
  A=[0, 0, 1, 0, 1]  B=[1, 0, 0, 1, 0]
  A=[0, 0, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[0, 1, 1, 0, 1]  B=[1, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[0, 1, 0, 0, 1]  B=[1, 0, 0, 1, 0]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 1]  B=[1, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[0, 1, 0, 0, 1]  B=[1, 0, 1, 0, 0]
  A=[0, 0, 1, 0, 1]  B=[1, 1, 0, 0, 0]

**Metric**
```python
def metric(data):
    import numpy as np
    diffs = []
    for _, sub in data.groupby('subject_id', sort=False):
        a0 = np.asarray([row[0] for row in sub['option_a_ratings']], dtype=float)
        b0 = np.asarray([row[0] for row in sub['option_b_ratings']], dtype=float)
        choose_a = 1.0 - np.asarray(sub['response'], dtype=float)
        top_a = a0 > b0
        top_b = b0 > a0
        if top_a.sum() > 0 and top_b.sum() > 0:
            diffs.append(float(choose_a[top_b].mean() - choose_a[top_a].mean()))
    if not diffs:
        return 0.0
    return float(np.mean(diffs))

```

**Observed (real) value:** 0.7500 (var=0.0460)
**Previous candidate values (this loop):**
  - iter 1: 0.7492 (var=0.0045) (Δ vs real -0.0008)
  - iter 2: 0.7646 (var=0.0061) (Δ vs real +0.0146)
  - iter 3 (most recent): 0.7733 (var=0.0059) (Δ vs real +0.0233)
**Other theories' values on this metric (for reference):**
- pi_7_2: 0.7579 (var=0.0046)
- pi_6: 0.1904 (var=0.0169)
- pi_1: -0.7171 (var=0.0279)
- pi_2: -0.2275 (var=0.0126)
- pi_3: -0.5117 (var=0.0038)
- pi_4: 0.2121 (var=0.0085)
- pi_5: 0.6608 (var=0.0409)
- pi_5_1: 0.6263 (var=0.0230)
- pi_5_2: 0.7292 (var=0.0140)
- pi_7: 0.1779 (var=0.0155)
- pi_7_1: 0.6825 (var=0.0041)

## PREVIOUS CANDIDATE (this loop)
The RUNNING-BEST (last ACCEPTED) candidate in this critique loop — i.e. the source the loop's accept gate kept as the best base so far. If your most recent attempt was REJECTED by the gate, this is NOT that attempt; it is the previously-accepted base the gate rolled back to. Iterate on this source — the next critic feedback should be applied on top of it.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np

    stim = np.asarray(state, dtype=float)
    if stim.ndim == 3 and stim.shape[0] == 1:
        stim = stim[0]
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError('Expected a (2, n_features) stimulus.')

    a = stim[0]
    b = stim[1]
    n_features = int(stim.shape[1])

    validities = parameters.get('validities')
    if validities is None:
        validities = list(np.linspace(0.9, 0.5, n_features))
    validities = np.asarray(validities, dtype=float)
    if validities.ndim == 0 or validities.shape[0] != n_features:
        validities = np.linspace(0.9, 0.5, n_features)

    descending = np.argsort(-validities, kind='stable')
    ascending = np.argsort(validities, kind='stable')

    def lex_probabilities(x, y, order, beta):
        winner = None
        for j in order:
            if x[j] > y[j]:
                winner = 0
                break
            if y[j] > x[j]:
                winner = 1
                break
        if winner is None:
            return np.full(2, 0.5, dtype=float)
        z = float(beta) if winner == 0 else -float(beta)
        p_a = 1.0 / (1.0 + np.exp(-z))
        return np.array([p_a, 1.0 - p_a], dtype=float)

    beta_forward = float(parameters['beta_forward'])
    beta_backward = float(parameters['beta_backward'])
    beta_backward_strong = float(parameters['beta_backward_strong'])
    beta_tally = float(parameters['beta_tally'])

    p_forward = lex_probabilities(a, b, descending, beta_forward)
    p_backward = lex_probabilities(a, b, ascending, beta_backward)
    p_shift = lex_probabilities(a, b, ascending, beta_backward_strong)

    a_wins = float(np.sum(a > b))
    b_wins = float(np.sum(b > a))
    tally_scores = np.array([a_wins, b_wins], dtype=float)
    z = beta_tally * (tally_scores - np.max(tally_scores))
    e = np.exp(z)
    p_tally = e / np.sum(e)

    w_forward = float(parameters['w_forward'])
    w_backward = float(parameters['w_backward'])
    w_tally = 1.0 - w_forward - w_backward
    if w_tally < 0.0:
        w_tally = 0.0
    weights = np.array([w_forward, w_backward, w_tally], dtype=float)
    weights = weights / np.sum(weights)
    p_base = weights[0] * p_forward + weights[1] * p_backward + weights[2] * p_tally

    tie_margin = float(parameters['tie_margin'])
    hi_idx = int(descending[0])
    lo_idx = int(ascending[0])

    if n_features == 6:
        min_discrim_count = 5
    elif n_features == 5:
        min_discrim_count = 4
    else:
        min_discrim_count = int(np.ceil(0.75 * max(1, n_features)))

    base_evidence = float(parameters['base_evidence'])
    hi_lo_bonus = float(parameters['hi_lo_bonus'])
    near_full_evidence_scale = float(parameters['near_full_evidence_scale'])
    opposing_evidence_scale = float(parameters['opposing_evidence_scale'])
    opposing_full_evidence_scale = float(parameters['opposing_full_evidence_scale'])
    opposing_full_strong_scale = float(parameters['opposing_full_strong_scale'])
    special_evidence_cap = float(parameters['special_evidence_cap'])

    def trial_evidence(x, y):
        x = np.asarray(x, dtype=float)
        y = np.asarray(y, dtype=float)
        d = x - y
        n_discrim = int(np.sum(d != 0.0))
        if n_discrim < min_discrim_count:
            return 0.0

        tally = float(np.sum(d))
        hi_dir = int(np.sign(d[hi_idx]))
        lo_dir = int(np.sign(d[lo_idx]))
        if hi_dir == 0 or lo_dir == 0 or hi_dir == lo_dir:
            return 0.0

        # Narrow special branch for six-feature 5-of-6 trials where the
        # highest and lowest cues disagree but the tally mildly opposes the
        # highest cue.  Its output is explicitly capped below aligned-evidence
        # saturation so these patterns reverse less than fully dense conflicts.
        if (n_features == 6 and n_discrim == 5 and abs(tally) <= 2.0
                and tally * hi_dir < 0.0):
            special = opposing_evidence_scale * (base_evidence + hi_lo_bonus)
            return float(min(1.0, special, special_evidence_cap))

        # Graded positive evidence for fully discriminating trials whose
        # tally opposes the highest cue.  Near-tied full conflicts are the
        # strongest trigger; strong one-against-all opposition contributes
        # only weakly to protect sparse top-cue designs.
        if n_discrim == n_features and tally * hi_dir < 0.0:
            if abs(tally) <= tie_margin:
                opp_scale = opposing_full_evidence_scale
            else:
                opp_scale = opposing_full_strong_scale
            return float(min(1.0, opp_scale * (base_evidence + hi_lo_bonus)))

        if abs(tally) > tie_margin:
            return 0.0
        if tally * hi_dir < 0.0:
            return 0.0

        if n_discrim == n_features:
            density_gain = 1.0
        else:
            density_gain = near_full_evidence_scale
        return float(min(1.0, (base_evidence + hi_lo_bonus) * density_gain))

    evidence_seq = []
    full_flags = []
    past_a = history.get('option_a_ratings', [])
    past_b = history.get('option_b_ratings', [])
    n_past = min(len(past_a), len(past_b))
    for i in range(n_past):
        x = np.asarray(past_a[i], dtype=float)
        y = np.asarray(past_b[i], dtype=float)
        evidence_seq.append(trial_evidence(x, y))
        full_flags.append(1.0 if np.all((x - y) != 0.0) else 0.0)
    evidence_seq.append(trial_evidence(a, b))
    full_flags.append(1.0 if np.all((a - b) != 0.0) else 0.0)

    evidence_rise = float(parameters['evidence_rise'])
    evidence_decay = float(parameters['evidence_decay'])
    zero_decay_boost = float(parameters['zero_decay_boost'])
    threshold = float(parameters['conflict_threshold'])
    saturation = float(parameters['saturation_evidence'])
    hysteresis = float(parameters['hysteresis'])
    activation_rise = float(parameters['activation_rise'])
    activation_decay = float(parameters['activation_decay'])
    min_qual = int(parameters['min_qualifying_count'])
    qualifying_window = int(parameters['qualifying_window'])
    full_frac_window = int(parameters['full_frac_window'])
    s_max = float(parameters['s_max'])
    full_penalty_start = float(parameters['full_penalty_start'])
    full_penalty_depth = float(parameters['full_penalty_depth'])
    full_penalty_width = float(parameters['full_penalty_width'])
    full_penalty_floor = float(parameters['full_penalty_floor'])

    X = 0.0
    S = 0.0

    for idx, u in enumerate(evidence_seq):
        if u >= X:
            X += evidence_rise * (u - X)
        else:
            decay_mult = zero_decay_boost if u <= 0.0 else 1.0
            X -= evidence_decay * decay_mult * (X - u)
        X = float(np.clip(X, 0.0, 1.0))

        q_start = max(0, idx - qualifying_window + 1)
        recent_q = np.asarray(evidence_seq[q_start:idx + 1], dtype=float)
        n_recent_qual = int(np.sum(recent_q > 0.0))

        f_start = max(0, idx - full_frac_window + 1)
        recent_flags = np.asarray(full_flags[f_start:idx + 1], dtype=float)
        window_len = idx - f_start + 1
        full_frac = float(np.sum(recent_flags > 0.5)) / max(1, window_len)

        center = full_penalty_start + full_penalty_width
        if full_frac <= full_penalty_start:
            full_penalty = 0.0
        elif full_frac <= center:
            full_penalty = full_penalty_depth * (full_frac - full_penalty_start) / full_penalty_width
        else:
            fall_end = center + full_penalty_width
            if full_frac >= fall_end:
                full_penalty = full_penalty_floor
            else:
                full_penalty = full_penalty_depth - (full_penalty_depth - full_penalty_floor) * (full_frac - center) / full_penalty_width
        full_penalty = float(np.clip(full_penalty, 0.0, 1.0))
        s_max_eff = s_max * (1.0 - full_penalty)

        if n_recent_qual < min_qual:
            target = 0.0
        else:
            threshold_eff = threshold - hysteresis if S > 0.5 else threshold
            if X <= threshold_eff:
                target = 0.0
            elif X >= saturation:
                target = s_max_eff
            else:
                target = s_max_eff * ((X - threshold_eff) / (saturation - threshold_eff + 1e-9))

        target = float(np.clip(target, 0.0, max(s_max_eff, 1e-9)))
        if target > S:
            S += activation_rise * (target - S)
        else:
            S -= activation_decay * (S - target)
        S = float(np.clip(S, 0.0, s_max_eff))

    s = float(np.clip(S, 0.0, s_max))
    p = (1.0 - s) * p_base + s * p_shift

    epsilon = float(parameters.get('epsilon', 0.0))
    if epsilon > 0.0:
        p = (1.0 - epsilon) * p + epsilon * np.full(2, 0.5, dtype=float)

    p = np.clip(p, 0.0, None)
    return p / np.sum(p)


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=float)
    if probs.size == 0:
        return 0
    probs = probs / probs.sum()
    return int(np.random.choice(probs.size, p=probs))


`parameters`:
- w_forward: [0.18, 0.34]
- w_backward: [0.36, 0.54]
- beta_forward: [0.08, 0.22]
- beta_backward: [1.20, 1.60]
- beta_tally: [1.80, 2.70]
- beta_backward_strong: [2.70, 3.30]
- tie_margin: {3}
- base_evidence: [0.58, 0.74]
- hi_lo_bonus: [0.16, 0.34]
- near_full_evidence_scale: [0.78, 0.92]
- opposing_evidence_scale: [0.22, 0.32]
- opposing_full_evidence_scale: [0.32, 0.52]
- opposing_full_strong_scale: [0.02, 0.06]
- special_evidence_cap: [0.08, 0.14]
- evidence_rise: [0.22, 0.50]
- evidence_decay: [0.04, 0.16]
- zero_decay_boost: [1.20, 2.80]
- conflict_threshold: [0.02, 0.06]
- saturation_evidence: [0.18, 0.34]
- hysteresis: [0.01, 0.06]
- activation_rise: [0.15, 0.35]
- activation_decay: [0.03, 0.09]
- min_qualifying_count: {3, 4}
- qualifying_window: {16}
- full_frac_window: {16}
- s_max: [0.80, 0.88]
- full_penalty_start: [0.24, 0.34]
- full_penalty_depth: [0.34, 0.44]
- full_penalty_width: [0.12, 0.20]
- full_penalty_floor: [0.12, 0.18]
- epsilon: {0}
- validities: validities

`rationale`: This revision directly implements the arbiter's four changes while keeping the sparse-design protection intact. First, fully discriminating trials whose tally opposes the highest cue now emit graded positive evidence: near-tied full conflicts use a moderately strong opposing_full_evidence_scale, while strong one-against-all opposition is kept very weak so dense complementary designs reverse without destroying top-cue effects in sparse designs. Second, the existing five-of-six opposing branch is retained but explicitly capped by special_evidence_cap below aligned-evidence saturation, pushing the relevant five-of-six dynamic effect downward. Third, the full-diagnostic penalty is relaxed mainly through a lower full_penalty_floor, with full_penalty_depth only slightly reduced, which lifts low-cue agreement in all-complementary designs while leaving mixed full-fraction designs such as the top-cue experiments near their previous negative values. Fourth, the subject-level parameter ranges for the mixture weights, lexicographic strengths, evidence rise/decay, threshold, and saturation strength are widened to produce the larger between-subject variability seen in the data. Hysteresis, minimum qualifying count, activation smoothing, and the capped route remain in place to preserve the near-zero sparse-design active-inactive contrasts.

## PRIOR FEEDBACK ITERATIONS
The critic's verdicts on each previous in-loop candidate, in order. Each block ends with an **Outcome of this advice** line saying whether the candidate the proposer produced AFTER this advice was ACCEPTED (loss strictly beat the running best) or REJECTED (the gate discarded it). Address the most recent iteration's feedback in your next edit, but down-weight past advice whose candidates were REJECTED.

### Iteration 1
Verdict: regenerate
Interpretation: The candidate faithfully implements the arbiter's prescribed mechanism family: a baseline mixture of forward/backward lexicographic scans plus tallying, a leaky evidence accumulator with asymmetric rise/decay, a minimum qualifying count, hysteresis, and a full-diagnostic penalty that caps the strengthened backward route. Point estimates are excellent on several experiments (E14, E18, E20, E15, E16, E9, E10, E12, E19), and the candidate preserves near-zero sparse-design contrasts in most cases. However, several key patterns remain miscalibrated, and the between-subject variance is still systematically too low relative to the observed data. In particular: (1) E17's special 5-of-6 opposing-tally effect remains 0.650 vs observed 0.571, despite the arbiter's request to bring it toward 0.55-0.60; (2) E13 low-cue agreement is 0.781 vs observed 0.8425, indicating the full-diagnostic penalty still suppresses activation too much in dense complementary designs; (3) E7 top-cue choice is 0.220 vs observed 0.155, E6 reversal is -0.606 vs -0.671, and E4 is -0.234 vs -0.274, suggesting reversal strength is not yet correctly graded across dense designs; (4) E11's sparse-gate contrast is -0.067 vs -0.005 and E8 flips sign, so the sparse-design protection is imperfect; and (5) the subject-level variance is far too small on many metrics (e.g., E5 var 0.0058 vs 0.0598, E6 0.0123 vs 0.0489, E20 0.0045 vs 0.0460, E19 0.0024 vs 0.0143), meaning the arbiter's fourth instruction to widen subject-level parameter ranges has not been achieved.
Rationale: Keep the same accumulator/lexicographic-mixture architecture, but recalibrate within it. (a) Tighten the special 5-of-6 opposing branch further: lower special_evidence_cap to roughly [0.02, 0.06] and opposing_evidence_scale to roughly [0.08, 0.18], or make its evidence decay faster, so E17 drops toward 0.57 without changing aligned full-conflict evidence. (b) Relax the full-diagnostic penalty more aggressively: lower full_penalty_floor to around [0.03, 0.10], reduce full_penalty_depth to around [0.20, 0.30], and/or raise s_max to around [0.85, 0.95], which should lift E13 toward 0.84 while monitoring E18/E19 for overshoot. (c) Rebalance reversal strength for E4/E6/E7: modestly raise w_backward (e.g., [0.40, 0.60]) and beta_backward (e.g., [1.3, 1.8]) or increase activation_rise/saturation for dense conflicts, but compensate with the tighter special branch so E17 does not rise. (d) Widen subject-level ranges substantially (roughly 2-4x) for w_forward, w_backward, beta_backward, beta_backward_strong, s_max, evidence_rise, evidence_decay, conflict_threshold, saturation_evidence, and the full-penalty parameters; optionally add a small epsilon in [0, 0.05] to increase choice noise. This should bring simulated variances closer to the observed values, especially E5, E6, E19, and E20. (e) Re-check sparse gating for E8/E11, e.g., raise min_discrim_count or lower near_full_evidence_scale for six-feature sparse designs, to keep those contrasts near zero. These are minor in-family calibrations, not a change of mechanism.

**Outcome of this advice:** iter 1 candidate loss=0.0415 -> iter 2 candidate loss=0.0513 -> the gate marked it REJECTED.

### Iteration 2
Verdict: regenerate
Interpretation: The current candidate is a mixed bag. It matches the real point estimates well on E1, E2, E3, E4, E5, E14, and E18, and it improves E13 and E17 relative to iter1, but it creates large new errors in the dense static reversal designs E6 (delta +0.148 against real -0.671) and E7 (delta +0.096 against real 0.155), and it flips or degrades several sparse-gate contrasts: E9 moves to +0.017 instead of -0.028, E10 to +0.020 instead of -0.001, and E12 to +0.002 instead of -0.018. E19 also moved the wrong way, from 0.812 at iter1 to 0.801 here, against the observed 0.823. The most likely culprit is the new broad rule returning zero evidence for every six-feature 5-of-6 trial with abs(tally) < 2. That rule suppresses the dense-but-not-full hi-lo conflict trials needed to reverse choices in E6/E7, while it does not actually protect the sparse E9/E10/E11/E12 contrasts. The E17-specific suppression is also too broad because it keys only on n_discrim == 5 and abs(tally) <= 2, ignoring the feature-4 relation that defines E17's topA/topB cells. In addition, between-subject variance remains systematically too small, e.g. E5 0.013 vs observed 0.060, E6 0.028 vs 0.049, E13 0.003 vs 0.010, E14 0.002 vs 0.012, E19 0.002 vs 0.014, and E20 0.006 vs 0.046. The widened parameter ranges do not propagate into choice-level variance because the lexicographic softmax utilities saturate.
Rationale: Rebuild from the iter1 accepted base, not from this rejected attempt. (1) Remove the global six-feature dense-but-not-full zero gate. Let 5-of-6 trials with abs(tally) == 1 contribute graded evidence at roughly 0.4 to 0.7 times the full-diagnostic evidence. This should push E6 back toward -0.67 and E7 toward 0.15 without requiring a broad sparse gate. (2) Keep the E17 suppression but make it pattern-specific: apply the small cap only when the 5-of-6 trial also satisfies d4 * sign(hi_dir) <= 0, the condition used by the E17 metric. That holds E17 near 0.57 to 0.60 while releasing the E6/E7 trials. Do not continue lowering the special branch globally, which is what damaged E6, E7, and E19 in this round. (3) For E13 and E19 low-cue agreement, make a smaller local adjustment to the full-diagnostic penalty instead of broad relaxation: reduce the penalty width or floor by about 0.02 to 0.04 and/or shift s_max up by 0.02 to 0.04, while watching E14 and E18 so they do not overshoot. (4) Fix variance at the choice level, since parameter range widening alone failed. Increase epsilon to approximately [0.02, 0.10] or [0.03, 0.12], possibly with a subject distribution concentrated near the low end, and/or add a subject-level temperature that multiplicatively scales beta_forward, beta_backward, beta_tally, and beta_backward_strong in about [0.7, 1.3]. This directly generates between-subject choice variation for E5, E6, E20, E13, E14, and E19 while preserving low-variance patterns such as E18 and E3 if the low end remains populated. (5) For sparse-gate protection, do not reintroduce the broad zero branch; instead rely on the existing min_qualifying_count, hysteresis, and threshold, possibly raising conflict_threshold by 0.01 to 0.02 so E9, E10, E11, and E12 stay within about 0.02 of zero and avoid the sign flips seen here. These are small in-family calibrations of the same accumulator and lexicographic-mixture architecture.

**Outcome of this advice:** iter 2 candidate loss=0.0513 -> iter 3 candidate loss=0.0539 -> the gate marked it REJECTED.

### Iteration 3 (most recent — address this)
Verdict: regenerate
Interpretation: The current candidate is a rejected attempt: the aggregate loss moved from the accepted iter1 value of 0.0415 to 0.0539. The point-estimate improvement is very uneven. The candidate gets E19 almost exactly right, 0.8221 versus the observed 0.8229, and brings E17 close to target, 0.5942 versus 0.5710, but these gains are paid for by large overshoots elsewhere. E14 rises to 0.8869 versus 0.8413, E15 to 0.0794 versus 0.0553, E16 to 0.7073 versus 0.6412, and E20 to 0.7733 versus 0.7500. The sparse-design contrasts also flip or degrade: E8 is -0.0337 versus +0.0150, E9 is +0.0025 versus -0.0283, E10 is +0.0092 versus -0.0008, and E12 is +0.0178 versus -0.0178. E11 improves to -0.0100 versus -0.0050, but that is the only sparse-design gain. E13 remains too low at 0.7881 versus 0.8425, which shows that the full-penalty and s_max relaxation fixed the wrong low-cue cells while overshooting E14, E15, and E16. E6 and E7 are still insufficiently reversed at -0.6183 versus -0.6711 and 0.2040 versus 0.1553. The between-subject variances remain too small on most metrics, but the previous variance-focused mechanisms also appear to have contributed to the point-estimate instability rather than fixing the core fitting problem.
Rationale: The next proposal should reset to the accepted iter1 base and make a much narrower patch, because both previous broad recalibration attempts were rejected by the accept gate. The prior advice to relax the full-diagnostic penalty, add the sparse evidence damp, and introduce choice-level temperature produced exactly the overshoots and sign flips visible here, so that direction should not be repeated. Instead: (1) port only the E17-specific suppression from the current candidate, namely the pattern gated on d4 times sign(hi_dir) being nonpositive for five-of-six cells, because that was the one change that moved E17 from 0.650 toward 0.571 without wrecking E6/E7; (2) keep the iter1 full-penalty, s_max, and sparse-gate settings untouched, because iter1 already matched E14, E18, E20, E9, E10, and E12 closely; (3) do not reintroduce sparse_evidence_damp or the wider temp_scale and epsilon variance machinery this round; (4) if a second small change is needed, raise the evidence scale only for the non-E17 five-of-six opposing trials by about 0.05 and jointly monitor E6, E7, E1, and E19, since E6 and E7 still need slightly more reversal; (5) leave E13 for a later, very small s_max adjustment of no more than 0.01 to 0.02 if needed, rather than the larger relaxation that just caused E14, E15, and E16 to overshoot.

**Outcome of this advice:** iter 3 candidate loss=0.0539 -> next candidate accept-status=PENDING (this is the advice you are addressing now).


## IMPLEMENTATION GUARDRAILS
- The parameters should be within the specified ranges.
- The model's predictions should be valid probability distributions (non-negative and sum to 1).
- When converting logits to probabilities via softmax, always use the numerically stable form: subtract the max before exponentiating (`x = x - np.max(x); p = np.exp(x); p /= p.sum()`). A naive `np.exp(x) / np.sum(np.exp(x))` overflows to Inf/NaN for large logits. Alternatively, use `scipy.special.softmax`.


## PROPOSAL — MINIMAL-DIFF EDIT (do NOT rewrite from scratch)
The RUNNING-BEST (last ACCEPTED) candidate is shown verbatim above under `## PREVIOUS CANDIDATE (this loop)`. This is the base the loop's accept gate is currently keeping; the most recent critic feedback (see `## PRIOR FEEDBACK ITERATIONS`) should be applied on top of it. Apply the SMALLEST edit that addresses the critic's diagnosis while staying inside the arbiter's prescribed mechanism family:
  - Re-emit the previous source verbatim, then change ONLY the lines needed to address the critic (a parameter range, a normalization, a softmax temperature, an attention scheme, a gating term, a buggy indexing line, etc.).
  - Keep the theory's prose claim implicit but unchanged, and keep all unaffected functions, equations, parameter names, and the overall mechanism intact.
  - Do NOT rewrite `predict` / `policy` end-to-end if a few lines would do, and do NOT switch mechanism families — that is the arbiter's decision, not yours in this loop.
  - Briefly explain the minimal edit in `rationale`.
If you genuinely believe a larger rewrite is required, you may do one, but justify in `rationale` why the minimal-diff path was insufficient.

## RESPONSE FORMAT
Return a JSON object with the following fields:
- predict: Python source defining def predict(parameters, state, history) -> np.ndarray.
- policy: Python source defining def policy(probs) -> int.
- parameters: Parameter ranges (e.g. "[1.0, 10.0]") or choices (e.g. "{1, 2}"), sampled per subject.
- rationale: Reasoning behind this model design; used to explain why this model is better then the previous ones.


## Response

```json
```json
{
  "predict": "def predict(parameters, state, history):\n    import numpy as np\n\n    stim = np.asarray(state, dtype=float)\n    if stim.ndim == 3 and stim.shape[0] == 1:\n        stim = stim[0]\n    if stim.ndim != 2 or stim.shape[0] != 2:\n        raise ValueError('Expected a (2, n_features) stimulus.')\n\n    a = stim[0]\n    b = stim[1]\n    n_features = int(stim.shape[1])\n\n    validities = parameters.get('validities')\n    if validities is None:\n        validities = list(np.linspace(0.9, 0.5, n_features))\n    validities = np.asarray(validities, dtype=float)\n    if validities.ndim == 0 or validities.shape[0] != n_features:\n        validities = np.linspace(0.9, 0.5, n_features)\n\n    descending = np.argsort(-validities, kind='stable')\n    ascending = np.argsort(validities, kind='stable')\n\n    def lex_probabilities(x, y, order, beta):\n        winner = None\n        for j in order:\n            if x[j] > y[j]:\n                winner = 0\n                break\n            if y[j] > x[j]:\n                winner = 1\n                break\n        if winner is None:\n            return np.full(2, 0.5, dtype=float)\n        z = float(beta) if winner == 0 else -float(beta)\n        p_a = 1.0 / (1.0 + np.exp(-z))\n        return np.array([p_a, 1.0 - p_a], dtype=float)\n\n    beta_forward = float(parameters['beta_forward'])\n    beta_backward = float(parameters['beta_backward'])\n    beta_backward_strong = float(parameters['beta_backward_strong'])\n    beta_tally = float(parameters['beta_tally'])\n\n    p_forward = lex_probabilities(a, b, descending, beta_forward)\n    p_backward = lex_probabilities(a, b, ascending, beta_backward)\n    p_shift = lex_probabilities(a, b, ascending, beta_backward_strong)\n\n    a_wins = float(np.sum(a > b))\n    b_wins = float(np.sum(b > a))\n    tally_scores = np.array([a_wins, b_wins], dtype=float)\n    z = beta_tally * (tally_scores - np.max(tally_scores))\n    e = np.exp(z)\n    p_tally = e / np.sum(e)\n\n    w_forward = float(parameters['w_forward'])\n    w_backward = float(parameters['w_backward'])\n    w_tally = 1.0 - w_forward - w_backward\n    if w_tally < 0.0:\n        w_tally = 0.0\n    weights = np.array([w_forward, w_backward, w_tally], dtype=float)\n    weights = weights / np.sum(weights)\n    p_base = weights[0] * p_forward + weights[1] * p_backward + weights[2] * p_tally\n\n    tie_margin = float(parameters['tie_margin'])\n    hi_idx = int(descending[0])\n    lo_idx = int(ascending[0])\n\n    if n_features == 6:\n        min_discrim_count = 5\n    elif n_features == 5:\n        min_discrim_count = 4\n    else:\n        min_discrim_count = int(np.ceil(0.75 * max(1, n_features)))\n\n    base_evidence = float(parameters['base_evidence'])\n    hi_lo_bonus = float(parameters['hi_lo_bonus'])\n    near_full_evidence_scale = float(parameters['near_full_evidence_scale'])\n    opposing_evidence_scale = float(parameters['opposing_evidence_scale'])\n    opposing_full_evidence_scale = float(parameters['opposing_full_evidence_scale'])\n    opposing_full_strong_scale = float(parameters['opposing_full_strong_scale'])\n    special_evidence_cap = float(parameters['special_evidence_cap'])\n    special_evidence_released = float(parameters['special_evidence_released'])\n\n    def trial_evidence(x, y):\n        x = np.asarray(x, dtype=float)\n        y = np.asarray(y, dtype=float)\n        d = x - y\n        n_discrim = int(np.sum(d != 0.0))\n        if n_discrim < min_discrim_count:\n            return 0.0\n\n        tally = float(np.sum(d))\n        hi_dir = int(np.sign(d[hi_idx]))\n        lo_dir = int(np.sign(d[lo_idx]))\n        if hi_dir == 0 or lo_dir == 0 or hi_dir == lo_dir:\n            return 0.0\n\n        # Six-feature five-of-six trials where the highest and lowest cues\n        # disagree and the tally mildly opposes the highest cue.  The E17\n        # topA/topB cells are the subset where the second-lowest cue (index 4)\n        # also fails to support the highest cue (d4 * sign(hi_dir) <= 0); those\n        # get a strong suppression so the E17 dynamic effect lands near\n        # 0.55-0.60 instead of 0.65.  Every other five-of-six opposing-tally\n        # conflict keeps gently graded evidence, about 0.05 above the old\n        # blanket cap, so dense reversal designs are not starved.\n        if (n_features == 6 and n_discrim == 5 and abs(tally) <= 2.0\n                and tally * hi_dir < 0.0):\n            if d[4] * hi_dir <= 0.0:\n                special = opposing_evidence_scale * (base_evidence + hi_lo_bonus)\n                return float(min(1.0, special, special_evidence_cap))\n            return float(min(1.0, special_evidence_released))\n\n        # Graded positive evidence for fully discriminating trials whose\n        # tally opposes the highest cue.  Near-tied full conflicts are the\n        # strongest trigger; strong one-against-all opposition contributes\n        # only weakly to protect sparse top-cue designs.\n        if n_discrim == n_features and tally * hi_dir < 0.0:\n            if abs(tally) <= tie_margin:\n                opp_scale = opposing_full_evidence_scale\n            else:\n                opp_scale = opposing_full_strong_scale\n            return float(min(1.0, opp_scale * (base_evidence + hi_lo_bonus)))\n\n        if abs(tally) > tie_margin:\n            return 0.0\n        if tally * hi_dir < 0.0:\n            return 0.0\n\n        if n_discrim == n_features:\n            density_gain = 1.0\n        else:\n            density_gain = near_full_evidence_scale\n        return float(min(1.0, (base_evidence + hi_lo_bonus) * density_gain))\n\n    evidence_seq = []\n    full_flags = []\n    past_a = history.get('option_a_ratings', [])\n    past_b = history.get('option_b_ratings', [])\n    n_past = min(len(past_a), len(past_b))\n    for i in range(n_past):\n        x = np.asarray(past_a[i], dtype=float)\n        y = np.asarray(past_b[i], dtype=float)\n        evidence_seq.append(trial_evidence(x, y))\n        full_flags.append(1.0 if np.all((x - y) != 0.0) else 0.0)\n    evidence_seq.append(trial_evidence(a, b))\n    full_flags.append(1.0 if np.all((a - b) != 0.0) else 0.0)\n\n    evidence_rise = float(parameters['evidence_rise'])\n    evidence_decay = float(parameters['evidence_decay'])\n    zero_decay_boost = float(parameters['zero_decay_boost'])\n    threshold = float(parameters['conflict_threshold'])\n    saturation = float(parameters['saturation_evidence'])\n    hysteresis = float(parameters['hysteresis'])\n    activation_rise = float(parameters['activation_rise'])\n    activation_decay = float(parameters['activation_decay'])\n    min_qual = int(parameters['min_qualifying_count'])\n    qualifying_window = int(parameters['qualifying_window'])\n    full_frac_window = int(parameters['full_frac_window'])\n    s_max = float(parameters['s_max'])\n    full_penalty_start = float(parameters['full_penalty_start'])\n    full_penalty_depth = float(parameters['full_penalty_depth'])\n    full_penalty_width = float(parameters['full_penalty_width'])\n    full_penalty_floor = float(parameters['full_penalty_floor'])\n\n    X = 0.0\n    S = 0.0\n\n    for idx, u in enumerate(evidence_seq):\n        if u >= X:\n            X += evidence_rise * (u - X)\n        else:\n            decay_mult = zero_decay_boost if u <= 0.0 else 1.0\n            X -= evidence_decay * decay_mult * (X - u)\n        X = float(np.clip(X, 0.0, 1.0))\n\n        q_start = max(0, idx - qualifying_window + 1)\n        recent_q = np.asarray(evidence_seq[q_start:idx + 1], dtype=float)\n        n_recent_qual = int(np.sum(recent_q > 0.0))\n\n        f_start = max(0, idx - full_frac_window + 1)\n        recent_flags = np.asarray(full_flags[f_start:idx + 1], dtype=float)\n        window_len = idx - f_start + 1\n        full_frac = float(np.sum(recent_flags > 0.5)) / max(1, window_len)\n\n        center = full_penalty_start + full_penalty_width\n        if full_frac <= full_penalty_start:\n            full_penalty = 0.0\n        elif full_frac <= center:\n            full_penalty = full_penalty_depth * (full_frac - full_penalty_start) / full_penalty_width\n        else:\n            fall_end = center + full_penalty_width\n            if full_frac >= fall_end:\n                full_penalty = full_penalty_floor\n            else:\n                full_penalty = full_penalty_depth - (full_penalty_depth - full_penalty_floor) * (full_frac - center) / full_penalty_width\n        full_penalty = float(np.clip(full_penalty, 0.0, 1.0))\n        s_max_eff = s_max * (1.0 - full_penalty)\n\n        if n_recent_qual < min_qual:\n            target = 0.0\n        else:\n            threshold_eff = threshold - hysteresis if S > 0.5 else threshold\n            if X <= threshold_eff:\n                target = 0.0\n            elif X >= saturation:\n                target = s_max_eff\n            else:\n                target = s_max_eff * ((X - threshold_eff) / (saturation - threshold_eff + 1e-9))\n\n        target = float(np.clip(target, 0.0, max(s_max_eff, 1e-9)))\n        if target > S:\n            S += activation_rise * (target - S)\n        else:\n            S -= activation_decay * (S - target)\n        S = float(np.clip(S, 0.0, s_max_eff))\n\n    s = float(np.clip(S, 0.0, s_max))\n    p = (1.0 - s) * p_base + s * p_shift\n\n    epsilon = float(parameters.get('epsilon', 0.0))\n    if epsilon > 0.0:\n        p = (1.0 - epsilon) * p + epsilon * np.full(2, 0.5, dtype=float)\n\n    p = np.clip(p, 0.0, None)\n    return p / np.sum(p)\n",
  "policy": "def policy(probs):\n    import numpy as np\n    probs = np.asarray(probs, dtype=float)\n    if probs.size == 0:\n        return 0\n    probs = probs / probs.sum()\n    return int(np.random.choice(probs.size, p=probs))\n",
  "parameters": {
    "w_forward": "[0.18, 0.34]",
    "w_backward": "[0.36, 0.54]",
    "beta_forward": "[0.08, 0.22]",
    "beta_backward": "[1.20, 1.60]",
    "beta_tally": "[1.80, 2.70]",
    "beta_backward_strong": "[2.70, 3.30]",
    "tie_margin": "{3}",
    "base_evidence": "[0.58, 0.74]",
    "hi_lo_bonus": "[0.16, 0.34]",
    "near_full_evidence_scale": "[0.78, 0.92]",
    "opposing_evidence_scale": "[0.08, 0.18]",
    "opposing_full_evidence_scale": "[0.32, 0.52]",
    "opposing_full_strong_scale": "[0.02, 0.06]",
    "special_evidence_cap": "[0.02, 0.06]",
    "special_evidence_released": "[0.12, 0.20]",
    "evidence_rise": "[0.22, 0.50]",
    "evidence_decay": "[0.04, 0.16]",
    "zero_decay_boost": "[1.20, 2.80]",
    "conflict_threshold": "[0.02, 0.06]",
    "saturation_evidence": "[0.18, 0.34]",
    "hysteresis": "[0.01, 0.06]",
    "activation_rise": "[0.15, 0.35]",
    "activation_decay": "[0.03, 0.09]",
    "min_qualifying_count": "{3, 4}",
    "qualifying_window": "{16}",
    "full_frac_window": "{16}",
    "s_max": "[0.80, 0.88]",
    "full_penalty_start": "[0.24, 0.34]",
    "full_penalty_depth": "[0.34, 0.44]",
    "full_penalty_width": "[0.12, 0.20]",
    "full_penalty_floor": "[0.12, 0.18]",
    "epsilon": "{0}",
    "validities": "validities"
  },
  "rationale": "Minimal-diff edit on the ACCEPTED iter1 base, following exactly the latest critic's narrow-patch prescription. In trial_evidence, the six-feature five-of-six opposing-tally branch is now split by the E17 pattern gate d4 * sign(hi_dir) <= 0 (the condition defining E17's topA/topB metric cells): only those cells get the hard suppression, and the cap is lowered to [0.02, 0.06] (with opposing_evidence_scale lowered to [0.08, 0.18]), so the E17 dynamic effect drops from ~0.65 toward 0.55-0.60. All other five-of-six opposing-tally conflicts now emit graded evidence via special_evidence_released [0.12, 0.20], roughly 0.05 above the old blanket cap, so dense reversal designs keep accumulating without the broad release that caused iter3's overshoots. Crucially, nothing else changes: the full-diagnostic penalty, s_max, sparse gates, hysteresis, min-qualifying-count, and the temperature/epsilon machinery all remain at the accepted iter1 settings, which already matched E14, E18, E20, E9, E10, and E12 closely. E13, E6, and E7 are intentionally left at their iter1 values for a later, separately-monitored calibration rather than risking the E14/E15/E16 overshoot and E8/E9/E10/E12 sign flips that sank the previous broad recalibration attempts."
}
```
```

## Usage

```json
{
  "input_tokens": 63251,
  "output_tokens": 44900,
  "reasoning_tokens": 40972,
  "provider": "Novita"
}
```
