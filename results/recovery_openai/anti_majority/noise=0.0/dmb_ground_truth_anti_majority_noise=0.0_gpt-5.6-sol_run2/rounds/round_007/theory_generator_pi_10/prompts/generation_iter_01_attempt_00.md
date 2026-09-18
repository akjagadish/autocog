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
- THEORY 1 = `pi_8`
- THEORY 2 = `pi_9`
- The recommendation below acts on THEORY 1 (= `pi_8`).

Replace pi_8 with a Density-Invariant Conflict-Arbitration theory that competes with pi_9 without retaining generic diagnostic-cue overload. The new theory should posit: (1) a count accumulator driven by signed mark margin and unaffected by mutually canceling added cues, with stronger and less prematurely saturating growth than pi_9 so it can match Experiments 5, 6, and 12; (2) a centered reliability channel whose accessibility depends on the coherence and magnitude of signed reliability contributions, not active-cue count or active-validity standard deviation, preserving the null density effects in Experiments 1, 11, and 16 and the near-invariance pattern in Experiment 2; and (3) nonlinear arbitration when count and reliability conflict. That arbitration should depend on relative signed evidence and conflict geometry rather than display density, allowing strong count behavior in pure-margin tasks but reversals or compression such as Experiment 10 when larger margins are paired with systematically opposing reliability structure. Coherent high-versus-low reliability blocks should remain usable even in dense displays, as suggested by Experiment 13, whereas additions that introduce genuinely opposing reliability contributions may reduce reliability influence through coherence loss, as in Experiment 15. Retain stable semantic polarity, channel-weight heterogeneity, precision heterogeneity, and lapse, but calibrate their ranges jointly across all experiments; do not use subject heterogeneity to manufacture pooled null effects that are individually large.

## THEORY LEADERBOARD
A small set of prior picked theories shown for reference. Overall score is in `[0, 1]`, higher = better, computed as `1 - L2_norm(normalized_per_experiment_distances) / max_L2_norm`. 1.0 means closest to the real value on every experiment+metric pair; 0.0 means farthest. Each entry below carries the same depth of detail as the PREVIOUS MODEL INSTANCE above so you can borrow concrete mechanisms when useful.

### `pi_9` (overall score: 0.812)

**Description**
Channel-Specific Coherence Integration theory: binary counts and cue reliabilities are encoded by distinct cognitive channels before being combined. The count channel rapidly computes the difference between option-level numbers of marked ratings. It depends only on that signed margin, so adding mutually canceling cues does not dilute count evidence. Its response is smooth and bounded, reflecting saturation of an approximate magnitude representation rather than unlimited linear accumulation. The reliability channel instead binds each discriminating cue's identity to its communicated validity. It first removes the validity component redundant with the count margin and then measures the signed coherence of the remaining cue-validity contributions. A reliability residual supported by mutually consistent contributions receives high gain, whereas the same residual embedded in opposing contributions receives lower gain because maintaining the required cue-identity bindings is difficult. This loss is determined by evidence coherence and communicated validity-profile contrast, not by feature count, diagnostic-cue count, or a generic load threshold. Stable subject differences govern relative allocation to the two channels and response precision. A stable semantic-polarity belief determines whether marks are interpreted as adverse or beneficial, and a small lapse process captures stimulus-independent choices.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Channel-Specific Coherence Integration expects shape "
            f"(2, n_features); got {stim.shape}."
        )

    a, b = stim[0], stim[1]
    n_features = int(stim.shape[1])
    validities = np.asarray(parameters["validities"], dtype=float)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} != n_features {n_features}."
        )

    difference = a - b
    count_difference = float(np.sum(difference))

    # Stable integration style allocates expression strength between two
    # separately computed channels. The smooth transformation allows broad
    # subject heterogeneity without imposing discrete strategy classes.
    raw_style = float(parameters["reliability_style"])
    style = 0.5 + 0.5 * np.tanh(2.2 * (2.0 * raw_style - 1.0)) / np.tanh(2.2)
    count_allocation = 1.30 - 0.60 * style
    reliability_allocation = 0.35 + 1.35 * style

    # The count channel reads only the option-level mark difference. Hence
    # mutually canceling added cues have exactly no effect. Saturation is
    # gradual and smooth rather than a hard margin rule or load-dependent
    # divisive compression.
    count_scale = float(parameters["count_scale"])
    count_signal = (
        float(parameters["count_gain"])
        * count_allocation
        * np.tanh(count_difference / count_scale)
    )

    # Reliability is represented as evidence orthogonal to ordinary tallying.
    # Centering ensures that a common shift of all communicated validities
    # cannot masquerade as additional count evidence.
    centered_validities = validities - float(np.mean(validities))
    signed_components = centered_validities * difference
    reliability_residual = float(np.sum(signed_components))
    absolute_support = float(np.sum(np.abs(signed_components)))

    # Coherence compares the net residual with all reliability evidence that
    # had to be identity-bound. It is one for uniformly directed support and
    # approaches zero when a fixed residual is embedded in opposing groups.
    # It contains no explicit count-margin, display-size, or cue-count term.
    if absolute_support > 1e-12:
        coherence = abs(reliability_residual) / absolute_support
    else:
        coherence = 0.0
    coherence = float(np.clip(coherence, 0.0, 1.0))

    # Communicated profiles with meaningful reliability contrast make identity
    # bindings more distinguishable. This is a global property of the stated
    # profile, not a trial-level overload proxy.
    profile_mean = float(np.mean(validities))
    profile_spread = float(np.sqrt(np.mean((validities - profile_mean) ** 2)))
    profile_range = float(np.max(validities) - np.min(validities))
    if profile_range > 1e-12:
        profile_contrast = np.clip(2.0 * profile_spread / profile_range, 0.0, 1.0)
    else:
        profile_contrast = 0.0

    coherence_power = float(parameters["coherence_power"])
    coherent_access = coherence ** coherence_power
    profile_factor = (
        1.0
        + float(parameters["profile_contrast_gain"])
        * profile_contrast
    )

    # A nonzero floor permits reliability sensitivity even for diffuse fields,
    # while the binding term produces selective attenuation when opposing
    # reliability contributions proliferate.
    reliability_gain = (
        float(parameters["reliability_floor"])
        + float(parameters["coherent_binding_gain"])
        * coherent_access
        * profile_factor
    )
    reliability_signal = (
        reliability_allocation
        * reliability_gain
        * reliability_residual
    )

    # The independently summarized channels meet only after their respective
    # transformations. Precision is stable within subject and introduces
    # persistent heterogeneity in the expression of both summaries.
    markedness_evidence = float(parameters["response_precision"]) * (
        count_signal + reliability_signal
    )

    # Positive markedness indicates that A carries more adverse evidence and
    # therefore favors B under the dominant adverse-mark interpretation.
    adverse_logits = np.array(
        [-0.5 * markedness_evidence, 0.5 * markedness_evidence], dtype=float
    )
    adverse_logits -= np.max(adverse_logits)
    adverse_probs = np.exp(adverse_logits)
    adverse_probs /= adverse_probs.sum()

    # Semantic polarity is stable across trials. The alternative beneficial
    # interpretation reverses the complete markedness representation and thus
    # preserves exact A/B reversal symmetry.
    beneficial_probs = adverse_probs[::-1]
    polarity = float(parameters["adverse_polarity_confidence"])
    core_probs = polarity * adverse_probs + (1.0 - polarity) * beneficial_probs

    lapse = float(parameters["lapse_rate"])
    probs = (1.0 - lapse) * core_probs + lapse * np.array([0.5, 0.5])
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        return np.array([0.5, 0.5], dtype=float)
    return probs / total

`policy(probs) -> int`:
def policy(probs):
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        probs = np.ones(len(probs), dtype=np.float64) / float(len(probs))
    else:
        probs /= total
    return int(np.random.choice(len(probs), p=probs))

`parameters`:
- validities: validities
- reliability_style: [0.0, 1.0]
- count_gain: [1.9, 3.0]
- count_scale: [2.8, 4.8]
- reliability_floor: [0.08, 0.30]
- coherent_binding_gain: [0.25, 0.78]
- coherence_power: [0.65, 1.65]
- profile_contrast_gain: [0.0, 0.45]
- response_precision: [0.68, 1.48]
- adverse_polarity_confidence: [0.80, 1.0]
- lapse_rate: [0.0, 0.12]

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=-0.4355 (var=0.0764) vs this=-0.2385 (var=0.0189)
- Experiment 2: real=0.0000 (var=0.0000) vs this=0.0000 (var=0.0000)
- Experiment 3: real=0.7367 (var=0.0520) vs this=0.5867 (var=0.0425)
- Experiment 4: real=-0.4825 (var=0.0708) vs this=-0.2604 (var=0.0238)
- Experiment 5: real=0.2306 (var=0.0353) vs this=0.1341 (var=0.0070)
- Experiment 6: real=0.1062 (var=0.0136) vs this=0.1197 (var=0.0076)
- Experiment 7: real=0.0392 (var=0.0080) vs this=0.0608 (var=0.0085)
- Experiment 8: real=-28.0000 (var=21.1456) vs this=52.0000 (var=39.3984)
- Experiment 9: real=-0.0407 (var=0.3436) vs this=0.6833 (var=1.1030)
- Experiment 10: real=0.8750 (var=0.0078) vs this=0.7897 (var=0.0064)
- Experiment 11: real=0.8442 (var=0.0078) vs this=0.8175 (var=0.0077)
- Experiment 12: real=0.0793 (var=0.0131) vs this=0.0515 (var=0.0013)
- Experiment 13: real=0.0315 (var=0.0055) vs this=0.0347 (var=0.0034)
- Experiment 14: real=-0.0264 (var=0.0053) vs this=0.0026 (var=0.0076)
- Experiment 15: real=0.0056 (var=0.0069) vs this=0.0183 (var=0.0110)
- Experiment 16: real=-1.6297 (var=0.0178) vs this=-2.0646 (var=0.0086)


---

### `pi_5` (overall score: 0.584)

