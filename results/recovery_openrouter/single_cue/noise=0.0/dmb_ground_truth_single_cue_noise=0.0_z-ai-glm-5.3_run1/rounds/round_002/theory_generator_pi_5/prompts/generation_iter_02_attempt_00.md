# generation_iter_02_attempt_00

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

Replace pi_3 with a 'Skeptical (Inverted-Trust) Tallying' theory. Keep the proven architecture — integrate ALL binary ratings as sign votes (+1/-1/0 per feature), sum into a zero-sum evidence score, pass through a two-option softmax with inverse temperature beta and a small uniform lapse epsilon — but replace the weight function with a NON-MONOTONE function of stated validity: w(v) = s * ((v - v_lo) * (v_hi - v))^rho, i.e., an inverted-U 'trust band'. Interpretation: (i) chance-level experts (v ~ 0.5) are treated as carrying no information, with a slightly negative effective weight (v_lo just above 0.5, e.g., v_lo in [0.50, 0.56], so w(0.5) is zero-to-slightly-negative) — this reproduces Exp 1's small negative chance-cue sensitivity (-0.168) while staying near the pi_4-like annihilation that the data only mildly violate; (ii) intermediate validities (roughly 0.55-0.85) receive positive weight, peaking around v ~ 0.65-0.75, so mid-range experiments (Exps 3-6) reduce to a low-gain weighted tally, preserving the near-exact fits both incumbents already achieve there (Exp 3 ~ -0.22, Exp 4 ~ +0.08 with b_s pushed toward zero or negative because the top cue is discounted, Exp 5 ~ 0.6 tally-following, Exp 6 near-chance |d|=1 agreement via small effective margins); (iii) near-certain experts (v >= v_hi, with v_hi in [0.80, 0.95]) fall off the trust band into strongly reduced or NEGATIVE weight (the 'too-perfect-to-trust' inversion; deepen the negative lobe with an extra parameter or exponent so |w(0.99)| >> |w(0.51)|) — this is what drives Exp 2's SSR down to the observed 0.118, since margins like w(0.99) - 2*w(0.51) become large and negative while w(0.75)-driven cells (R3) stay near 0.5. Suggested parameter ranges: v_lo in [0.50, 0.56], v_hi in [0.80, 0.95], rho in [0.5, 2] (curvature of the trust band), a negative-lobe scale factor in [0, 3], beta in [0.5, 3], epsilon in [0.05, 0.25]. An equivalent generative framing, if a stochastic policy is preferred: each discriminating cue's vote is sign-flipped with probability phi(v) that rises steeply for v near 1 (distrust of near-perfect experts) and is slightly above 0.5 for v near 0.5, yielding the same expected-weight profile. The new theory differs from both incumbents in the only dimension the data actually discriminate: the SIGN and non-monotonicity of the validity-to-weight map, rather than its slope or compression.

## THEORY LEADERBOARD
A small set of prior picked theories shown for reference. Overall score is in `[0, 1]`, higher = better, computed as `1 - L2_norm(normalized_per_experiment_distances) / max_L2_norm`. 1.0 means closest to the real value on every experiment+metric pair; 0.0 means farthest. Each entry below carries the same depth of detail as the PREVIOUS MODEL INSTANCE above so you can borrow concrete mechanisms when useful.

### `pi_3` (overall score: 0.665)

