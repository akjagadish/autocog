# generation_iter_07_attempt_00

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
- THEORY 1 = `pi_8`
- THEORY 2 = `pi_6`
- The recommendation below acts on THEORY 2 (= `pi_6`).

Replace pi_6 with a new theory of inferred dependence among experts in represented reliability space. The central claim should be that people treat similarly reliable experts as partially dependent sources, so corroboration depends on both cue count and reliability diversity. Implement coalition evidence using a smooth similarity kernel over compressed diagnosticity—for example, an effective-evidence or precision calculation based on pairwise reliability-space similarities—rather than pi_8's special triadic duplicate-pair-in-context detector. Similar cues should share informational credit, while reliability-distant cues contribute more independent evidence. The mechanism should operate at every coalition size but accumulate nonlinearly, yielding weak dyadic gap effects and much stronger three-cue clustered-versus-distributed effects without an explicit n>=3 switch. Include sublinear count growth, a stable subject-level dependence/similarity sensitivity, compressed validity representation, exchangeable zero-centered cue salience, and lapse/response sensitivity. It should predict the robust distributed-coalition preferences in Experiments 1 and 14 and the graded early-gap release in Experiment 2, but with more moderate magnitudes than the current pi_8 instantiation. It must also preserve the established cross-task constraints: the count/majority patterns in Experiments 3–5, near-zero population positional and serial-organization effects in Experiments 6–11, the strong dyadic composition result in Experiment 12, and only a small dyadic reliability-gap contrast in Experiment 13. This would provide a substantive alternative explanation—general inferred source dependence—rather than copying pi_8's cardinality-specific contextual topology operation.

## THEORY LEADERBOARD
A small set of prior picked theories shown for reference. Overall score is in `[0, 1]`, higher = better, computed as `1 - L2_norm(normalized_per_experiment_distances) / max_L2_norm`. 1.0 means closest to the real value on every experiment+metric pair; 0.0 means farthest. Each entry below carries the same depth of detail as the PREVIOUS MODEL INSTANCE above so you can borrow concrete mechanisms when useful.

### `pi_8` (overall score: 0.916)