**Description**
Discrepancy-Evoked Residual Audit with Capacity-Limited Tie Escalation: people first form an adverse-markedness preference from a nonlinear count difference, while count-residualized validity information remains continuously available. Count discrepancies evoke an additional validity audit, but exact count ties trigger a distinct escalation because tallying provides no provisional winner. This tie escalation is strongest when the cue set fits within a fixed attentional capacity and rapidly dilutes as the number of cues exceeds that capacity. Stable subject differences in tie escalation complement existing differences in count reliance, discrepancy auditing, semantic polarity, precision, and lapses.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Discrepancy-Evoked Residual Audit expects shape "
            f"(2, n_features); got {stim.shape}."
        )

    a, b = stim[0], stim[1]
    n_features = stim.shape[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} != n_features {n_features}."
        )

    difference = a - b
    count_difference = float(np.sum(difference))
    margin = abs(count_difference)

    # A bounded provisional tally prevents the strength of the count signal
    # from growing without limit as experiments add more features.
    count_scale = float(parameters["count_scale"])
    count_signal = float(parameters["count_strength"]) * np.tanh(
        count_difference / count_scale
    )

    # Small discrepancies leave the provisional tally relatively uncertain.
    # This redistributes count strength away from margins one and two without
    # weakening the separately reinforced moderate and extreme branches.
    if 0.0 < margin <= 2.0:
        count_signal *= float(parameters["small_margin_attenuation"])

    # Reinforce moderate discrepancies without changing margin-one or
    # margin-two behavior and without adding growth to the extreme branch.
    if 3.0 <= margin < 5.0:
        count_signal += (
            float(parameters["intermediate_count_reinforcement"])
            * float(np.sign(count_difference))
        )

    # Selectively reinforce only decisive margins, leaving small- and
    # moderate-margin behavior otherwise unchanged.
    if margin >= 5.0:
        extreme_activation = np.tanh(max(0.0, margin - 4.0))
        count_signal += (
            float(parameters["extreme_count_tail"])
            * float(np.sign(count_difference))
            * extreme_activation
        )

    # Centering cue validity removes the component of weighted evidence that
    # simply restates which option has more marks. The remaining signal asks
    # whether an option's marks are carried by unusually reliable experts.
    centered_validities = validities - float(np.mean(validities))
    residual_validity = float(np.dot(centered_validities, difference))

    # Validity is always available through baseline_validity_gain. A count
    # discrepancy evokes an extra audit, maximal at a one-mark margin and
    # progressively suppressed when the count margin is already decisive.
    baseline_gain = float(parameters["baseline_validity_gain"])
    audit_gain = float(parameters["audit_gain"])
    audit_decay = float(parameters["audit_decay"])
    if margin > 0.0:
        discrepancy_activation = margin * np.exp(
            -audit_decay * max(0.0, margin - 1.0)
        )
    else:
        discrepancy_activation = 0.0
    validity_gain = baseline_gain + audit_gain * discrepancy_activation

    # When tallying supplies no provisional winner, validity inspection is
    # escalated. The escalation is diluted beyond a seven-cue attentional
    # capacity, separating compact tie problems from large cue arrays while
    # retaining the nonzero validity floor in every task.
    if np.isclose(margin, 0.0):
        tie_capacity = np.exp(-max(0.0, float(n_features) - 7.0))
        validity_gain += float(parameters["tie_validity_bonus"]) * tie_capacity

    # A small, structurally localized audit may be elicited at margin three.
    # Its reduced range prevents it from counteracting moderate count evidence.
    if np.isclose(margin, 3.0):
        validity_gain += float(parameters["margin_three_audit_gain"])

    markedness_evidence = count_signal + validity_gain * residual_validity
    markedness_evidence *= float(parameters["response_precision"])

    # Positive evidence means A carries the greater adverse burden and hence
    # favors B. The alternative semantic interpretation reverses all evidence,
    # and stable polarity confidence mixes the two interpretations.
    adverse_logits = np.array(
        [-0.5 * markedness_evidence, 0.5 * markedness_evidence], dtype=float
    )
    adverse_logits -= np.max(adverse_logits)
    adverse_probs = np.exp(adverse_logits)
    adverse_probs /= adverse_probs.sum()

    beneficial_probs = adverse_probs[::-1]
    polarity = float(parameters["adverse_polarity_confidence"])
    core_probs = polarity * adverse_probs + (1.0 - polarity) * beneficial_probs

    lapse = float(parameters["lapse_rate"])
    probs = (1.0 - lapse) * core_probs + lapse * np.array([0.5, 0.5])
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        return np.array([0.5, 0.5], dtype=float)
    return probs / total

`policy(probs) -> int`:
def policy(probs):
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        probs = np.ones(len(probs), dtype=np.float64) / len(probs)
    else:
        probs /= total
    return int(np.random.choice(len(probs), p=probs))

`parameters`:
- validities: validities
- count_strength: [2.1, 3.5]
- count_scale: [1.2, 2.0]
- small_margin_attenuation: [0.72, 0.92]
- intermediate_count_reinforcement: [1.6, 3.4]
- extreme_count_tail: [1.0, 2.8]
- baseline_validity_gain: [0.38, 0.88]
- tie_validity_bonus: [0.05, 1.05]
- audit_gain: [0.9, 1.6]
- audit_decay: [0.7, 1.4]
- margin_three_audit_gain: [0.0, 0.1]
- response_precision: [0.75, 1.4]
- adverse_polarity_confidence: [0.74, 1.0]
- lapse_rate: [0.0, 0.15]

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=-0.4355 (var=0.0764) vs this=-0.2945 (var=0.0273)
- Experiment 2: real=0.0000 (var=0.0000) vs this=0.0000 (var=0.0000)
- Experiment 3: real=0.7367 (var=0.0520) vs this=0.6617 (var=0.0343)
- Experiment 4: real=-0.4825 (var=0.0708) vs this=-0.3983 (var=0.0255)
- Experiment 5: real=0.2306 (var=0.0353) vs this=0.2406 (var=0.0065)
- Experiment 6: real=0.1062 (var=0.0136) vs this=0.0940 (var=0.0057)
- Experiment 7: real=0.0392 (var=0.0080) vs this=-0.0929 (var=0.0062)
- Experiment 8: real=-28.0000 (var=21.1456) vs this=12.0000 (var=54.0224)
- Experiment 9: real=-0.0407 (var=0.3436) vs this=-1.6900 (var=0.8398)
- Experiment 10: real=0.8750 (var=0.0078) vs this=0.8325 (var=0.0068)
- Experiment 11: real=0.8442 (var=0.0078) vs this=0.7937 (var=0.0092)
- Experiment 12: real=0.0793 (var=0.0131) vs this=0.1059 (var=0.0024)
- Experiment 13: real=0.0315 (var=0.0055) vs this=-0.0049 (var=0.0022)
- Experiment 14: real=-0.0264 (var=0.0053) vs this=-0.0057 (var=0.0066)
- Experiment 15: real=0.0056 (var=0.0069) vs this=-0.0006 (var=0.0063)
- Experiment 16: real=-1.6297 (var=0.0178) vs this=-0.6994 (var=0.0109)


---

### `pi_8` (overall score: 0.497)

**Description**
Resource-Adaptive Diagnostic Field Integration theory: people establish a stable interpretation of whether marked ratings are adverse or beneficial, then allocate attention to currently discriminating evidence rather than total displayed feature count. Count and reliability information form a joint diagnostic field. Tally evidence accumulates smoothly with count margin, while reliability attention increases when discriminating cues expose a salient and internally organized reliability contrast. Accessibility is additionally calibrated by the clustering structure of the full communicated validity profile: coherent high-versus-low reliability blocks preserve attention, whereas uniformly graded profiles receive less reliability amplification. Only an unusually large set of simultaneously discriminating cues creates overload; under such overload, count evidence is divisively compressed, especially at larger margins. Opposing count and reliability signals usually inhibit one another through smooth conflict normalization. However, this normalization is locally weaker when the first count advantage appears, because a single additional mark is treated as diagnostic evidence rather than as a reason to globally discount the pre-existing reliability field. Stable subject-level integration style follows a softly polarized continuum between predominantly tally-oriented and predominantly reliability-sensitive policies. Subjects also differ stably in how deterministically they express their integrated evidence. This precision heterogeneity is mean-preserving and becomes less behaviorally expressed as diagnostic demand and overload increase, producing persistent individual differences in ordinary tasks without destabilizing dense displays or changing semantic polarity.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Resource-Adaptive Diagnostic Field Integration expects shape "
            f"(2, n_features); got {stim.shape}."
        )

    a, b = stim[0], stim[1]
    n_features = int(stim.shape[1])
    validities = np.asarray(parameters["validities"], dtype=float)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} != n_features {n_features}."
        )

    difference = a - b
    discriminating = np.abs(difference) > 0.5
    n_discriminating = float(np.sum(discriminating))
    count_difference = float(np.sum(difference))
    margin = abs(count_difference)

    # A stable integration style creates a softly polarized continuum between
    # tally-oriented and reliability-sensitive subjects. It changes relative
    # allocation but does not create trial-specific strategy switches.
    raw_style = float(parameters["reliability_style"])
    style = 0.5 + 0.5 * np.tanh(2.5 * (2.0 * raw_style - 1.0)) / np.tanh(2.5)
    count_allocation = 1.25 - 0.50 * style
    reliability_allocation = 0.45 + 1.10 * style

    # Ordinary count margins accumulate smoothly and approximately linearly
    # near zero, with gradual bounded compression rather than margin-one
    # saturation.
    count_scale = float(parameters["count_scale"])
    base_count = count_scale * np.tanh(count_difference / count_scale)

    # Resource demand is determined by the number of cues that actually need
    # comparison. Non-discriminating display elements impose no direct load.
    # Softplus supplies a differentiable transition with no feature-count knee.
    span = float(parameters["diagnostic_span"])
    softness = float(parameters["overload_softness"])
    z = (n_discriminating - span) / softness
    overload = softness * (np.log1p(np.exp(-abs(z))) + max(z, 0.0))

    # Dense diagnostic fields selectively compress larger count margins. The
    # powered activation is negligible at margin one but rises smoothly for
    # margins around five and above.
    margin_scale = float(parameters["compression_margin_scale"])
    margin_power = float(parameters["margin_activation_power"])
    if margin > 0.0:
        margin_activation = margin ** margin_power / (
            margin ** margin_power + margin_scale ** margin_power
        )
    else:
        margin_activation = 0.0
    count_divisor = 1.0 + float(parameters["overload_compression"]) * overload * margin_activation
    count_signal = (
        float(parameters["count_gain"])
        * count_allocation
        * base_count
        / count_divisor
    )

    # Reliability evidence is residualized against the common tally
    # component. Its accessibility depends on diagnostic contrast and on how
    # coherently the currently discriminating cues organize that contrast.
    centered_validities = validities - float(np.mean(validities))
    reliability_residual = float(np.dot(centered_validities, difference))

    # Clustering is computed from the full communicated validity profile, not
    # from the active subset. A large gap relative to ordinary profile spacing
    # identifies a genuinely organized high-versus-low reliability structure.
    sorted_validities = np.sort(validities)
    profile_gaps = np.diff(sorted_validities)
    positive_gaps = profile_gaps[profile_gaps > 1e-9]
    if positive_gaps.size > 0:
        largest_gap = float(np.max(positive_gaps))
        typical_gap = float(np.median(positive_gaps))
        profile_clustering = np.clip(
            (largest_gap - typical_gap) / (largest_gap + typical_gap + 1e-9),
            0.0,
            1.0,
        )
    else:
        profile_clustering = 0.0

    if n_discriminating > 0.0:
        active_centered = centered_validities[discriminating]
        contrast = float(np.std(active_centered))
        profile_range = float(np.max(validities) - np.min(validities))
        contrast_salience = contrast / (contrast + 0.25 * profile_range + 1e-9)

        absolute_reliability = float(
            np.sum(np.abs(centered_validities[discriminating] * difference[discriminating]))
        )
        organization = abs(reliability_residual) / (absolute_reliability + 1e-9)
    else:
        contrast_salience = 0.0
        organization = 0.0

    # Smooth validity gradients receive less amplification, while clustered
    # profiles retain nearly all of the accepted model's diagnostic attention.
    profile_attention = 0.70 + 0.30 * profile_clustering
    diagnostic_attention = (
        float(parameters["baseline_reliability_attention"])
        + float(parameters["contrast_attention_gain"])
        * contrast_salience
        * organization
        * profile_attention
    )

    # Unorganized reliability detail can suffer under heavy diagnostic load,
    # while a coherent high-versus-low contrast remains available even in a
    # large display.
    reliability_divisor = 1.0 + (
        float(parameters["diffuse_reliability_compression"])
        * overload
        * (1.0 - organization)
    )
    reliability_signal = (
        reliability_allocation
        * diagnostic_attention
        * reliability_residual
        / reliability_divisor
    )

    # Count and reliability are jointly represented. When they recommend
    # opposite markedness directions, divisive cross-inhibition usually
    # reduces total confidence smoothly. A narrow notch around margin one
    # prevents the first count cue from producing excessive normalization.
    scale_sum = abs(count_signal) + abs(reliability_signal)
    if scale_sum > 1e-12 and count_signal * reliability_signal < 0.0:
        conflict = (
            4.0 * abs(count_signal * reliability_signal)
            / (scale_sum * scale_sum + 1e-12)
        )
    else:
        conflict = 0.0

    margin_one_notch = np.exp(-((margin - 1.0) / 0.55) ** 2)
    conflict *= 1.0 - 0.40 * margin_one_notch

    joint_divisor = 1.0 + float(parameters["conflict_normalization"]) * conflict

    # Stable, symmetric precision deviations increase ordinary-task
    # heterogeneity without shifting mean precision. Their expression is
    # attenuated when many cues must be compared and further attenuated by the
    # same overload signal that regulates dense diagnostic fields.
    precision_shrinkage = (
        1.0 + overload + n_discriminating / max(span, 1e-9)
    )
    effective_response_precision = (
        float(parameters["response_precision"])
        + float(parameters["precision_deviation"]) / precision_shrinkage
    )

    markedness_evidence = effective_response_precision * (
        count_signal + reliability_signal
    ) / joint_divisor

    # Positive markedness means A carries more adverse evidence and therefore
    # favors choosing B under the dominant adverse-mark interpretation.
    adverse_logits = np.array(
        [-0.5 * markedness_evidence, 0.5 * markedness_evidence], dtype=float
    )
    adverse_logits -= np.max(adverse_logits)
    adverse_probs = np.exp(adverse_logits)
    adverse_probs /= adverse_probs.sum()

    beneficial_probs = adverse_probs[::-1]
    polarity = float(parameters["adverse_polarity_confidence"])
    core_probs = polarity * adverse_probs + (1.0 - polarity) * beneficial_probs

    lapse = float(parameters["lapse_rate"])
    probs = (1.0 - lapse) * core_probs + lapse * np.array([0.5, 0.5])
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        return np.array([0.5, 0.5], dtype=float)
    return probs / total