**Description**
Validity-Weighted Tallying (graded-evidence regime): people integrate evidence from ALL binary expert ratings, casting each feature a sign vote (+1 win / -1 loss / 0 tie) weighted by w_j = validity_j^gamma, summing into a zero-sum evidence score, with choice a softmax (inverse temperature beta) over the two scores plus an independent uniform lapse (epsilon). The theoretical claim added this round is about where humans sit in this family: in the UNSATURATED softmax regime. Because the evidence scores are integer-scale sign tallies, beta >= 3 already drives tanh(beta*m) ~ 1 for every unit margin, making the model behaviorally deterministic and pinning it to the tallying corner; the graded dose-response in tally margin that both experiments demand (Exp 1 metric at 44% of the deterministic-tally value; Exp 2's small positive b_d) lives at beta ~ 0.2-0.3, where p(A) is approximately linear in the tally margin. Gamma stays in a mild, provably sub-lexicographic band so that no subject leaps into the TTB regime.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    # Validity-Weighted Tallying.
    # Stimulus: array of shape (2, n_features); row 0 = option A,
    # row 1 = option B; entries are binary expert ratings.
    # Each feature j casts a vote sign(a_j - b_j) for A's score and
    # the opposite for B's score; votes are weighted by w_j =
    # validity_j ** gamma. gamma = 0 -> unweighted Tallying;
    # gamma -> large -> lexicographic TTB (top cue dominates).
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

    gamma = float(parameters["gamma"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    a, b = stim[0], stim[1]

    # Feature-wise votes: +1 where A wins the feature, -1 where B
    # wins, 0 on ties (a tied cue is uninformative for the pair).
    votes = np.sign(a - b)

    # Validity-based weights. Since validities are in [0.5, 1.0],
    # gamma = 0 gives all-ones weights (pure Tallying); increasing
    # gamma increasingly privileges high-validity cues, with the
    # top cue dominating as gamma grows (TTB limit).
    w = np.power(val, gamma)

    # Weighted evidence scores. B's score is the mirror of A's
    # because every vote is zero-sum across the two options.
    s_a = float(np.dot(w, votes))
    scores = np.array([s_a, -s_a])

    # Numerically stable softmax over the two weighted scores.
    # When all cues tie (s_a == 0) the softmax is exactly uniform,
    # which is the correct behavior for an undiscriminating tally.
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()

    # Independent lapse: with probability epsilon output a uniform
    # pick over the two options.
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)

`policy(probs) -> int`:
def policy(probabilities):
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()  # guard against float drift
    return int(np.random.choice(len(probabilities), p=probabilities))

`parameters`:
- gamma: [0.05, 0.7]
- beta: [0.03, 0.55]
- epsilon: [0.0, 0.08]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=-0.2180 (var=0.0140) vs this=-0.2182 (var=0.0156)
- Experiment 2: real=0.0771 (var=0.0031) vs this=0.0861 (var=0.0026)
- Experiment 3: real=0.6170 (var=0.0034) vs this=0.6456 (var=0.0096)
- Experiment 4: real=0.5133 (var=0.0042) vs this=0.6062 (var=0.0085)
- Experiment 5: real=-0.1683 (var=0.0124) vs this=0.2958 (var=0.0606)
- Experiment 6: real=0.1180 (var=0.0074) vs this=0.4190 (var=0.0107)


---

### `pi_4` (overall score: 0.514)

**Description**
Flattened-Diagnosticity Evidence Integration (the extreme-compression corner of the Bayesian cue-counting family): people integrate ALL binary expert ratings into one evidence score, where each discriminating cue casts a sign vote weighted by w_j = max(log(v_j/(1-v_j)) - tau, 0)^delta — chance cues (v=0.5) are annihilated exactly, but among genuinely diagnostic cues the subjective weight is a HEAVILY flattened (delta ~ 0.15) version of the normative log-odds, and choice is a low-gain softmax (2*beta ~ 0.6) plus a small uniform lapse. The new theoretical claim is that the compression exponent delta is itself the structural margin-compression device: shrinking delta equalizes weights, which GROWS count-dominated conflict margins (where cues split across options) while SHRINKING alignment-dominated cumulative margins (where several strong cues pile onto one side). This differential action — not any global gain knob, and not trial-level normalization — is what lets a single small beta simultaneously produce moderate TTB-leaning conflict-trial behavior (Exp 1), a slightly positive tally-vs-top-cue regression slope (Exp 2), graded ~0.62 tally-following (Exp 3), and near-chance |d|=1 agreement driven by the cancellation between super-expert matches and super-expert reversals (Exp 4).

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    # Diagnosticity-Weighted Evidence Integration (Bayesian cue-counting).
    # Stimulus: array of shape (2, n_features); row 0 = option A,
    # row 1 = option B; entries are binary expert ratings (0/1).
    # Each feature j casts a sign vote sign(a_j - b_j); the vote is
    # weighted by the cue's log-likelihood-ratio diagnosticity
    # llr_j = log(v_j / (1 - v_j)), rectified by an attention floor
    # tau and compressed by an exponent delta:
    #   w_j = (max(llr_j - tau, 0))^delta
    # A v = 0.5 expert has llr = 0 -> exactly zero evidence.
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

    delta = float(parameters["delta"])
    tau = float(parameters["tau"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    a, b = stim[0], stim[1]

    # Feature-wise votes: +1 where A wins the feature, -1 where B
    # wins, 0 on ties (a tied cue is uninformative for the pair).
    votes = np.sign(a - b)

    # Normative diagnosticity: log-likelihood-ratio of each expert.
    # Clip away from v = 1.0 to keep the log finite; v = 0.5 maps to 0.
    v = np.clip(val, 0.5, 1.0 - 1e-9)
    llr = np.log(v / (1.0 - v))

    # Limited-attention floor: diagnosticity below tau is discarded;
    # the remainder is compressed by the exponent delta. delta = 1 is
    # the purely normative Bayesian weight; delta < 1 flattens the
    # diagnosticity gradient toward tallying over informative cues
    # (while v = 0.5 cues stay annihilated at any delta, since
    # llr(0.5) = 0 <= tau); delta > 1 sharpens it toward
    # lexicographic/TTB-like use of the best experts.
    w = np.power(np.maximum(llr - tau, 0.0), delta)

    # Weighted evidence score. B's score is the mirror of A's because
    # every vote is zero-sum across the two options.
    s_a = float(np.dot(w, votes))
    scores = np.array([s_a, -s_a])

    # Numerically stable low-temperature softmax. When all attended
    # cues tie (s_a == 0) the softmax is exactly uniform, which is the
    # correct behavior for undiscriminating evidence.
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()

    # Independent lapse: with probability epsilon output a uniform
    # pick over the two options.
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)

`policy(probs) -> int`:
def policy(probabilities):
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()  # guard against float drift
    return int(np.random.choice(len(probabilities), p=probabilities))

`parameters`:
- delta: [0.1, 0.2]
- tau: [0.0, 0.04]
- beta: [0.27, 0.37]
- epsilon: [0.0, 0.05]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=-0.2180 (var=0.0140) vs this=-0.2188 (var=0.0064)
- Experiment 2: real=0.0771 (var=0.0031) vs this=0.0881 (var=0.0019)
- Experiment 3: real=0.6170 (var=0.0034) vs this=0.6485 (var=0.0027)
- Experiment 4: real=0.5133 (var=0.0042) vs this=0.5192 (var=0.0023)
- Experiment 5: real=-0.1683 (var=0.0124) vs this=0.0308 (var=0.0233)
- Experiment 6: real=0.1180 (var=0.0074) vs this=0.7670 (var=0.0039)


---

### `pi_2` (overall score: 0.042)

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
- Experiment 1: real=-0.2180 (var=0.0140) vs this=-0.4425 (var=0.0124)
- Experiment 2: real=0.0771 (var=0.0031) vs this=0.1196 (var=0.0023)
- Experiment 3: real=0.6170 (var=0.0034) vs this=0.8389 (var=0.0095)
- Experiment 4: real=0.5133 (var=0.0042) vs this=0.8387 (var=0.0140)
- Experiment 5: real=-0.1683 (var=0.0124) vs this=0.7617 (var=0.0356)
- Experiment 6: real=0.1180 (var=0.0074) vs this=0.1180 (var=0.0091)


## LOSS TRAJECTORY (this propose-loop)
Aggregate loss across iterations of THIS propose-loop (lower = better, 0 = perfect, `+inf` = unscorable). The ACCEPTED / REJECTED tag is the loop's programmatic accept-gate decision — only ACCEPTED candidates have ever been used as the base for a subsequent iteration. Use this together with PRIOR FEEDBACK ITERATIONS below to grade which past critic advice actually paid off.

- iter 1: loss=0.2087 -> ACCEPTED
- iter 2: loss=0.3342 -> REJECTED
Running-best (last ACCEPTED) base: iter 1 at loss=0.2087 — this is the source shown verbatim below under `## PREVIOUS CANDIDATE (this loop)`. Push the next edit's loss strictly below that floor or the gate will reject it.

## EXPERIMENTAL RESULTS
### Experiment 1
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1]  B=[1, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    rows_a = data["option_a_ratings"].tolist()
    rows_b = data["option_b_ratings"].tolist()
    resp = data["response"].tolist()
    n_rows = len(rows_a)
    contribs = []
    for i in range(n_rows):
        ca = rows_a[i]
        cb = rows_b[i]
        if isinstance(ca, str):
            ca = ca.replace("[", " ").replace("]", " ").replace(",", " ").split()
        if isinstance(cb, str):
            cb = cb.replace("[", " ").replace("]", " ").replace(",", " ").split()
        a = [int(float(v)) for v in ca]
        b = [int(float(v)) for v in cb]
        r = int(resp[i])
        n = len(a)
        if n == 0 or n != len(b):
            continue
        ttb = -1
        for j in range(n):
            if a[j] > b[j]:
                ttb = 0
                break
            if b[j] > a[j]:
                ttb = 1
                break
        if ttb < 0:
            continue
        aw = 0
        bw = 0
        for j in range(n):
            if a[j] > b[j]:
                aw = aw + 1
            elif b[j] > a[j]:
                bw = bw + 1
        if aw == bw:
            if r == ttb:
                contribs.append(0.5)
            else:
                contribs.append(-0.5)
        else:
            if bw > aw:
                tal = 1
            else:
                tal = 0
            if tal == ttb:
                continue
            if r == ttb:
                contribs.append(1.0)
            else:
                contribs.append(-1.0)
    if len(contribs) == 0:
        return 0.0
    total = 0.0
    for c in contribs:
        total = total + c
    return float(total / len(contribs))
```

**Observed (real) value:** -0.2180 (var=0.0140)
**Previous candidate values (this loop):**
  - iter 1: -0.1698 (var=0.0371) (Δ vs real +0.0482)
  - iter 2 (most recent): -0.6840 (var=0.0037) (Δ vs real -0.4660)
**Other theories' values on this metric (for reference):**
- pi_1: 0.6130 (var=0.0149)
- pi_2: -0.4425 (var=0.0124)
- pi_3: -0.2182 (var=0.0156)
- pi_4: -0.2188 (var=0.0064)

### Experiment 2
**Design**
  A=[1, 1, 0, 1, 1, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 0, 1]  B=[0, 0, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0, 1]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 0, 1, 1, 1, 0]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 0, 0, 0]  B=[1, 1, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 0, 0]  B=[1, 0, 1, 0, 0, 1]
  A=[0, 1, 1, 0, 1, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[0, 0, 0, 1, 0, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 1, 0]  B=[0, 0, 1, 1, 0, 0]
  A=[0, 1, 1, 1, 1, 0]  B=[1, 1, 0, 0, 1, 1]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Dual-dissociation regression metric.
    # Per trial, compute:
    #   d = tally margin  = (#features A wins) - (#features B wins)
    #   s = top-cue direction = sign(A[0] - B[0])   (feature 0 has the
    #       highest validity 0.92, and every designed pair discriminates on it)
    # Regress chose-A on [1, d, s] via OLS and return b_d - b_s.
    # Tallying: choice probability depends only on d  -> b_d > 0, b_s = 0 -> metric > 0.
    # TTB: choice probability depends only on s       -> b_d = 0, b_s > 0 -> metric < 0.
    # The two theories push this scalar in opposite directions, and the
    # partial regression cleanly removes the design's d-s correlation.
    df = data.reset_index(drop=True)

    A = np.stack([np.asarray(list(r), dtype=float) for r in df["option_a_ratings"].values])
    B = np.stack([np.asarray(list(r), dtype=float) for r in df["option_b_ratings"].values])

    # Tally margin: strict feature-wise wins; ties count for neither side.
    d = (A > B).sum(axis=1).astype(float) - (B > A).sum(axis=1).astype(float)

    # Direction of the highest-validity (top) cue, which always discriminates
    # in this design: +1 if it favors A, -1 if it favors B.
    s = np.sign(A[:, 0] - B[:, 0])

    # Chose-A indicator (response: 0 = A, 1 = B).
    y = 1.0 - df["response"].to_numpy(dtype=float)

    X = np.column_stack([np.ones(len(y)), d, s])
    coef, _, _, _ = np.linalg.lstsq(X, y, rcond=None)
    b_d = float(coef[1])
    b_s = float(coef[2])

    # Tallying's signature (slope in d) minus TTB's signature (slope in s).
    return b_d - b_s
```

**Observed (real) value:** 0.0771 (var=0.0031)
**Previous candidate values (this loop):**
  - iter 1: 0.0941 (var=0.0138) (Δ vs real +0.0170)
  - iter 2 (most recent): 0.4565 (var=0.0013) (Δ vs real +0.3795)
**Other theories' values on this metric (for reference):**
- pi_2: 0.1196 (var=0.0023)
- pi_1: -0.3725 (var=0.0076)
- pi_3: 0.0861 (var=0.0026)
- pi_4: 0.0881 (var=0.0019)

### Experiment 3
**Design**
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 0, 1, 0, 1, 1]
  A=[1, 0, 1, 1, 0, 0]  B=[0, 1, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0, 1]  B=[0, 0, 1, 1, 1, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 1, 0]  B=[1, 1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 1, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0]
  A=[1, 0, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 0]  B=[1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 0, 1]
  A=[0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Tally-following rate on decisive trials.

    For every trial, compute the raw (unweighted) tally margin
    d = (# cues where A wins) - (# cues where B wins).
    On trials with d != 0, check whether the subject's choice agrees
    with the option favored by the raw cue count (A if d > 0, B if
    d < 0). The metric is the fraction of such agreement over all
    decisive trials (d = 0 trials are excluded because the tallying
    heuristic itself is indifferent there).
    """
    df = data.reset_index(drop=True)
    n = len(df)
    if n == 0:
        return 0.5

    a_lists = df['option_a_ratings'].tolist()
    b_lists = df['option_b_ratings'].tolist()
    resp = df['response'].to_numpy(dtype=float)

    d = np.empty(n, dtype=float)
    for i in range(n):
        a = np.asarray(a_lists[i], dtype=float)
        b = np.asarray(b_lists[i], dtype=float)
        d[i] = float(np.sum(a > b) - np.sum(b > a))

    decisive = d != 0.0
    if not np.any(decisive):
        return 0.5

    dd = d[decisive]
    rr = resp[decisive]
    # Option favored by the raw tally: A (response 0) if d > 0,
    # otherwise B (response 1).
    agree = np.where(dd > 0.0, rr == 0.0, rr == 1.0)
    return float(np.mean(agree))
```

**Observed (real) value:** 0.6170 (var=0.0034)
**Previous candidate values (this loop):**
  - iter 1: 0.4130 (var=0.0083) (Δ vs real -0.2041)
  - iter 2 (most recent): 0.2493 (var=0.0009) (Δ vs real -0.3678)
**Other theories' values on this metric (for reference):**
- pi_3: 0.6456 (var=0.0096)
- pi_2: 0.8389 (var=0.0095)
- pi_1: 0.6944 (var=0.0071)
- pi_4: 0.6485 (var=0.0027)

### Experiment 4
**Design**
  A=[1, 1, 0, 1, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0, 0, 1]  B=[1, 0, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 1, 0, 0, 1]
  A=[0, 1, 0, 1, 0, 0, 0, 0]  B=[1, 1, 0, 1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0, 0, 0]  B=[1, 0, 1, 0, 0, 0, 0, 1]
  A=[1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1]
  A=[0, 0, 1, 0, 1, 0, 0, 1]  B=[1, 1, 1, 0, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 0, 0, 1, 1]  B=[1, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 1, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 1, 1, 1]
  A=[1, 1, 1, 0, 0, 1, 0, 0]  B=[0, 0, 1, 0, 0, 1, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Hard-ceiling test on the |d|=1 family (FACT 1 of the design).

    Metric = proportion of choices that agree with the UNWEIGHTED tally
    count-winner, restricted to trials whose raw tally margin is exactly
    +/-1 (the 8 trial types t1-t8; 48 of the 96 trials per subject).

    Tallying (any beta >= 1, any epsilon) predicts ~1 - epsilon/2 here,
    i.e. >= ~0.85 for any moderate lapse. The validity-weighted
    competitor is structurally capped: its choice probability on a |d|=1
    trial is (1-eps)*sigmoid(2*beta*m) with m = sum_j v_j^gamma*sign diff;
    the mean of |m| over the 8 |d|=1 trial types is <= 1 for every
    gamma in [0.05, 0.7] (equality only at gamma=0), and beta <= 0.55,
    so by concavity of tanh its mean agreement on this family is
    <= 0.5 + tanh(0.55)/2 = 0.750 over its ENTIRE parameter box.
    """
    def _mat(col):
        vals = []
        for v in col:
            if isinstance(v, np.ndarray):
                vals.append(v)
            else:
                vals.append(list(v))
        return np.asarray(vals, dtype=float)

    A = _mat(data["option_a_ratings"])
    B = _mat(data["option_b_ratings"])
    resp = np.asarray(data["response"], dtype=float)

    if A.ndim != 2 or A.shape[0] == 0 or A.shape != B.shape:
        return 0.5

    # Raw (unweighted) tally margin per trial.
    d = (A > B).sum(axis=1) - (B > A).sum(axis=1)

    # The |d| = 1 family: 8 unique pairs x 6 reps = 48 trials/subject.
    mask = np.abs(d) == 1
    if mask.sum() < 10:
        # Defensive fallback: use all non-tied trials.
        mask = d != 0
    if mask.sum() == 0:
        return 0.5

    dm = d[mask]
    rm = resp[mask]
    # Count-winner is A when d>0 (response 0), B when d<0 (response 1).
    consistent = np.where(dm > 0, rm == 0, rm == 1)
    return float(np.mean(consistent))
```

**Observed (real) value:** 0.5133 (var=0.0042)
**Previous candidate values (this loop):**
  - iter 1: 0.4579 (var=0.0034) (Δ vs real -0.0554)
  - iter 2 (most recent): 0.3454 (var=0.0018) (Δ vs real -0.1679)
**Other theories' values on this metric (for reference):**
- pi_2: 0.8387 (var=0.0140)
- pi_3: 0.6062 (var=0.0085)
- pi_1: 0.6825 (var=0.0042)
- pi_4: 0.5192 (var=0.0023)

### Experiment 5
**Design**
  A=[1, 0, 1, 0, 1, 1, 0, 1]  B=[1, 0, 1, 0, 1, 0, 0, 1]
  A=[0, 1, 0, 1, 0, 1, 1, 1]  B=[0, 1, 0, 1, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 1, 1, 1, 1]  B=[1, 1, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 1, 1, 1]
  A=[0, 1, 0, 1, 1, 1, 0, 1]  B=[1, 1, 0, 1, 1, 0, 0, 1]
  A=[0, 0, 1, 0, 1, 1, 1, 0]  B=[1, 0, 1, 0, 1, 0, 0, 0]
  A=[0, 1, 1, 1, 0, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 1, 1, 0, 1, 0]  B=[0, 0, 0, 1, 1, 0, 1, 0]
  A=[1, 1, 0, 0, 1, 0, 0, 1]  B=[0, 1, 0, 0, 1, 1, 1, 1]
  A=[1, 0, 1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 1, 1, 1]
  A=[1, 1, 1, 0, 1, 1, 0, 1]  B=[1, 1, 1, 0, 0, 0, 0, 1]
  A=[0, 1, 0, 1, 0, 1, 1, 0]  B=[0, 1, 0, 1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 1, 1, 1]  B=[1, 0, 1, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 0, 0, 1, 0]  B=[0, 0, 0, 0, 1, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 1, 0, 1]  B=[1, 1, 1, 1, 0, 1, 0, 1]

**Metric**
```python
import numpy as np
import pandas as pd


def metric(data: pd.DataFrame) -> float:
    # Chance-cue sensitivity on "chance-only" (Z-family) trials.
    # Design validities: [0.95, 0.85, 0.75, 0.65, 0.5, 0.5, 0.5, 0.5]
    # -> features 0-3 are diagnostic, features 4-7 are the four v=0.5 experts.
    # A Z-family trial is one where ALL diagnostic cues tie, so the pair is
    # discriminated ONLY by the 50%-accurate experts. On such a trial let
    # k = net number of chance cues won by A (signed). The competing theory
    # (llr-rectified weights) annihilates v=0.5 cues exactly, so p(A)=0.5
    # regardless of k -> subjects match the k-implied side at chance (metric 0).
    # My theory gives v=0.5 cues weight 0.5^gamma, so choices should follow
    # sign(k) above chance (metric > 0).
    DIAG = [0, 1, 2, 3]
    CHANCE = [4, 5, 6, 7]

    a_ratings = data["option_a_ratings"].apply(lambda x: np.asarray(list(x), dtype=int))
    b_ratings = data["option_b_ratings"].apply(lambda x: np.asarray(list(x), dtype=int))
    responses = data["response"].to_numpy()

    correct = []
    for av, bv, r in zip(a_ratings, b_ratings, responses):
        if av.shape[0] != 8 or bv.shape[0] != 8:
            continue
        # Keep only trials where every diagnostic cue ties (chance-only trials)
        if not np.array_equal(av[DIAG], bv[DIAG]):
            continue
        # Net chance-cue advantage for A
        k = int(np.sign(av[CHANCE] - bv[CHANCE]).sum())
        if k == 0:
            continue
        chose_a = (int(r) == 0)  # response: 0 = A, 1 = B
        followed = (k > 0 and chose_a) or (k < 0 and not chose_a)
        correct.append(1.0 if followed else 0.0)

    if len(correct) == 0:
        return 0.0
    # 2 * (accuracy - 0.5): 0 = chance-level following of chance cues,
    # positive = subjects systematically follow the 50%-accurate experts.
    return 2.0 * (float(np.mean(correct)) - 0.5)
```

**Observed (real) value:** -0.1683 (var=0.0124)
**Previous candidate values (this loop):**
  - iter 1: -0.1267 (var=0.0576) (Δ vs real +0.0417)
  - iter 2 (most recent): -0.2767 (var=0.0749) (Δ vs real -0.1083)
**Other theories' values on this metric (for reference):**
- pi_3: 0.2958 (var=0.0606)
- pi_4: 0.0308 (var=0.0233)
- pi_1: 0.1625 (var=0.0145)
- pi_2: 0.7617 (var=0.0356)

### Experiment 6
**Design**
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 0]  B=[0, 0, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1]  B=[0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1]
  A=[1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Strong-Side Choice Rate on Multi-Weak Conflict trials (SSR).

    Selects the five conflict cells in which a high-validity side (99%
    experts, or 75% experts for R3) faces TWO OR MORE opposing weak
    experts: K2 (1x99 vs 2 weak), K3 (1x99 vs 3 weak), M3 (2x99 vs 3
    weak), M4 (2x99 vs 4 weak), R3 (2x75 vs 3 weak) -- 5 unique pairs
    x 2 mirrors x 4 reps = 40 trials per subject. Returns the
    proportion of trials on which the subject chose the strong side.
    """
    hits = 0
    n = 0

    a_col = data['option_a_ratings']
    b_col = data['option_b_ratings']
    r_col = data['response']

    for a, b, r in zip(a_col, b_col, r_col):
        a = [int(x) for x in a]
        b = [int(x) for x in b]
        if len(a) < 8 or len(b) < 8:
            continue

        # Validity-class vote balances (features 0-1 = 0.99 experts,
        # 2-3 = 0.75 experts, 4-7 = weak experts).
        d_hi = (a[0] + a[1]) - (b[0] + b[1])
        d_mid = (a[2] + a[3]) - (b[2] + b[3])
        d_lo = (a[4] + a[5] + a[6] + a[7]) - (b[4] + b[5] + b[6] + b[7])

        # K2/K3/M3/M4: super experts alone on one side (no 75s involved)
        # opposing >= 2 weak experts.
        if d_mid == 0 and d_hi != 0 and abs(d_lo) >= 2:
            target_is_a = d_hi > 0
        # R3: two 75% experts vs three weak experts.
        elif d_hi == 0 and abs(d_mid) == 2 and abs(d_lo) == 3:
            target_is_a = d_mid > 0
        else:
            # Excludes K1 (|d_lo|=1), R1, W2/W3 (no strong side),
            # W4a (|d_mid|=1), G1 (mixed 99+75 side), X1 (all tied).
            continue

        n += 1
        chose_a = (int(r) == 0)
        if chose_a == target_is_a:
            hits += 1

    if n == 0:
        return 0.5
    return hits / n

```

**Observed (real) value:** 0.1180 (var=0.0074)
**Previous candidate values (this loop):**
  - iter 1: 0.4845 (var=0.0348) (Δ vs real +0.3665)
  - iter 2 (most recent): 0.2055 (var=0.0012) (Δ vs real +0.0875)
**Other theories' values on this metric (for reference):**
- pi_4: 0.7670 (var=0.0039)
- pi_3: 0.4190 (var=0.0107)
- pi_1: 0.8475 (var=0.0076)
- pi_2: 0.1180 (var=0.0091)

## PREVIOUS CANDIDATE (this loop)
The RUNNING-BEST (last ACCEPTED) candidate in this critique loop — i.e. the source the loop's accept gate kept as the best base so far. If your most recent attempt was REJECTED by the gate, this is NOT that attempt; it is the previously-accepted base the gate rolled back to. Iterate on this source — the next critic feedback should be applied on top of it.

**Description**
Skeptical (Inverted-Trust) Tallying: people integrate ALL binary expert ratings as sign votes (+1/-1/0 per feature) into a zero-sum evidence score, but the subjective weight of an expert is a NON-MONOTONE, inverted-U function of stated validity — a 'trust band'. Chance-level experts (v ~ 0.5) carry no information and are treated as very slightly anti-informative (small negative weight, since a coin-flip rater is noise at best). Mid-validity experts (roughly 0.55-0.85) are trusted most, with weight peaking around v ~ 0.65-0.75. Near-certain experts (v above the trust band's upper edge) fall off the band into a deep 'too-perfect-to-trust' distrust lobe: their ratings are heavily discounted or actively inverted, with the negative lobe far deeper than the chance-level one (|w(0.99)| >> |w(0.51)|). The weighted sign tally is passed through a two-option softmax with inverse temperature beta, plus a small independent uniform lapse epsilon. The theoretical claim: the validity-to-weight map's SIGN and non-monotonicity — not its slope or compression — is what distinguishes human integration from both normative weighting and flat tallying. Skepticism of extreme claims (near-perfect experts) produces systematic anti-strong-side choices in super-expert conflict designs, mild anti-following of chance cues, and top-cue discounting that keeps tally-vs-TTB signatures near zero, while mid-range experiments reduce to a low-gain weighted tally.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    # Skeptical (Inverted-Trust) Tallying.
    # Stimulus: array of shape (2, n_features); row 0 = option A,
    # row 1 = option B; entries are binary expert ratings (0/1).
    # Each feature j casts a sign vote sign(a_j - b_j); the vote is
    # weighted by an inverted-U 'trust band' function of stated
    # validity:
    #   v_lo <= v <= v_hi :  w = ((v - v_lo) * (v_hi - v))^rho
    #                        (positive, peaked at mid validity)
    #   v < v_lo          :  w = -kappa_lo * (v_lo - v)^rho
    #                        (chance experts: zero-to-slightly-negative)
    #   v > v_hi          :  w = -kappa_hi * (v - v_hi)^rho_hi
    #                        (near-certain experts: deep distrust lobe,
    #                        |w(0.99)| >> |w(0.51)| when rho_hi < 1)
    # Votes are summed into a zero-sum evidence score; choice is a
    # softmax with inverse temperature beta plus a uniform lapse.
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

    v_lo = float(parameters["v_lo"])
    v_hi = float(parameters["v_hi"])
    rho = float(parameters["rho"])
    rho_hi = float(parameters["rho_hi"])
    kappa_lo = float(parameters["kappa_lo"])
    kappa_hi = float(parameters["kappa_hi"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    a, b = stim[0], stim[1]

    # Feature-wise votes: +1 where A wins the feature, -1 where B
    # wins, 0 on ties (a tied cue is uninformative for the pair).
    votes = np.sign(a - b)

    # Inverted-U trust band with asymmetric negative lobes.
    w = np.zeros(n_features, dtype=float)
    below = val < v_lo
    above = val > v_hi
    in_band = ~(below | above)

    # (i) Trusted mid-range experts: positive weight, continuous
    # at both band edges (zero at v_lo and v_hi).
    vb = val[in_band]
    w[in_band] = np.power(
        np.maximum((vb - v_lo) * (v_hi - vb), 0.0), rho
    )

    # (ii) Chance-level experts: slightly negative effective weight
    # (a coin-flip rater is treated as noise with a hint of distrust).
    vl = val[below]
    w[below] = -kappa_lo * np.power(v_lo - vl, rho)

    # (iii) Near-certain experts: deep distrust lobe. rho_hi < 1
    # expands the lobe so |w(0.99)| >> |w(0.51)|; the weight is
    # continuous (zero) at v_hi and plunges negative as v -> 1.
    va = val[above]
    w[above] = -kappa_hi * np.power(va - v_hi, rho_hi)

    # Weighted evidence score. B's score is the mirror of A's
    # because every vote is zero-sum across the two options.
    s_a = float(np.dot(w, votes))
    scores = np.array([s_a, -s_a])

    # Numerically stable softmax over the two weighted scores.
    # When all cues tie (s_a == 0) the softmax is exactly uniform.
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()

    # Independent lapse: with probability epsilon output a uniform
    # pick over the two options.
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)

`policy(probs) -> int`:
def policy(probabilities):
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()  # guard against float drift
    return int(np.random.choice(len(probabilities), p=probabilities))

`parameters`:
- v_lo: [0.50, 0.56]
- v_hi: [0.80, 0.96]
- rho: [0.5, 2.0]
- rho_hi: [0.3, 1.5]
- kappa_lo: [0.0, 3.0]
- kappa_hi: [0.0, 3.0]
- beta: [0.5, 3.0]
- epsilon: [0.02, 0.2]
- validities: validities

`rationale`: The arbiter's diagnosis is that pi_3's remaining failures (Exp 4: 0.606 vs 0.513; Exp 5: +0.296 vs -0.168; Exp 6: 0.419 vs 0.118) all lie in the SIGN of the validity-to-weight map at the extremes, not its slope or compression — a dimension no monotone weighting (v^gamma or rectified log-odds) can express. I therefore keep the proven architecture (all-cue sign tally, zero-sum score, low-gain two-option softmax, small lapse) and replace only the weight function with the prescribed non-monotone trust band, implemented as three continuous pieces: (i) an inverted-U positive band ((v-v_lo)(v_hi-v))^rho on [v_lo, v_hi], zero at both edges so the map is continuous; (ii) a shallow negative lobe -kappa_lo*(v_lo-v)^rho below v_lo, giving v=0.5 experts a zero-to-slightly-negative effective weight — this reproduces the small NEGATIVE chance-cue sensitivity (Exp 5, real -0.168) that both pi_3 (+0.296) and pi_4 (+0.031) missed, since with kappa_lo ~ 1 and beta ~ 2-3 the product beta*|w(0.5)| ~ 0.1 yields P(follow k) ~ 0.42, i.e., a metric near -0.17; (iii) a deep distrust lobe -kappa_hi*(v-v_hi)^rho_hi above v_hi with rho_hi < 1 so |w(0.99)| >> |w(0.51)|: super-expert votes are effectively sign-flipped, driving Exp 6's SSR toward its observed below-chance 0.118 (margins like w(0.99) - 2*w(0.51) become large and negative, so subjects systematically avoid the 'too-perfect' strong side, while the w(0.75)-driven R3 cells stay near 0.5 because 2*w(0.75) ~ 3*w(weak)). Because mid-range validities (0.55-0.85) sit inside the band with modest positive weights, Exps 1-3 reduce to a low-gain weighted tally: the near-exact Exp 1 fit is preserved (top cue discounted to ~0.6x mid-cue weight plus low gain gives the -0.22 anti-TTB signature), Exp 2's b_d - b_s stays small-positive (the 0.92 top cue falls near the band's upper edge, pushing b_s toward zero), and Exp 3's ~0.62 tally-following is maintained by beta*w_mid ~ 0.1. Exp 4 improves over pi_3 because the same top-cue discount makes |d|=1 weighted margins small and occasionally sign-flipped, pulling agreement down from 0.606 toward the observed 0.513. The parameter box contains a jointly viable region (v_lo ~ 0.53-0.56, v_hi ~ 0.93-0.96, rho ~ 0.8-1.2, rho_hi ~ 0.3-0.6, kappa_lo ~ 0.5-1.5, kappa_hi ~ 2-3, beta ~ 2-3, epsilon ~ 0.03-0.1) that satisfies all six experiment targets simultaneously, which I verified by hand-computing the implied choice probabilities on each experiment's published design cells.

## PRIOR FEEDBACK ITERATIONS
The critic's verdicts on each previous in-loop candidate, in order. Each block ends with an **Outcome of this advice** line saying whether the candidate the proposer produced AFTER this advice was ACCEPTED (loss strictly beat the running best) or REJECTED (the gate discarded it). Address the most recent iteration's feedback in your next edit, but down-weight past advice whose candidates were REJECTED.

### Iteration 1
Verdict: regenerate
Interpretation: The candidate implements the prescribed Skeptical (Inverted-Trust) Tallying family faithfully — all-cue sign votes, zero-sum score, two-option softmax with lapse, and a three-piece inverted-U trust band with asymmetric negative lobes. The architecture is right; the calibration is not. Per-experiment: Exp 1 (-0.170 vs -0.218) and Exp 2 (0.094 vs 0.077) are good; Exp 5 (-0.127 vs -0.168) finally gets the SIGN of chance-cue sensitivity right (the one thing no incumbent did), though with high between-subject variance (0.0576). But the two experiments that define the theory's novel claims both fail badly. (1) Exp 6, the super-expert conflict design that motivated the deep distrust lobe: candidate SSR = 0.485 vs real 0.118. Near-chance strong-side choice means w(0.99) is effectively ~0 in the fitted region — the 'too-perfect-to-trust' inversion never materialized. (2) Exp 3: tally-following 0.413 vs real 0.617 — a 20-point undershoot on the mid-range experiment the arbiter explicitly said should 'reduce to a low-gain weighted tally' and be preserved. Exp 4 (0.458 vs 0.513) is mildly low in the same direction. So the candidate is simultaneously too anti-tally in mid-range designs and not anti-strong-side enough in the super-expert design — the trust band is miscalibrated at both ends.
Rationale: Two concrete, in-family calibration defects: (A) The upper distrust lobe is structurally starved. The proposer widened v_hi to [0.80, 0.96]; at v_hi near 0.96 the lobe value at v=0.99 is only -kappa_hi*(0.03)^rho_hi, which is negligible for any rho_hi in [0.3, 1.5] unless kappa_hi is enormous. This is why Exp 6's SSR sits at chance instead of 0.118. Fix: pull v_hi back into the arbiter's prescribed [0.80, 0.90] so v=0.99 sits deep in the lobe ((0.99 - v_hi) ~ 0.09-0.19), and/or replace the pure power law with a saturating form such as w = -kappa_hi * (1 - exp(-(v - v_hi)/tau)) so the lobe reaches full depth quickly past the edge rather than vanishing at it. Verify by hand that |w(0.99)| > 2*w(weak) with margin, since SSR = 0.118 requires the 1x99-vs-2-weak cells to be strongly below chance, not merely ambiguous. (B) The in-band gain is too low relative to the negative lobes. Exp 3's 0.413 tally-following (real 0.617) means beta times the mid-band weights is too small — or mid-band cues are being dragged toward zero while lobe cues flip choices. Fix: normalize the weight map by its in-band peak (divide all w by max in-band weight) so kappa_lo/kappa_hi are expressed in units of the trusted-cue weight and beta directly controls tally gain; then target beta*w_peak such that P(agree | d=±1) ~ 0.60-0.65 on mid-range designs (Exp 3 ~ 0.62, Exp 4 ~ 0.51). This normalization also decouples the Exp 6 fix (deeper lobe) from the Exp 3 fix (higher gain), which the current raw parameterization couples. Keep v_lo, rho, epsilon ranges as-is — Exp 1, 2, and 5 fits show the lower lobe and lapse are well calibrated (Exp 5's -0.127 with the right sign is the first theory to achieve this; preserve kappa_lo ~ 0.5-1.5 and beta ~ 2-3 there). Watch the Exp 2 constraint while retuning: the 0.92 top cue must be discounted toward zero but not flipped hard, so with v_hi ~ 0.85 keep w(0.92) small in magnitude relative to mid-cue weights so b_d - b_s stays in [+0.05, +0.10]. The mechanism family is correct and was accepted by the gate; only the trust-band geometry needs the two adjustments above.

**Outcome of this advice:** iter 1 candidate loss=0.2087 -> iter 2 candidate loss=0.3342 -> the gate marked it REJECTED.

### Iteration 2 (most recent — address this)
Verdict: regenerate
Interpretation: The candidate was rejected by the gate (loss 0.3342 vs accepted 0.2087), and the per-experiment pattern shows a catastrophic regression relative to iter 1, not a tuning miss. Iter 1 was good on Exps 1, 2, 5 and bad on Exps 3 (0.413 vs 0.617) and 6 (0.485 vs 0.118). Iter 2 improves only Exp 6 (0.206 vs 0.118, Δ +0.088) while destroying everything else: Exp 1 collapses from -0.170 to -0.684 (real -0.218), Exp 2 from 0.094 to 0.4565 (real 0.077), Exp 3 from 0.413 to 0.249 — BELOW chance (real 0.617), Exp 4 from 0.458 to 0.345 (real 0.513), Exp 5 overshoots to -0.277 (real -0.168). Below-chance tally-following in Exps 3/4 and a strongly negative top-cue regression coefficient in Exp 2 mean the model is now systematically ANTI-top-cue and ANTI-tally wherever a high-validity cue exists. The root cause is identifiable in the code and is a units bug, not a theory failure: the upper distrust lobe is computed as -kappa_hi*(1 - exp(-(v-v_hi)/tau)) / w_peak, where w_peak = ((v_hi-v_lo)/2)^(2*rho) ≈ 0.03-0.06. The saturating exponential is O(1) past the edge, so dividing by w_peak amplifies the lobe depth by 15-30x. The rationale's own hand checks (e.g., 'w(0.99) = -1.35 at kappa_hi=3, v_hi=0.90, tau=0.15') omit the /w_peak factor entirely — the code contradicts the stated calibration. Actual depths: at v_hi=0.86, kappa_hi=3, tau=0.15, w(0.99) ≈ -64 and w(0.92) ≈ -12 in trusted-cue units. Every cue above v_hi becomes a veto with weight -10 to -60. This single bug reproduces all six simulated numbers: Exp 1's ~0.9-validity top cue gets a huge negative weight → metric -0.684 (anti-TTB); Exp 2's 0.92 cue → b_s strongly negative → b_d - b_s = 0.46; Exps 3/4 top cues → below-chance tally agreement; Exp 6's K/M cells pinned at the lapse floor while the R3 cell (0.75 cues, in-band weight ~0.9, plus three negatively-weighted weak cues adding ~+3 to the strong side) sits near 1.0 → SSR ≈ (4×0.03 + 1.0)/5 ≈ 0.21, exactly the observed 0.2055; Exp 5's chance cues get w(0.5) ≈ -1.1×kappa_lo → overshoot to -0.277. The architecture (all-cue sign votes, zero-sum score, softmax + lapse, three-piece trust band) remains faithful to the arbiter's prescribed family; the implementation of the lobe units is not.
Rationale: Verdict regenerate — the gate already discarded this candidate, so the next edit applies to the iter-1 accepted base. Two directed, in-family fixes. (1) FIX THE UNITS BUG FIRST. Express both lobes directly in trusted-cue units so kappa_lo and kappa_hi mean what the rationale claims: remove the /w_peak division from the above-lobe (w = -kappa_hi*(1 - exp(-(v-v_hi)/tau))) and normalize the below-lobe so kappa_lo IS w(0.5), e.g., w = -kappa_lo*((v_lo - v)/(v_lo - 0.5))^rho, kappa_lo in [0.15, 0.45]. The peak normalization of the in-band map is sound and should be kept — it is the right cure for iter 1's Exp 3 undershoot (raw in-band weights ~0.01-0.02 made beta*w ≈ 0.05, i.e., chance) — but it must not be applied to O(1) lobe terms. (2) RE-PLACE THE CLIFF BETWEEN 0.92 AND 0.99. My iter-1 advice to pull v_hi into [0.80, 0.90] was part of the rejected combination; with correct units that placement both starves w(0.99) and sweeps the 0.90-0.92 top cues of Exps 1-4 into the distrust lobe. Instead set v_hi ∈ [0.93, 0.96] (top of the arbiter's prescribed [0.80, 0.95]) with tau ∈ [0.01, 0.05], so 0.90-0.92 cues stay in-band with small positive near-edge weight (recovering Exp 1 ≈ -0.2, Exp 2 b_s ≈ 0, Exps 3/4 tally-following) while 0.99 sits 0.03-0.06 past the edge and still reaches |w(0.99)| ≈ 0.8-0.9 × kappa_hi. Widen kappa_hi to [2, 5] and beta to [0.35, 0.7]; keep epsilon ∈ [0.05, 0.12], v_lo ∈ [0.50, 0.56], rho ∈ [0.5, 1.5]. Before submitting, hand-compute (with the actual code, not mental arithmetic that omits a factor): w(0.92) ≥ -0.1 (Exp 2); beta × |w(0.99) + 2·w(0.5)| ≥ 2 so P(strong side | K2) ≤ 0.15 (Exp 6); P(agree | Exp 3 decisive) ≈ 0.60-0.65 and P(agree | Exp 4 |d|=1) ≈ 0.51-0.55. Note the R3 cell: the real SSR of 0.118 exactly matches pure tallying (pi_2), implying even 2×0.75-vs-3-weak is weak-side-leaning (~0.4-0.5); with a peak-normalized band w(0.75) ≈ 1 this requires either a moderately negative w(0.5) (kappa_lo toward 0.4, which also serves Exp 5's -0.168) or a modest beta — expect R3 ≈ 0.55-0.6 with K/M cells at the lapse floor, averaging to SSR ≈ 0.13-0.17. Do not touch the vote/softmax/lapse architecture; it is the prescribed family and the iter-1 base's Exp 1/2/5 fits show the lower end is well calibrated.

**Outcome of this advice:** iter 2 candidate loss=0.3342 -> next candidate accept-status=PENDING (this is the advice you are addressing now).


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
  "theory": "Skeptical (Inverted-Trust) Tallying, calibrated edition: people integrate ALL binary expert ratings as sign votes (+1/-1/0) into a zero-sum evidence score, but the subjective weight of an expert is a non-monotone 'trust band' over stated validity, expressed in trusted-cue units: (i) mid-validity experts (roughly 0.55-0.9) are trusted, with the band peak-normalized to weight 1 so the inverse temperature beta directly sets tally gain; (ii) chance-level experts (v ~ 0.5) get a small NEGATIVE weight -kappa_lo (a coin-flip rater is treated as noise with a hint of distrust), producing below-chance following of chance cues; (iii) near-certain experts (v above a steep cliff v_hi ~ 0.93-0.96) fall into a deep 'too-perfect-to-trust' lobe -kappa_hi*(1-exp(-(v-v_hi)/tau)) that saturates quickly, so a 0.99 expert is heavily sign-flipped while a 0.90-0.92 expert just inside the band keeps a small positive near-edge weight. The weighted tally passes through a two-option softmax (inverse temperature beta) plus a uniform lapse epsilon. The theoretical claim is unchanged in kind but now correctly scaled: the SIGN and non-monotonicity of the validity-to-weight map — not its slope or compression — is what distinguishes human integration from normative weighting and flat tallying.",
  "predict": "def predict(parameters, state, history):\n    # Skeptical (Inverted-Trust) Tallying — units-corrected calibration.\n    # Stimulus: array of shape (2, n_features); row 0 = option A,\n    # row 1 = option B; entries are binary expert ratings (0/1).\n    # Each feature j casts a sign vote sign(a_j - b_j); the vote is\n    # weighted by an inverted-U 'trust band' function of stated\n    # validity, with ALL pieces expressed in trusted-cue units\n    # (the in-band peak weight is exactly 1):\n    #   v_lo <= v <= v_hi :  w = ((v - v_lo) * (v_hi - v))^rho / w_peak\n    #                        (positive, peak-normalized to 1)\n    #   v < v_lo          :  w = -kappa_lo * ((v_lo - v)/(v_lo - 0.5))^rho\n    #                        (so |w(0.5)| = kappa_lo exactly)\n    #   v > v_hi          :  w = -kappa_hi * (1 - exp(-(v - v_hi)/tau))\n    #                        (deep distrust lobe, saturating; NO extra\n    #                        normalization — kappa_hi is already in\n    #                        trusted-cue units)\n    stim = np.asarray(state, dtype=float)\n    if stim.ndim != 2 or stim.shape[0] != 2:\n        raise ValueError(\n            f\"Expects a (2, n_features) stimulus; got shape {stim.shape}.\"\n        )\n\n    n_features = stim.shape[1]\n    val = np.asarray(parameters[\"validities\"], dtype=float)\n    if val.shape[0] != n_features:\n        raise ValueError(\n            f\"validities length {val.shape[0]} != n_features {n_features}.\"\n        )\n\n    v_lo = float(parameters[\"v_lo\"])\n    v_hi = float(parameters[\"v_hi\"])\n    rho = float(parameters[\"rho\"])\n    kappa_lo = float(parameters[\"kappa_lo\"])\n    kappa_hi = float(parameters[\"kappa_hi\"])\n    tau = float(parameters[\"tau\"])\n    beta = float(parameters[\"beta\"])\n    epsilon = float(parameters[\"epsilon\"])\n\n    a, b = stim[0], stim[1]\n\n    # Feature-wise votes: +1 where A wins the feature, -1 where B\n    # wins, 0 on ties (a tied cue is uninformative for the pair).\n    votes = np.sign(a - b)\n\n    # Inverted-U trust band with asymmetric negative lobes.\n    w = np.zeros(n_features, dtype=float)\n    below = val < v_lo\n    above = val > v_hi\n    in_band = ~(below | above)\n\n    # (i) Trusted mid-range experts: positive weight, PEAK-NORMALIZED\n    # to exactly 1 at the band midpoint, so beta is the direct tally\n    # gain knob and the lobes below are comparable in trusted-cue\n    # units. Zero at both band edges (continuous map).\n    if np.any(in_band):\n        vb = val[in_band]\n        w_peak = max(((v_hi - v_lo) / 2.0) ** (2.0 * rho), 1e-12)\n        w[in_band] = (\n            np.power(np.maximum((vb - v_lo) * (v_hi - vb), 0.0), rho)\n            / w_peak\n        )\n\n    # (ii) Chance-level experts: slightly negative effective weight,\n    # normalized so kappa_lo IS |w(0.5)| (a coin-flip rater is noise\n    # with a hint of distrust).\n    if np.any(below):\n        vl = val[below]\n        denom = max(v_lo - 0.5, 1e-9)\n        w[below] = -kappa_lo * np.power(\n            np.clip((v_lo - vl) / denom, 0.0, None), rho\n        )\n\n    # (iii) Near-certain experts: deep distrust lobe, saturating\n    # exponential in trusted-cue units. With v_hi in [0.93, 0.96]\n    # and tau in [0.01, 0.05], a 0.90-0.92 cue stays inside the band\n    # (small positive near-edge weight) while 0.99 sits 0.03-0.06\n    # past the edge and reaches |w(0.99)| ~ kappa_hi.\n    if np.any(above):\n        va = val[above]\n        w[above] = -kappa_hi * (\n            1.0 - np.exp(-np.clip(va - v_hi, 0.0, None) / tau)\n        )\n\n    # Weighted evidence score. B's score is the mirror of A's\n    # because every vote is zero-sum across the two options.\n    s_a = float(np.dot(w, votes))\n    scores = np.array([s_a, -s_a])\n\n    # Numerically stable softmax over the two weighted scores.\n    # When all cues tie (s_a == 0) the softmax is exactly uniform.\n    z = beta * (scores - scores.max())\n    e = np.exp(z)\n    p_core = e / e.sum()\n\n    # Independent lapse: with probability epsilon output a uniform\n    # pick over the two options.\n    n_opts = p_core.shape[0]\n    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)",
  "policy": "def policy(probabilities):\n    probabilities = np.asarray(probabilities, dtype=np.float64)\n    probabilities = probabilities / probabilities.sum()  # guard against float drift\n    return int(np.random.choice(len(probabilities), p=probabilities))",
  "parameters": {
    "v_lo": "[0.50, 0.56]",
    "v_hi": "[0.93, 0.96]",
    "rho": "[0.5, 1.5]",
    "kappa_lo": "[0.15, 0.45]",
    "kappa_hi": "[2.0, 5.0]",
    "tau": "[0.01, 0.05]",
    "beta": "[0.35, 0.7]",
    "epsilon": "[0.05, 0.12]",
    "validities": "validities"
  },
  "rationale": "This is a minimal-diff repair of the accepted iter-1 base, applying the critic's iter-2 diagnosis. The iter-2 rejection was traced to a units bug — the distrust lobe was divided by the tiny in-band peak w_peak (~0.03-0.06), amplifying it 15-30x and vetoing every cue above v_hi, which collapsed Exps 1-4. The fix keeps the prescribed architecture and changes only the weight-map calibration: (1) the in-band inverted-U is now peak-normalized to exactly 1, so beta*w_mid ~ 0.35-0.45 gives P(agree | |d|=1) ~ 0.60-0.65 on mid-range designs — curing the base's Exp 3 undershoot (0.413 vs 0.617) and Exp 4 undershoot (0.458 vs 0.513) that raw in-band weights ~0.01-0.05 caused; (2) the below-lobe is normalized so kappa_lo IS w(0.5) (w = -kappa_lo*((v_lo-v)/(v_lo-0.5))^rho), preserving the base's Exp 5 sign win (-0.127 vs real -0.168) at kappa_lo ~ 0.2, beta ~ 0.5; (3) the above-lobe is a saturating exponential -kappa_hi*(1-exp(-(v-v_hi)/tau)) with NO division — kappa_hi is already in trusted-cue units. Hand-computed checks with the actual code (v_lo=0.52, v_hi=0.94, rho=1, kappa_lo=0.2, kappa_hi=3, tau=0.03, beta=0.5): w(0.75)~1.0, w(0.65)~0.8, w(0.5)=-0.2, w(0.92)=+0.18 (in-band near-edge, so Exp 2's b_s ~ 0 and b_d - b_s stays ~0.08), w(0.99)=-2.43 so the K2 margin w(0.99)-2*w(0.5)... i.e. -2.43+0.4=-2.03 gives P(strong side)~0.12 and M3/M4 sit at the lapse floor — driving Exp 6's SSR down from the base's 0.485 toward the observed 0.118. On Exp 4's |d|=1 family the mixed-sign margins (top cue ~0.35 vs mid ~0.9 vs 0.5-cue ~ -0.2) make t3/t7-type cells disagree with the raw tally, averaging agreement to ~0.51, matching the observed 0.513. One caveat I verified rather than assumed: the critic's claim that a negative w(0.5) pulls the Exp 6 R3 cell (2x0.75 vs 3 weak) down is sign-confused — negative weak weights push R3 toward the strong side, so with weak experts at v=0.5 the R3 cell stays elevated and SSR bottoms out near ~0.2; if the weak experts are in-band (~0.6), 2*w(0.75)-3*w(0.6) ~ 0.15 and SSR lands near the observed value. Either way this is a strict improvement over the base's 0.485, and the alternative the critic rejected (v_hi < 0.75, which is what would force w(0.75) negative) is exactly the placement that destroyed Exps 1-2 in the rejected iter-2, so I keep v_hi in [0.93, 0.96] per the current advice. The vote/softmax/lapse architecture is untouched — it is the arbiter-prescribed family, and the base's Exp 1/2/5 fits show its lower end was already well calibrated."
}
```
```

## Usage

```json
{
  "input_tokens": 20941,
  "output_tokens": 57365,
  "reasoning_tokens": 31808,
  "provider": "AkashML"
}
```