**Description**
Contextual Reliability-Region Compression proposes that people integrate every discriminating expert rating into an exchangeable option-level coalition while representing advertised validities on a strongly compressed reliability-region scale. Coalition evidence grows sublinearly, and stable count calibration can make a third cue either corroborative or partially redundant. Redundancy is order-specific in cardinality but not spatial position: two-cue coalitions receive only a smooth joint-diagnostic composition discount, whereas coalitions of three or more undergo a contextual topology operation. In the latter operation, two cues occupying nearly the same represented reliability region are compressed toward one informational unit when another cue occupies a distinct region. In equal-cardinality contests between multi-cue coalitions, people additionally compare the coalitions' topology relationally. This relational comparison is moderately concave: modest clustered-versus-distributed differences are transmitted approximately linearly, whereas larger differences receive stronger diminishing amplification. The comparison fades smoothly when coalition cardinalities differ, preserving independently calibrated count judgments. Topology sensitivity is stable and heterogeneous across subjects, while pair-composition sensitivity is comparatively narrow. Stable, zero-centered idiosyncratic cue salience permits individual configuration preferences without population-level onset, closure, recency, adjacency, entry, or exit effects. Because subjects receive no outcome feedback, these representations remain fixed across trials.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history) -> np.ndarray:
    stim = np.asarray(state, dtype=np.float64)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Contextual Reliability-Region Compression expects shape "
            f"(2, n_features); got {stim.shape}."
        )

    a, b = stim[0], stim[1]
    n_features = int(stim.shape[1])

    validities = np.asarray(parameters["validities"], dtype=np.float64)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} != n_features {n_features}."
        )

    raw_salience = np.asarray(
        parameters["cue_salience_profile"], dtype=np.float64
    )
    if raw_salience.ndim != 1 or raw_salience.size != n_features:
        raise ValueError(
            f"cue_salience_profile length {raw_salience.size} != "
            f"n_features {n_features}."
        )

    validity_compression = float(parameters["validity_compression"])
    validity_reliance = float(parameters["validity_reliance"])
    salience_strength = float(parameters["salience_strength"])
    coalition_saturation = float(parameters["coalition_saturation"])
    count_calibration = float(parameters["count_calibration"])
    count_calibration_strength = float(parameters["count_calibration_strength"])
    pair_composition_sensitivity = float(
        parameters["pair_composition_sensitivity"]
    )
    topology_sensitivity = float(parameters["topology_sensitivity"])
    topology_contrast_gain = float(parameters["topology_contrast_gain"])
    cluster_bandwidth = float(parameters["cluster_bandwidth"])
    context_scale = float(parameters["context_scale"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    # Reliability is encoded on a diagnosticity scale, but differences are
    # strongly compressed. Mean normalization prevents an experiment's
    # overall validity level from changing the generic evidence scale.
    v = np.clip(validities, 0.500001, 0.999999)
    log_odds = np.log(v / (1.0 - v))
    represented_diagnosticity = np.power(
        np.maximum(log_odds, 1e-12), validity_compression
    )
    represented_diagnosticity /= max(
        float(np.mean(represented_diagnosticity)), 1e-12
    )

    reliability_weight = (
        (1.0 - validity_reliance) * np.ones(n_features, dtype=np.float64)
        + validity_reliance * represented_diagnosticity
    )

    # Components are exchangeably sampled and centered within each subject.
    # Thus salience is stable and can generate individual differences, but
    # no display position has a positive population-level privilege.
    centered_salience = raw_salience - float(np.mean(raw_salience))
    attention = np.exp(
        np.clip(salience_strength * centered_salience, -10.0, 10.0)
    )
    attention /= max(float(np.mean(attention)), 1e-12)

    cue_weights = reliability_weight * attention
    cue_weights /= max(float(np.mean(cue_weights)), 1e-12)

    difference = a - b
    a_support = np.flatnonzero(difference > 0.0)
    b_support = np.flatnonzero(difference < 0.0)
    n_a = int(a_support.size)
    n_b = int(b_support.size)

    if n_a == 0 and n_b == 0:
        return np.array([0.5, 0.5], dtype=np.float64)

    bounded_diagnosticity = np.clip(2.0 * v - 1.0, 0.0, 1.0)

    def triadic_topology(indices):
        idx = np.asarray(indices, dtype=int)
        n = int(idx.size)
        if n < 3:
            return 0.0

        scores = []
        # Topological distance is computed in the same compressed,
        # mean-normalized reliability-region coordinate used by cognition,
        # rather than in raw advertised-validity units.
        for x in range(n - 2):
            for y in range(x + 1, n - 1):
                for z in range(y + 1, n):
                    triad = np.sort(
                        represented_diagnosticity[idx[[x, y, z]]]
                    )
                    lower_gap = float(triad[1] - triad[0])
                    upper_gap = float(triad[2] - triad[1])

                    if lower_gap <= upper_gap:
                        cluster_gap = lower_gap
                        cluster_center = 0.5 * float(triad[0] + triad[1])
                        outsider = float(triad[2])
                    else:
                        cluster_gap = upper_gap
                        cluster_center = 0.5 * float(triad[1] + triad[2])
                        outsider = float(triad[0])

                    separation = abs(outsider - cluster_center)
                    duplicate_affinity = np.exp(
                        -0.5 * (cluster_gap / cluster_bandwidth) ** 2
                    )
                    contextual_distinctness = separation / (
                        separation + context_scale
                    )
                    scores.append(
                        float(duplicate_affinity * contextual_distinctness)
                    )

        if not scores:
            return 0.0

        # A smooth probabilistic union detects whether the coalition contains
        # at least one duplicate-pair-in-context relation without privileging
        # a cue identity, ordering, or spatial adjacency.
        scores = np.clip(np.asarray(scores, dtype=np.float64), 0.0, 0.999999)
        return float(1.0 - np.prod(1.0 - scores))

    def coalition_signal(indices):
        idx = np.asarray(indices, dtype=int)
        n = int(idx.size)
        if n == 0:
            return 0.0

        total = float(np.sum(cue_weights[idx]))

        if n >= 3:
            topology = triadic_topology(idx)
            # Sensitivity maps smoothly to the fraction of one informational
            # unit removed. At its upper limit a near-duplicate pair is worth
            # approximately one unit rather than two; all cues nevertheless
            # retain a positive contribution.
            compression_fraction = (
                1.0 - np.exp(-topology_sensitivity * topology)
            )
            coalition_unit = float(np.mean(cue_weights[idx]))
            total -= compression_fraction * coalition_unit
            total = max(total, 1e-12)

        signal = total / (float(n) ** coalition_saturation)
        return float(signal)

    def pair_composition_load(indices):
        idx = np.asarray(indices, dtype=int)
        n = int(idx.size)
        if n < 2:
            return 0.0

        products = []
        for i in range(n - 1):
            for j in range(i + 1, n):
                products.append(
                    float(
                        bounded_diagnosticity[idx[i]]
                        * bounded_diagnosticity[idx[j]]
                    )
                )
        return float(np.mean(products)) if products else 0.0

    topology_a = triadic_topology(a_support)
    topology_b = triadic_topology(b_support)
    evidence_a = coalition_signal(a_support)
    evidence_b = coalition_signal(b_support)

    # The status of third and later members is flexibly but boundedly
    # calibrated. This is a count-level corroboration judgment, not a cue
    # position mechanism, and is stable across the subject's trials.
    if n_a >= 2 and n_b >= 2:
        extra_a = float(max(n_a - 2, 0))
        extra_b = float(max(n_b - 2, 0))
        evidence_a *= np.exp(
            np.clip(
                count_calibration_strength * count_calibration * extra_a,
                -4.0,
                4.0,
            )
        )
        evidence_b *= np.exp(
            np.clip(
                count_calibration_strength * count_calibration * extra_b,
                -4.0,
                4.0,
            )
        )

        # Dyadic redundancy is deliberately gap-free and equality-free: it
        # depends only on smooth joint diagnostic composition. Centering the
        # adjustment between options avoids introducing an overall bias.
        load_difference = (
            pair_composition_load(a_support)
            - pair_composition_load(b_support)
        )
        size_scale = 1.0 if n_a == n_b else 0.60
        shift = (
            pair_composition_sensitivity * size_scale * load_difference
        )
        evidence_a *= np.exp(np.clip(-0.5 * shift, -4.0, 4.0))
        evidence_b *= np.exp(np.clip(0.5 * shift, -4.0, 4.0))

    # A relational topology comparison amplifies a clustered-versus-
    # distributed distinction when both alternatives support genuinely
    # multi-cue interpretations. Logistic cardinality gates and a smooth
    # balance factor make this additional contrast negligible in 3-versus-2
    # and one-versus-many judgments, leaving count calibration in control.
    # Moderate concavity preserves small contrasts approximately linearly
    # while selectively attenuating larger topology differences.
    multi_a = 1.0 / (1.0 + np.exp(-6.0 * (float(n_a) - 2.5)))
    multi_b = 1.0 / (1.0 + np.exp(-6.0 * (float(n_b) - 2.5)))
    if n_a > 0 and n_b > 0:
        log_size_ratio = np.log(float(n_a) / float(n_b))
        cardinality_balance = np.exp(-6.0 * log_size_ratio * log_size_ratio)
    else:
        cardinality_balance = 0.0
    raw_topology_contrast = topology_a - topology_b
    mild_topology_contrast = np.tanh(1.8 * raw_topology_contrast) / 1.8
    topology_shift = (
        topology_contrast_gain
        * multi_a
        * multi_b
        * cardinality_balance
        * topology_sensitivity
        / (1.0 + topology_sensitivity)
        * mild_topology_contrast
    )
    evidence_a *= np.exp(np.clip(-0.5 * topology_shift, -4.0, 4.0))
    evidence_b *= np.exp(np.clip(0.5 * topology_shift, -4.0, 4.0))

    net_a = evidence_a - evidence_b
    logits = np.array(
        [0.5 * beta * net_a, -0.5 * beta * net_a], dtype=np.float64
    )
    logits = logits - np.max(logits)
    probs = np.exp(logits)
    probs /= probs.sum()

    probs = (1.0 - epsilon) * probs + epsilon * 0.5
    probs = np.maximum(probs, 0.0)
    total_probability = float(probs.sum())
    if not np.isfinite(total_probability) or total_probability <= 0.0:
        return np.array([0.5, 0.5], dtype=np.float64)
    return probs / total_probability


`policy(probs) -> int`:
def policy(probs) -> int:
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.maximum(probs, 0.0)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        probs = np.ones(len(probs), dtype=np.float64) / float(len(probs))
    else:
        probs /= total
    return int(np.random.choice(len(probs), p=probs))


`parameters`:
- validities: validities
- cue_salience_profile: [(-1.0, 1.0)] * n_features
- validity_compression: [0.16, 0.32]
- validity_reliance: [0.025, 0.070]
- salience_strength: [0.12, 0.27]
- coalition_saturation: [0.74, 0.84]
- count_calibration: [-0.75, 0.25]
- count_calibration_strength: [0.36, 0.48]
- pair_composition_sensitivity: [2.10, 2.65]
- topology_sensitivity: [0.40, 8.00]
- topology_contrast_gain: [1.50, 2.75]
- cluster_bandwidth: [0.018, 0.040]
- context_scale: [0.025, 0.060]
- beta: [1.02, 1.30]
- epsilon: [0.03, 0.08]

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=-0.1217 (var=0.0117) vs this=-0.1358 (var=0.0111)
- Experiment 2: real=-0.2642 (var=0.0087) vs this=-0.2221 (var=0.0114)
- Experiment 3: real=-0.0410 (var=0.0003) vs this=-0.0376 (var=0.0003)
- Experiment 4: real=0.5087 (var=0.0038) vs this=0.4759 (var=0.0052)
- Experiment 5: real=0.5021 (var=0.0024) vs this=0.4940 (var=0.0029)
- Experiment 6: real=0.4400 (var=0.2464) vs this=0.5000 (var=0.2500)
- Experiment 7: real=0.0219 (var=0.0094) vs this=0.0088 (var=0.0097)
- Experiment 8: real=0.0117 (var=0.0101) vs this=-0.0042 (var=0.0116)
- Experiment 9: real=0.4958 (var=0.0041) vs this=0.5056 (var=0.0026)
- Experiment 10: real=0.1723 (var=0.0081) vs this=0.1646 (var=0.0019)
- Experiment 11: real=0.0317 (var=0.0030) vs this=0.0125 (var=0.0063)
- Experiment 12: real=0.6692 (var=0.0068) vs this=0.7031 (var=0.0082)
- Experiment 13: real=0.3242 (var=0.0194) vs this=0.5346 (var=0.0171)
- Experiment 14: real=0.5869 (var=0.0047) vs this=0.6616 (var=0.0045)


---

### `pi_6` (overall score: 0.854)

**Description**
Exchangeable Corroboration with Idiosyncratic Salience proposes that people retain the direction of every discriminating expert rating but strongly compress instructed differences in expert validity. Supporting cues are integrated into option-level coalitions whose evidence increases sublinearly, so additional agreement provides corroboration with diminishing marginal impact. Subjects differ in how they calibrate coalition members beyond the first two: a signed, stable calibration parameter makes an additional cue corroborative for some people and partially redundant for others. Separately, jointly diagnostic cues can be perceived as partially redundant: an order-free composition term discounts coalitions containing several simultaneously strong cues, with its effect centered between the competing coalitions. This composition discount is strongest for equal-sized coalitions but remains moderately active when coalition sizes differ. Cue order has no population-level directional role. Instead, each subject has a stable, broad cue-salience profile drawn from a zero-centered exchangeable distribution and centered again within the display. Consequently, individual subjects can show substantial configuration preferences, but there is no common early, late, onset, closure, or entry-versus-exit advantage. Choices result from the difference between the two saturated coalition signals, transformed by response sensitivity and an independent lapse process. Because no outcome feedback is supplied, neither validity beliefs nor salience profiles are learned across trials.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    stim = np.asarray(state, dtype=np.float64)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Exchangeable Corroboration with Idiosyncratic Salience expects "
            f"shape (2, n_features); got {stim.shape}."
        )

    a, b = stim[0], stim[1]
    n_features = int(stim.shape[1])

    validities = np.asarray(parameters["validities"], dtype=np.float64)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} != n_features {n_features}."
        )

    raw_salience = np.asarray(parameters["cue_salience_profile"], dtype=np.float64)
    if raw_salience.ndim != 1 or raw_salience.size != n_features:
        raise ValueError(
            f"cue_salience_profile length {raw_salience.size} != n_features "
            f"{n_features}."
        )

    validity_compression = float(parameters["validity_compression"])
    validity_reliance = float(parameters["validity_reliance"])
    salience_strength = float(parameters["salience_strength"])
    coalition_saturation = float(parameters["coalition_saturation"])
    corroboration_calibration = float(parameters["corroboration_calibration"])
    corroboration_strength = float(parameters["corroboration_strength"])
    composition_redundancy = float(parameters["composition_redundancy"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    # Instructed reliability is represented on a diagnosticity scale, but
    # differences among experts are strongly compressed.
    v = np.clip(validities, 0.500001, 0.999999)
    diagnosticity = np.log(v / (1.0 - v))
    diagnosticity = np.power(np.maximum(diagnosticity, 1e-12), validity_compression)
    diagnosticity /= max(float(np.mean(diagnosticity)), 1e-12)

    # Salience is a stable subject-level profile, not a fixed position rule.
    # Centering removes a subject's global offset. Because profile components
    # have identical sampling distributions, no serial position has a
    # population-positive expected advantage.
    centered_salience = raw_salience - float(np.mean(raw_salience))
    attentional_weight = np.exp(
        np.clip(salience_strength * centered_salience, -10.0, 10.0)
    )
    attentional_weight /= max(float(np.mean(attentional_weight)), 1e-12)

    reliability_weight = (
        (1.0 - validity_reliance) * np.ones(n_features, dtype=np.float64)
        + validity_reliance * diagnosticity
    )
    cue_weights = reliability_weight * attentional_weight
    cue_weights /= max(float(np.mean(cue_weights)), 1e-12)

    differences = a - b
    a_support = np.flatnonzero(differences > 0.0)
    b_support = np.flatnonzero(differences < 0.0)
    n_a = int(a_support.size)
    n_b = int(b_support.size)

    if n_a == 0 and n_b == 0:
        return np.array([0.5, 0.5], dtype=np.float64)

    def coalition_signal(indices):
        n = int(indices.size)
        if n == 0:
            return 0.0
        # Every discriminating cue contributes. Division by n**saturation
        # makes total evidence grow approximately as n**(1-saturation),
        # implementing diminishing marginal corroboration without stopping.
        total = float(np.sum(cue_weights[indices]))
        return total / (float(n) ** coalition_saturation)

    def composition_load(indices):
        # Mean pairwise joint diagnostic strength is a bounded, order-free
        # measure of potential redundancy. It is high when several members
        # are all strongly diagnostic, not when a coalition merely appears
        # early or late in the display.
        idx = np.asarray(indices, dtype=int)
        n = int(idx.size)
        if n < 2:
            return 0.0
        bounded_strength = np.clip(2.0 * v[idx] - 1.0, 0.0, 1.0)
        pair_sum = 0.0
        pair_count = 0
        for i in range(n):
            for j in range(i + 1, n):
                pair_sum += float(bounded_strength[i] * bounded_strength[j])
                pair_count += 1
        return pair_sum / float(max(pair_count, 1))

    evidence_a = coalition_signal(a_support)
    evidence_b = coalition_signal(b_support)

    # Calibration of excess coalition membership is invoked only when both
    # options already have multi-cue interpretations. Thus it captures the
    # psychological status of a third or later coalition member rather than
    # introducing a general position gate. Positive values treat extra cues
    # as corroboration; negative values treat them as redundancy.
    if n_a >= 2 and n_b >= 2:
        extra_a = float(max(n_a - 2, 0))
        extra_b = float(max(n_b - 2, 0))
        log_adjustment_a = (
            corroboration_strength * corroboration_calibration * extra_a
        )
        log_adjustment_b = (
            corroboration_strength * corroboration_calibration * extra_b
        )
        evidence_a *= np.exp(np.clip(log_adjustment_a, -10.0, 10.0))
        evidence_b *= np.exp(np.clip(log_adjustment_b, -10.0, 10.0))

        # Decouple composition from the heterogeneous size calibration.
        # Coalitions containing several jointly strong cues receive a mild
        # redundancy discount. Centering the adjustment between options
        # prevents a global response bias. Composition is most diagnostic
        # when coalition sizes are equal and remains moderately active in
        # size conflicts without becoming a spatial or directional gate.
        load_difference = composition_load(a_support) - composition_load(b_support)
        composition_scale = 1.0 if n_a == n_b else 0.60
        composition_shift = (
            composition_redundancy * composition_scale * load_difference
        )
        evidence_a *= np.exp(np.clip(-0.5 * composition_shift, -10.0, 10.0))
        evidence_b *= np.exp(np.clip(0.5 * composition_shift, -10.0, 10.0))

    net_a = evidence_a - evidence_b
    logits = np.array(
        [0.5 * beta * net_a, -0.5 * beta * net_a], dtype=np.float64
    )
    logits -= np.max(logits)
    probs = np.exp(logits)
    probs /= probs.sum()

    probs = (1.0 - epsilon) * probs + epsilon * 0.5
    probs = np.maximum(probs, 0.0)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        return np.array([0.5, 0.5], dtype=np.float64)
    return probs / total


`policy(probs) -> int`:
def policy(probs):
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.maximum(probs, 0.0)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        probs = np.ones(len(probs), dtype=np.float64) / float(len(probs))
    else:
        probs /= total
    return int(np.random.choice(len(probs), p=probs))


`parameters`:
- validities: validities
- cue_salience_profile: [(-1.0, 1.0)] * n_features
- validity_compression: [0.16, 0.34]
- validity_reliance: [0.02, 0.07]
- salience_strength: [0.18, 0.42]
- coalition_saturation: [0.76, 0.86]
- corroboration_calibration: [-1.30, 0.70]
- corroboration_strength: [0.40, 0.50]
- composition_redundancy: [2.00, 2.80]
- beta: [0.82, 1.12]
- epsilon: [0.03, 0.09]

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=-0.1217 (var=0.0117) vs this=-0.0779 (var=0.0176)
- Experiment 2: real=-0.2642 (var=0.0087) vs this=-0.2321 (var=0.0159)
- Experiment 3: real=-0.0410 (var=0.0003) vs this=-0.0366 (var=0.0003)
- Experiment 4: real=0.5087 (var=0.0038) vs this=0.5046 (var=0.0065)
- Experiment 5: real=0.5021 (var=0.0024) vs this=0.5123 (var=0.0025)
- Experiment 6: real=0.4400 (var=0.2464) vs this=0.3600 (var=0.2304)
- Experiment 7: real=0.0219 (var=0.0094) vs this=0.0257 (var=0.0065)
- Experiment 8: real=0.0117 (var=0.0101) vs this=-0.0154 (var=0.0165)
- Experiment 9: real=0.4958 (var=0.0041) vs this=0.4996 (var=0.0028)
- Experiment 10: real=0.1723 (var=0.0081) vs this=0.2057 (var=0.0035)
- Experiment 11: real=0.0317 (var=0.0030) vs this=0.0217 (var=0.0086)
- Experiment 12: real=0.6692 (var=0.0068) vs this=0.4883 (var=0.0028)
- Experiment 13: real=0.3242 (var=0.0194) vs this=0.0158 (var=0.0163)
- Experiment 14: real=0.5869 (var=0.0047) vs this=0.5012 (var=0.0028)


---

### `pi_7` (overall score: 0.679)

**Description**
Reliability-Schema Source Inference proposes that decision makers treat expert agreement as evidence generated by latent informational sources rather than as conditionally independent votes. Advertised validities identify experts' reliability schemas. Dependence inference operates at two scales: an extremely narrow component assigns nearly identical, jointly extreme experts a high probability of sharing a source, while a narrower but stronger shoulder captures partial dependence among merely similar reliability schemas. For two-member coalitions, an additional equality-specific jointly extreme source prior produces nonlinear skepticism toward exactly matched reliable experts without increasing dependence for larger coalitions. Thus equally extreme coalitions can be discounted sharply without treating moderately heterogeneous coalitions as fully independent. Every discriminating cue contributes, but its contribution is divided by inferred latent-source overlap. Coalition evidence has diminishing returns, and nominal count corroboration is capped after three members. The transition from two to three members receives an additional corroboration gain only to the extent that the coalition represents informationally diverse sources. Stable subject-level priors over source dependence and count-versus-independence tradeoffs produce heterogeneous three-versus-two judgments without rewarding arbitrarily large coalitions. Communicated reliability differences are strongly compressed, preventing a single advertised-best expert from dominating a diverse majority. The computation is exchangeable over expert identities and contains no onset, closure, recency, adjacency, entry, exit, or other spatial parsing mechanism.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history) -> np.ndarray:
    stim = np.asarray(state, dtype=np.float64)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Reliability-Schema Source Inference expects shape "
            f"(2, n_features); got {stim.shape}."
        )

    a, b = stim[0], stim[1]
    n_features = int(stim.shape[1])

    validities = np.asarray(parameters["validities"], dtype=np.float64)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} != n_features {n_features}."
        )

    validity_compression = float(parameters["validity_compression"])
    validity_reliance = float(parameters["validity_reliance"])
    coalition_saturation = float(parameters["coalition_saturation"])
    dependence_prior = float(parameters["dependence_prior"])
    equality_pair_strength = float(parameters["equality_pair_strength"])
    similarity_bandwidth = float(parameters["similarity_bandwidth"])
    shoulder_strength = float(parameters["shoulder_strength"])
    shoulder_bandwidth = float(parameters["shoulder_bandwidth"])
    extremity_threshold = float(parameters["extremity_threshold"])
    extremity_slope = float(parameters["extremity_slope"])
    overlap_curvature = float(parameters["overlap_curvature"])
    count_independence_tradeoff = float(
        parameters["count_independence_tradeoff"]
    )
    diverse_third_gain = float(parameters["diverse_third_gain"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    # Advertised reliability is represented, but ordinal differences are
    # strongly compressed before use. The mean normalization keeps overall
    # evidence scale comparable across experiments with different validity
    # schedules.
    v = np.clip(validities, 0.500001, 0.999999)
    diagnosticity = np.log(v / (1.0 - v))
    compressed = np.power(np.maximum(diagnosticity, 1e-12), validity_compression)
    compressed /= max(float(np.mean(compressed)), 1e-12)
    cue_weights = (
        (1.0 - validity_reliance) * np.ones(n_features, dtype=np.float64)
        + validity_reliance * compressed
    )
    cue_weights /= max(float(np.mean(cue_weights)), 1e-12)

    differences = a - b
    a_support = np.flatnonzero(differences > 0.0)
    b_support = np.flatnonzero(differences < 0.0)

    if a_support.size == 0 and b_support.size == 0:
        return np.array([0.5, 0.5], dtype=np.float64)

    def coalition_signal(indices):
        idx = np.asarray(indices, dtype=int)
        n = int(idx.size)
        if n == 0:
            return 0.0
        if n == 1:
            return float(cue_weights[idx[0]])

        coalition_v = v[idx]
        overlap = np.zeros(n, dtype=np.float64)
        pair_posteriors = []

        # The narrow component detects almost identical reliability schemas.
        # A moderate-width shoulder represents partial common-source
        # inference for nonidentical but similar experts. An extra narrow
        # prior applies only to jointly extreme two-member coalitions, keeping
        # exact-pair skepticism separate from dependence among larger groups.
        for i in range(n):
            for j in range(i + 1, n):
                reliability_gap = float(coalition_v[i] - coalition_v[j])
                narrow_similarity = np.exp(
                    -0.5 * (reliability_gap / similarity_bandwidth) ** 2
                )
                shoulder_similarity = np.exp(
                    -0.5 * (reliability_gap / shoulder_bandwidth) ** 2
                )
                pair_extremity = 0.5 * float(coalition_v[i] + coalition_v[j])
                extreme_gate = 1.0 / (
                    1.0
                    + np.exp(
                        -np.clip(
                            extremity_slope
                            * (pair_extremity - extremity_threshold),
                            -50.0,
                            50.0,
                        )
                    )
                )

                narrow_affinity = (
                    dependence_prior
                    * narrow_similarity
                    * (0.01 + 0.99 * extreme_gate)
                )
                if n == 2:
                    narrow_affinity += (
                        equality_pair_strength
                        * narrow_similarity
                        * extreme_gate
                    )
                shoulder_affinity = (
                    shoulder_strength
                    * shoulder_similarity
                    * (0.10 + 0.90 * extreme_gate)
                )
                source_affinity = narrow_affinity + shoulder_affinity
                overlap[i] += source_affinity
                overlap[j] += source_affinity
                pair_posteriors.append(
                    source_affinity / (1.0 + source_affinity)
                )

        # Shared-source overlap is converted superlinearly into redundancy.
        # This permits sharp skepticism toward exactly equal extreme pairs
        # while preserving useful evidence from heterogeneous additions.
        independent_contributions = cue_weights[idx] / np.power(
            1.0 + overlap, overlap_curvature
        )
        independent_total = float(np.sum(independent_contributions))

        signal = independent_total / (float(n) ** coalition_saturation)

        # Nominal count corroboration is capped after the third member rather
        # than growing exponentially throughout a large coalition.
        capped_count_steps = float(min(n - 1, 2))
        signal *= np.exp(
            np.clip(
                count_independence_tradeoff * capped_count_steps,
                -10.0,
                10.0,
            )
        )

        # Crossing from two to at least three cues provides corroboration only
        # when those cues are inferred to represent informationally diverse
        # sources. The bonus is then capped, so fourth and later cues do not
        # receive repeated generic count rewards.
        if n >= 3:
            mean_shared_source = float(np.mean(pair_posteriors))
            effective_diversity = np.clip(
                1.0 - mean_shared_source, 0.0, 1.0
            )
            signal *= np.exp(
                np.clip(diverse_third_gain * effective_diversity, -10.0, 10.0)
            )

        return float(signal)

    evidence_a = coalition_signal(a_support)
    evidence_b = coalition_signal(b_support)
    net_a = evidence_a - evidence_b

    logits = np.array(
        [0.5 * beta * net_a, -0.5 * beta * net_a], dtype=np.float64
    )
    logits -= np.max(logits)
    probs = np.exp(logits)
    probs /= probs.sum()

    probs = (1.0 - epsilon) * probs + epsilon * 0.5
    probs = np.maximum(probs, 0.0)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        return np.array([0.5, 0.5], dtype=np.float64)
    return probs / total


`policy(probs) -> int`:
def policy(probs) -> int:
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.maximum(probs, 0.0)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        probs = np.ones(len(probs), dtype=np.float64) / float(len(probs))
    else:
        probs /= total
    return int(np.random.choice(len(probs), p=probs))


`parameters`:
- validities: validities
- validity_compression: [0.14, 0.30]
- validity_reliance: [0.01, 0.06]
- coalition_saturation: [0.62, 0.72]
- dependence_prior: [2.10, 3.90]
- equality_pair_strength: [0.60, 1.80]
- similarity_bandwidth: [0.010, 0.022]
- shoulder_strength: [0.62, 0.92]
- shoulder_bandwidth: [0.032, 0.065]
- extremity_threshold: [0.72, 0.78]
- extremity_slope: [20.0, 30.0]
- overlap_curvature: [2.10, 3.10]
- count_independence_tradeoff: [-0.02, 0.16]
- diverse_third_gain: [0.20, 0.40]
- beta: [1.20, 1.48]
- epsilon: [0.02, 0.06]

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=-0.1217 (var=0.0117) vs this=-0.3083 (var=0.0280)
- Experiment 2: real=-0.2642 (var=0.0087) vs this=-0.0892 (var=0.0075)
- Experiment 3: real=-0.0410 (var=0.0003) vs this=-0.0224 (var=0.0002)
- Experiment 4: real=0.5087 (var=0.0038) vs this=0.4932 (var=0.0039)
- Experiment 5: real=0.5021 (var=0.0024) vs this=0.5052 (var=0.0023)
- Experiment 6: real=0.4400 (var=0.2464) vs this=0.3200 (var=0.2176)
- Experiment 7: real=0.0219 (var=0.0094) vs this=-0.0108 (var=0.0126)
- Experiment 8: real=0.0117 (var=0.0101) vs this=-0.0021 (var=0.0101)
- Experiment 9: real=0.4958 (var=0.0041) vs this=0.4946 (var=0.0027)
- Experiment 10: real=0.1723 (var=0.0081) vs this=0.1814 (var=0.0023)
- Experiment 11: real=0.0317 (var=0.0030) vs this=0.2729 (var=0.0090)
- Experiment 12: real=0.6692 (var=0.0068) vs this=0.5575 (var=0.0028)
- Experiment 13: real=0.3242 (var=0.0194) vs this=0.3412 (var=0.0162)
- Experiment 14: real=0.5869 (var=0.0047) vs this=0.5816 (var=0.0036)


## LOSS TRAJECTORY (this propose-loop)
Aggregate loss across iterations of THIS propose-loop (lower = better, 0 = perfect, `+inf` = unscorable). The ACCEPTED / REJECTED tag is the loop's programmatic accept-gate decision — only ACCEPTED candidates have ever been used as the base for a subsequent iteration. Use this together with PRIOR FEEDBACK ITERATIONS below to grade which past critic advice actually paid off.

- iter 1: loss=0.1428 -> ACCEPTED
- iter 2: loss=0.1163 -> ACCEPTED
- iter 3: loss=0.1133 -> ACCEPTED
- iter 4: loss=0.1157 -> REJECTED
- iter 5: loss=0.1137 -> REJECTED
- iter 6: loss=0.1100 -> ACCEPTED
- iter 7: loss=0.1154 -> REJECTED
Running-best (last ACCEPTED) base: iter 6 at loss=0.1100 — this is the source shown verbatim below under `## PREVIOUS CANDIDATE (this loop)`. Push the next edit's loss strictly below that floor or the gate will reject it.

## EXPERIMENTAL RESULTS
### Experiment 1
**Design**
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Mean signed endorsement of the highest-validity cue's winner."""
    scores = []
    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=float)
        b = np.asarray(row["option_b_ratings"], dtype=float)
        response = int(row["response"])

        # Feature 0 is the uniquely highest-validity cue in this design.
        if a[0] > b[0]:
            top_cue_winner = 0
        elif b[0] > a[0]:
            top_cue_winner = 1
        else:
            continue

        scores.append(1.0 if response == top_cue_winner else -1.0)

    if len(scores) == 0:
        return float("nan")
    return float(np.mean(scores))
```

**Observed (real) value:** -0.1217 (var=0.0117)
**Previous candidate values (this loop):**
  - iter 1: -0.0533 (var=0.0157) (Δ vs real +0.0683)
  - iter 2: -0.3067 (var=0.0123) (Δ vs real -0.1850)
  - iter 3: -0.2508 (var=0.0222) (Δ vs real -0.1292)
  - iter 4: -0.1729 (var=0.0127) (Δ vs real -0.0512)
  - iter 5: -0.2546 (var=0.0148) (Δ vs real -0.1329)
  - iter 6: -0.2146 (var=0.0128) (Δ vs real -0.0929)
  - iter 7 (most recent): -0.2767 (var=0.0119) (Δ vs real -0.1550)
**Other theories' values on this metric (for reference):**
- pi_1: 0.7129 (var=0.0389)
- pi_2: -0.6354 (var=0.0266)
- pi_3: -0.1033 (var=0.0092)
- pi_4: -0.1246 (var=0.0114)
- pi_5: -0.1179 (var=0.0105)
- pi_6: -0.0779 (var=0.0176)
- pi_7: -0.3083 (var=0.0280)
- pi_8: -0.1358 (var=0.0111)

### Experiment 2
**Design**
  A=[1, 1, 1, 0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 1, 1, 0, 1]
  A=[0, 0, 0, 1, 1, 1, 0, 1]  B=[1, 1, 1, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 1, 1, 0, 0, 1]  B=[0, 1, 1, 0, 0, 1, 0, 1]
  A=[0, 1, 1, 0, 0, 1, 0, 1]  B=[1, 0, 0, 1, 1, 0, 0, 1]
  A=[0, 1, 1, 1, 0, 0, 0, 1]  B=[0, 0, 0, 0, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 1, 1, 1, 1]  B=[0, 1, 1, 1, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 1, 1, 0, 0]  B=[1, 0, 1, 1, 0, 0, 1, 0]
  A=[1, 0, 1, 1, 0, 0, 1, 0]  B=[1, 1, 0, 0, 1, 1, 0, 0]
  A=[0, 1, 1, 1, 1, 0, 0, 0]  B=[0, 1, 0, 0, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0, 1, 1, 1]  B=[0, 1, 1, 1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 1, 1, 0]  B=[1, 0, 0, 1, 1, 0, 0, 1]
  A=[1, 0, 0, 1, 1, 0, 0, 1]  B=[1, 0, 1, 0, 0, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Mean signed agreement with the highest-validity discriminating cue."""
    if data is None or len(data) == 0:
        return 0.0

    signed_agreements = []
    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=float)
        b = np.asarray(row["option_b_ratings"], dtype=float)

        # Features are already ordered from highest to lowest validity.
        differing = np.flatnonzero(a != b)
        if differing.size == 0:
            continue

        j = int(differing[0])
        ttb_response = 0 if a[j] > b[j] else 1
        observed_response = int(row["response"])
        signed_agreements.append(1.0 if observed_response == ttb_response else -1.0)

    if not signed_agreements:
        return 0.0
    return float(np.mean(signed_agreements))
```

**Observed (real) value:** -0.2642 (var=0.0087)
**Previous candidate values (this loop):**
  - iter 1: -0.0129 (var=0.0094) (Δ vs real +0.2512)
  - iter 2: 0.0317 (var=0.0120) (Δ vs real +0.2958)
  - iter 3: 0.0358 (var=0.0120) (Δ vs real +0.3000)
  - iter 4: -0.0096 (var=0.0094) (Δ vs real +0.2546)
  - iter 5: 0.0108 (var=0.0147) (Δ vs real +0.2750)
  - iter 6: 0.0125 (var=0.0103) (Δ vs real +0.2767)
  - iter 7 (most recent): 0.0292 (var=0.0065) (Δ vs real +0.2933)
**Other theories' values on this metric (for reference):**
- pi_2: -0.0008 (var=0.0102)
- pi_1: 0.7221 (var=0.0226)
- pi_3: -0.1892 (var=0.0123)
- pi_4: -0.2667 (var=0.0120)
- pi_5: -0.2217 (var=0.0089)
- pi_6: -0.2321 (var=0.0159)
- pi_7: -0.0892 (var=0.0075)
- pi_8: -0.2221 (var=0.0114)

### Experiment 3
**Design**
  A=[1, 1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0, 1, 0]  B=[0, 0, 0, 1, 0, 0, 1]
  A=[1, 0, 0, 1, 0, 1, 0]  B=[0, 1, 0, 0, 0, 0, 1]
  A=[0, 1, 0, 1, 0, 1, 0]  B=[1, 0, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 1, 1]  B=[0, 1, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 1, 1]  B=[1, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 1]  B=[1, 1, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0, 1]  B=[1, 1, 0, 0, 0, 1, 0]
  A=[0, 1, 0, 0, 0, 0, 1]  B=[1, 0, 0, 1, 0, 1, 0]
  A=[1, 0, 0, 0, 0, 0, 1]  B=[0, 1, 0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    if len(data) == 0:
        return 0.0

    # Fixed, preregistered midpoint instantiation of the advocated model.
    validities = np.array([0.52, 0.58, 0.65, 0.72, 0.80, 0.88, 0.95], dtype=float)
    balance = 0.30
    recency = 2.10
    curvature = 0.825
    saturation = 0.725
    beta = 0.90
    epsilon = 0.05

    v = np.clip(validities, 0.500001, 0.999999)
    diagnosticity = np.log(v / (1.0 - v))
    diagnosticity /= np.max(diagnosticity)
    diagnosticity = np.power(np.maximum(diagnosticity, 0.0), curvature)
    diagnosticity /= np.mean(diagnosticity)

    position = np.arange(len(validities), dtype=float) / float(len(validities) - 1)
    accessibility = np.exp(recency * position)
    accessibility /= np.mean(accessibility)

    cue_weights = balance * diagnosticity + (1.0 - balance) * accessibility
    cue_weights /= np.mean(cue_weights)

    predicted_majority_probs = []
    chose_majority = []

    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=float)
        b = np.asarray(row["option_b_ratings"], dtype=float)
        d = a - b

        # Orient every pair toward the option winning the 3-versus-2 tally.
        tally_margin = float(np.sum(d > 0) - np.sum(d < 0))
        if tally_margin == 0.0 or len(d) != len(cue_weights):
            continue
        majority_is_a = tally_margin > 0.0
        oriented = d if majority_is_a else -d

        positive = oriented > 0.0
        negative = oriented < 0.0
        n_pos = max(int(np.sum(positive)), 1)
        n_neg = max(int(np.sum(negative)), 1)
        min_n = min(n_pos, n_neg)

        pos_evidence = float(np.dot(cue_weights, np.maximum(oriented, 0.0)))
        neg_evidence = float(np.dot(cue_weights, np.maximum(-oriented, 0.0)))
        evidence = (
            pos_evidence / (max(1.0, float(n_pos) / float(min_n)) ** saturation)
            - neg_evidence / (max(1.0, float(n_neg) / float(min_n)) ** saturation)
        )

        core_p = 1.0 / (1.0 + np.exp(-np.clip(beta * evidence, -50.0, 50.0)))
        predicted_p = (1.0 - epsilon) * core_p + epsilon * 0.5
        predicted_majority_probs.append(predicted_p)

        response = int(row["response"])
        chose_majority.append(float((response == 0) if majority_is_a else (response == 1)))

    if len(predicted_majority_probs) == 0:
        return 0.0

    p = np.asarray(predicted_majority_probs, dtype=float)
    y = np.asarray(chose_majority, dtype=float)
    contrast = p - np.mean(p)
    return float(np.mean(contrast * (y - 0.5)))

```

**Observed (real) value:** -0.0410 (var=0.0003)
**Previous candidate values (this loop):**
  - iter 1: -0.0003 (var=0.0003) (Δ vs real +0.0407)
  - iter 2: 0.0030 (var=0.0003) (Δ vs real +0.0440)
  - iter 3: -0.0001 (var=0.0002) (Δ vs real +0.0409)
  - iter 4: -0.0005 (var=0.0003) (Δ vs real +0.0405)
  - iter 5: 0.0016 (var=0.0003) (Δ vs real +0.0426)
  - iter 6: -0.0002 (var=0.0003) (Δ vs real +0.0408)
  - iter 7 (most recent): -0.0017 (var=0.0002) (Δ vs real +0.0393)
**Other theories' values on this metric (for reference):**
- pi_3: 0.0860 (var=0.0002)
- pi_2: -0.0017 (var=0.0001)
- pi_1: 0.0899 (var=0.0009)
- pi_4: -0.0260 (var=0.0002)
- pi_5: -0.0237 (var=0.0003)
- pi_6: -0.0366 (var=0.0003)
- pi_7: -0.0224 (var=0.0002)
- pi_8: -0.0376 (var=0.0003)

### Experiment 4
**Design**
  A=[1, 0, 1, 0, 1, 0, 1, 0, 1]  B=[1, 1, 0, 0, 1, 0, 1, 0, 1]
  A=[1, 0, 1, 1, 1, 0, 1, 0, 1]  B=[1, 1, 1, 0, 1, 0, 1, 0, 1]
  A=[1, 0, 1, 0, 1, 0, 1, 0, 1]  B=[1, 1, 1, 0, 0, 0, 1, 0, 1]
  A=[1, 0, 1, 0, 1, 1, 1, 0, 1]  B=[1, 1, 1, 0, 1, 0, 1, 0, 1]
  A=[1, 0, 1, 0, 1, 0, 1, 0, 1]  B=[1, 1, 1, 0, 1, 0, 0, 0, 1]
  A=[1, 0, 1, 0, 1, 0, 1, 1, 1]  B=[1, 1, 1, 0, 1, 0, 1, 0, 1]
  A=[1, 1, 0, 0, 1, 0, 1, 0, 1]  B=[1, 0, 1, 0, 1, 0, 1, 0, 1]
  A=[1, 1, 1, 0, 1, 0, 1, 0, 1]  B=[1, 0, 1, 1, 1, 0, 1, 0, 1]
  A=[1, 1, 1, 0, 0, 0, 1, 0, 1]  B=[1, 0, 1, 0, 1, 0, 1, 0, 1]
  A=[1, 1, 1, 0, 1, 0, 1, 0, 1]  B=[1, 0, 1, 0, 1, 1, 1, 0, 1]
  A=[1, 1, 1, 0, 1, 0, 0, 0, 1]  B=[1, 0, 1, 0, 1, 0, 1, 0, 1]
  A=[1, 1, 1, 0, 1, 0, 1, 0, 1]  B=[1, 0, 1, 0, 1, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    weighted_choices = []
    weights = []

    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=float)
        b = np.asarray(row["option_b_ratings"], dtype=float)
        if a.shape != b.shape or a.ndim != 1 or a.size < 2:
            continue

        differing = np.flatnonzero(a != b)
        if differing.size != 2:
            continue

        early = int(np.min(differing))
        late = int(np.max(differing))
        late_supports_a = bool(a[late] > b[late])
        later_option_response = 0 if late_supports_a else 1
        chose_later_supported_option = float(int(row["response"]) == later_option_response)

        # Approximate matched-filter weight for the competing theory's
        # exponential positional-accessibility contrast.
        scale = float(a.size - 1)
        weight = np.exp(2.1 * late / scale) - np.exp(2.1 * early / scale)
        if np.isfinite(weight) and weight > 0.0:
            weighted_choices.append(chose_later_supported_option)
            weights.append(weight)

    if len(weights) == 0:
        return float("nan")

    return float(np.average(np.asarray(weighted_choices), weights=np.asarray(weights)))
```

**Observed (real) value:** 0.5087 (var=0.0038)
**Previous candidate values (this loop):**
  - iter 1: 0.5109 (var=0.0065) (Δ vs real +0.0022)
  - iter 2: 0.4825 (var=0.0071) (Δ vs real -0.0262)
  - iter 3: 0.4965 (var=0.0082) (Δ vs real -0.0122)
  - iter 4: 0.5000 (var=0.0053) (Δ vs real -0.0086)
  - iter 5: 0.5087 (var=0.0043) (Δ vs real +0.0000)
  - iter 6: 0.5131 (var=0.0045) (Δ vs real +0.0044)
  - iter 7 (most recent): 0.5016 (var=0.0074) (Δ vs real -0.0071)
**Other theories' values on this metric (for reference):**
- pi_2: 0.5017 (var=0.0041)
- pi_3: 0.6281 (var=0.0049)
- pi_1: 0.1476 (var=0.0116)
- pi_4: 0.5061 (var=0.0029)
- pi_5: 0.4957 (var=0.0036)
- pi_6: 0.5046 (var=0.0065)
- pi_7: 0.4932 (var=0.0039)
- pi_8: 0.4759 (var=0.0052)

### Experiment 5
**Design**
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 0, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 1, 0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 0, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 0, 1, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 0, 0, 0, 1, 1, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 1, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 1, 0]  B=[0, 0, 0, 1, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 1, 0]  B=[0, 0, 0, 0, 1, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    if len(data) == 0:
        return 0.5

    a = np.vstack(data["option_a_ratings"].apply(lambda x: np.asarray(x, dtype=float)).to_numpy())
    b = np.vstack(data["option_b_ratings"].apply(lambda x: np.asarray(x, dtype=float)).to_numpy())
    responses = pd.to_numeric(data["response"], errors="coerce").to_numpy(dtype=float)

    n_features = a.shape[1]
    if n_features == 1:
        positional_weights = np.ones(1, dtype=float)
    else:
        positions = np.arange(n_features, dtype=float) / float(n_features - 1)
        positional_weights = np.exp(2.1 * positions)

    # Positive evidence means positional accessibility favors A; negative
    # evidence means it favors B.
    accessibility_difference = np.dot(a - b, positional_weights)
    valid = np.isfinite(responses) & (accessibility_difference != 0.0)
    if not np.any(valid):
        return 0.5

    chose_a = responses[valid] == 0.0
    accessibility_favors_a = accessibility_difference[valid] > 0.0
    accessibility_aligned = chose_a == accessibility_favors_a
    return float(np.mean(accessibility_aligned))
```

**Observed (real) value:** 0.5021 (var=0.0024)
**Previous candidate values (this loop):**
  - iter 1: 0.4971 (var=0.0031) (Δ vs real -0.0050)
  - iter 2: 0.5127 (var=0.0016) (Δ vs real +0.0106)
  - iter 3: 0.5056 (var=0.0022) (Δ vs real +0.0035)
  - iter 4: 0.4983 (var=0.0023) (Δ vs real -0.0037)
  - iter 5: 0.5094 (var=0.0020) (Δ vs real +0.0073)
  - iter 6: 0.5025 (var=0.0028) (Δ vs real +0.0004)
  - iter 7 (most recent): 0.4908 (var=0.0025) (Δ vs real -0.0112)
**Other theories' values on this metric (for reference):**
- pi_3: 0.5692 (var=0.0021)
- pi_4: 0.3798 (var=0.0029)
- pi_1: 0.1575 (var=0.0119)
- pi_2: 0.4992 (var=0.0023)
- pi_5: 0.5098 (var=0.0033)
- pi_6: 0.5123 (var=0.0025)
- pi_7: 0.5052 (var=0.0023)
- pi_8: 0.4940 (var=0.0029)

### Experiment 6
**Design**
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0]
  A=[0, 0, 0, 1, 1, 0, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 1, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    if data is None or len(data) == 0:
        return float("nan")

    df = data[["subject_id", "option_a_ratings", "option_b_ratings", "response"]].copy()

    def early_coalition_choice(row):
        a = np.asarray(row["option_a_ratings"], dtype=float)
        b = np.asarray(row["option_b_ratings"], dtype=float)
        if a.size < 3 or b.size < 3:
            return np.nan
        score_a = float(np.sum(a[:3]))
        score_b = float(np.sum(b[:3]))
        if score_a == score_b:
            return np.nan
        early_side = 0 if score_a > score_b else 1
        return float(int(row["response"]) == early_side)

    df["chose_early_coalition"] = df.apply(early_coalition_choice, axis=1)
    rates = df.groupby("subject_id", sort=False)["chose_early_coalition"].mean().dropna()
    if len(rates) == 0:
        return float("nan")

    # Fraction of subjects whose majority choice favors the fixed early
    # three-cue coalition rather than the later two-cue coalition.
    return float(np.mean(rates.to_numpy(dtype=float) > 0.5))
```

**Observed (real) value:** 0.4400 (var=0.2464)
**Previous candidate values (this loop):**
  - iter 1: 0.2600 (var=0.1924) (Δ vs real -0.1800)
  - iter 2: 0.2200 (var=0.1716) (Δ vs real -0.2200)
  - iter 3: 0.2200 (var=0.1716) (Δ vs real -0.2200)
  - iter 4: 0.3000 (var=0.2100) (Δ vs real -0.1400)
  - iter 5: 0.2400 (var=0.1824) (Δ vs real -0.2000)
  - iter 6: 0.2600 (var=0.1924) (Δ vs real -0.1800)
  - iter 7 (most recent): 0.2000 (var=0.1600) (Δ vs real -0.2400)
**Other theories' values on this metric (for reference):**
- pi_4: 0.9800 (var=0.0196)
- pi_3: 0.0000 (var=0.0000)
- pi_1: 1.0000 (var=0.0000)
- pi_2: 1.0000 (var=0.0000)
- pi_5: 0.3200 (var=0.2176)
- pi_6: 0.3600 (var=0.2304)
- pi_7: 0.3200 (var=0.2176)
- pi_8: 0.5000 (var=0.2500)

### Experiment 7
**Design**
  A=[1, 1, 0, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0]
  A=[1, 0, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0]
  A=[1, 1, 0, 0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0]
  A=[1, 0, 0, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0]
  A=[1, 1, 0, 0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0]  B=[1, 1, 0, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0]  B=[1, 0, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0]  B=[1, 1, 0, 0, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0]  B=[1, 1, 0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1, 1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    entry_sum = 0.0
    entry_weight = 0.0
    exit_sum = 0.0
    exit_weight = 0.0

    for row in data.itertuples(index=False):
        a = np.asarray(row.option_a_ratings, dtype=float)
        b = np.asarray(row.option_b_ratings, dtype=float)
        diff = a - b
        pos = np.flatnonzero(diff > 0)
        neg = np.flatnonzero(diff < 0)

        # Identify the three-cue coalition and whether it supports A or B.
        if pos.size == 3 and neg.size == 2:
            coalition = pos
            endorsed_three = 1.0 if int(row.response) == 0 else 0.0
        elif neg.size == 3 and pos.size == 2:
            coalition = neg
            endorsed_three = 1.0 if int(row.response) == 1 else 0.0
        else:
            continue

        gaps = np.diff(coalition).astype(float)
        if gaps.size != 2:
            continue

        first_compact = bool(gaps[0] == 1 and gaps[1] > 1)
        last_compact = bool(gaps[1] == 1 and gaps[0] > 1)
        if not (first_compact or last_compact):
            continue

        # Larger separation makes entry- versus exit-compact organization
        # more distinct. This bounded weight is the difference between the
        # two adjacent-link binding strengths.
        weight = abs(np.exp(-(gaps[0] - 1.0)) - np.exp(-(gaps[1] - 1.0)))

        if first_compact:
            entry_sum += weight * endorsed_three
            entry_weight += weight
        else:
            exit_sum += weight * endorsed_three
            exit_weight += weight

    if entry_weight <= 0.0 or exit_weight <= 0.0:
        return 0.0

    return float(entry_sum / entry_weight - exit_sum / exit_weight)

```

**Observed (real) value:** 0.0219 (var=0.0094)
**Previous candidate values (this loop):**
  - iter 1: -0.0170 (var=0.0102) (Δ vs real -0.0389)
  - iter 2: 0.0075 (var=0.0094) (Δ vs real -0.0144)
  - iter 3: 0.0056 (var=0.0097) (Δ vs real -0.0162)
  - iter 4: -0.0007 (var=0.0082) (Δ vs real -0.0226)
  - iter 5: 0.0091 (var=0.0070) (Δ vs real -0.0128)
  - iter 6: -0.0090 (var=0.0083) (Δ vs real -0.0308)
  - iter 7 (most recent): -0.0051 (var=0.0102) (Δ vs real -0.0270)
**Other theories' values on this metric (for reference):**
- pi_5: 0.2360 (var=0.0123)
- pi_4: 0.0009 (var=0.0095)
- pi_1: 0.0069 (var=0.0048)
- pi_2: -0.0035 (var=0.0050)
- pi_3: -0.0376 (var=0.0081)
- pi_6: 0.0257 (var=0.0065)
- pi_7: -0.0108 (var=0.0126)
- pi_8: 0.0088 (var=0.0097)

### Experiment 8
**Design**
  A=[1, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 1, 0, 0]  B=[0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0]  B=[1, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    early_choices = []
    late_choices = []

    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=float)
        b = np.asarray(row["option_b_ratings"], dtype=float)
        differences = a - b
        a_support = np.flatnonzero(differences > 0)
        b_support = np.flatnonzero(differences < 0)
        response = int(row["response"])

        if a_support.size == 3 and b_support.size == 2:
            onset_difference = int(a_support[0]) - int(b_support[0])
            chose_three = float(response == 0)
        elif a_support.size == 2 and b_support.size == 3:
            onset_difference = int(b_support[0]) - int(a_support[0])
            chose_three = float(response == 1)
        else:
            continue

        if onset_difference < 0:
            early_choices.append(chose_three)
        elif onset_difference > 0:
            late_choices.append(chose_three)

    if len(early_choices) == 0 or len(late_choices) == 0:
        return 0.0

    return float(np.mean(early_choices) - np.mean(late_choices))
```

**Observed (real) value:** 0.0117 (var=0.0101)
**Previous candidate values (this loop):**
  - iter 1: 0.0137 (var=0.0116) (Δ vs real +0.0021)
  - iter 2: -0.0050 (var=0.0083) (Δ vs real -0.0167)
  - iter 3: -0.0017 (var=0.0117) (Δ vs real -0.0133)
  - iter 4: 0.0008 (var=0.0100) (Δ vs real -0.0108)
  - iter 5: -0.0092 (var=0.0107) (Δ vs real -0.0208)
  - iter 6: -0.0025 (var=0.0119) (Δ vs real -0.0142)
  - iter 7 (most recent): 0.0054 (var=0.0089) (Δ vs real -0.0062)
**Other theories' values on this metric (for reference):**
- pi_4: 0.2729 (var=0.0146)
- pi_5: -0.0100 (var=0.0101)
- pi_1: 0.7325 (var=0.0409)
- pi_2: -0.0042 (var=0.0038)
- pi_3: -0.4775 (var=0.0097)
- pi_6: -0.0154 (var=0.0165)
- pi_7: -0.0021 (var=0.0101)
- pi_8: -0.0042 (var=0.0116)

### Experiment 9
**Design**
  A=[1, 0, 1, 0, 0, 1, 1, 0]  B=[0, 1, 0, 1, 1, 0, 1, 0]
  A=[1, 0, 0, 1, 0, 1, 1, 0]  B=[0, 1, 1, 0, 1, 0, 1, 0]
  A=[1, 0, 0, 0, 1, 1, 1, 0]  B=[0, 1, 1, 1, 0, 0, 1, 0]
  A=[0, 1, 1, 0, 0, 1, 1, 0]  B=[1, 0, 0, 1, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0, 1, 1, 0]  B=[1, 0, 1, 0, 1, 0, 1, 0]
  A=[0, 1, 0, 0, 1, 1, 1, 0]  B=[1, 0, 1, 1, 0, 0, 1, 0]
  A=[0, 0, 1, 0, 1, 1, 1, 0]  B=[1, 1, 0, 1, 0, 0, 1, 0]
  A=[0, 0, 0, 1, 1, 1, 1, 0]  B=[1, 1, 1, 0, 0, 0, 1, 0]
  A=[0, 1, 0, 1, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0, 1, 1, 0]
  A=[0, 1, 1, 0, 1, 0, 1, 0]  B=[1, 0, 0, 1, 0, 1, 1, 0]
  A=[0, 1, 1, 1, 0, 0, 1, 0]  B=[1, 0, 0, 0, 1, 1, 1, 0]
  A=[1, 0, 0, 1, 1, 0, 1, 0]  B=[0, 1, 1, 0, 0, 1, 1, 0]
  A=[1, 0, 1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 1, 1, 0]
  A=[1, 0, 1, 1, 0, 0, 1, 0]  B=[0, 1, 0, 0, 1, 1, 1, 0]
  A=[1, 1, 0, 1, 0, 0, 1, 0]  B=[0, 0, 1, 0, 1, 1, 1, 0]
  A=[1, 1, 1, 0, 0, 0, 1, 0]  B=[0, 0, 0, 1, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    closure_choices = []

    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=np.float64)
        b = np.asarray(row["option_b_ratings"], dtype=np.float64)
        difference = a - b
        discriminating = np.flatnonzero(difference != 0.0)

        if discriminating.size == 0:
            continue

        # The closure coalition is the option supported by the final
        # discriminating cue, irrespective of whether it is displayed as A or B.
        last_index = int(discriminating[-1])
        closure_response = 0 if difference[last_index] > 0.0 else 1
        closure_choices.append(float(int(row["response"]) == closure_response))

    if len(closure_choices) == 0:
        return float("nan")

    return float(np.mean(np.asarray(closure_choices, dtype=np.float64)))
```

**Observed (real) value:** 0.4958 (var=0.0041)
**Previous candidate values (this loop):**
  - iter 1: 0.5073 (var=0.0022) (Δ vs real +0.0115)
  - iter 2: 0.5015 (var=0.0025) (Δ vs real +0.0056)
  - iter 3: 0.4946 (var=0.0029) (Δ vs real -0.0013)
  - iter 4: 0.5071 (var=0.0025) (Δ vs real +0.0112)
  - iter 5: 0.4958 (var=0.0020) (Δ vs real +0.0000)
  - iter 6: 0.5008 (var=0.0023) (Δ vs real +0.0050)
  - iter 7 (most recent): 0.4933 (var=0.0014) (Δ vs real -0.0025)
**Other theories' values on this metric (for reference):**
- pi_5: 0.6108 (var=0.0033)
- pi_6: 0.4996 (var=0.0028)
- pi_1: 0.4104 (var=0.0015)
- pi_2: 0.4985 (var=0.0025)
- pi_3: 0.6115 (var=0.0020)
- pi_4: 0.6271 (var=0.0029)
- pi_7: 0.4946 (var=0.0027)
- pi_8: 0.5056 (var=0.0026)

### Experiment 10
**Design**
  A=[1, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 1, 0]
  A=[0, 1, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 1, 0]
  A=[0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 1, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 1, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 1, 0]  B=[0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    validities = np.asarray([
        0.68, 0.74, 0.80, 0.86, 0.92, 0.97, 0.55, 0.70,
        0.68, 0.74, 0.80, 0.86, 0.92, 0.97, 0.60, 0.70
    ], dtype=np.float64)
    bounded = np.clip(2.0 * validities - 1.0, 0.0, 1.0)

    weighted_choices = []
    weights = []

    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=np.float64)
        b = np.asarray(row["option_b_ratings"], dtype=np.float64)
        if a.size != validities.size or b.size != validities.size:
            continue

        differences = a - b
        a_support = np.flatnonzero(differences > 0.0)
        b_support = np.flatnonzero(differences < 0.0)
        if a_support.size != 2 or b_support.size != 2:
            continue

        a_equal = bool(np.isclose(validities[a_support[0]], validities[a_support[1]]))
        b_equal = bool(np.isclose(validities[b_support[0]], validities[b_support[1]]))
        if a_equal == b_equal:
            continue

        load_a = float(bounded[a_support[0]] * bounded[a_support[1]])
        load_b = float(bounded[b_support[0]] * bounded[b_support[1]])
        weight = abs(load_a - load_b)
        if not np.isfinite(weight) or weight <= 0.0:
            continue

        response = int(row["response"])
        chose_equal = float((response == 0) if a_equal else (response == 1))
        weighted_choices.append(weight * chose_equal)
        weights.append(weight)

    total_weight = float(np.sum(weights))
    if total_weight <= 0.0:
        return 0.5
    return float(np.sum(weighted_choices) / total_weight)

```

**Observed (real) value:** 0.1723 (var=0.0081)
**Previous candidate values (this loop):**
  - iter 1: 0.4007 (var=0.0041) (Δ vs real +0.2283)
  - iter 2: 0.2723 (var=0.0020) (Δ vs real +0.1000)
  - iter 3: 0.2460 (var=0.0034) (Δ vs real +0.0736)
  - iter 4: 0.2399 (var=0.0031) (Δ vs real +0.0676)
  - iter 5: 0.2754 (var=0.0033) (Δ vs real +0.1031)
  - iter 6: 0.2748 (var=0.0031) (Δ vs real +0.1025)
  - iter 7 (most recent): 0.2640 (var=0.0038) (Δ vs real +0.0917)
**Other theories' values on this metric (for reference):**
- pi_6: 0.2057 (var=0.0035)
- pi_5: 0.5023 (var=0.0031)
- pi_1: 0.8796 (var=0.0067)
- pi_2: 0.4978 (var=0.0039)
- pi_3: 0.5414 (var=0.0029)
- pi_4: 0.3753 (var=0.0039)
- pi_7: 0.1814 (var=0.0023)
- pi_8: 0.1646 (var=0.0019)

### Experiment 11
**Design**
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]
  A=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]  B=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]  B=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    def subject_contrast(df):
        high_gap = []
        low_gap = []

        for _, row in df.iterrows():
            a = np.asarray(row["option_a_ratings"], dtype=float)
            b = np.asarray(row["option_b_ratings"], dtype=float)
            d = a - b

            # Target coalitions occupy cues 0--15; cues 16--17 are the
            # fixed reference coalition. Each target coalition is one of
            # the adjacent cue pairs (0,1), (2,3), ..., (14,15).
            target_idx = np.flatnonzero(d[:16] != 0.0)
            if target_idx.size != 2:
                continue

            pair_id = int(np.min(target_idx) // 2)
            direction = float(np.mean(d[target_idx]))
            if direction == 0.0:
                continue

            target_response = 0 if direction > 0.0 else 1
            chose_target = float(int(row["response"]) == target_response)

            # Low gaps comprise 0.00 and 0.04; high gaps comprise 0.10
            # and 0.18. This uses all 96 observations per subject.
            if pair_id <= 3:
                low_gap.append(chose_target)
            else:
                high_gap.append(chose_target)

        if len(high_gap) == 0 or len(low_gap) == 0:
            return np.nan
        return float(np.mean(high_gap) - np.mean(low_gap))

    if "subject_id" in data.columns:
        values = [subject_contrast(df) for _, df in data.groupby("subject_id", sort=False)]
    else:
        values = [subject_contrast(data)]

    values = np.asarray(values, dtype=float)
    values = values[np.isfinite(values)]
    if values.size == 0:
        return np.nan
    return float(np.mean(values))
```

**Observed (real) value:** 0.0317 (var=0.0030)
**Previous candidate values (this loop):**
  - iter 1: 0.0813 (var=0.0113) (Δ vs real +0.0496)
  - iter 2: 0.1129 (var=0.0103) (Δ vs real +0.0813)
  - iter 3: 0.1367 (var=0.0085) (Δ vs real +0.1050)
  - iter 4: 0.1771 (var=0.0088) (Δ vs real +0.1454)
  - iter 5: 0.1238 (var=0.0070) (Δ vs real +0.0921)
  - iter 6: 0.1300 (var=0.0056) (Δ vs real +0.0983)
  - iter 7 (most recent): 0.1167 (var=0.0090) (Δ vs real +0.0850)
**Other theories' values on this metric (for reference):**
- pi_7: 0.2729 (var=0.0090)
- pi_6: 0.0217 (var=0.0086)
- pi_1: 0.0167 (var=0.0064)
- pi_2: -0.0292 (var=0.0133)
- pi_3: 0.1604 (var=0.0061)
- pi_4: 0.0054 (var=0.0079)
- pi_5: 0.0146 (var=0.0117)
- pi_8: 0.0125 (var=0.0063)

### Experiment 12
**Design**
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    distributed = {(3, 4, 5), (9, 10, 11)}

    def subject_score(df):
        records = []
        for _, row in df.iterrows():
            a = np.asarray(row['option_a_ratings'], dtype=float)
            b = np.asarray(row['option_b_ratings'], dtype=float)
            diff = a - b
            a_support = tuple(np.flatnonzero(diff > 0).tolist())
            b_support = tuple(np.flatnonzero(diff < 0).tolist())
            a_is_distributed = a_support in distributed
            b_is_distributed = b_support in distributed
            if a_is_distributed == b_is_distributed:
                continue
            chose_a = int(row['response']) == 0
            chose_distributed = (
                (chose_a and a_is_distributed) or
                ((not chose_a) and b_is_distributed)
            )
            records.append((a_is_distributed, float(chose_distributed)))

        if not records:
            return np.nan

        records = pd.DataFrame(records, columns=['distributed_on_a', 'choice'])
        role_means = records.groupby('distributed_on_a')['choice'].mean()
        if len(role_means) == 2:
            return float(0.5 * (role_means.loc[False] + role_means.loc[True]))
        return float(records['choice'].mean())

    if len(data) == 0:
        return float('nan')

    if 'subject_id' in data.columns:
        scores = [subject_score(df) for _, df in data.groupby('subject_id', sort=False)]
    else:
        scores = [subject_score(data)]
    scores = np.asarray(scores, dtype=float)
    scores = scores[np.isfinite(scores)]
    return float(np.mean(scores)) if scores.size else float('nan')
```

**Observed (real) value:** 0.6692 (var=0.0068)
**Previous candidate values (this loop):**
  - iter 1: 0.5158 (var=0.0034) (Δ vs real -0.1533)
  - iter 2: 0.6660 (var=0.0027) (Δ vs real -0.0031)
  - iter 3: 0.6835 (var=0.0024) (Δ vs real +0.0144)
  - iter 4: 0.6600 (var=0.0021) (Δ vs real -0.0092)
  - iter 5: 0.7094 (var=0.0031) (Δ vs real +0.0402)
  - iter 6: 0.6763 (var=0.0026) (Δ vs real +0.0071)
  - iter 7 (most recent): 0.6973 (var=0.0019) (Δ vs real +0.0281)
**Other theories' values on this metric (for reference):**
- pi_6: 0.4883 (var=0.0028)
- pi_7: 0.5575 (var=0.0028)
- pi_1: 0.1550 (var=0.0096)
- pi_2: 0.5073 (var=0.0027)
- pi_3: 0.6663 (var=0.0014)
- pi_4: 0.5715 (var=0.0020)
- pi_5: 0.5602 (var=0.0027)
- pi_8: 0.7031 (var=0.0082)

### Experiment 13
**Design**
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1]  B=[0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    if data is None or len(data) == 0:
        return float('nan')

    cell_values = {}
    for _, row in data.iterrows():
        a = np.asarray(row['option_a_ratings'], dtype=int)
        b = np.asarray(row['option_b_ratings'], dtype=int)
        response = int(row['response'])

        # In this design, distributed coalitions occupy cues 6--11 and
        # clustered coalitions occupy cues 0--5. Identify which display side
        # contains the distributed coalition from discriminating support.
        a_support = np.flatnonzero(a > b)
        b_support = np.flatnonzero(b > a)
        a_is_distributed = (
            a_support.size > 0 and np.all(a_support >= 6)
        )
        b_is_distributed = (
            b_support.size > 0 and np.all(b_support >= 6)
        )

        if a_is_distributed == b_is_distributed:
            continue

        chose_distributed = (
            (response == 0 and a_is_distributed) or
            (response == 1 and b_is_distributed)
        )
        signed_choice = 1.0 if chose_distributed else -1.0

        # Equal-weight the eight unique configurations so that the statistic
        # remains mirror-corrected even if a few trials are missing.
        key = (tuple(a.tolist()), tuple(b.tolist()))
        if key not in cell_values:
            cell_values[key] = []
        cell_values[key].append(signed_choice)

    if not cell_values:
        return float('nan')

    cell_means = [float(np.mean(values)) for values in cell_values.values()]
    return float(np.mean(cell_means))

```

**Observed (real) value:** 0.3242 (var=0.0194)
**Previous candidate values (this loop):**
  - iter 1: 0.1679 (var=0.0096) (Δ vs real -0.1563)
  - iter 2: 0.3754 (var=0.0128) (Δ vs real +0.0512)
  - iter 3: 0.4000 (var=0.0099) (Δ vs real +0.0758)
  - iter 4: 0.4321 (var=0.0096) (Δ vs real +0.1079)
  - iter 5: 0.4167 (var=0.0102) (Δ vs real +0.0925)
  - iter 6: 0.3613 (var=0.0122) (Δ vs real +0.0371)
  - iter 7 (most recent): 0.3629 (var=0.0124) (Δ vs real +0.0387)
**Other theories' values on this metric (for reference):**
- pi_8: 0.5346 (var=0.0171)
- pi_6: 0.0158 (var=0.0163)
- pi_1: -0.6938 (var=0.0472)
- pi_2: 0.0129 (var=0.0129)
- pi_3: 0.6592 (var=0.0081)
- pi_4: 0.2250 (var=0.0097)
- pi_5: 0.2188 (var=0.0122)
- pi_7: 0.3412 (var=0.0162)

### Experiment 14
**Design**
  A=[0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Concentrate on the direct endpoint comparison and the three early
    # reliability-gap transitions where region release should be largest.
    diagnostic_pairs = {(0, 1), (1, 2), (2, 3), (0, 5)}
    distributed_choices = []

    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=np.int8)
        b = np.asarray(row["option_b_ratings"], dtype=np.int8)
        diff = a - b
        a_support = np.flatnonzero(diff > 0)
        b_support = np.flatnonzero(diff < 0)

        if a_support.size == 0 or b_support.size == 0:
            continue

        # Each coalition occupies one of six consecutive three-cue blocks.
        a_block = int(a_support[0] // 3)
        b_block = int(b_support[0] // 3)
        pair = tuple(sorted((a_block, b_block)))
        if pair not in diagnostic_pairs:
            continue

        response = int(row["response"])
        chosen_block = a_block if response == 0 else b_block
        distributed_block = max(a_block, b_block)
        distributed_choices.append(float(chosen_block == distributed_block))

    if not distributed_choices:
        return float("nan")
    return float(np.mean(distributed_choices))
```

**Observed (real) value:** 0.5869 (var=0.0047)
**Previous candidate values (this loop):**
  - iter 1: 0.5253 (var=0.0038) (Δ vs real -0.0616)
  - iter 2: 0.5931 (var=0.0046) (Δ vs real +0.0062)
  - iter 3: 0.5931 (var=0.0039) (Δ vs real +0.0062)
  - iter 4: 0.6047 (var=0.0031) (Δ vs real +0.0178)
  - iter 5: 0.5969 (var=0.0025) (Δ vs real +0.0100)
  - iter 6: 0.6053 (var=0.0036) (Δ vs real +0.0184)
  - iter 7 (most recent): 0.5778 (var=0.0035) (Δ vs real -0.0091)
**Other theories' values on this metric (for reference):**
- pi_6: 0.5012 (var=0.0028)
- pi_8: 0.6616 (var=0.0045)
- pi_1: 0.1222 (var=0.0090)
- pi_2: 0.5122 (var=0.0043)
- pi_3: 0.6784 (var=0.0035)
- pi_4: 0.6269 (var=0.0040)
- pi_5: 0.6112 (var=0.0040)
- pi_7: 0.5816 (var=0.0036)

## PREVIOUS CANDIDATE (this loop)
The RUNNING-BEST (last ACCEPTED) candidate in this critique loop — i.e. the source the loop's accept gate kept as the best base so far. If your most recent attempt was REJECTED by the gate, this is NOT that attempt; it is the previously-accepted base the gate rolled back to. Iterate on this source — the next critic feedback should be applied on top of it.

**Description**
Reliability-Space Credit Sharing proposes that people interpret agreement among experts through an inferred dependence network defined entirely in represented reliability space. Advertised validities have two related but distinct cognitive representations: a strongly compressed representation determines each cue's direct evidential weight, while a separately calibrated fixed-anchor representation determines inferred dependence. Within any option-supporting coalition, every expert shares informational credit with similarly represented experts according to a smooth, sharply localized similarity kernel. An expert surrounded by reliability-near neighbors therefore contributes less independent evidence, whereas reliability-distant experts contribute nearly undiluted evidence. The steep but continuous kernel concentrates redundancy around extremely similar reliability representations, producing a strong equality penalty without a broad dyadic reliability-gap gradient. Credit sharing applies at every coalition size, without an equality detector, dyadic/triadic switch, spatial grouping rule, or duplicate-pair-in-context operation. Because additional coalition members create multiple possible similarity relations, local dependence can accumulate nonlinearly in larger coalitions even when its effect on a single nonidentical pair is weak. Effective evidence is additionally subject to generic sublinear count growth. Stable subject-level dependence sensitivity, overlap curvature, compressed validity reliance, and exchangeable zero-centered cue salience generate individual differences without population-level serial-position effects. Choices arise from response sensitivity plus an independent lapse process, and representations remain fixed because no outcome feedback is provided.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history) -> np.ndarray:
    stim = np.asarray(state, dtype=np.float64)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Reliability-Space Credit Sharing expects shape (2, n_features); got {stim.shape}."
        )

    a, b = stim[0], stim[1]
    n_features = int(stim.shape[1])

    validities = np.asarray(parameters["validities"], dtype=np.float64)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} != n_features {n_features}."
        )

    raw_salience = np.asarray(
        parameters["cue_salience_profile"], dtype=np.float64
    )
    if raw_salience.ndim != 1 or raw_salience.size != n_features:
        raise ValueError(
            f"cue_salience_profile length {raw_salience.size} != n_features {n_features}."
        )

    validity_compression = float(parameters["validity_compression"])
    direct_validity_compression = float(
        parameters["direct_validity_compression"]
    )
    validity_reliance = float(parameters["validity_reliance"])
    salience_strength = float(parameters["salience_strength"])
    coalition_saturation = float(parameters["coalition_saturation"])
    dependence_sensitivity = float(parameters["dependence_sensitivity"])
    similarity_bandwidth = float(parameters["similarity_bandwidth"])
    overlap_curvature = float(parameters["overlap_curvature"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    # Dependence and direct cue weighting use separately compressed versions
    # of the same instructed validity. Both retain the fixed 0.75 reference,
    # so their scales remain invariant across experiments.
    v = np.clip(validities, 0.500001, 0.999999)
    log_diagnosticity = np.log(v / (1.0 - v))
    reference_diagnosticity = np.log(0.75 / 0.25)

    represented = np.power(
        np.maximum(log_diagnosticity, 1e-12), validity_compression
    )
    represented /= max(
        float(reference_diagnosticity ** validity_compression), 1e-12
    )

    direct_represented = np.power(
        np.maximum(log_diagnosticity, 1e-12),
        direct_validity_compression,
    )
    direct_represented /= max(
        float(reference_diagnosticity ** direct_validity_compression),
        1e-12,
    )

    reliability_weight = (
        (1.0 - validity_reliance) * np.ones(n_features, dtype=np.float64)
        + validity_reliance * direct_represented
    )

    # Subject-specific salience is exchangeable over cue identities and is
    # centered within the display, precluding a population onset or recency
    # advantage while allowing stable individual configuration preferences.
    centered_salience = raw_salience - float(np.mean(raw_salience))
    attention = np.exp(
        np.clip(salience_strength * centered_salience, -10.0, 10.0)
    )
    attention /= max(float(np.mean(attention)), 1e-12)

    cue_weights = reliability_weight * attention
    cue_weights /= max(float(np.mean(cue_weights)), 1e-12)

    difference = a - b
    a_support = np.flatnonzero(difference > 0.0)
    b_support = np.flatnonzero(difference < 0.0)

    if a_support.size == 0 and b_support.size == 0:
        return np.array([0.5, 0.5], dtype=np.float64)

    def coalition_signal(indices):
        idx = np.asarray(indices, dtype=int)
        n = int(idx.size)
        if n == 0:
            return 0.0
        if n == 1:
            return float(cue_weights[idx[0]])

        coordinates = represented[idx]
        gaps = coordinates[:, None] - coordinates[None, :]

        # A smooth super-Gaussian concentrates inferred dependence around
        # extremely close reliability representations. It remains continuous
        # and cardinality-general, but decays faster than the previous
        # Gaussian outside the local overlap neighborhood.
        scaled_gaps = gaps / max(similarity_bandwidth, 1e-12)
        similarity = np.exp(-0.5 * np.power(scaled_gaps, 4.0))
        np.fill_diagonal(similarity, 0.0)
        local_overlap = np.sum(similarity, axis=1)

        # Divisive credit allocation approximates precision loss under
        # correlated sources. In a pair, each cue has only one possible
        # neighbor. In larger coalitions, multiple pairwise overlaps converge
        # on each member and create nonlinear redundancy without a size gate.
        independence_fraction = np.power(
            1.0 + dependence_sensitivity * local_overlap,
            -overlap_curvature,
        )
        effective_total = float(
            np.sum(cue_weights[idx] * independence_fraction)
        )

        # Generic count normalization makes corroboration sublinear even for
        # reliability-diverse coalitions. Dependence can further reduce the
        # marginal value of clustered additions but never deletes a cue.
        signal = effective_total / (float(n) ** coalition_saturation)
        return float(max(signal, 0.0))

    evidence_a = coalition_signal(a_support)
    evidence_b = coalition_signal(b_support)
    net_a = evidence_a - evidence_b

    logits = np.array(
        [0.5 * beta * net_a, -0.5 * beta * net_a], dtype=np.float64
    )
    logits = logits - np.max(logits)
    probs = np.exp(logits)
    probs /= probs.sum()

    probs = (1.0 - epsilon) * probs + epsilon * 0.5
    probs = np.maximum(probs, 0.0)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        return np.array([0.5, 0.5], dtype=np.float64)
    return probs / total


`policy(probs) -> int`:
def policy(probs) -> int:
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.maximum(probs, 0.0)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        probs = np.ones(len(probs), dtype=np.float64) / float(len(probs))
    else:
        probs /= total
    return int(np.random.choice(len(probs), p=probs))


`parameters`:
- validities: validities
- cue_salience_profile: [(-1.0, 1.0)] * n_features
- validity_compression: [0.22, 0.27]
- direct_validity_compression: [0.08, 0.14]
- validity_reliance: [0.008, 0.025]
- salience_strength: [0.12, 0.28]
- coalition_saturation: [0.64, 0.72]
- dependence_sensitivity: [2.90, 3.50]
- similarity_bandwidth: [0.006, 0.009]
- overlap_curvature: [0.80, 0.90]
- beta: [1.12, 1.38]
- epsilon: [0.03, 0.08]

`rationale`: This is a minimal edit of the accepted iteration-3 model. Direct evidential weighting now uses a separate, more strongly compressed validity representation and a lower, narrower reliance range, while the accepted fixed-anchor dependence coordinate is retained. This removes the unnecessary constraint that the same compression parameter must simultaneously govern direct cue weights and inferred source similarity. The Gaussian kernel is changed only in shape to a smooth super-Gaussian and its bandwidth is narrowed moderately. That produces a steeper local falloff: exact and extremely close reliability matches can still be discounted strongly in Experiment 10, but nonzero dyadic gaps should cease generating the broad gradient that inflated Experiment 11. Multiple close relations can nevertheless accumulate through the unchanged nodewise overlap equation in three-cue coalitions, preserving the general dependence explanation of Experiments 2 and 12–14 without a cardinality switch. Coalition saturation, dependence strength, overlap curvature, beta, lapse, salience, and the accepted divisive credit-sharing equation are otherwise unchanged. Thus the edit directly addresses the latest diagnosis without repeating the rejected broad-tail or inverse-precision substitutions.

## PRIOR FEEDBACK ITERATIONS
The critic's verdicts on each previous in-loop candidate, in order. Each block ends with an **Outcome of this advice** line saying whether the candidate the proposer produced AFTER this advice was ACCEPTED (loss strictly beat the running best) or REJECTED (the gate discarded it). Address the most recent iteration's feedback in your next edit, but down-weight past advice whose candidates were REJECTED.

### Iteration 1
Verdict: regenerate
Interpretation: The candidate is faithful to the prescribed inferred-dependence family and successfully preserves the null positional/serial patterns: Experiments 4, 5, 7, 8, and 9 are close to observed values. However, its reliability-space dependence signal is much too weak on the central composition tests. Distributed-coalition preference is underestimated in Experiment 12 (0.5158 versus 0.6692), Experiment 13 (0.1679 versus 0.3242), and Experiment 14 (0.5253 versus 0.5869). The equal-versus-diverse composition effect in Experiment 10 is also far too weak: the candidate chooses the equal-reliability coalition at 0.4007 rather than the observed 0.1723. At the same time, it produces too broad a dyadic gap gradient in Experiment 11 (0.0813 versus 0.0317), with excessive between-subject variance. Thus the kernel is paradoxically insufficiently punitive at exact or very close reliability overlap but too responsive across wider reliability gaps. Generic count evidence is also too suppressed: the candidate underpredicts majority/count effects in Experiments 1, 2, 3, and 6, most dramatically in Experiment 2 (-0.0129 versus -0.2642) and Experiment 3 (-0.0003 versus -0.0410).
Rationale: Keep the smooth reliability-space credit-sharing mechanism, but recalibrate its shape and count normalization. Use a narrower similarity bandwidth together with stronger local dependence sensitivity or curvature. This should sharply discount exact and near-equal coalitions, improving Experiments 10 and 12–14, while allowing similarity to decay sooner so that the broad dyadic gap contrast in Experiment 11 becomes smaller rather than larger. Prefer a smooth, sharply peaked kernel or adjusted distance normalization—not an equality detector or cardinality switch. Separately, reduce coalition_saturation moderately so that three-cue and larger majorities retain more evidence; the present 0.70–0.82 range over-normalizes count and contributes to the misses in Experiments 1–3 and 6. Lowering saturation must be paired with the sharper near-overlap discount so clustered triads do not become indiscriminately stronger. A modest increase in beta can amplify composition contrasts only after those structural changes; beta alone would not fix the incorrect E10/E11 profile. Finally, narrow the between-subject dependence/bandwidth ranges after calibration, because Experiment 11's simulated variance is much too large. The null positional results should be protected by retaining centered exchangeable salience and avoiding any serial-position term.

**Outcome of this advice:** iter 1 candidate loss=0.1428 -> iter 2 candidate loss=0.1163 -> the gate marked it ACCEPTED.

### Iteration 2
Verdict: regenerate
Interpretation: The candidate remains faithful to the prescribed smooth reliability-space dependence family, and the accepted revision made substantial progress: Experiments 12 and 14 are now essentially exact, Experiment 13 is reasonably close, and the population-level positional and serial nulls in Experiments 4, 5, and 7–9 remain well preserved. Nevertheless, the fit is not yet experiment-invariant. The largest failure is Experiment 2, where the model predicts slightly positive agreement with the highest-validity discriminating cue (0.0317) while humans show a strong reversal (-0.2642). Count behavior is also miscalibrated in opposite directions across tasks: the model overstates majority opposition to the top cue in Experiment 1 (-0.3067 versus -0.1217), yet underpredicts the early three-cue coalition in Experiment 6 (0.2200 versus 0.4400) and misses Experiment 3's negative pattern. The dyadic dependence profile remains wrong as well: the exact/equal-reliability penalty is still too weak in Experiment 10 (0.2723 versus 0.1723), while the broader reliability-gap contrast is too large in Experiment 11 (0.1129 versus 0.0317), with excessive subject variance. Thus the previous sharper-kernel adjustment helped the central triadic composition tests but did not produce a transferable reliability metric across experiments.
Rationale: Build on the accepted sharper credit-sharing model, but do not repeat the previous broad push toward lower coalition saturation: although that revision improved aggregate loss and Experiments 12–14, it drove Experiment 1 past the target and did not repair Experiments 2, 3, or 6. Use an intermediate or slightly higher saturation range between the two iterations to moderate Experiment 1, rather than lowering it again. More importantly, revise the reliability-coordinate normalization within the same mechanism family. Dividing represented diagnosticity by each experiment's mean makes a single bandwidth denote different absolute reliability gaps in different validity sets; this likely explains why the kernel fits Experiments 12–14 but fails to transfer to Experiments 1–3 and produces the wrong E10/E11 profile. Anchor compressed log-diagnosticity to a fixed scale or fixed reference interval across experiments, then retune a sharply local smooth bandwidth. The target is stronger discounting at equality or extremely small gaps for Experiment 10, but faster decay outside that neighborhood to reduce Experiment 11, without increasing the already accurate Experiment 12 and 14 effects. Narrow subject-level bandwidth/compression variation as well, because Experiment 11 variance remains far above observed. Finally, diagnose Experiment 2 at the deterministic evidence level before changing beta: its sign is wrong, so response sensitivity cannot fix it. Check how the anchored coordinates and divisive overlap rank the opposing three-cue coalitions, and adjust validity reliance or kernel distance scaling so collective diverse evidence can overturn the first discriminating cue. Retain centered exchangeable salience and avoid positional terms, equality detectors, or cardinality switches.

**Outcome of this advice:** iter 2 candidate loss=0.1163 -> iter 3 candidate loss=0.1133 -> the gate marked it ACCEPTED.

### Iteration 3
Verdict: regenerate
Interpretation: The accepted fixed-anchor revision modestly improves aggregate loss and remains faithful to the prescribed reliability-space credit-sharing family. It preserves the near-null positional and serial effects in Experiments 4, 5, and 7–9, fits Experiment 12 closely, and is essentially exact in Experiment 14. Experiment 10 also moved in the correct direction. However, the theory is not yet experiment-invariant. Experiment 2 remains the decisive failure: predicted agreement with the first discriminating cue has the wrong sign and is near zero (0.0358) rather than the strong human reversal (-0.2642). Experiment 6 also substantially underestimates endorsement of the three-cue coalition (0.2200 versus 0.4400), and Experiment 3 misses its negative majority pattern. Meanwhile, Experiment 1 still overstates majority opposition to the top-validity cue (-0.2508 versus -0.1217). The dyadic dependence profile remains miscalibrated: the equal-reliability coalition is still chosen too often in Experiment 10 (0.2460 versus 0.1723), whereas the broader gap effect in Experiment 11 is now much too large (0.1367 versus 0.0317). Experiment 13 is also somewhat excessive (0.4000 versus 0.3242). Thus the fixed anchor helped transfer overall, but the current single-scale Gaussian does not jointly deliver a sharp equality penalty, weak dyadic gap effects, and strong graded triadic diversity effects.
Rationale: Retain the accepted fixed reliability anchor and the general credit-sharing mechanism, but change the shape of the smooth similarity kernel rather than repeating another global bandwidth or saturation shift. The previous normalization advice was accepted and improved loss, Experiment 1, and Experiment 10, but it simultaneously increased the Experiment 11 gap contrast and did not repair Experiment 2; another move in the same single-bandwidth direction is therefore unlikely to solve the tradeoff. Within the prescribed family, try a smooth sharply peaked core plus a weak broader component, or an equivalent super-Gaussian/shape-controlled kernel. The narrow core should impose a stronger penalty at equality for Experiment 10 and decay rapidly enough to suppress Experiment 11, while a weak tail can accumulate over the three pairwise relations in triads and produce the graded release needed in Experiment 2 without creating a large one-pair dyadic effect. Couple this with slightly stronger nonlinear overlap curvature so weak pairwise similarities matter collectively in triads, still without any coalition-size switch. Do not broadly lower coalition saturation again: that earlier combined push overshot Experiment 1 and failed to improve Experiment 6. Instead, modestly restore validity reliance to give the uniquely best cue more leverage in Experiment 1, while using the revised triadic overlap accumulation—not reduced validity weighting—to generate Experiment 2's reversal. Check deterministic trial rankings in Experiment 2 to ensure the diverse coalition actually wins before tuning beta. Finally, narrow dependence-shape heterogeneity after calibration, because Experiment 11's simulated between-subject variance remains far above the observed variance. Preserve centered exchangeable salience and all positional null constraints.

**Outcome of this advice:** iter 3 candidate loss=0.1133 -> iter 4 candidate loss=0.1157 -> the gate marked it REJECTED.

### Iteration 4
Verdict: regenerate
Interpretation: The candidate remains faithful to the prescribed inferred-dependence family and retains several important successes: Experiment 12 is close (0.6600 versus 0.6692), Experiment 14 is reasonably close (0.6047 versus 0.5869), and the positional/serial controls in Experiments 4, 5, and 7–9 remain near zero. It also improves Experiment 1 and, modestly, Experiments 6 and 10 relative to the accepted iteration 3 base. Nevertheless, the two-scale-kernel revision was rejected by the loss gate and does not resolve the central cross-experiment conflict. Experiment 2 still has essentially the wrong qualitative pattern: -0.0096 instead of the strong human reversal of -0.2642. Experiment 3 remains near zero rather than -0.0410, and Experiment 6 still underpredicts three-cue endorsement (0.3000 versus 0.4400). Most importantly, the weak broad tail makes the supposedly small dyadic gap effect dramatically worse in Experiment 11: 0.1771 versus 0.0317, up from 0.1367 in the accepted base. Experiment 13 similarly rises farther above its target (0.4321 versus 0.3242). Experiment 10 remains insufficiently punitive at equality (0.2399 versus 0.1723). Thus the added tail produces broad reliability-gap sensitivity in dyads without generating the required triadic reversal in Experiment 2—the opposite of its intended selective accumulation.
Rationale: Because the current candidate was rejected, build again from the accepted iteration 3 fixed-anchor model rather than extending the rejected core-plus-tail change. My previous recommendation to add a broad tail and stronger overlap curvature did not help, so do not repeat it or increase dependence sensitivity further. Try a different in-family evidence calculation: retain one compact smooth reliability-similarity kernel, but replace the current additive nodewise-overlap/divisive heuristic with a regularized coalition-level effective-precision calculation (for example, a similarity/correlation matrix with an eigenvalue floor or ridge, followed by a bounded effective-information calculation). This remains exactly the prescribed inferred-source-dependence mechanism, but can discount a nearly singular equal-reliability coalition strongly while preventing many moderate pairwise similarities from creating an unbounded dyadic gap gradient. Normalize or saturate coalition-level redundancy rather than adding a broad pairwise tail.

Calibrate this equation against deterministic trial rankings before adjusting beta: it must make the non-first-cue coalition win substantially more often in Experiment 2; the present near-zero metric shows that response noise is not the limiting factor. At the same time, explicitly constrain the high-minus-low dyadic contrast in Experiment 11 near 0.03 and the Experiment 13 contrast near 0.32. Preserve the accepted fixed reliability anchor, centered exchangeable salience, and current count normalization initially; previous broad saturation changes did not solve Experiments 2, 3, or 6. Once the dependence equation has the correct signs, only a small intermediate adjustment to coalition saturation or beta should be used to recover Experiment 6 without again overshooting Experiment 1. Narrow salience/dependence heterogeneity after calibration, since Experiment 11 variance remains about three times the observed value. Protect the already good Experiment 12 and the positional nulls throughout.

**Outcome of this advice:** iter 4 candidate loss=0.1157 -> iter 5 candidate loss=0.1137 -> the gate marked it REJECTED.

### Iteration 5
Verdict: regenerate
Interpretation: The candidate is faithful to the prescribed inferred-dependence family, but the effective-precision substitution was rejected by the gate and slightly regresses from the accepted iteration-3 base. It preserves the positional and serial nulls in Experiments 4, 5, and 7–9 and remains close on Experiment 14. However, the central pattern is still not experiment-invariant. Experiment 2 remains qualitatively wrong: agreement with the first discriminating cue is near zero and positive (0.0108), whereas humans strongly reverse it (-0.2642). Count and majority behavior is also inconsistent: Experiment 1 shows excessive opposition to the top cue (-0.2546 versus -0.1217), Experiments 3 and 6 understate the relevant majority effects, and Experiment 6 reaches only 0.2400 versus 0.4400. The dependence profile remains too broad but insufficiently sharp at equality: the equal-coalition choice in Experiment 10 is too high (0.2754 versus 0.1723), while Experiment 11's gap contrast is almost four times too large (0.1238 versus 0.0317) and its subject variance is over twice the observed value. Experiments 12 and 13 also overshoot (0.7094 versus 0.6692 and 0.4167 versus 0.3242). Relative to the accepted base, the precision calculation worsens Experiments 1, 10, 12, and 13 without repairing Experiment 2.
Rationale: Build from the unchanged accepted iteration-3 base. My previous recommendation to replace its redundancy calculation with inverse-matrix effective precision produced a rejected candidate, so do not repeat or further strengthen that substitution. Try a different, smaller in-family adjustment: decouple the reliability representation used for direct cue weighting from the representation used to infer dependence. At present the same compressed coordinate controls both reliability_weight and kernel distances, forcing a tradeoff: changes intended to sharpen coalition redundancy also create excessive direct gap sensitivity in Experiment 11. Retain the fixed anchor, but give direct validity weighting its own stronger compression and lower, narrower reliance range, while independently calibrating the smooth dependence coordinate and bandwidth. This should suppress the broad E11 gradient without eliminating the local redundancy needed for Experiments 10 and 12–14. Use the accepted bounded coalition-redundancy rule initially rather than another global evidence-form replacement. Calibrate deterministic rankings first: the alternative coalition must win substantially more often in Experiment 2, equality must be more strongly discounted in Experiment 10, and nonzero dyadic gaps must contribute much less in Experiment 11. A smooth shape-controlled kernel with a steep local falloff is permissible, but do not reintroduce the previously rejected broad tail or increase global dependence strength. Hold coalition saturation and beta near the accepted values during this test; earlier broad count and response-sensitivity changes did not solve Experiments 2, 3, or 6 and risked further overshooting Experiment 1. After obtaining the correct deterministic signs, only a small intermediate saturation adjustment should be considered. Preserve centered exchangeable salience and narrow dependence/representation heterogeneity to reduce the excessive Experiment-11 variance.

**Outcome of this advice:** iter 5 candidate loss=0.1137 -> iter 6 candidate loss=0.1100 -> the gate marked it ACCEPTED.

### Iteration 6
Verdict: regenerate
Interpretation: The accepted decoupling of direct validity weighting from dependence coordinates improved the running-best loss and brought Experiment 13 closer while preserving the strong fit in Experiment 12 and the near-null positional/serial effects in Experiments 4, 5, and 7–9. The candidate is therefore faithful to the prescribed reliability-space dependence family and represents genuine progress. It is not yet experiment-invariant, however. Experiment 2 remains the clearest qualitative failure: the candidate predicts near-zero, slightly positive agreement with the first discriminating cue (0.0125), whereas humans show a strong reversal (-0.2642). Count-related behavior also remains inconsistent: Experiment 1 overpredicts opposition to the highest-validity cue (-0.2146 versus -0.1217), Experiment 3 is effectively null rather than negative, and Experiment 6 substantially underpredicts endorsement of the three-cue coalition (0.2600 versus 0.4400). The dependence profile still fails its key dyadic calibration: Experiment 10 does not penalize equal-reliability corroboration enough (0.2748 versus 0.1723), while Experiment 11 produces a reliability-gap contrast about four times too large (0.1300 versus 0.0317), with excessive between-subject variance. Experiments 12–14 are comparatively successful, although Experiment 14 is slightly high. Thus the current sharply localized kernel fits several triadic composition tests but still cannot combine a strong equality penalty, weak nonzero dyadic-gap effects, and the required graded multi-cue reversal.
Rationale: Build on this accepted candidate: the previous advice to separate direct and dependence representations helped, so retain that separation, the fixed anchor, centered exchangeable salience, and the current general credit-sharing family. The next adjustment should target how pairwise similarities combine within a coalition, rather than again widening the kernel, adding a broad tail, replacing the rule with inverse precision, or globally changing saturation—all of those directions were previously ineffective or rejected. Introduce a modest smooth superlinear transform of aggregate local overlap, such as using (sum_j similarity_ij)^q with q slightly above 1 before divisive credit allocation. This remains cardinality-general and has no n>=3 switch: for a dyad, a nonexact similarity below one is attenuated, reducing Experiment 11, while exact similarity remains one and can still receive the strong penalty needed in Experiment 10; in a triad, two moderate similarities can jointly exceed one and accumulate nonlinearly, potentially producing the missing Experiment 2 reversal. Pair this with a small reduction in baseline dependence sensitivity if necessary so Experiments 12–14, already near target, do not become too strong. Calibrate deterministic trial rankings before changing beta: the alternative coalition must systematically beat the first-cue coalition in Experiment 2, not merely become noisier. Keep direct validity reliance low and strongly compressed, but consider slightly less compression in the dependence coordinate so genuinely nonzero gaps separate more rapidly; compensate bandwidth only enough to preserve exact/near-equality discounting. Do not use a broad saturation shift to address Experiments 1 and 6, since their opposite errors indicate coalition-composition misranking rather than a single count-strength problem. After the structural profile is correct, only a small intermediate adjustment to saturation or response sensitivity should be attempted. Finally, narrow dependence-coordinate and kernel heterogeneity to bring Experiment 11 variance down toward 0.003 without sacrificing the positional nulls.

**Outcome of this advice:** iter 6 candidate loss=0.1100 -> iter 7 candidate loss=0.1154 -> the gate marked it REJECTED.

### Iteration 7 (most recent — address this)
Verdict: regenerate
Interpretation: The candidate remains faithful to the prescribed inferred-dependence family, but the current superlinear-overlap revision was rejected by the accept gate and worsened aggregate loss from 0.1100 to 0.1154. Its main successes remain the near-null positional and serial effects in Experiments 4, 5, and 7–9, a reasonably strong distributed-coalition effect in Experiment 12, and close fits in Experiments 13–14. However, it is not experiment-invariant. Experiment 2 is still qualitatively wrong and deteriorated: predicted agreement with the first discriminating cue is +0.0292 rather than the observed reversal of -0.2642. Experiment 1 now overstates opposition to the best cue (-0.2767 versus -0.1217), Experiment 6 further underpredicts endorsement of the three-cue coalition (0.2000 versus 0.4400), and Experiment 3 remains effectively null. The dyadic profile is also still incorrect: Experiment 10 requires a stronger equality penalty (0.2640 versus 0.1723), while Experiment 11 requires a much smaller nonzero-gap contrast (0.1167 versus 0.0317) and substantially less between-subject variance. Experiment 12 now overshoots as well (0.6973 versus 0.6692). Thus raising aggregate local overlap to a power above one slightly reduced the excessive Experiment-11 contrast, but amplified the wrong coalition structures in Experiments 1, 2, 6, and 12.
Rationale: Build from the unchanged accepted iteration-6 base. My previous recommendation to add a superlinear local-overlap exponent was rejected, so do not retain or further increase q; return overlap_exponent to 1 rather than repeating that direction. The next revision should target the dependence-coordinate geometry, which was not changed in this attempt. Keep the accepted separation between direct and dependence representations, but modestly reduce compression in the dependence coordinate—e.g. test a somewhat higher validity_compression range—while retuning a single narrow, sharply bounded smooth kernel on that transformed scale. This can change which Experiment-2 triads are judged clustered versus diverse, while allowing nonzero dyadic gaps in Experiment 11 to leave the narrow similarity neighborhood more rapidly. Pair a narrower core with only a small increase in local dependence curvature if needed to strengthen the exact/near-exact penalty in Experiment 10; do not add a broad tail or increase global dependence sensitivity, since those earlier directions were rejected and tended to overshoot Experiments 11–13.

Before stochastic simulation, explicitly inspect deterministic coalition signals for every Experiment-2 trial. The dependence mapping must make the coalition opposing the first discriminating cue win often enough to produce a negative metric; the persistent near-zero or positive result across all iterations shows that beta, lapse, and sampling noise cannot repair the current ranking. Use Experiments 10 and 11 jointly as calibration constraints: preserve a strong smooth penalty at equality while forcing similarities at the low-but-nonzero gaps to decay sharply. Hold coalition_saturation and beta near the accepted iteration-6 values during this structural test, because broad count changes previously traded Experiment 1 against Experiment 6 without fixing Experiment 2. Once the coalition rankings are correct, consider only a small intermediate count adjustment. Finally, narrow dependence-compression, bandwidth, and salience ranges to reduce Experiment 11's simulated variance from 0.0090 toward 0.0030, while retaining centered exchangeable salience and the successful positional nulls.

**Outcome of this advice:** iter 7 candidate loss=0.1154 -> next candidate accept-status=PENDING (this is the advice you are addressing now).


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
  "theory": "Reliability-Space Credit Sharing proposes that people interpret agreement among experts through an inferred dependence network defined entirely in represented reliability space. Advertised validities have two related but distinct cognitive representations: a strongly compressed representation determines each cue's direct evidential weight, while a separately calibrated fixed-anchor representation determines inferred dependence. Within any option-supporting coalition, every expert shares informational credit with similarly represented experts according to a smooth, sharply localized similarity kernel. An expert surrounded by reliability-near neighbors therefore contributes less independent evidence, whereas reliability-distant experts contribute nearly undiluted evidence. The steep but continuous kernel concentrates redundancy around extremely similar reliability representations, producing a strong equality penalty without a broad dyadic reliability-gap gradient. Credit sharing applies at every coalition size, without an equality detector, dyadic/triadic switch, spatial grouping rule, or duplicate-pair-in-context operation. Because additional coalition members create multiple possible similarity relations, local dependence can accumulate nonlinearly in larger coalitions even when its effect on a single nonidentical pair is weak. Effective evidence is additionally subject to generic sublinear count growth. Stable subject-level dependence sensitivity, overlap curvature, compressed validity reliance, and exchangeable zero-centered cue salience generate individual differences without population-level serial-position effects. Choices arise from response sensitivity plus an independent lapse process, and representations remain fixed because no outcome feedback is provided.",
  "predict": "def predict(parameters, state, history) -> np.ndarray:\n    stim = np.asarray(state, dtype=np.float64)\n    if stim.ndim != 2 or stim.shape[0] != 2:\n        raise ValueError(\n            f\"Reliability-Space Credit Sharing expects shape (2, n_features); got {stim.shape}.\"\n        )\n\n    a, b = stim[0], stim[1]\n    n_features = int(stim.shape[1])\n\n    validities = np.asarray(parameters[\"validities\"], dtype=np.float64)\n    if validities.ndim != 1 or validities.size != n_features:\n        raise ValueError(\n            f\"validities length {validities.size} != n_features {n_features}.\"\n        )\n\n    raw_salience = np.asarray(\n        parameters[\"cue_salience_profile\"], dtype=np.float64\n    )\n    if raw_salience.ndim != 1 or raw_salience.size != n_features:\n        raise ValueError(\n            f\"cue_salience_profile length {raw_salience.size} != n_features {n_features}.\"\n        )\n\n    validity_compression = float(parameters[\"validity_compression\"])\n    direct_validity_compression = float(\n        parameters[\"direct_validity_compression\"]\n    )\n    validity_reliance = float(parameters[\"validity_reliance\"])\n    salience_strength = float(parameters[\"salience_strength\"])\n    coalition_saturation = float(parameters[\"coalition_saturation\"])\n    dependence_sensitivity = float(parameters[\"dependence_sensitivity\"])\n    similarity_bandwidth = float(parameters[\"similarity_bandwidth\"])\n    overlap_curvature = float(parameters[\"overlap_curvature\"])\n    beta = float(parameters[\"beta\"])\n    epsilon = float(parameters[\"epsilon\"])\n\n    # Dependence and direct cue weighting use separately compressed versions\n    # of the same instructed validity. Both retain the fixed 0.75 reference,\n    # so their scales remain invariant across experiments.\n    v = np.clip(validities, 0.500001, 0.999999)\n    log_diagnosticity = np.log(v / (1.0 - v))\n    reference_diagnosticity = np.log(0.75 / 0.25)\n\n    represented = np.power(\n        np.maximum(log_diagnosticity, 1e-12), validity_compression\n    )\n    represented /= max(\n        float(reference_diagnosticity ** validity_compression), 1e-12\n    )\n\n    direct_represented = np.power(\n        np.maximum(log_diagnosticity, 1e-12),\n        direct_validity_compression,\n    )\n    direct_represented /= max(\n        float(reference_diagnosticity ** direct_validity_compression),\n        1e-12,\n    )\n\n    reliability_weight = (\n        (1.0 - validity_reliance) * np.ones(n_features, dtype=np.float64)\n        + validity_reliance * direct_represented\n    )\n\n    # Subject-specific salience is exchangeable over cue identities and is\n    # centered within the display, precluding a population onset or recency\n    # advantage while allowing stable individual configuration preferences.\n    centered_salience = raw_salience - float(np.mean(raw_salience))\n    attention = np.exp(\n        np.clip(salience_strength * centered_salience, -10.0, 10.0)\n    )\n    attention /= max(float(np.mean(attention)), 1e-12)\n\n    cue_weights = reliability_weight * attention\n    cue_weights /= max(float(np.mean(cue_weights)), 1e-12)\n\n    difference = a - b\n    a_support = np.flatnonzero(difference > 0.0)\n    b_support = np.flatnonzero(difference < 0.0)\n\n    if a_support.size == 0 and b_support.size == 0:\n        return np.array([0.5, 0.5], dtype=np.float64)\n\n    def coalition_signal(indices):\n        idx = np.asarray(indices, dtype=int)\n        n = int(idx.size)\n        if n == 0:\n            return 0.0\n        if n == 1:\n            return float(cue_weights[idx[0]])\n\n        coordinates = represented[idx]\n        gaps = coordinates[:, None] - coordinates[None, :]\n\n        # A smooth super-Gaussian concentrates inferred dependence around\n        # extremely close reliability representations. It remains continuous\n        # and cardinality-general, but decays faster than the previous\n        # Gaussian outside the local overlap neighborhood.\n        scaled_gaps = gaps / max(similarity_bandwidth, 1e-12)\n        similarity = np.exp(-0.5 * np.power(scaled_gaps, 4.0))\n        np.fill_diagonal(similarity, 0.0)\n        local_overlap = np.sum(similarity, axis=1)\n\n        # Divisive credit allocation approximates precision loss under\n        # correlated sources. In a pair, each cue has only one possible\n        # neighbor. In larger coalitions, multiple pairwise overlaps converge\n        # on each member and create nonlinear redundancy without a size gate.\n        independence_fraction = np.power(\n            1.0 + dependence_sensitivity * local_overlap,\n            -overlap_curvature,\n        )\n        effective_total = float(\n            np.sum(cue_weights[idx] * independence_fraction)\n        )\n\n        # Generic count normalization makes corroboration sublinear even for\n        # reliability-diverse coalitions. Dependence can further reduce the\n        # marginal value of clustered additions but never deletes a cue.\n        signal = effective_total / (float(n) ** coalition_saturation)\n        return float(max(signal, 0.0))\n\n    evidence_a = coalition_signal(a_support)\n    evidence_b = coalition_signal(b_support)\n    net_a = evidence_a - evidence_b\n\n    logits = np.array(\n        [0.5 * beta * net_a, -0.5 * beta * net_a], dtype=np.float64\n    )\n    logits = logits - np.max(logits)\n    probs = np.exp(logits)\n    probs /= probs.sum()\n\n    probs = (1.0 - epsilon) * probs + epsilon * 0.5\n    probs = np.maximum(probs, 0.0)\n    total = float(probs.sum())\n    if not np.isfinite(total) or total <= 0.0:\n        return np.array([0.5, 0.5], dtype=np.float64)\n    return probs / total\n",
  "policy": "def policy(probs) -> int:\n    probs = np.asarray(probs, dtype=np.float64)\n    probs = np.maximum(probs, 0.0)\n    total = float(probs.sum())\n    if not np.isfinite(total) or total <= 0.0:\n        probs = np.ones(len(probs), dtype=np.float64) / float(len(probs))\n    else:\n        probs /= total\n    return int(np.random.choice(len(probs), p=probs))\n",
  "parameters": {
    "validities": "validities",
    "cue_salience_profile": "[(-1.0, 1.0)] * n_features",
    "validity_compression": "[0.30, 0.34]",
    "direct_validity_compression": "[0.08, 0.14]",
    "validity_reliance": "[0.008, 0.025]",
    "salience_strength": "[0.12, 0.28]",
    "coalition_saturation": "[0.64, 0.72]",
    "dependence_sensitivity": "[2.90, 3.30]",
    "similarity_bandwidth": "[0.0045, 0.0065]",
    "overlap_curvature": "[0.88, 0.96]",
    "beta": "[1.12, 1.38]",
    "epsilon": "[0.03, 0.08]"
  },
  "rationale": "This is a parameter-only edit of the accepted iteration-6 model. The rejected superlinear-overlap transform is not retained: pairwise similarities still combine through the accepted additive local-overlap rule. The dependence coordinate is made less compressed by increasing validity_compression, while the single super-Gaussian core is narrowed. Consequently, genuinely nonzero reliability gaps separate more rapidly on the fixed-anchor coordinate, which should suppress the excessive broad dyadic gradient in Experiment 11 and reduce the modest overshoots in Experiments 12–14. Exact matches remain at unit similarity regardless of bandwidth. A small increase in overlap curvature therefore strengthens their smooth dependence penalty for Experiment 10 without increasing global dependence sensitivity. The dependence-sensitivity range is slightly narrowed to limit subject-level variance. Direct validity compression, direct reliance, count saturation, response sensitivity, lapse, and exchangeable salience are otherwise unchanged, protecting the accepted separation of direct weighting from dependence inference and the established positional nulls."
}
```

## Usage

```json
{
  "input_tokens": 41887,
  "output_tokens": 3082
}
```