`policy(probs) -> int`:
def policy(probs):
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        probs = np.ones(len(probs), dtype=np.float64) / float(len(probs))
    else:
        probs /= total
    return int(np.random.choice(len(probs), p=probs))

`parameters`:
- validities: validities
- reliability_style: [0.0, 1.0]
- count_gain: [0.80, 1.24]
- count_scale: [3.2, 5.8]
- diagnostic_span: [20.0, 23.0]
- overload_softness: [0.6, 1.2]
- compression_margin_scale: [2.2, 3.4]
- margin_activation_power: [2.6, 3.4]
- overload_compression: [0.45, 0.80]
- baseline_reliability_attention: [0.25, 0.61]
- contrast_attention_gain: [0.90, 1.50]
- diffuse_reliability_compression: [0.01, 0.08]
- conflict_normalization: [0.05, 0.35]
- response_precision: [0.78, 1.30]
- precision_deviation: [-0.28, 0.28]
- adverse_polarity_confidence: [0.82, 1.0]
- lapse_rate: [0.0, 0.12]

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=-0.4355 (var=0.0764) vs this=-0.2923 (var=0.0208)
- Experiment 2: real=0.0000 (var=0.0000) vs this=0.0000 (var=0.0000)
- Experiment 3: real=0.7367 (var=0.0520) vs this=0.7500 (var=0.0328)
- Experiment 4: real=-0.4825 (var=0.0708) vs this=-0.4454 (var=0.0299)
- Experiment 5: real=0.2306 (var=0.0353) vs this=0.1401 (var=0.0073)
- Experiment 6: real=0.1062 (var=0.0136) vs this=0.1287 (var=0.0071)
- Experiment 7: real=0.0392 (var=0.0080) vs this=0.1037 (var=0.0153)
- Experiment 8: real=-28.0000 (var=21.1456) vs this=-16.0000 (var=35.5776)
- Experiment 9: real=-0.0407 (var=0.3436) vs this=0.8355 (var=0.6985)
- Experiment 10: real=0.8750 (var=0.0078) vs this=0.8628 (var=0.0039)
- Experiment 11: real=0.8442 (var=0.0078) vs this=0.8721 (var=0.0046)
- Experiment 12: real=0.0793 (var=0.0131) vs this=0.0680 (var=0.0018)
- Experiment 13: real=0.0315 (var=0.0055) vs this=0.0333 (var=0.0023)
- Experiment 14: real=-0.0264 (var=0.0053) vs this=0.2169 (var=0.0099)
- Experiment 15: real=0.0056 (var=0.0069) vs this=0.2372 (var=0.0114)
- Experiment 16: real=-1.6297 (var=0.0178) vs this=-0.4757 (var=0.0061)


## LOSS TRAJECTORY (this propose-loop)
Aggregate loss across iterations of THIS propose-loop (lower = better, 0 = perfect, `+inf` = unscorable). The ACCEPTED / REJECTED tag is the loop's programmatic accept-gate decision — only ACCEPTED candidates have ever been used as the base for a subsequent iteration. Use this together with PRIOR FEEDBACK ITERATIONS below to grade which past critic advice actually paid off.

- iter 1: loss=0.1485 -> ACCEPTED
Running-best (last ACCEPTED) base: iter 1 at loss=0.1485 — this is the source shown verbatim below under `## PREVIOUS CANDIDATE (this loop)`. Push the next edit's loss strictly below that floor or the gate will reject it.

## EXPERIMENTAL RESULTS
### Experiment 1
**Design**
  A=[1, 0, 1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0, 1, 1]
  A=[1, 0, 0, 1, 0, 0, 0]  B=[0, 1, 1, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1, 1]
  A=[0, 1, 0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1, 0, 1]
  A=[1, 1, 0, 0, 1, 0, 0]  B=[1, 0, 1, 1, 0, 1, 1]
  A=[0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1, 1]
  A=[0, 1, 0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 1, 0, 0]
  A=[0, 1, 1, 0, 1, 1, 1]  B=[1, 0, 0, 1, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0, 1, 0]
  A=[1, 0, 1, 1, 0, 1, 1]  B=[1, 1, 0, 0, 1, 0, 0]
  A=[0, 0, 1, 1, 1, 1, 1]  B=[0, 1, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    aligned = []
    tally_margins = []

    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=float)
        b = np.asarray(row["option_b_ratings"], dtype=float)

        # Validities are strictly descending in feature order, so the first
        # feature that differs identifies the Take-The-Best winner.
        differing = np.flatnonzero(a != b)
        if differing.size == 0:
            continue
        j = int(differing[0])
        ttb_winner = 0 if a[j] > b[j] else 1

        a_wins = int(np.sum(a > b))
        b_wins = int(np.sum(b > a))
        tally_margins.append(abs(a_wins - b_wins))
        aligned.append(float(int(row["response"]) == ttb_winner))

    if len(aligned) == 0:
        return float("nan")

    aligned = np.asarray(aligned, dtype=float)
    tally_margins = np.asarray(tally_margins, dtype=int)
    tie = tally_margins == 0
    conflict = tally_margins > 0

    if not np.any(tie) or not np.any(conflict):
        return float("nan")

    # Tally-margin sensitivity: excess TTB agreement on tally ties relative
    # to trials where the tally favors the opposite option.
    return float(np.mean(aligned[tie]) - np.mean(aligned[conflict]))
```

**Observed (real) value:** -0.4355 (var=0.0764)
**Previous candidate values (this loop):**
  - iter 1 (most recent): -0.2818 (var=0.0182) (Δ vs real +0.1538)
**Other theories' values on this metric (for reference):**
- pi_1: -0.0052 (var=0.0117)
- pi_2: 0.3523 (var=0.0241)
- pi_3: -0.4570 (var=0.0555)
- pi_4: -0.3570 (var=0.0237)
- pi_5: -0.2945 (var=0.0273)
- pi_6: -0.3425 (var=0.0220)
- pi_7: -0.3760 (var=0.0198)
- pi_8: -0.2923 (var=0.0208)
- pi_9: -0.2385 (var=0.0189)

### Experiment 2
**Design**
  A=[1, 0, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0, 1]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[0, 1, 0, 1, 1, 0]  B=[0, 0, 1, 1, 1, 0]
  A=[1, 1, 0, 0, 1, 0]  B=[1, 0, 0, 0, 1, 1]
  A=[0, 1, 1, 0, 0, 1]  B=[0, 1, 0, 1, 0, 1]
  A=[1, 0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0, 1]
  A=[0, 1, 1, 1, 0, 0]  B=[0, 1, 1, 0, 1, 0]
  A=[1, 0, 1, 1, 1, 0]  B=[1, 0, 1, 1, 0, 1]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 0, 0, 1, 0, 1]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[0, 0, 1, 1, 1, 0]  B=[0, 1, 0, 1, 1, 0]
  A=[1, 0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 1, 0]
  A=[0, 1, 0, 1, 0, 1]  B=[0, 1, 1, 0, 0, 1]
  A=[1, 0, 0, 1, 0, 1]  B=[1, 0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 1, 0]  B=[0, 1, 1, 1, 0, 0]
  A=[1, 0, 1, 1, 0, 1]  B=[1, 0, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Score each choice against the winner designated by the highest-validity
    # discriminating cue. Validities are strictly decreasing with feature index.
    signed_scores = []

    for a_cell, b_cell, response in zip(
        data["option_a_ratings"],
        data["option_b_ratings"],
        data["response"]
    ):
        a = np.asarray(a_cell, dtype=float)
        b = np.asarray(b_cell, dtype=float)
        differing = np.flatnonzero(a != b)
        if differing.size == 0:
            continue

        first = int(differing[0])
        ttb_winner = 0 if a[first] > b[first] else 1
        signed_scores.append(1.0 if int(response) == ttb_winner else -1.0)

    if not signed_scores:
        return float("nan")

    alignment = float(np.mean(signed_scores))

    # This corresponds to choosing the validity-ordered winner on more than
    # 62.5% of trials. It is well beyond ordinary finite-sample fluctuation
    # around Tallying's predicted 50%, while remaining below typical TTB rates.
    return float(alignment > 0.25)

```

**Observed (real) value:** 0.0000 (var=0.0000)
**Previous candidate values (this loop):**
  - iter 1 (most recent): 0.0000 (var=0.0000) (Δ vs real +0.0000)
**Other theories' values on this metric (for reference):**
- pi_2: 0.0000 (var=0.0000)
- pi_1: 1.0000 (var=0.0900)
- pi_3: 0.0000 (var=0.0000)
- pi_4: 0.0000 (var=0.0000)
- pi_5: 0.0000 (var=0.0000)
- pi_6: 0.0000 (var=0.0000)
- pi_7: 0.0000 (var=0.0000)
- pi_8: 0.0000 (var=0.0000)
- pi_9: 0.0000 (var=0.0000)

### Experiment 3
**Design**
  A=[1, 1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1]
  A=[1, 1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 1]  B=[1, 1, 1, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 1, 1, 0]  B=[0, 1, 1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 1, 1, 0]  B=[0, 0, 1, 1, 0, 0, 1]
  A=[1, 0, 1, 0, 1, 0, 0]  B=[1, 0, 0, 1, 0, 0, 1]
  A=[0, 0, 0, 1, 0, 1, 0]  B=[0, 0, 0, 0, 1, 0, 1]
  A=[0, 1, 1, 1, 0, 0, 0]  B=[1, 0, 0, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 0, 0, 1]  B=[0, 1, 0, 0, 1, 1, 0]
  A=[1, 0, 0, 1, 0, 0, 1]  B=[1, 0, 1, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 1, 0, 1]  B=[0, 0, 0, 1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    scores = []
    for a_cell, b_cell, response in zip(
        data["option_a_ratings"],
        data["option_b_ratings"],
        data["response"]
    ):
        a = np.asarray(a_cell, dtype=float)
        b = np.asarray(b_cell, dtype=float)
        count_delta = float(np.sum(a) - np.sum(b))

        # Restrict attention to the strongly diagnostic count-margin trials.
        if abs(count_delta) >= 5.0:
            response_sign = 2.0 * float(response) - 1.0  # B=+1, A=-1
            scores.append(float(np.sign(count_delta) * response_sign))

    if len(scores) == 0:
        return 0.0
    return float(np.mean(scores))
```

**Observed (real) value:** 0.7367 (var=0.0520)
**Previous candidate values (this loop):**
  - iter 1 (most recent): 0.7550 (var=0.0326) (Δ vs real +0.0183)
**Other theories' values on this metric (for reference):**
- pi_3: 0.6383 (var=0.0899)
- pi_2: -0.7000 (var=0.0639)
- pi_1: -0.6600 (var=0.0730)
- pi_4: 0.7317 (var=0.0354)
- pi_5: 0.6617 (var=0.0343)
- pi_6: 0.7217 (var=0.0254)
- pi_7: 0.7817 (var=0.0222)
- pi_8: 0.7500 (var=0.0328)
- pi_9: 0.5867 (var=0.0425)

### Experiment 4
**Design**
  A=[0, 1, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 1, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 0, 0]  B=[0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1, 0]  B=[0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 0]  B=[0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1]  B=[0, 0, 0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 0]
  A=[0, 0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Weighted choice alignment with the feature-count majority."""
    if data is None or len(data) == 0:
        return 0.0

    weighted_scores = []
    weights = []

    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=float)
        b = np.asarray(row["option_b_ratings"], dtype=float)
        count_delta = float(np.sum(a) - np.sum(b))

        # Count ties do not identify a tallying preference and are omitted.
        if count_delta == 0.0:
            continue

        response = int(row["response"])
        # +1 when the option with more positive ratings was selected,
        # -1 when the option with fewer positive ratings was selected.
        choice_sign = 1.0 if response == 0 else -1.0
        alignment = choice_sign * np.sign(count_delta)

        # Margin-two trials receive more weight because both theories make
        # more precise, oppositely directed predictions on them.
        weight = abs(count_delta)
        weighted_scores.append(weight * alignment)
        weights.append(weight)

    if not weights:
        return 0.0
    return float(np.sum(weighted_scores) / np.sum(weights))

```

**Observed (real) value:** -0.4825 (var=0.0708)
**Previous candidate values (this loop):**
  - iter 1 (most recent): -0.4654 (var=0.0243) (Δ vs real +0.0171)
**Other theories' values on this metric (for reference):**
- pi_2: 0.7229 (var=0.0432)
- pi_3: -0.4696 (var=0.0469)
- pi_1: -0.6617 (var=0.0574)
- pi_4: -0.5396 (var=0.0205)
- pi_5: -0.3983 (var=0.0255)
- pi_6: -0.6242 (var=0.0183)
- pi_7: -0.6488 (var=0.0220)
- pi_8: -0.4454 (var=0.0299)
- pi_9: -0.2604 (var=0.0238)

### Experiment 5
**Design**
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]  B=[0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1]  B=[0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]  B=[0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    validities = np.array(
        [1.0, 0.98, 0.96, 0.94, 0.92, 0.58, 0.56, 0.54, 0.52, 0.5, 0.5],
        dtype=float,
    )

    validity_advantage = []
    chose_fewer_marks = []

    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=float)
        b = np.asarray(row["option_b_ratings"], dtype=float)
        response = int(row["response"])

        count_a = float(a.sum())
        count_b = float(b.sum())

        if count_a > count_b:
            # A is the option with more marks; B has fewer marks.
            rich_minus_sparse = a - b
            fewer_choice = float(response == 1)
        elif count_b > count_a:
            # B is the option with more marks; A has fewer marks.
            rich_minus_sparse = b - a
            fewer_choice = float(response == 0)
        else:
            # Not expected in this design, but omit count ties safely.
            continue

        validity_advantage.append(float(np.dot(validities, rich_minus_sparse)))
        chose_fewer_marks.append(fewer_choice)

    x = np.asarray(validity_advantage, dtype=float)
    y = np.asarray(chose_fewer_marks, dtype=float)
    if x.size < 2:
        return 0.0

    x_centered = x - x.mean()
    denominator = float(np.dot(x_centered, x_centered))
    if denominator <= 0.0 or not np.isfinite(denominator):
        return 0.0

    # OLS slope of choosing the fewer-mark option on the validity-weighted
    # advantage held by the more-marked option.
    return float(np.dot(x_centered, y - y.mean()) / denominator)

```

**Observed (real) value:** 0.2306 (var=0.0353)
**Previous candidate values (this loop):**
  - iter 1 (most recent): 0.1669 (var=0.0060) (Δ vs real -0.0637)
**Other theories' values on this metric (for reference):**
- pi_3: 0.0002 (var=0.0045)
- pi_4: 0.2053 (var=0.0075)
- pi_1: -0.2514 (var=0.0060)
- pi_2: -0.0002 (var=0.0032)
- pi_5: 0.2406 (var=0.0065)
- pi_6: 0.2402 (var=0.0072)
- pi_7: 0.1866 (var=0.0085)
- pi_8: 0.1401 (var=0.0073)
- pi_9: 0.1341 (var=0.0070)

### Experiment 6
**Design**
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 0, 0, 0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0, 0, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0, 0, 1, 1, 1, 0, 0]  B=[0, 0, 1, 1, 1, 0, 0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0, 0, 0, 1, 1, 0, 1]  B=[0, 0, 1, 1, 1, 0, 1, 0, 0, 1, 0]
  A=[1, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0]  B=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]  B=[0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0, 1, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 1, 0, 0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0, 0, 1, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 1, 0, 1, 0, 0, 1, 0]  B=[1, 1, 0, 0, 0, 0, 0, 1, 1, 0, 1]
  A=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    validities = np.array(
        [0.99, 0.94, 0.89, 0.84, 0.79, 0.74, 0.69, 0.64, 0.59, 0.54, 0.50],
        dtype=float,
    )

    if len(data) == 0:
        return float("nan")

    a = np.vstack(data["option_a_ratings"].apply(lambda z: np.asarray(z, dtype=float)).to_numpy())
    b = np.vstack(data["option_b_ratings"].apply(lambda z: np.asarray(z, dtype=float)).to_numpy())
    response = data["response"].to_numpy(dtype=float)

    # Orient each complementary stimulus so that the option marked by the
    # highest-validity expert is the reference marked option.
    orientation = np.sign(a[:, 0] - b[:, 0])
    usable = np.isfinite(response) & (orientation != 0)
    if np.sum(usable) < 2:
        return float("nan")

    orientation = orientation[usable]
    response = response[usable]
    diff = (a[usable] - b[usable])

    # Weighted markedness of the highest-validity-marked option relative to
    # its alternative. Complementary presentations receive the same x value.
    x = orientation * np.dot(diff, validities)

    # One means choosing the option unmarked by the highest-validity expert.
    y = np.where(orientation > 0, response, 1.0 - response)

    # Within-data OLS slope. Centering removes the competitor's subject-level
    # but condition-invariant preference for the unmarked option.
    xc = x - np.mean(x)
    denom = float(np.dot(xc, xc))
    if not np.isfinite(denom) or denom <= 0.0:
        return float("nan")
    return float(np.dot(xc, y - np.mean(y)) / denom)

```

**Observed (real) value:** 0.1062 (var=0.0136)
**Previous candidate values (this loop):**
  - iter 1 (most recent): 0.1461 (var=0.0039) (Δ vs real +0.0398)
**Other theories' values on this metric (for reference):**
- pi_4: 0.2086 (var=0.0061)
- pi_3: 0.0054 (var=0.0029)
- pi_1: 0.0091 (var=0.0021)
- pi_2: 0.0039 (var=0.0034)
- pi_5: 0.0940 (var=0.0057)
- pi_6: 0.2569 (var=0.0066)
- pi_7: 0.2163 (var=0.0049)
- pi_8: 0.1287 (var=0.0071)
- pi_9: 0.1197 (var=0.0076)

### Experiment 7
**Design**
  A=[1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]
  A=[1, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 1, 1, 1, 1, 1]
  A=[1, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 1, 1, 1, 1, 1]
  A=[1, 1, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 1, 1, 1, 1]
  A=[1, 1, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 1, 1, 1, 1]
  A=[1, 1, 1, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 1, 1, 1]
  A=[1, 1, 1, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 1, 1]
  A=[1, 1, 1, 1, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 1, 1]
  A=[1, 1, 1, 1, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 1]
  A=[1, 1, 1, 1, 1, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 1]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]  B=[0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]  B=[0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 1, 1, 1, 1, 1]  B=[1, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 1, 1, 1, 1, 1]  B=[1, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 1, 1, 1, 1]  B=[1, 1, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 1, 1, 1, 1]  B=[1, 1, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 1, 1, 1]  B=[1, 1, 1, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 1, 1, 1]  B=[1, 1, 1, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 1, 1]  B=[1, 1, 1, 1, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 1, 1]  B=[1, 1, 1, 1, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 1]  B=[1, 1, 1, 1, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 1]  B=[1, 1, 1, 1, 1, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 1, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    validities = np.array([
        0.50, 0.51, 0.52, 0.53, 0.54, 0.55, 0.56, 0.75,
        1.00, 0.99, 0.98, 0.97, 0.96, 0.95, 0.94
    ], dtype=float)
    centered = validities - validities.mean()

    aligned_choices = []
    margins = []
    for a_cell, b_cell, response in zip(
        data["option_a_ratings"],
        data["option_b_ratings"],
        data["response"]
    ):
        a = np.asarray(a_cell, dtype=float)
        b = np.asarray(b_cell, dtype=float)
        difference = a - b
        margin = abs(float(difference.sum()))
        residual = float(np.dot(centered, difference))

        # Code 1 when the chosen option is the one whose marks are relatively
        # concentrated among above-mean-validity experts. This makes reversed
        # A/B versions contribute in the same psychological direction.
        if residual < 0.0:
            aligned = float(int(response) == 1)  # B is the high-validity side
        elif residual > 0.0:
            aligned = float(int(response) == 0)  # A is the high-validity side
        else:
            continue

        aligned_choices.append(aligned)
        margins.append(margin)

    aligned_choices = np.asarray(aligned_choices, dtype=float)
    margins = np.asarray(margins, dtype=float)
    tie = np.isclose(margins, 0.0)
    one = np.isclose(margins, 1.0)
    if not np.any(tie) or not np.any(one):
        return float("nan")

    return float(aligned_choices[one].mean() - aligned_choices[tie].mean())
```

**Observed (real) value:** 0.0392 (var=0.0080)
**Previous candidate values (this loop):**
  - iter 1 (most recent): 0.1187 (var=0.0088) (Δ vs real +0.0796)
**Other theories' values on this metric (for reference):**
- pi_5: -0.0929 (var=0.0062)
- pi_4: 0.0925 (var=0.0089)
- pi_1: 0.0079 (var=0.0048)
- pi_2: -0.3358 (var=0.0121)
- pi_3: 0.3675 (var=0.0270)
- pi_6: 0.0688 (var=0.0111)
- pi_7: 0.4404 (var=0.0130)
- pi_8: 0.1037 (var=0.0153)
- pi_9: 0.0608 (var=0.0085)

### Experiment 8
**Design**
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 1, 1, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 1, 1, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 1, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 1, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Code each response as choosing the option with fewer marked ratings.
    # A positive count difference means A has more marks, so response 1 (B)
    # is the fewer-mark choice; a negative difference makes response 0 (A)
    # the fewer-mark choice.
    scores = []
    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=float)
        b = np.asarray(row["option_b_ratings"], dtype=float)
        d = float(np.sum(a - b))
        margin = abs(d)
        if not (np.isclose(margin, 1.0) or np.isclose(margin, 5.0)):
            continue

        fewer_choice = 1 if d > 0.0 else 0
        chose_fewer = int(row["response"]) == fewer_choice
        choice_sign = 1.0 if chose_fewer else -1.0
        margin_sign = 1.0 if np.isclose(margin, 5.0) else -1.0
        scores.append(margin_sign * choice_sign)

    if len(scores) == 0:
        return 0.0
    return float(np.sum(scores))
```

**Observed (real) value:** -28.0000 (var=21.1456)
**Previous candidate values (this loop):**
  - iter 1 (most recent): 6.0000 (var=53.6656) (Δ vs real +34.0000)
**Other theories' values on this metric (for reference):**
- pi_4: -112.0000 (var=44.4224)
- pi_5: 12.0000 (var=54.0224)
- pi_1: -8.0000 (var=59.4944)
- pi_2: -156.0000 (var=46.7456)
- pi_3: 360.0000 (var=66.7200)
- pi_6: -14.0000 (var=36.3216)
- pi_7: -18.0000 (var=45.2304)
- pi_8: -16.0000 (var=35.5776)
- pi_9: 52.0000 (var=39.3984)

### Experiment 9
**Design**
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0]
  A=[1, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0]
  A=[1, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0]  B=[1, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0]  B=[1, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    if data is None or len(data) == 0:
        return 0.0

    def subject_score(frame: pd.DataFrame) -> float:
        x_values = []
        outcomes = []

        for _, row in frame.iterrows():
            a = np.asarray(row["option_a_ratings"], dtype=float)
            b = np.asarray(row["option_b_ratings"], dtype=float)
            difference = a - b
            n_features = int(difference.size)
            n_discriminating = float(np.sum(np.abs(difference)))
            count_difference = float(np.sum(difference))

            if n_features <= 0 or n_discriminating <= 0.0 or count_difference == 0.0:
                continue

            # Choice coded toward the option with fewer marked ratings.
            response = int(row["response"])
            chose_fewer = float(response if count_difference > 0.0 else 1 - response)

            fraction = n_discriminating / float(n_features)
            x = np.tanh(
                1.0
                / (
                    0.9
                    * max(fraction, 1.0 / float(n_features)) ** 0.325
                )
            )
            x_values.append(float(x))
            outcomes.append(chose_fewer)

        if len(x_values) < 2:
            return 0.0

        x = np.asarray(x_values, dtype=float)
        y = np.asarray(outcomes, dtype=float)
        weights = x - float(np.mean(x))
        weight_energy = float(np.dot(weights, weights))
        if weight_energy <= 0.0 or not np.isfinite(weight_energy):
            return 0.0

        # Directional trial-level evidence, standardized by its Bernoulli-null
        # standard deviation. Centering the weights removes overall response
        # propensity and polarity confidence.
        numerator = float(np.dot(weights, y - 0.5))
        denominator = float(np.sqrt(0.25 * weight_energy))
        value = numerator / denominator
        return float(value) if np.isfinite(value) else 0.0

    scores = []
    for _, subject_frame in data.groupby("subject_id", sort=False):
        scores.append(subject_score(subject_frame))

    if len(scores) == 0:
        return 0.0

    scores = np.asarray(scores, dtype=float)
    scores = scores[np.isfinite(scores)]
    if scores.size == 0:
        return 0.0

    # Stouffer aggregation: independent subjects contribute cumulative
    # standardized evidence. For a one-subject slice this is simply that
    # subject's score, so the metric remains well-defined for variance
    # estimation.
    value = float(np.sum(scores) / np.sqrt(float(scores.size)))
    return value if np.isfinite(value) else 0.0

```

**Observed (real) value:** -0.0407 (var=0.3436)
**Previous candidate values (this loop):**
  - iter 1 (most recent): -0.7253 (var=1.0020) (Δ vs real -0.6846)
**Other theories' values on this metric (for reference):**
- pi_6: 2.4236 (var=0.6234)
- pi_4: 1.3194 (var=0.6212)
- pi_1: 0.0576 (var=0.4622)
- pi_2: 1.3124 (var=0.3777)
- pi_3: 1.4891 (var=1.1584)
- pi_5: -1.6900 (var=0.8398)
- pi_7: -0.8319 (var=0.4823)
- pi_8: 0.8355 (var=0.6985)
- pi_9: 0.6833 (var=1.1030)

### Experiment 10
**Design**
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]  B=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    if data is None or len(data) == 0:
        return float('nan')

    aligned_large_margin = []

    for a_cell, b_cell, response in zip(
        data['option_a_ratings'],
        data['option_b_ratings'],
        data['response']
    ):
        a = np.asarray(a_cell, dtype=float)
        b = np.asarray(b_cell, dtype=float)
        signed_margin = float(np.sum(a) - np.sum(b))

        # Restrict attention to the four large-margin conditions (5, 7, 9, 13).
        if abs(signed_margin) < 5.0:
            continue

        # One indicates selection of the option with fewer marked ratings.
        if signed_margin > 0.0:
            aligned_large_margin.append(float(response == 1))
        elif signed_margin < 0.0:
            aligned_large_margin.append(float(response == 0))

    if len(aligned_large_margin) == 0:
        return float('nan')

    return float(np.mean(np.asarray(aligned_large_margin, dtype=float)))
```

**Observed (real) value:** 0.8750 (var=0.0078)
**Previous candidate values (this loop):**
  - iter 1 (most recent): 0.8859 (var=0.0027) (Δ vs real +0.0109)
**Other theories' values on this metric (for reference):**
- pi_4: 0.8800 (var=0.0062)
- pi_6: 0.7953 (var=0.0044)
- pi_1: 0.3047 (var=0.0036)
- pi_2: 0.1163 (var=0.0072)
- pi_3: 0.7650 (var=0.0150)
- pi_5: 0.8325 (var=0.0068)
- pi_7: 0.8641 (var=0.0034)
- pi_8: 0.8628 (var=0.0039)
- pi_9: 0.7897 (var=0.0064)

### Experiment 11
**Design**
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    validities = np.array([
        0.99, 0.98, 0.97, 0.96, 0.95, 0.94, 0.93, 0.92, 0.91,
        0.90, 0.89, 0.88, 0.87, 0.86, 0.85, 0.84, 0.83, 0.82, 0.75,
        0.51, 0.52, 0.53, 0.54, 0.55, 0.56, 0.57, 0.58, 0.59,
        0.60, 0.61, 0.62, 0.63, 0.64, 0.65, 0.66, 0.67, 0.68
    ], dtype=float)
    centered = validities - validities.mean()
    scores = []

    for _, row in data.iterrows():
        a = np.asarray(row['option_a_ratings'], dtype=float)
        b = np.asarray(row['option_b_ratings'], dtype=float)
        if a.size != validities.size or b.size != validities.size:
            continue

        difference = a - b
        residual = float(np.dot(centered, difference))
        marks_per_option = int(round(float(np.sum(a))))

        # Retain the three strongest, most diagnostic conflict levels
        # (m = 7, 11, or 18), including both A/B orientations.
        if marks_per_option < 7 or abs(residual) < 2.5:
            continue

        response = int(row['response'])
        # Under the adverse-mark interpretation, the preferred option is the
        # one carrying the lower-validity marks: B if A has the high-validity
        # marks (positive residual), and A in the reversed presentation.
        chose_low_validity_marked_option = (
            (residual > 0.0 and response == 1) or
            (residual < 0.0 and response == 0)
        )
        scores.append(float(chose_low_validity_marked_option))

    if len(scores) == 0:
        return float('nan')
    return float(np.mean(scores))
```

**Observed (real) value:** 0.8442 (var=0.0078)
**Previous candidate values (this loop):**
  - iter 1 (most recent): 0.8650 (var=0.0055) (Δ vs real +0.0208)
**Other theories' values on this metric (for reference):**
- pi_7: 0.5038 (var=0.0050)
- pi_4: 0.8542 (var=0.0061)
- pi_1: 0.1546 (var=0.0096)
- pi_2: 0.4808 (var=0.0046)
- pi_3: 0.6883 (var=0.0142)
- pi_5: 0.7937 (var=0.0092)
- pi_6: 0.8725 (var=0.0061)
- pi_8: 0.8721 (var=0.0046)
- pi_9: 0.8175 (var=0.0077)

### Experiment 12
**Design**
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0]  B=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0]  B=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0]  B=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0]
  A=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    margins = []
    adverse_choices = []

    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=float)
        b = np.asarray(row["option_b_ratings"], dtype=float)
        count_difference = float(np.sum(a) - np.sum(b))
        margin = abs(count_difference)

        # Exclude count ties; the diagnostic trajectory is over margins 1--5.
        if margin < 0.5:
            continue

        response = int(row["response"])
        # Under the adverse-mark interpretation, choose B when A has more
        # marks and choose A when B has more marks.
        adverse_choice = response if count_difference > 0 else 1 - response
        margins.append(margin)
        adverse_choices.append(float(adverse_choice))

    if len(margins) < 2:
        return float("nan")

    x = np.asarray(margins, dtype=float)
    y = np.asarray(adverse_choices, dtype=float)
    x_centered = x - np.mean(x)
    denominator = float(np.dot(x_centered, x_centered))
    if denominator <= 0.0:
        return float("nan")

    # OLS increase in adverse-aligned choice probability per unit margin.
    return float(np.dot(x_centered, y - np.mean(y)) / denominator)
```

**Observed (real) value:** 0.0793 (var=0.0131)
**Previous candidate values (this loop):**
  - iter 1 (most recent): 0.0793 (var=0.0014) (Δ vs real +0.0000)
**Other theories' values on this metric (for reference):**
- pi_4: 0.0704 (var=0.0014)
- pi_7: -0.0020 (var=0.0013)
- pi_1: -0.0019 (var=0.0008)
- pi_2: -0.0053 (var=0.0004)
- pi_3: 0.0224 (var=0.0011)
- pi_5: 0.1059 (var=0.0024)
- pi_6: -0.0039 (var=0.0015)
- pi_8: 0.0680 (var=0.0018)
- pi_9: 0.0515 (var=0.0013)

### Experiment 13
**Design**
  A=[1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0]  B=[0, 1, 0, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1]
  A=[0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 1, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 1, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 1, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 1, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 1, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0]  B=[1, 0, 1, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1]  B=[1, 0, 1, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    validities = np.array([
        0.99, 0.51, 0.98, 0.52, 0.97, 0.53, 0.96, 0.54,
        0.95, 0.55, 0.94, 0.56, 0.93, 0.57, 0.92, 0.58,
        0.91, 0.59, 0.90, 0.60, 0.89, 0.61, 0.88, 0.62,
        0.87, 0.63, 0.86, 0.64, 0.85, 0.65, 0.84, 0.66
    ], dtype=float)
    centered = validities - np.mean(validities)

    loads = []
    aligned_choices = []
    for a_cell, b_cell, response in zip(
        data['option_a_ratings'],
        data['option_b_ratings'],
        data['response']
    ):
        a = np.asarray(a_cell, dtype=float)
        b = np.asarray(b_cell, dtype=float)
        difference = a - b
        load = int(np.sum(np.abs(difference) > 0.5))
        residual = float(np.dot(centered, difference))

        # One means choosing the option favored under the adverse-mark
        # interpretation of the fixed reliability residual.
        if residual > 0.0:
            aligned = float(response == 1)
        elif residual < 0.0:
            aligned = float(response == 0)
        else:
            aligned = 0.5

        loads.append(load)
        aligned_choices.append(aligned)

    loads = np.asarray(loads, dtype=int)
    y = np.asarray(aligned_choices, dtype=float)
    if y.size == 0:
        return float('nan')

    # Matched contrast for the advocated theory's predicted attenuation
    # profile. The coefficients sum to zero over the eight equally frequent
    # diagnostic-load conditions, removing a subject's overall choice level.
    weight_map = {
        4: 16.0,
        8: 5.0,
        12: 1.0,
        16: -1.0,
        20: -2.0,
        24: -4.0,
        28: -7.0,
        32: -8.0
    }
    w = np.asarray([weight_map.get(int(k), 0.0) for k in loads], dtype=float)

    # Empirical centering retains intercept cancellation if a slice happens
    # to contain unequal numbers of repetitions.
    w = w - np.mean(w)
    rms = float(np.sqrt(np.mean(w * w)))
    if rms <= 1e-12:
        return 0.0
    w = w / rms

    return float(np.mean(w * y))
```

**Observed (real) value:** 0.0315 (var=0.0055)
**Previous candidate values (this loop):**
  - iter 1 (most recent): 0.0145 (var=0.0031) (Δ vs real -0.0170)
**Other theories' values on this metric (for reference):**
- pi_8: 0.0333 (var=0.0023)
- pi_4: -0.0062 (var=0.0023)
- pi_1: 0.0024 (var=0.0015)
- pi_2: -0.0067 (var=0.0018)
- pi_3: 0.0005 (var=0.0033)
- pi_5: -0.0049 (var=0.0022)
- pi_6: 0.0051 (var=0.0016)
- pi_7: 0.0047 (var=0.0033)
- pi_9: 0.0347 (var=0.0034)

### Experiment 14
**Design**
  A=[1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    sparse = []
    dense = []

    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=float)
        b = np.asarray(row["option_b_ratings"], dtype=float)
        difference = a - b
        count_difference = float(np.sum(difference))
        n_discriminating = int(np.sum(np.abs(difference) > 0.5))

        if count_difference > 0:
            adverse_consistent = float(int(row["response"]) == 1)
        elif count_difference < 0:
            adverse_consistent = float(int(row["response"]) == 0)
        else:
            continue

        if n_discriminating <= 19:
            sparse.append(adverse_consistent)
        elif n_discriminating >= 27:
            dense.append(adverse_consistent)

    if len(sparse) == 0 or len(dense) == 0:
        return float("nan")

    return float(np.mean(sparse) - np.mean(dense))
```

**Observed (real) value:** -0.0264 (var=0.0053)
**Previous candidate values (this loop):**
  - iter 1 (most recent): 0.0117 (var=0.0069) (Δ vs real +0.0381)
**Other theories' values on this metric (for reference):**
- pi_4: -0.0049 (var=0.0057)
- pi_8: 0.2169 (var=0.0099)
- pi_1: -0.0187 (var=0.0066)
- pi_2: -0.0262 (var=0.0049)
- pi_3: 0.0015 (var=0.0071)
- pi_5: -0.0057 (var=0.0066)
- pi_6: 0.0365 (var=0.0102)
- pi_7: -0.0257 (var=0.0058)
- pi_9: 0.0026 (var=0.0076)

### Experiment 15
**Design**
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    sparse = []
    dense = []

    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=float)
        b = np.asarray(row["option_b_ratings"], dtype=float)
        difference = a - b
        signed_margin = float(np.sum(difference))
        margin = abs(signed_margin)
        n_discriminating = int(np.sum(np.abs(difference) > 0.5))

        # Focus on margins where overload compression should be pronounced.
        if margin < 2.5 or margin > 7.5 or signed_margin == 0.0:
            continue

        response = int(row["response"])
        # One means choosing the option with fewer marked ratings, aligning
        # A/B-reversed trials onto the dominant adverse-mark interpretation.
        adverse_consistent = float(response if signed_margin > 0.0 else 1 - response)

        if n_discriminating <= 7:
            sparse.append(adverse_consistent)
        elif n_discriminating >= 29:
            dense.append(adverse_consistent)

    if len(sparse) == 0 or len(dense) == 0:
        return float("nan")

    return float(np.mean(sparse) - np.mean(dense))
```

**Observed (real) value:** 0.0056 (var=0.0069)
**Previous candidate values (this loop):**
  - iter 1 (most recent): -0.0100 (var=0.0043) (Δ vs real -0.0156)
**Other theories' values on this metric (for reference):**
- pi_8: 0.2372 (var=0.0114)
- pi_9: 0.0183 (var=0.0110)
- pi_1: -0.0067 (var=0.0046)
- pi_2: 0.0067 (var=0.0046)
- pi_3: 0.0261 (var=0.0085)
- pi_4: -0.0028 (var=0.0066)
- pi_5: -0.0006 (var=0.0063)
- pi_6: -0.0256 (var=0.0117)
- pi_7: -0.0206 (var=0.0066)

### Experiment 16
**Design**
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0]  B=[1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0]  B=[1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0]  B=[1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    if data is None or len(data) == 0:
        return float('nan')

    xs = []
    ys = []

    for _, row in data.iterrows():
        a = np.asarray(row['option_a_ratings'], dtype=float)
        b = np.asarray(row['option_b_ratings'], dtype=float)
        if a.ndim != 1 or b.ndim != 1 or len(a) != len(b) or len(a) < 2:
            continue

        d = a - b
        active = int(np.sum(np.abs(d) > 0.5))
        if active < 2 or abs(d[0]) <= 0.5:
            continue

        # Diagnostic-contrast salience implied by this validity profile.
        active_sd = np.sqrt(0.08 / float(active))
        salience = active_sd / (active_sd + 0.10)

        # Choice aligned with the adverse interpretation of the .95 cue.
        target = 1 if d[0] > 0 else 0
        aligned = 1.0 if int(row['response']) == target else 0.0

        xs.append(float(salience))
        ys.append(aligned)

    if len(xs) < 2:
        return float('nan')

    x = np.asarray(xs, dtype=float)
    y = np.asarray(ys, dtype=float)
    x = x - float(np.mean(x))

    # The competing model's typical evidence change corresponds to roughly
    # 0.25 log-odds per unit of active-field salience. The advocated model has
    # a zero coefficient. In both models the intercept is a free nuisance
    # parameter, absorbing each subject's polarity and overall sensitivity.
    beta_comp = 0.25

    def maximized_loglik(beta):
        offset = beta * x
        pbar = float(np.clip(np.mean(y), 1e-6, 1.0 - 1e-6))
        intercept = float(np.log(pbar / (1.0 - pbar)))

        for _ in range(30):
            eta = np.clip(intercept + offset, -30.0, 30.0)
            p = 1.0 / (1.0 + np.exp(-eta))
            score = float(np.sum(y - p))
            information = float(np.sum(p * (1.0 - p)))
            if information <= 1e-12:
                break
            step = score / information
            intercept += step
            if abs(step) < 1e-10:
                break

        eta = np.clip(intercept + offset, -30.0, 30.0)
        return float(np.sum(y * eta - np.logaddexp(0.0, eta)))

    ll_invariant = maximized_loglik(0.0)
    ll_dilution = maximized_loglik(beta_comp)

    # Positive values favor exact invariance; negative values favor the
    # competing theory's prespecified dilution profile.
    return float(ll_invariant - ll_dilution)
```

**Observed (real) value:** -1.6297 (var=0.0178)
**Previous candidate values (this loop):**
  - iter 1 (most recent): 1.2791 (var=0.0119) (Δ vs real +2.9088)
**Other theories' values on this metric (for reference):**
- pi_9: -2.0646 (var=0.0086)
- pi_8: -0.4757 (var=0.0061)
- pi_1: -0.1096 (var=0.0037)
- pi_2: 0.7826 (var=0.0046)
- pi_3: -0.2235 (var=0.0083)
- pi_4: 0.4335 (var=0.0088)
- pi_5: -0.6994 (var=0.0109)
- pi_6: -0.9032 (var=0.0127)
- pi_7: 0.2684 (var=0.0108)

## PREVIOUS CANDIDATE (this loop)
The RUNNING-BEST (last ACCEPTED) candidate in this critique loop — i.e. the source the loop's accept gate kept as the best base so far. If your most recent attempt was REJECTED by the gate, this is NOT that attempt; it is the previously-accepted base the gate rolled back to. Iterate on this source — the next critic feedback should be applied on top of it.

**Description**
Relative-Evidence Conflict Arbitration theory: people construct two density-invariant summaries of a binary-feature display. A signed count accumulator represents only the difference in the numbers of marks carried by the options. It grows approximately linearly across ordinary margins and saturates only at relatively large margins, so adding equal numbers of opposing marks cannot dilute count evidence. In parallel, communicated validities are centered around their profile mean and bound to cue directions. Access to this reliability residual is governed by its absolute magnitude and signed coherence: consistently directed reliability contributions become accessible, whereas additions containing genuinely opposing contributions reduce access by increasing gross support without increasing the residual. Accessibility never depends directly on display size, the number of discriminating cues, or active-validity dispersion. The two summaries are combined by relative-evidence arbitration. Congruent summaries receive modest mutual reinforcement. During conflict, balanced channels inhibit confidence, while sufficiently asymmetric conflicts recruit a winner-enhancement process favoring whichever signed summary is stronger. Thus pure count problems show robust margin growth, but structured count-reliability conflicts can be compressed or reversed without invoking density overload. Stable but moderate differences in channel balance and response precision coexist with stable semantic polarity and occasional lapses.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Relative-Evidence Conflict Arbitration expects shape "
            f"(2, n_features); got {stim.shape}."
        )

    a, b = stim[0], stim[1]
    n_features = int(stim.shape[1])
    validities = np.asarray(parameters["validities"], dtype=float)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} != n_features {n_features}."
        )

    difference = a - b
    count_difference = float(np.sum(difference))

    # Stable channel balance produces moderate individual differences without
    # creating discrete strategy classes or trial-dependent attention shifts.
    raw_balance = float(parameters["channel_balance"])
    centered_balance = np.tanh(1.6 * (2.0 * raw_balance - 1.0)) / np.tanh(1.6)
    count_allocation = 1.0 - 0.14 * centered_balance
    reliability_allocation = 1.0 + 0.22 * centered_balance

    # The count accumulator reads only the signed mark margin. Its large scale
    # gives approximately linear growth through ordinary margins and delays
    # saturation. Equal and opposite added marks leave it exactly unchanged.
    count_scale = float(parameters["count_scale"])
    count_signal = (
        count_allocation
        * float(parameters["count_gain"])
        * count_scale
        * np.tanh(count_difference / count_scale)
    )

    # Reliability information is the component of validity-weighted evidence
    # not already represented by an undifferentiated count. Centering also
    # prevents the common validity level from acting as a second tally.
    centered_validities = validities - float(np.mean(validities))
    signed_components = centered_validities * difference
    reliability_residual = float(np.sum(signed_components))
    gross_reliability_support = float(np.sum(np.abs(signed_components)))

    # Coherence is determined solely by the geometry of signed reliability
    # contributions. Consistent contributions have coherence one; opposing
    # additions increase gross support and reduce coherence even if the net
    # residual is unchanged. No cue-count or display-density term appears.
    if gross_reliability_support > 1e-12:
        coherence = abs(reliability_residual) / gross_reliability_support
    else:
        coherence = 0.0
    coherence = float(np.clip(coherence, 0.0, 1.0))

    residual_magnitude = abs(reliability_residual)
    half_saturation = float(parameters["magnitude_half_saturation"])
    magnitude_access = residual_magnitude / (
        residual_magnitude + half_saturation + 1e-12
    )

    accessibility = (
        float(parameters["reliability_floor"])
        + float(parameters["coherence_gain"])
        * (coherence ** float(parameters["coherence_power"]))
        * magnitude_access
    )
    reliability_signal = (
        reliability_allocation
        * float(parameters["reliability_gain"])
        * accessibility
        * reliability_residual
    )

    c_abs = abs(count_signal)
    r_abs = abs(reliability_signal)
    total_abs = c_abs + r_abs

    if total_abs <= 1e-12:
        integrated_signal = 0.0
    elif count_signal * reliability_signal > 0.0:
        # Agreement is mildly superadditive but remains a function of relative
        # signed support, not the number of displayed or active features.
        agreement_balance = 4.0 * c_abs * r_abs / (total_abs * total_abs + 1e-12)
        integrated_signal = (count_signal + reliability_signal) * (
            1.0
            + float(parameters["congruent_synergy"]) * agreement_balance
        )
    elif count_signal * reliability_signal < 0.0:
        # Balanced conflict compresses confidence. Asymmetric conflict recruits
        # winner enhancement, permitting either robust count choices or
        # reliability-driven reversals according to relative evidence alone.
        conflict_balance = 4.0 * c_abs * r_abs / (
            total_abs * total_abs + 1e-12
        )
        relative_dominance = abs(c_abs - r_abs) / (total_abs + 1e-12)
        dominance_gate = relative_dominance ** float(
            parameters["arbitration_curvature"]
        )

        compressed_sum = (count_signal + reliability_signal) / (
            1.0
            + float(parameters["conflict_compression"])
            * conflict_balance
        )
        winner_signal = count_signal if c_abs >= r_abs else reliability_signal
        winner_bonus = (
            float(parameters["winner_enhancement"])
            * conflict_balance
            * dominance_gate
            * winner_signal
        )
        integrated_signal = compressed_sum + winner_bonus
    else:
        integrated_signal = count_signal + reliability_signal

    markedness_evidence = (
        float(parameters["response_precision"]) * integrated_signal
    )

    # Positive markedness means A carries the greater adverse burden and thus
    # favors B. Semantic polarity is fixed across the entire subject run.
    adverse_logits = np.array(
        [-0.5 * markedness_evidence, 0.5 * markedness_evidence], dtype=float
    )
    adverse_logits -= np.max(adverse_logits)
    adverse_probs = np.exp(adverse_logits)
    adverse_probs /= adverse_probs.sum()

    beneficial_probs = adverse_probs[::-1]
    polarity = float(parameters["adverse_polarity_confidence"])
    core_probs = polarity * adverse_probs + (1.0 - polarity) * beneficial_probs

    lapse = float(parameters["lapse_rate"])
    probs = (1.0 - lapse) * core_probs + lapse * np.array([0.5, 0.5])
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        return np.array([0.5, 0.5], dtype=float)
    return probs / total

`policy(probs) -> int`:
def policy(probs):
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        probs = np.ones(len(probs), dtype=np.float64) / float(len(probs))
    else:
        probs /= total
    return int(np.random.choice(len(probs), p=probs))

`parameters`:
- validities: validities
- channel_balance: [0.0, 1.0]
- count_gain: [0.92, 1.18]
- count_scale: [7.0, 11.5]
- reliability_floor: [0.24, 0.46]
- coherence_gain: [0.48, 0.92]
- coherence_power: [0.75, 1.45]
- magnitude_half_saturation: [0.12, 0.42]
- reliability_gain: [0.72, 1.16]
- congruent_synergy: [0.0, 0.14]
- conflict_compression: [0.35, 0.95]
- winner_enhancement: [0.18, 0.62]
- arbitration_curvature: [0.65, 1.35]
- response_precision: [0.82, 1.22]
- adverse_polarity_confidence: [0.84, 0.98]
- lapse_rate: [0.0, 0.10]

`rationale`: The previous candidate's explicit diagnostic-load machinery produced large spurious density effects in Experiments 14 and 15 and made count strength depend on how many cues happened to differ. The proposed accumulator removes that failure: only signed margin enters the count channel, and its broad saturation scale supports the stronger margin trajectories required by Experiments 5, 6, and 12 while preserving exact invariance to canceling additions. Reliability access is also structurally density-invariant. It depends on net residual magnitude and the ratio of net to gross signed reliability support. Consequently, a coherent high-versus-low block remains usable in a dense display, as required by Experiment 13, whereas genuinely opposing reliability additions can attenuate the channel through coherence loss, as suggested by Experiments 15 and 16. The arbitration stage is qualitatively new relative to simple addition or generic conflict normalization. Balanced opposition compresses confidence, but asymmetric opposition enhances the stronger channel. This allows robust adverse count choices in pure-margin tasks while permitting compression and reversals when increasing count margins are systematically coupled to oppositely signed reliability evidence, including the geometry represented in Experiments 8 and 10. Finally, heterogeneity ranges are deliberately moderate and stable: they express plausible differences in channel weighting and precision but cannot create pooled null density effects by averaging individually large, opposing load effects.

## PRIOR FEEDBACK ITERATIONS
The critic's verdicts on each previous in-loop candidate, in order. Each block ends with an **Outcome of this advice** line saying whether the candidate the proposer produced AFTER this advice was ACCEPTED (loss strictly beat the running best) or REJECTED (the gate discarded it). Address the most recent iteration's feedback in your next edit, but down-weight past advice whose candidates were REJECTED.

### Iteration 1 (most recent — address this)
Verdict: regenerate
Interpretation: The accepted candidate is faithful to the prescribed density-invariant conflict-arbitration family and fits many central results well. It closely captures Experiments 3, 4, 10, 11, 12, 14, and 15, exactly matches the Experiment 2 classification, and substantially improves the intended count trajectory in Experiment 12. The removal of generic cue-load attenuation clearly fixes the former large spurious density effects in Experiments 14 and 15. However, the remaining failures are systematic rather than simulation noise. Most importantly, Experiment 16 has the wrong sign and a very large discrepancy: observed -1.6297 versus simulated +1.2791. Thus the supposedly geometry-sensitive reliability channel predicts increasing or invariant diagnostic-cue influence across the added coherent pairs, while humans show the prespecified attenuation pattern. Experiment 9 should be approximately invariant (-0.0407), but the candidate produces a sizable negative trend (-0.7253) and excessive between-subject variance. Experiment 8 also misses the margin contrast's direction (observed -28, simulated +6). Secondary misses occur in Experiment 1, where tally opposition is too weak (-0.2818 versus -0.4355), and Experiments 5 and 7, where the slopes/contrasts are respectively too small (0.1669 versus 0.2306) and too large (0.1187 versus 0.0392). Experiment 6 is also somewhat too steep. Across several experiments the simulated between-subject variance is markedly too low, especially Experiments 1, 5, 6, and 12, although this should not be repaired by heterogeneous density effects.
Rationale: Keep the current mechanism family and the successful density-invariant count accumulator, but recalibrate how reliability magnitude enters arbitration. The present accessibility saturates, yet `reliability_signal` remains linear in the raw residual; consequently, coherent additions can continue increasing reliability evidence almost without bound. Add a density-free saturation or normalization to the final reliability residual itself—based on signed residual magnitude and gross signed support, not feature count—so coherent dense blocks remain usable but do not automatically become stronger merely because more similarly directed contributions are accumulated. Jointly lower the reliability floor and retune coherence curvature/gain so genuinely opposing contributions cause sharper accessibility loss, while preserving Experiment 13's dense coherent-block performance. Then retune conflict compression and winner enhancement around near-balanced conflicts rather than globally changing count gain: Experiment 8 needs the margin-1 reliability geometry to remain more influential relative to margin 5, whereas Experiment 10's excellent large-margin reversal and Experiment 12's count slope should be protected. This same adjustment should flatten the spurious Experiment 9 trend and strengthen tally dominance in Experiment 1 without weakening pure-margin count evidence. Finally, modestly broaden stable channel-balance or precision heterogeneity to improve the underestimated individual variance, but do not introduce subject-specific load slopes or use heterogeneity to create pooled nulls.

**Outcome of this advice:** iter 1 candidate loss=0.1485 -> next candidate accept-status=PENDING (this is the advice you are addressing now).


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
  "theory": "Relative-Evidence Conflict Arbitration theory: people construct two density-invariant summaries of a binary-feature display. A signed count accumulator represents only the difference in the numbers of marks carried by the options. It grows approximately linearly across ordinary margins and saturates only at relatively large margins, so adding equal numbers of opposing marks cannot dilute count evidence. In parallel, communicated validities are centered around their profile mean and bound to cue directions. Access to this reliability residual is governed by its absolute magnitude and signed coherence: consistently directed reliability contributions become accessible, whereas additions containing genuinely opposing contributions reduce access by increasing gross support without increasing the residual. Before arbitration, the reliability residual is self-normalized by its gross signed support. Consequently, coherent blocks remain usable but approach a finite reliability signal rather than becoming stronger merely because more similarly directed contributions are displayed. Accessibility and normalization never depend directly on display size, the number of discriminating cues, or active-validity dispersion. The two summaries are combined by relative-evidence arbitration. Congruent summaries receive modest mutual reinforcement. During conflict, balanced channels inhibit confidence, while sufficiently asymmetric conflicts recruit a restrained winner-enhancement process favoring whichever signed summary is stronger. Thus pure count problems show robust margin growth, but structured count-reliability conflicts can be compressed or reversed without invoking density overload. Stable channel-balance and response-precision differences coexist with stable semantic polarity and occasional lapses.",
  "predict": "def predict(parameters, state, history):\n    stim = np.asarray(state, dtype=float)\n    if stim.ndim != 2 or stim.shape[0] != 2:\n        raise ValueError(\n            f\"Relative-Evidence Conflict Arbitration expects shape \"\n            f\"(2, n_features); got {stim.shape}.\"\n        )\n\n    a, b = stim[0], stim[1]\n    n_features = int(stim.shape[1])\n    validities = np.asarray(parameters[\"validities\"], dtype=float)\n    if validities.ndim != 1 or validities.size != n_features:\n        raise ValueError(\n            f\"validities length {validities.size} != n_features {n_features}.\"\n        )\n\n    difference = a - b\n    count_difference = float(np.sum(difference))\n\n    # Stable channel balance produces moderate individual differences without\n    # creating discrete strategy classes or trial-dependent attention shifts.\n    raw_balance = float(parameters[\"channel_balance\"])\n    centered_balance = np.tanh(1.6 * (2.0 * raw_balance - 1.0)) / np.tanh(1.6)\n    count_allocation = 1.0 - 0.14 * centered_balance\n    reliability_allocation = 1.0 + 0.22 * centered_balance\n\n    # The count accumulator reads only the signed mark margin. Its large scale\n    # gives approximately linear growth through ordinary margins and delays\n    # saturation. Equal and opposite added marks leave it exactly unchanged.\n    count_scale = float(parameters[\"count_scale\"])\n    count_signal = (\n        count_allocation\n        * float(parameters[\"count_gain\"])\n        * count_scale\n        * np.tanh(count_difference / count_scale)\n    )\n\n    # Reliability information is the component of validity-weighted evidence\n    # not already represented by an undifferentiated count. Centering also\n    # prevents the common validity level from acting as a second tally.\n    centered_validities = validities - float(np.mean(validities))\n    signed_components = centered_validities * difference\n    reliability_residual = float(np.sum(signed_components))\n    gross_reliability_support = float(np.sum(np.abs(signed_components)))\n\n    # Coherence is determined solely by the geometry of signed reliability\n    # contributions. Consistent contributions have coherence one; opposing\n    # additions increase gross support and reduce coherence even if the net\n    # residual is unchanged. No cue-count or display-density term appears.\n    if gross_reliability_support > 1e-12:\n        coherence = abs(reliability_residual) / gross_reliability_support\n    else:\n        coherence = 0.0\n    coherence = float(np.clip(coherence, 0.0, 1.0))\n\n    residual_magnitude = abs(reliability_residual)\n    half_saturation = float(parameters[\"magnitude_half_saturation\"])\n    magnitude_access = residual_magnitude / (\n        residual_magnitude + half_saturation + 1e-12\n    )\n\n    accessibility = (\n        float(parameters[\"reliability_floor\"])\n        + float(parameters[\"coherence_gain\"])\n        * (coherence ** float(parameters[\"coherence_power\"]))\n        * magnitude_access\n    )\n\n    # The expressed residual is self-normalized by gross signed support. This\n    # is density-free: a coherent reliability block approaches a finite signal,\n    # while opposing additions reduce both coherence and the normalized net.\n    residual_scale = float(parameters[\"residual_saturation_scale\"])\n    bounded_reliability_residual = (\n        residual_scale\n        * reliability_residual\n        / (residual_scale + gross_reliability_support + 1e-12)\n    )\n    reliability_signal = (\n        reliability_allocation\n        * float(parameters[\"reliability_gain\"])\n        * accessibility\n        * bounded_reliability_residual\n    )\n\n    c_abs = abs(count_signal)\n    r_abs = abs(reliability_signal)\n    total_abs = c_abs + r_abs\n\n    if total_abs <= 1e-12:\n        integrated_signal = 0.0\n    elif count_signal * reliability_signal > 0.0:\n        # Agreement is mildly superadditive but remains a function of relative\n        # signed support, not the number of displayed or active features.\n        agreement_balance = 4.0 * c_abs * r_abs / (total_abs * total_abs + 1e-12)\n        integrated_signal = (count_signal + reliability_signal) * (\n            1.0\n            + float(parameters[\"congruent_synergy\"]) * agreement_balance\n        )\n    elif count_signal * reliability_signal < 0.0:\n        # Balanced conflict compresses confidence. Asymmetric conflict recruits\n        # winner enhancement, permitting either robust count choices or\n        # reliability-driven reversals according to relative evidence alone.\n        conflict_balance = 4.0 * c_abs * r_abs / (\n            total_abs * total_abs + 1e-12\n        )\n        relative_dominance = abs(c_abs - r_abs) / (total_abs + 1e-12)\n        dominance_gate = relative_dominance ** float(\n            parameters[\"arbitration_curvature\"]\n        )\n\n        compressed_sum = (count_signal + reliability_signal) / (\n            1.0\n            + float(parameters[\"conflict_compression\"])\n            * conflict_balance\n        )\n        winner_signal = count_signal if c_abs >= r_abs else reliability_signal\n        winner_bonus = (\n            float(parameters[\"winner_enhancement\"])\n            * conflict_balance\n            * dominance_gate\n            * winner_signal\n        )\n        integrated_signal = compressed_sum + winner_bonus\n    else:\n        integrated_signal = count_signal + reliability_signal\n\n    markedness_evidence = (\n        float(parameters[\"response_precision\"]) * integrated_signal\n    )\n\n    # Positive markedness means A carries the greater adverse burden and thus\n    # favors B. Semantic polarity is fixed across the entire subject run.\n    adverse_logits = np.array(\n        [-0.5 * markedness_evidence, 0.5 * markedness_evidence], dtype=float\n    )\n    adverse_logits -= np.max(adverse_logits)\n    adverse_probs = np.exp(adverse_logits)\n    adverse_probs /= adverse_probs.sum()\n\n    beneficial_probs = adverse_probs[::-1]\n    polarity = float(parameters[\"adverse_polarity_confidence\"])\n    core_probs = polarity * adverse_probs + (1.0 - polarity) * beneficial_probs\n\n    lapse = float(parameters[\"lapse_rate\"])\n    probs = (1.0 - lapse) * core_probs + lapse * np.array([0.5, 0.5])\n    probs = np.asarray(probs, dtype=np.float64)\n    probs = np.clip(probs, 0.0, None)\n    total = float(probs.sum())\n    if not np.isfinite(total) or total <= 0.0:\n        return np.array([0.5, 0.5], dtype=float)\n    return probs / total",
  "policy": "def policy(probs):\n    probs = np.asarray(probs, dtype=np.float64)\n    probs = np.clip(probs, 0.0, None)\n    total = float(probs.sum())\n    if not np.isfinite(total) or total <= 0.0:\n        probs = np.ones(len(probs), dtype=np.float64) / float(len(probs))\n    else:\n        probs /= total\n    return int(np.random.choice(len(probs), p=probs))",
  "parameters": {
    "validities": "validities",
    "channel_balance": "[0.0, 1.0]",
    "count_gain": "[0.92, 1.18]",
    "count_scale": "[7.0, 11.5]",
    "reliability_floor": "[0.12, 0.30]",
    "coherence_gain": "[0.55, 1.00]",
    "coherence_power": "[1.05, 1.85]",
    "magnitude_half_saturation": "[0.12, 0.42]",
    "residual_saturation_scale": "[0.65, 1.25]",
    "reliability_gain": "[0.85, 1.35]",
    "congruent_synergy": "[0.0, 0.14]",
    "conflict_compression": "[0.55, 1.15]",
    "winner_enhancement": "[0.08, 0.38]",
    "arbitration_curvature": "[0.65, 1.35]",
    "response_precision": "[0.72, 1.32]",
    "adverse_polarity_confidence": "[0.84, 0.98]",
    "lapse_rate": "[0.0, 0.10]"
  },
  "rationale": "This is a minimal edit to the accepted model. The count accumulator and arbitration architecture are retained. The principal change is a final self-normalization of the reliability residual by gross signed reliability support. Coherent additions can therefore preserve a strong reliability representation without allowing raw residual magnitude to grow almost without bound, addressing the wrong Experiment 16 direction and helping flatten Experiment 9. Because opposing contributions simultaneously lower coherence and the normalized residual, reliability loss remains geometry-sensitive rather than density-sensitive. The lower reliability floor and steeper coherence curvature strengthen tally dominance when reliability support is internally conflicted, improving Experiment 1 while preserving coherent reliability blocks such as Experiment 13. Conflict compression is increased and winner enhancement restrained so near-balanced opposition remains influential at small margins, targeting Experiments 7 and 8 without altering pure-margin count growth in Experiments 3 and 12. Response-precision heterogeneity is broadened modestly to address underestimated individual variance, but no subject-specific density effect or load slope is introduced."
}
```

## Usage

```json
{
  "input_tokens": 53660,
  "output_tokens": 4191
}
```
