# generation_iter_05_attempt_00

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

Replace pi_10/RBIS with a new history-invariant theory of reliability-gated reason competition, rather than revising its current state machine. The new theory should preserve only the empirically useful principles that communicated validity matters, serial order can resolve genuinely tied top cues, and coalitions exhibit redundancy. It should reject ordinal reliability bands as the universal representation and eliminate all rules keyed to a particular feature count, exact display size, cue index, or arbitrary spatial-span threshold. Use a single task-invariant mechanism: continuously compressed validity evidence is accumulated within option coalitions under divisive redundancy; sparse credible opposition receives a graded diagnosticity gain; and increasing opponent multiplicity gradually saturates that gain and can restore an isolated high-validity anchor. Serial accessibility should be gated by an actual or psychologically indistinguishable top-validity tie and should not create a primacy crossover under a clear unique maximum. Display geometry should matter only through psychologically defensible quantities such as coalition size, validity composition, balance, and anchor isolation—not through raw index span. Stable subject differences should vary a small set of interpretable dimensions, such as validity compression, tie sensitivity, sparse-dissent sensitivity, redundancy, restoration threshold, and response precision, with correlated random effects rather than discrete exception-heavy interpretation types. This competitor should target the large positive recovery in Experiment 1 and the null geometry effect in Experiment 2, while also accommodating tied-cue order adherence in Experiments 3 and 7, no unique-maximum primacy crossover in Experiment 6, strong coalition override in Experiments 4, 8, 12, and 15, graded high-count recovery in Experiment 13, and the activation effect in Experiment 14. It should remain strictly history-invariant to respect the null learning evidence in Experiments 9, 16, and 18.

## THEORY LEADERBOARD
A small set of prior picked theories shown for reference. Overall score is in `[0, 1]`, higher = better, computed as `1 - L2_norm(normalized_per_experiment_distances) / max_L2_norm`. 1.0 means closest to the real value on every experiment+metric pair; 0.0 means farthest. Each entry below carries the same depth of detail as the PREVIOUS MODEL INSTANCE above so you can borrow concrete mechanisms when useful.

### `pi_8` (overall score: 0.651)

**Description**
Active-Cue Accessibility Competition (ACAC) proposes that people use a stable representation of communicated cue validity and evaluate only cues that discriminate on the current trial. Active cues first form option-specific coalitions. Coalition support accumulates smoothly but is compressed according to coalition size, validity similarity, and effective cue multiplicity, so additional concordant cues become increasingly redundant without triggering a categorical restoration rule. In unique-anchor configurations where both options have multiple active supporters, coalition evidence is additionally normalized toward effective coalition counts. This prevents the allocation of one relatively valid lower cue from producing an implicit presentation-order crossover. Decisions in this symmetrically normalized geometry are made with moderately greater response precision, reflecting reduced conflict after cue identities have been compressed; this suppresses sampling-induced primacy classifications and strengthens balanced-profile anchor evidence without introducing an order weight. The strongest currently active cue serves as a validity anchor. Opposition receives a sharply count-selective challenge enhancement centered on exactly one opponent. This enhancement is strongest for an isolated anchor and attenuated for embedded-anchor singleton dissent; larger opposing coalitions retain only a small, smooth inverse-count challenge tail. In the exact unique-anchor, isolated, one-opponent configuration, stable competition types form a heterogeneous mixture containing a small genuinely resistant group and a larger set of strongly challenge-accessible integrators. Challenge strength depends continuously on the anchor's absolute validity and validity advantage over the strongest opponent. Presentation order is consulted only when multiple currently active cues share maximal communicated validity. A bounded active-tie gate favors the earliest member of that tied set, with an additional conflict-geometry increment when lower-validity active cues precede tied maxima supporting opposing options. Inactive co-top cues cannot activate either component. Tie accessibility retains the same marginal distribution across subject types as in the previous model. Because the task provides no correctness feedback, ACAC explicitly excludes trial-history learning of cue concurrence, anti-concurrence, or discrimination frequency.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"ACAC expects state with shape (2, n_features); got {stim.shape}."
        )

    n_features = stim.shape[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    if validities.ndim != 1 or validities.shape[0] != n_features:
        raise ValueError(
            f"validities length {validities.shape[0]} != n_features {n_features}."
        )

    # Positive directions favor B and negative directions favor A.
    directions = np.sign(stim[1] - stim[0])
    active = np.flatnonzero(directions != 0)
    if active.size == 0:
        return np.array([0.5, 0.5], dtype=np.float64)

    validity_gain = float(parameters["validity_gain"])
    redundancy_strength = float(parameters["redundancy_strength"])
    redundancy_curvature = float(parameters["redundancy_curvature"])
    similarity_sensitivity = float(parameters["similarity_sensitivity"])
    compact_challenge = float(parameters["compact_challenge"])
    compact_peak = float(parameters["compact_peak"])
    compact_width = float(parameters["compact_width"])
    isolated_singleton_access = float(parameters["isolated_singleton_access"])
    challenge_tail = float(parameters["challenge_tail"])
    embedded_compact_scale = float(parameters["embedded_compact_scale"])
    challenge_gap_scale = float(parameters["challenge_gap_scale"])
    absolute_threshold = float(parameters["absolute_threshold"])
    absolute_slope = float(parameters["absolute_slope"])
    weak_anchor_gain = float(parameters["weak_anchor_gain"])
    isolation_gain = float(parameters["isolation_gain"])
    credibility_protection = float(parameters["credibility_protection"])
    active_tie_ceiling = float(parameters["active_tie_ceiling"])
    tie_activation_rate = float(parameters["tie_activation_rate"])
    conflict_tie_boost = float(parameters["conflict_tie_boost"])
    beta = float(parameters["beta"])
    lapse = float(parameters["lapse"])
    competition_type = int(parameters["competition_type"])

    # Six correlated mixture cells preserve the previous marginal distribution
    # of active-tie accessibility while assigning only one-sixth of subjects to
    # a genuinely singleton-resistant group. The remaining subjects express a
    # strong but heterogeneous exact-singleton challenge response.
    if competition_type == 0:       # genuinely singleton-resistant
        type_challenge = 0.05
        type_singleton_access = 0.00
    elif competition_type in (1, 2):  # strongly challenge-sensitive
        type_challenge = 4.50
        type_singleton_access = 0.00
    else:                            # strongly accessible integrators
        type_challenge = 1.00
        type_singleton_access = 1.50

    # Tie accessibility is crossed with singleton sensitivity so that changing
    # the singleton mixture does not change the marginal tie-type frequencies.
    if competition_type in (0, 1):
        type_tie = 1.65
    elif competition_type in (2, 3):
        type_tie = 0.30
    else:
        type_tie = 1.00

    def sigmoid(x):
        x = float(np.clip(x, -60.0, 60.0))
        return 1.0 / (1.0 + np.exp(-x))

    # Communicated accuracy is represented on a log-evidence scale. Centering
    # on the active maximum improves numerical stability without discarding
    # absolute validity, which is retained separately below.
    v = np.clip(validities, 0.500001, 0.999999)
    reliability = np.log(v / (1.0 - v))
    active_reference = float(np.max(reliability[active]))
    cue_weight = np.exp(validity_gain * (reliability - active_reference))

    a_cues = np.flatnonzero(directions < 0)
    b_cues = np.flatnonzero(directions > 0)
    n_a = int(a_cues.size)
    n_b = int(b_cues.size)

    def coalition_support(indices):
        n = int(indices.size)
        if n == 0:
            return 0.0

        weights = np.asarray(cue_weight[indices], dtype=float)
        raw_support = float(np.sum(weights))

        # Effective multiplicity changes smoothly with coalition composition.
        # A coalition containing several similarly accessible cues has a high
        # effective count and is compressed more strongly than a heterogeneous
        # coalition dominated by one cue.
        effective_n = raw_support / max(float(np.max(weights)), 1e-12)
        effective_excess = max(effective_n - 1.0, 0.0)

        coalition_v = validities[indices]
        validity_spread = float(np.std(coalition_v)) if n > 1 else 0.0
        similarity = np.exp(-similarity_sensitivity * validity_spread)
        discount = 1.0 + redundancy_strength * similarity * (
            effective_excess ** redundancy_curvature
        )
        return raw_support / max(discount, 1e-12)

    support_a = coalition_support(a_cues)
    support_b = coalition_support(b_cues)

    # The validity anchor is defined only over currently discriminating cues.
    active_v = validities[active]
    best_v = float(np.max(active_v))
    top_candidates = active[np.isclose(active_v, best_v, atol=1e-8)]
    anchor_cue = int(np.min(top_candidates))
    anchor_direction = float(directions[anchor_cue])
    unique_anchor = float(top_candidates.size == 1)

    # In unique-anchor multi-cue-versus-multi-cue configurations, normalize
    # coalition composition toward effective count support. This saturation
    # prevents reallocating one relatively valid lower cue from inducing an
    # implicit primacy crossover, while leaving isolated-anchor diagnostics
    # and all tied-top configurations unchanged.
    normalized_multicue_geometry = False
    if unique_anchor > 0.0 and n_a > 1 and n_b > 1:
        pooled_weight = float(np.mean(cue_weight[active]))

        def normalized_multicue_support(n):
            excess = float(n - 1)
            discount = 1.0 + redundancy_strength * (
                excess ** redundancy_curvature
            )
            return pooled_weight * float(n) / max(discount, 1e-12)

        support_a = normalized_multicue_support(n_a)
        support_b = normalized_multicue_support(n_b)
        normalized_multicue_geometry = True

    if anchor_direction > 0:
        anchor_indices = b_cues
        opponent_indices = a_cues
        anchor_support = support_b
        opponent_support = support_a
    else:
        anchor_indices = a_cues
        opponent_indices = b_cues
        anchor_support = support_a
        opponent_support = support_b

    anchor_count = int(anchor_indices.size)
    opponent_count = int(opponent_indices.size)

    # Absolute credibility and relative advantage are distinct. A cue can be
    # locally strongest yet remain challengeable when all active cues have low
    # communicated validity.
    weak_anchor = sigmoid(absolute_slope * (absolute_threshold - best_v))
    strong_anchor = 1.0 - weak_anchor

    if opponent_count > 0:
        strongest_opponent_v = float(np.max(validities[opponent_indices]))
        opponent_gap = max(best_v - strongest_opponent_v, 0.0)
    else:
        opponent_gap = 0.5

    gap_accessibility = np.exp(
        -opponent_gap / max(challenge_gap_scale, 1e-8)
    )
    gap_protection = 1.0 - gap_accessibility

    # Credibility protection is deliberately bounded so that merely moving a
    # relatively valid lower cue between coalitions cannot create an implicit
    # unique-anchor presentation-order effect.
    anchor_support *= 1.0 + (
        unique_anchor
        * credibility_protection
        * strong_anchor
        * gap_protection
    )

    if opponent_count > 0:
        # The high-amplitude component is extremely localized at one opponent.
        # Embedded singleton dissent receives only a bounded fraction of it,
        # whereas isolated one-versus-one conflict expresses the full stable
        # subject-type difference. In that exact geometry, a bounded access
        # increment selectively raises strongly accessible integrators while a
        # small mixture remains genuinely resistant.
        count_distance = (
            float(opponent_count) - compact_peak
        ) / max(compact_width, 1e-8)
        singleton_profile = np.exp(-0.5 * count_distance ** 2)

        if anchor_count == 1:
            singleton_geometry = 1.0
        else:
            singleton_geometry = embedded_compact_scale

        active_type_challenge = type_challenge
        if (
            unique_anchor > 0.0
            and anchor_count == 1
            and opponent_count == 1
            and top_candidates.size == 1
        ):
            active_type_challenge += (
                isolated_singleton_access * type_singleton_access
            )

        singleton_intensity = (
            active_type_challenge
            * compact_challenge
            * singleton_profile
            * singleton_geometry
        )
        smooth_tail = challenge_tail / float(opponent_count + 1)

        isolation = 1.0 / float(max(anchor_count, 1))
        geometry_gain = 1.0 + isolation_gain * isolation
        absolute_gain = 1.0 + weak_anchor_gain * weak_anchor

        challenge_multiplier = 1.0 + (
            singleton_intensity + smooth_tail
        ) * gap_accessibility * geometry_gain * absolute_gain
        opponent_support *= challenge_multiplier

    total_support = anchor_support + opponent_support
    if total_support <= 1e-12:
        core_evidence = 0.0
    else:
        anchor_margin = (anchor_support - opponent_support) / total_support
        core_evidence = anchor_direction * anchor_margin

    # A bounded order gate is activated exclusively by a tie among currently
    # active maximum-validity cues. Conflict among tied maxima receives an
    # additional activation increment only when lower-validity active cues
    # precede the tied set. This captures activation-sensitive accessibility
    # without increasing first-cue adherence in unique-maximum profiles.
    active_top_count = int(top_candidates.size)
    if active_top_count >= 2:
        tie_gate = (
            type_tie
            * active_tie_ceiling
            * (1.0 - np.exp(
                -tie_activation_rate * float(active_top_count - 1)
            ))
        )
        tied_directions = directions[top_candidates]
        tied_conflict = float(
            np.any(tied_directions > 0) and np.any(tied_directions < 0)
        )
        preceded_tied_set = float(int(active[0]) < anchor_cue)
        tie_gate += (
            type_tie
            * conflict_tie_boost
            * tied_conflict
            * preceded_tied_set
        )
    else:
        tie_gate = 0.0
    tie_gate = float(np.clip(tie_gate, 0.0, 0.95))

    choice_evidence = (
        (1.0 - tie_gate) * core_evidence
        + tie_gate * anchor_direction
    )

    # Symmetric multi-cue normalization removes much of the identity-based
    # conflict, so choices in that geometry are moderately more precise. This
    # affects neither isolated singleton competition nor active-top-tie trials.
    effective_beta = beta * (1.60 if normalized_multicue_geometry else 1.0)
    logits = effective_beta * np.array(
        [-0.5 * choice_evidence, 0.5 * choice_evidence],
        dtype=np.float64,
    )
    logits = logits - np.max(logits)
    probs = np.exp(logits)
    probs /= probs.sum()

    probs = (1.0 - lapse) * probs + lapse * np.array(
        [0.5, 0.5], dtype=np.float64
    )
    probs = np.clip(probs, 0.0, None)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        return np.array([0.5, 0.5], dtype=np.float64)
    probs /= total
    return probs.astype(np.float64)


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
- validity_gain: [0.05, 0.22]
- redundancy_strength: [0.62, 1.08]
- redundancy_curvature: [1.18, 1.58]
- similarity_sensitivity: [5.0, 14.0]
- compact_challenge: [5.0, 10.0]
- compact_peak: [0.98, 1.02]
- compact_width: [0.12, 0.25]
- isolated_singleton_access: [1.8, 2.8]
- challenge_tail: [0.08, 0.28]
- embedded_compact_scale: [0.08, 0.22]
- challenge_gap_scale: [0.08, 0.18]
- absolute_threshold: [0.68, 0.77]
- absolute_slope: [14.0, 32.0]
- weak_anchor_gain: [0.65, 1.75]
- isolation_gain: [0.35, 1.10]
- credibility_protection: [0.0, 0.18]
- active_tie_ceiling: [0.70, 0.90]
- tie_activation_rate: [1.25, 2.60]
- conflict_tie_boost: [0.60, 1.00]
- beta: [1.45, 3.80]
- lapse: [0.0, 0.10]
- competition_type: {0, 1, 2, 3, 4, 5}

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=1.0000 (var=0.0000) vs this=0.9300 (var=0.0601)
- Experiment 2: real=0.3242 (var=0.0174) vs this=0.4275 (var=0.0045)
- Experiment 3: real=0.0721 (var=0.0052) vs this=-0.0956 (var=0.0027)
- Experiment 4: real=0.0000 (var=0.0000) vs this=0.2200 (var=0.1716)
- Experiment 5: real=0.7900 (var=0.0184) vs this=0.7033 (var=0.0264)
- Experiment 6: real=-0.5450 (var=0.0462) vs this=-0.2550 (var=0.0318)
- Experiment 7: real=0.0052 (var=0.0075) vs this=0.0404 (var=0.0151)
- Experiment 8: real=0.0070 (var=0.0002) vs this=0.0072 (var=0.0002)
- Experiment 9: real=0.7250 (var=0.0723) vs this=0.5850 (var=0.0117)
- Experiment 10: real=0.4462 (var=0.0224) vs this=0.6150 (var=0.0107)
- Experiment 11: real=0.1093 (var=0.0652) vs this=0.1107 (var=0.0194)
- Experiment 12: real=0.3533 (var=0.0427) vs this=0.3488 (var=0.0128)
- Experiment 13: real=0.3275 (var=0.0184) vs this=0.5044 (var=0.0026)
- Experiment 14: real=0.0200 (var=0.1946) vs this=-0.1050 (var=0.1227)
- Experiment 15: real=0.8475 (var=0.0129) vs this=0.6492 (var=0.0078)
- Experiment 16: real=0.0263 (var=0.0299) vs this=-0.0081 (var=0.0183)
- Experiment 17: real=0.5600 (var=0.0288) vs this=0.0325 (var=0.0124)
- Experiment 18: real=0.0092 (var=0.0117) vs this=0.0279 (var=0.0087)


---

### `pi_6` (overall score: 0.608)

**Description**
Static Configuration-Contingent Integration (SCCI) claims that people form a fixed, instruction-based representation of cue reliability and apply it to the directional evidence profile on each trial. Each discriminating cue contributes reliability-weighted evidence, so independently supporting cues accumulate, while concordant cues are compressed as potentially redundant. This compression increases moderately convexly with coalition size, reflecting the declining informational value of each additional concordant cue. A bounded configuration gate supplements integration: strong protection of a uniquely most-valid cue is restricted to profiles in which that cue is isolated, has a sufficiently large communicated-validity advantage, and faces multiple concordant opponents. Cue uniqueness functions primarily as a tie detector, while a separate raw validity-gap criterion determines whether restoration is warranted. The transition to restoration is sharp, allowing an isolated anchor to be weak against one credible challenger but strongly protected against a redundant multi-cue bloc. Compact challenge amplification is strictly limited to isolated anchors and therefore cannot create general primacy effects when the anchor has allies. When the most-valid discriminating cues have equal communicated validity, they remain exchangeable in the integrator, but stable display order supplies a bounded tie-breaking anchor. Choices are history-invariant because concurrence, anti-concurrence, and discrimination frequency are not learned without correctness feedback. Stable profile heterogeneity arises from subject-level variation in validity sensitivity, coalition integration, redundancy, isolated-anchor challenge and restoration, tie-order bias, temperature, and lapse.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"SCCI expects state with shape (2, n_features); got {stim.shape}."
        )

    n_features = stim.shape[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    if validities.ndim != 1 or validities.shape[0] != n_features:
        raise ValueError(
            f"validities length {validities.shape[0]} != n_features {n_features}."
        )

    # Positive directions favor B and negative directions favor A.
    directions = np.sign(stim[1] - stim[0])
    active = np.flatnonzero(directions != 0)
    if active.size == 0:
        return np.array([0.5, 0.5], dtype=np.float64)

    validity_sensitivity = float(parameters["validity_sensitivity"])
    coalition_accumulation = float(parameters["coalition_accumulation"])
    redundancy_discount = float(parameters["redundancy_discount"])
    redundancy_curvature = float(parameters["redundancy_curvature"])
    profile_balance_gain = float(parameters["profile_balance_gain"])
    anchor_gate_strength = float(parameters["anchor_gate_strength"])
    challenge_strength = float(parameters["challenge_strength"])
    restoration_strength = float(parameters["restoration_strength"])
    restoration_threshold = float(parameters["restoration_threshold"])
    restoration_slope = float(parameters["restoration_slope"])
    restoration_gap_threshold = float(parameters["restoration_gap_threshold"])
    restoration_gap_slope = float(parameters["restoration_gap_slope"])
    tie_order_bias = float(parameters["tie_order_bias"])
    beta = float(parameters["beta"])
    lapse = float(parameters["lapse"])

    # Communicated validity is transformed into reliability evidence. The
    # subtraction only fixes scale and does not alter validity ordering.
    v = np.clip(validities, 0.500001, 0.999999)
    log_odds = np.log(v / (1.0 - v))
    active_reference = float(np.max(log_odds[active]))
    cue_weight = np.exp(
        validity_sensitivity * (log_odds - active_reference)
    )

    a_cues = np.flatnonzero(directions < 0)
    b_cues = np.flatnonzero(directions > 0)
    n_a = int(a_cues.size)
    n_b = int(b_cues.size)

    def coalition_support(indices):
        n = int(indices.size)
        if n == 0:
            return 0.0
        # Accumulation represents multiple nominally independent reasons.
        # A moderately convex denominator captures increasing redundancy
        # among additional cues in the same directional coalition.
        mean_reliability = float(np.mean(cue_weight[indices]))
        accumulated = mean_reliability * (float(n) ** coalition_accumulation)
        redundancy = 1.0 + redundancy_discount * (
            float(n - 1) ** redundancy_curvature
        )
        return accumulated / redundancy

    support_a = coalition_support(a_cues)
    support_b = coalition_support(b_cues)

    # Directional minorities receive only a very small configuration-based
    # salience adjustment. Most coalition effects arise from accumulation,
    # redundancy, and the isolated-anchor mechanism below.
    if n_a > 0 and n_b > 0 and n_a != n_b:
        if n_a < n_b:
            ratio = float(n_b) / float(n_a)
            support_a *= ratio ** profile_balance_gain
        else:
            ratio = float(n_a) / float(n_b)
            support_b *= ratio ** profile_balance_gain

    total_support = support_a + support_b
    core_evidence = (support_b - support_a) / max(total_support, 1e-12)

    # The validity anchor is the most-valid currently discriminating cue.
    # Equal-validity candidates have identical integrative weights; order is
    # consulted only to select a bounded tie anchor.
    active_v = validities[active]
    best_v = float(np.max(active_v))
    best_candidates = active[np.isclose(active_v, best_v, atol=1e-10)]
    anchor_cue = int(np.min(best_candidates))
    anchor_direction = float(directions[anchor_cue])

    # Uniqueness is a tie detector rather than a second graded validity-gap
    # penalty. The separate raw-gap sigmoid below selects strong anchors.
    if active.size > 1:
        sorted_active = np.sort(active_v)[::-1]
        validity_gap = float(sorted_active[0] - sorted_active[1])
    else:
        validity_gap = 0.5
    unique_anchor = float(best_candidates.size == 1)

    if anchor_direction > 0:
        anchor_side_count = n_b
        opposition_count = n_a
        anchor_side_support = support_b
        opposition_support = support_a
    else:
        anchor_side_count = n_a
        opposition_count = n_b
        anchor_side_support = support_a
        opposition_support = support_b

    isolated_anchor = float(anchor_side_count == 1)

    if opposition_count == 0:
        weak_opposition = 1.0
    else:
        relative_opposition = opposition_support / max(
            anchor_side_support + opposition_support, 1e-12
        )
        weak_opposition = np.exp(-4.0 * relative_opposition)

    # A single independent opponent receives extra challenge amplification
    # only when the validity anchor is genuinely isolated. Non-isolated
    # profiles are governed by ordinary static coalition integration.
    if opposition_count > 0:
        compact_challenge = np.exp(
            -4.0 * float(opposition_count - 1) ** 2
        )
        challenge_gain = isolated_anchor * (
            coalition_accumulation + challenge_strength
        )
        challenged_opposition = opposition_support * (
            1.0
            + unique_anchor * challenge_gain * compact_challenge
        )
        anchor_margin = (
            anchor_side_support - challenged_opposition
        ) / max(anchor_side_support + challenged_opposition, 1e-12)
        core_evidence = anchor_direction * anchor_margin

    # Strong restoration is specific to an isolated and clearly superior
    # anchor facing multiple concordant opponents. Count and raw validity-gap
    # thresholds vary across subjects, with a sharp gap transition separating
    # modest-gap profiles from genuinely strong-anchor configurations.
    opposition_restoration = 1.0 / (
        1.0 + np.exp(
            -restoration_slope
            * (float(opposition_count) - restoration_threshold)
        )
    )
    gap_restoration = 1.0 / (
        1.0 + np.exp(
            -restoration_gap_slope
            * (validity_gap - restoration_gap_threshold)
        )
    )
    unique_gate_profile = (
        0.01 * weak_opposition
        + isolated_anchor
        * restoration_strength
        * opposition_restoration
        * gap_restoration
    )
    unique_gate = anchor_gate_strength * unique_anchor * float(
        np.clip(unique_gate_profile, 0.0, 1.0)
    )

    # Stable order matters only when multiple currently discriminating cues
    # share the maximum communicated validity.
    tied_active_top = float(best_candidates.size > 1)
    tie_gate = tie_order_bias * tied_active_top

    gate = 1.0 - (1.0 - unique_gate) * (1.0 - tie_gate)
    gate = float(np.clip(gate, 0.0, 0.95))

    choice_evidence = (
        (1.0 - gate) * core_evidence
        + gate * anchor_direction
    )

    logits = beta * np.array(
        [-0.5 * choice_evidence, 0.5 * choice_evidence], dtype=np.float64
    )
    logits = logits - np.max(logits)
    probs = np.exp(logits)
    probs /= probs.sum()

    probs = (1.0 - lapse) * probs + lapse * np.array([0.5, 0.5])
    probs = np.clip(probs, 0.0, None)
    probs /= probs.sum()
    return probs.astype(np.float64)


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
- validity_sensitivity: [0.03, 0.35]
- coalition_accumulation: [0.98, 1.16]
- redundancy_discount: [0.30, 0.42]
- redundancy_curvature: [1.15, 1.45]
- profile_balance_gain: [0.0, 0.0]
- anchor_gate_strength: [0.90, 0.995]
- challenge_strength: [0.8, 2.8]
- restoration_strength: [0.95, 1.0]
- restoration_threshold: [1.15, 1.55]
- restoration_slope: [16.0, 30.0]
- restoration_gap_threshold: [0.055, 0.075]
- restoration_gap_slope: [160.0, 240.0]
- tie_order_bias: [0.58, 0.85]
- beta: [0.9, 3.4]
- lapse: [0.0, 0.12]

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=1.0000 (var=0.0000) vs this=0.9600 (var=0.0284)
- Experiment 2: real=0.3242 (var=0.0174) vs this=0.4562 (var=0.0022)
- Experiment 3: real=0.0721 (var=0.0052) vs this=-0.0462 (var=0.0019)
- Experiment 4: real=0.0000 (var=0.0000) vs this=0.2400 (var=0.1824)
- Experiment 5: real=0.7900 (var=0.0184) vs this=0.7727 (var=0.0071)
- Experiment 6: real=-0.5450 (var=0.0462) vs this=-0.1356 (var=0.0077)
- Experiment 7: real=0.0052 (var=0.0075) vs this=0.0092 (var=0.0215)
- Experiment 8: real=0.0070 (var=0.0002) vs this=0.0018 (var=0.0001)
- Experiment 9: real=0.7250 (var=0.0723) vs this=0.8094 (var=0.0121)
- Experiment 10: real=0.4462 (var=0.0224) vs this=0.7306 (var=0.0084)
- Experiment 11: real=0.1093 (var=0.0652) vs this=-0.0085 (var=0.0107)
- Experiment 12: real=0.3533 (var=0.0427) vs this=0.2700 (var=0.0168)
- Experiment 13: real=0.3275 (var=0.0184) vs this=0.5269 (var=0.0032)
- Experiment 14: real=0.0200 (var=0.1946) vs this=-0.0300 (var=0.2041)
- Experiment 15: real=0.8475 (var=0.0129) vs this=0.4733 (var=0.0064)
- Experiment 16: real=0.0263 (var=0.0299) vs this=-0.0259 (var=0.0278)
- Experiment 17: real=0.5600 (var=0.0288) vs this=-0.0106 (var=0.0189)
- Experiment 18: real=0.0092 (var=0.0117) vs this=0.0146 (var=0.0103)


---

### `pi_9` (overall score: 0.565)

**Description**
Static Configural Coalition Competition (S3C) proposes that decisions are reconstructed from the current cue display without learning from trial history. Each discriminating expert retains an identity-specific weight derived from communicated validity, but validity evidence is bounded to prevent a uniquely most-valid cue from becoming arbitrarily dominant. Serial accessibility is a distinct regime that is exactly absent under a clear unique maximum and operates only among genuinely tied or extremely near-tied active cues. Option-specific evidence accumulates with smooth within-coalition redundancy. Compact one- and two-cue opposition receives a display-based diagnosticity bonus, while the credibility of a coalition is computed through a bounded aggregation of its members' validity gaps so that moving one cue cannot induce a quasi-discrete change in competition. The effects of credibility and anchor isolation are likewise softly bounded. At larger opposition multiplicities, compact diagnosticity decays and a saturating restoration process can return choice toward a strong isolated anchor. This restoration receives a smooth pre-sigmoid increment when an effectively isolated anchor faces more than two opponents, while embedded anchors remain protected from that increment. Exact balance versus one-step imbalance can modulate response precision without changing evidence direction, allowing activation of an additional cue to sharpen an already configured coalition preference. Stable subject differences jointly vary validity compression, tied-cue accessibility, compact-dissent sensitivity, restoration, balance sensitivity, and response precision. In the absence of outcome feedback, no aspect of the model updates from trial history.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"S3C expects state with shape (2, n_features); got {stim.shape}."
        )

    n_features = stim.shape[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} != n_features {n_features}."
        )

    # S3C is deliberately history-invariant in this feedback-free task.
    _ = history

    directions = np.sign(stim[1] - stim[0])
    active = np.flatnonzero(directions != 0)
    if active.size == 0:
        return np.array([0.5, 0.5], dtype=np.float64)

    validity_sensitivity = float(parameters["validity_sensitivity"])
    validity_floor = float(parameters["validity_floor"])
    order_accessibility = float(parameters["order_accessibility"])
    accessibility_scale = float(parameters["accessibility_scale"])
    order_span = float(parameters["order_span"])
    balance_accessibility = float(parameters["balance_accessibility"])
    balance_scale = float(parameters["balance_scale"])
    redundancy_strength = float(parameters["redundancy_strength"])
    redundancy_curvature = float(parameters["redundancy_curvature"])
    similarity_sensitivity = float(parameters["similarity_sensitivity"])
    compact_dissent = float(parameters["compact_dissent"])
    compact_peak = float(parameters["compact_peak"])
    compact_width = float(parameters["compact_width"])
    compactness_gain = float(parameters["compactness_gain"])
    credibility_scale = float(parameters["credibility_scale"])
    isolation_gain = float(parameters["isolation_gain"])
    restoration_strength = float(parameters["restoration_strength"])
    restoration_threshold = float(parameters["restoration_threshold"])
    restoration_slope = float(parameters["restoration_slope"])
    balance_restoration = float(parameters["balance_restoration"])
    restoration_credibility = float(parameters["restoration_credibility"])
    isolation_restoration = float(parameters["isolation_restoration"])
    anchor_threshold = float(parameters["anchor_threshold"])
    anchor_slope = float(parameters["anchor_slope"])
    balance_precision_gain = float(parameters["balance_precision_gain"])
    balance_precision_width = float(parameters["balance_precision_width"])
    beta = float(parameters["beta"])
    lapse = float(parameters["lapse"])
    configuration_type = int(parameters["configuration_type"])

    # Correlated stable types alter several mechanisms together rather than
    # independently injecting trial-wise variability.
    if configuration_type == 0:       # coalition-sensitive integrator
        validity_floor = min(0.90, validity_floor + 0.12)
        order_accessibility *= 0.75
        restoration_strength *= 0.65
    elif configuration_type == 1:     # tied-order-sensitive integrator
        validity_floor = min(0.90, validity_floor + 0.00)
        order_accessibility *= 1.35
        restoration_strength *= 0.85
    else:                              # intermediate configural integrator
        validity_floor = min(0.90, validity_floor + 0.05)
        order_accessibility *= 0.90
        restoration_strength *= 1.00

    def sigmoid(x):
        return 1.0 / (1.0 + np.exp(-float(np.clip(x, -60.0, 60.0))))

    v = np.clip(validities, 0.500001, 0.999999)
    reliability = np.log(v / (1.0 - v))
    best_active_reliability = float(np.max(reliability[active]))

    active_v = validities[active]
    best_v = float(np.max(active_v))
    # Only genuine or extremely close top ties enter the order regime.
    best_candidates = active[np.isclose(active_v, best_v, atol=0.005)]
    tied_order_regime = bool(best_candidates.size > 1)

    # Identity-specific instruction weights with a bounded strongest-to-weakest
    # ratio. Validity ordering is preserved, but a single anchor cannot become
    # arbitrarily dominant under the exponential reliability transform.
    unbounded_weight = np.exp(
        validity_sensitivity * (reliability - best_active_reliability)
    )
    instruction_weight = (
        validity_floor + (1.0 - validity_floor) * unbounded_weight
    )

    a_cues = np.flatnonzero(directions < 0)
    b_cues = np.flatnonzero(directions > 0)
    n_a = int(a_cues.size)
    n_b = int(b_cues.size)
    count_imbalance = abs(n_b - n_a)

    # Serial accessibility is exactly absent under a clear unique maximum.
    # This cleanly separates validity-based choice from tied-order choice.
    near_balance = np.exp(
        -float(count_imbalance) / max(balance_scale, 1e-8)
    )
    access = np.ones(n_features, dtype=float)
    if tied_order_regime:
        for serial_rank, cue in enumerate(active):
            validity_closeness = np.exp(
                -(best_active_reliability - reliability[cue])
                / max(accessibility_scale, 1e-8)
            )
            serial_salience = np.exp(
                -float(serial_rank) / max(order_span, 1e-8)
            )
            activation_gate = (
                (1.0 - balance_accessibility)
                + balance_accessibility * near_balance
            )
            access[cue] += (
                order_accessibility
                * validity_closeness
                * serial_salience
                * activation_gate
            )

    accessible_weight = instruction_weight * access

    def coalition_support(indices):
        n = int(indices.size)
        if n == 0:
            return 0.0

        weights = np.asarray(accessible_weight[indices], dtype=float)
        raw = float(np.sum(weights))
        dominant = max(float(np.max(weights)), 1e-12)
        effective_multiplicity = raw / dominant
        excess = max(effective_multiplicity - 1.0, 0.0)

        coalition_validities = validities[indices]
        spread = (
            float(np.std(coalition_validities)) if n > 1 else 0.0
        )
        similarity = np.exp(-similarity_sensitivity * spread)
        redundancy = 1.0 + redundancy_strength * similarity * (
            excess ** redundancy_curvature
        )
        return raw / max(redundancy, 1e-12)

    support_a = coalition_support(a_cues)
    support_b = coalition_support(b_cues)

    # A communicated-validity tie is resolved by bounded current accessibility,
    # not by an unconditional first-cue rule.
    candidate_access = accessible_weight[best_candidates]
    anchor_cue = int(best_candidates[int(np.argmax(candidate_access))])
    anchor_direction = float(directions[anchor_cue])

    if anchor_direction > 0:
        anchor_indices = b_cues
        opponent_indices = a_cues
        anchor_support = support_b
        opponent_support = support_a
    else:
        anchor_indices = a_cues
        opponent_indices = b_cues
        anchor_support = support_a
        opponent_support = support_b

    anchor_count = int(anchor_indices.size)
    opponent_count = int(opponent_indices.size)

    def effective_multiplicity(indices):
        if indices.size == 0:
            return 0.0
        weights = np.asarray(accessible_weight[indices], dtype=float)
        return float(np.sum(weights)) / max(float(np.max(weights)), 1e-12)

    anchor_effective_n = effective_multiplicity(anchor_indices)
    opponent_effective_n = effective_multiplicity(opponent_indices)

    if opponent_count > 0:
        opponent_v = validities[opponent_indices]

        # Each member's validity gap is smoothly bounded before aggregation.
        # Consequently, adding or moving one relatively strong cue cannot
        # multiply coalition credibility by an arbitrarily large amount.
        raw_validity_gaps = np.maximum(best_v - opponent_v, 0.0)
        bounded_gap = float(np.mean(np.tanh(
            raw_validity_gaps / max(credibility_scale, 1e-8)
        )))
        opponent_credibility_gate = np.exp(-bounded_gap)

        # Absolute serial position can affect compactness only inside the tied
        # order regime. It is exactly disabled for clear unique maxima.
        serial_span = int(np.max(opponent_indices) - np.min(opponent_indices) + 1)
        compactness = float(opponent_count) / float(max(serial_span, 1))
        effective_compactness_gain = (
            compactness_gain if tied_order_regime else 0.0
        )

        count_distance = (
            opponent_effective_n - compact_peak
        ) / max(compact_width, 1e-8)
        compact_count_profile = np.exp(-0.5 * count_distance ** 2)

        # Isolation remains strongest for a lone anchor, but its contribution
        # is bounded rather than multiplying challenge without limit.
        isolation = 1.0 / float(max(anchor_count, 1))
        raw_isolation_bonus = isolation_gain * isolation
        bounded_isolation_bonus = raw_isolation_bonus / (
            1.0 + raw_isolation_bonus
        )
        challenge_multiplier = 1.0 + (
            compact_dissent
            * compact_count_profile
            * opponent_credibility_gate
            * (1.0 + effective_compactness_gain * compactness)
            * (1.0 + bounded_isolation_bonus)
        )
        opponent_support *= challenge_multiplier

    total = anchor_support + opponent_support
    if total <= 1e-12:
        core_evidence = 0.0
    else:
        anchor_margin = (anchor_support - opponent_support) / total
        core_evidence = anchor_direction * anchor_margin

    if anchor_count > 0:
        anchor_identity_share = float(accessible_weight[anchor_cue]) / max(
            float(np.sum(accessible_weight[anchor_indices])), 1e-12
        )
    else:
        anchor_identity_share = 0.0

    # The isolated-anchor increment now enters the pre-sigmoid restoration
    # scale. It turns on smoothly above two effective opponents and saturates,
    # while the cubed identity share protects embedded anchors.
    isolated_transition = sigmoid(
        restoration_slope * (opponent_effective_n - 2.35)
    )
    restoration_latent = (
        restoration_slope
        * (opponent_effective_n - restoration_threshold)
        + 4.0
        * isolation_restoration
        * (np.clip(anchor_identity_share, 0.0, 1.0) ** 3)
        * isolated_transition
    )
    high_count_gate = sigmoid(restoration_latent)
    balance_crossing = sigmoid(
        restoration_slope
        * ((opponent_effective_n - anchor_effective_n) - 0.5)
    )
    count_gate = max(
        high_count_gate,
        balance_restoration * balance_crossing
    )

    absolute_anchor_gate = sigmoid(
        anchor_slope * (best_v - anchor_threshold)
    )
    credibility_gate = (
        restoration_credibility
        + (1.0 - restoration_credibility) * absolute_anchor_gate
    )

    # Embedded anchors can be restored, but isolated anchors express the
    # effect most strongly.
    embedding_factor = 0.35 + 0.65 * np.sqrt(
        np.clip(anchor_identity_share, 0.0, 1.0)
    )
    restoration_gate = (
        restoration_strength
        * count_gate
        * credibility_gate
        * embedding_factor
    )
    restoration_gate = float(np.clip(restoration_gate, 0.0, 0.97))

    choice_evidence = (
        (1.0 - restoration_gate) * core_evidence
        + restoration_gate * anchor_direction
    )

    # Moving one member away from exact balance can sharpen an already formed
    # directional preference. This display-only modulation changes precision,
    # not evidence direction, and is disabled in the tied-order regime.
    if tied_order_regime:
        effective_beta = beta
    else:
        width = max(balance_precision_width, 1e-8)
        one_step_profile = np.exp(
            -0.5 * ((float(count_imbalance) - 1.0) / width) ** 2
        )
        balanced_profile = np.exp(
            -0.5 * (float(count_imbalance) / width) ** 2
        )
        precision_shift = balance_precision_gain * (
            one_step_profile - balanced_profile
        )
        effective_beta = beta * np.exp(
            float(np.clip(precision_shift, -1.8, 1.8))
        )

    logits = effective_beta * np.array(
        [-0.5 * choice_evidence, 0.5 * choice_evidence],
        dtype=np.float64,
    )
    logits = logits - np.max(logits)
    probs = np.exp(logits)
    probs /= probs.sum()

    probs = (1.0 - lapse) * probs + lapse * np.array(
        [0.5, 0.5], dtype=np.float64
    )
    probs = np.clip(probs, 0.0, None)
    normalizer = float(probs.sum())
    if not np.isfinite(normalizer) or normalizer <= 0.0:
        return np.array([0.5, 0.5], dtype=np.float64)
    probs /= normalizer
    return probs.astype(np.float64)


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
- validity_sensitivity: [0.08, 0.70]
- validity_floor: [0.58, 0.76]
- order_accessibility: [1.20, 3.80]
- accessibility_scale: [0.10, 0.75]
- order_span: [0.55, 2.50]
- balance_accessibility: [0.55, 1.0]
- balance_scale: [0.45, 1.80]
- redundancy_strength: [0.35, 1.40]
- redundancy_curvature: [1.05, 2.20]
- similarity_sensitivity: [2.0, 16.0]
- compact_dissent: [1.5, 6.5]
- compact_peak: [1.10, 1.60]
- compact_width: [0.45, 0.90]
- compactness_gain: [0.20, 1.50]
- credibility_scale: [0.025, 0.16]
- isolation_gain: [0.25, 1.50]
- restoration_strength: [0.65, 0.97]
- restoration_threshold: [2.25, 3.60]
- restoration_slope: [3.5, 11.0]
- balance_restoration: [0.45, 1.0]
- restoration_credibility: [0.30, 0.70]
- isolation_restoration: [0.15, 0.55]
- anchor_threshold: [0.66, 0.82]
- anchor_slope: [10.0, 35.0]
- balance_precision_gain: [0.75, 1.60]
- balance_precision_width: [0.45, 0.75]
- beta: [1.3, 5.0]
- lapse: [0.0, 0.13]
- configuration_type: {0, 1, 2}

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=1.0000 (var=0.0000) vs this=1.0000 (var=0.0000)
- Experiment 2: real=0.3242 (var=0.0174) vs this=0.4777 (var=0.0037)
- Experiment 3: real=0.0721 (var=0.0052) vs this=0.0273 (var=0.0071)
- Experiment 4: real=0.0000 (var=0.0000) vs this=0.3800 (var=0.2356)
- Experiment 5: real=0.7900 (var=0.0184) vs this=0.6785 (var=0.0080)
- Experiment 6: real=-0.5450 (var=0.0462) vs this=-0.3984 (var=0.0281)
- Experiment 7: real=0.0052 (var=0.0075) vs this=0.1459 (var=0.0178)
- Experiment 8: real=0.0070 (var=0.0002) vs this=0.0115 (var=0.0002)
- Experiment 9: real=0.7250 (var=0.0723) vs this=0.7538 (var=0.0365)
- Experiment 10: real=0.4462 (var=0.0224) vs this=0.5681 (var=0.0203)
- Experiment 11: real=0.1093 (var=0.0652) vs this=0.0435 (var=0.0122)
- Experiment 12: real=0.3533 (var=0.0427) vs this=0.1708 (var=0.0122)
- Experiment 13: real=0.3275 (var=0.0184) vs this=0.4288 (var=0.0042)
- Experiment 14: real=0.0200 (var=0.1946) vs this=0.0900 (var=0.2244)
- Experiment 15: real=0.8475 (var=0.0129) vs this=0.8521 (var=0.0068)
- Experiment 16: real=0.0263 (var=0.0299) vs this=0.0106 (var=0.0320)
- Experiment 17: real=0.5600 (var=0.0288) vs this=0.4031 (var=0.0261)
- Experiment 18: real=0.0092 (var=0.0117) vs this=-0.0196 (var=0.0100)


## LOSS TRAJECTORY (this propose-loop)
Aggregate loss across iterations of THIS propose-loop (lower = better, 0 = perfect, `+inf` = unscorable). The ACCEPTED / REJECTED tag is the loop's programmatic accept-gate decision — only ACCEPTED candidates have ever been used as the base for a subsequent iteration. Use this together with PRIOR FEEDBACK ITERATIONS below to grade which past critic advice actually paid off.

- iter 1: loss=0.2039 -> ACCEPTED
- iter 2: loss=0.2224 -> REJECTED
- iter 3: loss=0.1853 -> ACCEPTED
- iter 4: loss=0.1960 -> REJECTED
- iter 5: loss=0.2322 -> REJECTED
Running-best (last ACCEPTED) base: iter 3 at loss=0.1853 — this is the source shown verbatim below under `## PREVIOUS CANDIDATE (this loop)`. Push the next edit's loss strictly below that floor or the gate will reject it.

## EXPERIMENTAL RESULTS
### Experiment 1
**Design**
  A=[1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1]
  A=[0, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1]  B=[0, 1, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1, 1, 1]  B=[0, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 1, 1, 1, 1]  B=[0, 1, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Prevalence of subjects choosing the first-discriminating-cue winner above chance."""
    if data is None or len(data) == 0:
        return float("nan")

    def subject_score(subj):
        agreements = []
        for _, row in subj.iterrows():
            a = np.asarray(row["option_a_ratings"], dtype=float)
            b = np.asarray(row["option_b_ratings"], dtype=float)
            diff = a - b
            discriminating = np.flatnonzero(diff != 0)
            if discriminating.size == 0:
                continue
            first = int(discriminating[0])
            ttb_response = 0 if diff[first] > 0 else 1
            agreements.append(float(int(row["response"]) == ttb_response))

        if len(agreements) == 0:
            return float("nan")
        rate = float(np.mean(agreements))
        if rate > 0.5:
            return 1.0
        if rate < 0.5:
            return 0.0
        return 0.5

    scores = []
    for _, subj in data.groupby("subject_id", sort=False):
        score = subject_score(subj)
        if np.isfinite(score):
            scores.append(score)

    return float(np.mean(scores)) if len(scores) else float("nan")
```

**Observed (real) value:** 1.0000 (var=0.0000)
**Previous candidate values (this loop):**
  - iter 1: 1.0000 (var=0.0000) (Δ vs real +0.0000)
  - iter 2: 1.0000 (var=0.0000) (Δ vs real +0.0000)
  - iter 3: 1.0000 (var=0.0000) (Δ vs real +0.0000)
  - iter 4: 0.9600 (var=0.0384) (Δ vs real -0.0400)
  - iter 5 (most recent): 1.0000 (var=0.0000) (Δ vs real +0.0000)
**Other theories' values on this metric (for reference):**
- pi_1: 0.9900 (var=0.0049)
- pi_2: 0.0000 (var=0.0000)
- pi_3: 1.0000 (var=0.0000)
- pi_4: 1.0000 (var=0.0000)
- pi_5: 1.0000 (var=0.0000)
- pi_6: 0.9600 (var=0.0284)
- pi_7: 0.9400 (var=0.0464)
- pi_8: 0.9300 (var=0.0601)
- pi_9: 1.0000 (var=0.0000)
- pi_10: 1.0000 (var=0.0000)

### Experiment 2
**Design**
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 1, 1]  B=[1, 0, 0, 0, 0, 1, 0, 0]
  A=[1, 0, 1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 1, 0, 1]
  A=[0, 1, 0, 1, 0, 1, 0, 1]  B=[1, 0, 1, 0, 1, 0, 1, 0]
  A=[1, 0, 1, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 0, 0, 1]  B=[1, 0, 1, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 0, 1, 0]  B=[1, 0, 0, 1, 0, 1, 0, 1]
  A=[1, 0, 0, 1, 0, 1, 0, 1]  B=[1, 0, 1, 0, 1, 0, 1, 0]
  A=[1, 0, 1, 0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0, 1, 0, 1]
  A=[1, 0, 1, 0, 0, 1, 0, 1]  B=[1, 0, 1, 0, 1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Proportion of choices consistent with the highest-validity discriminating cue."""
    if len(data) == 0:
        return float("nan")

    aligned = []
    for a_cell, b_cell, response in zip(
        data["option_a_ratings"],
        data["option_b_ratings"],
        data["response"],
    ):
        a = np.asarray(a_cell, dtype=float)
        b = np.asarray(b_cell, dtype=float)
        favored = None

        # Features are already ordered from highest to lowest validity.
        for j in range(min(len(a), len(b))):
            if a[j] > b[j]:
                favored = 0
                break
            if b[j] > a[j]:
                favored = 1
                break

        # Omit completely nondiscriminating pairs, although none occur in
        # the specified design.
        if favored is not None:
            aligned.append(float(int(response) == favored))

    if not aligned:
        return float("nan")
    return float(np.mean(aligned))
```

**Observed (real) value:** 0.3242 (var=0.0174)
**Previous candidate values (this loop):**
  - iter 1: 0.5010 (var=0.0142) (Δ vs real +0.1769)
  - iter 2: 0.6246 (var=0.0076) (Δ vs real +0.3004)
  - iter 3: 0.5298 (var=0.0072) (Δ vs real +0.2056)
  - iter 4: 0.5004 (var=0.0118) (Δ vs real +0.1762)
  - iter 5 (most recent): 0.6058 (var=0.0092) (Δ vs real +0.2817)
**Other theories' values on this metric (for reference):**
- pi_2: 0.4848 (var=0.0022)
- pi_1: 0.8492 (var=0.0121)
- pi_3: 0.3298 (var=0.0054)
- pi_4: 0.9925 (var=0.0001)
- pi_5: 0.3463 (var=0.0061)
- pi_6: 0.4562 (var=0.0022)
- pi_7: 0.5233 (var=0.0053)
- pi_8: 0.4275 (var=0.0045)
- pi_9: 0.4777 (var=0.0037)
- pi_10: 0.5487 (var=0.0373)

### Experiment 3
**Design**
  A=[0, 1, 0, 0, 1, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 1, 0]
  A=[1, 1, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 1, 0, 0, 1, 0]
  A=[0, 0, 1, 0, 1, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 0, 1, 0, 1, 0]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 1, 0, 1, 0]
  A=[0, 0, 0, 1, 1, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 1, 0]
  A=[1, 0, 0, 1, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Balanced-minus-imbalanced change in choosing Expert 5's winner."""
    if data is None or len(data) == 0:
        return float("nan")

    interaction_scores = []
    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=float)
        b = np.asarray(row["option_b_ratings"], dtype=float)
        if a.size < 5 or b.size != a.size:
            continue

        diff = b - a
        signs = np.sign(diff)
        n_b = int(np.sum(signs > 0))
        n_a = int(np.sum(signs < 0))
        imbalance = abs(n_b - n_a)

        # The design's critical conditions are exact 2-vs-2 balance and
        # 3-vs-1 imbalance. Ignore any unexpected rows.
        if imbalance == 0:
            condition_sign = 1.0
        elif imbalance == 2:
            condition_sign = -1.0
        else:
            continue

        # Expert 5 is feature index 4 and always identifies the TTB winner.
        if diff[4] > 0:
            expert5_winner = 1
        elif diff[4] < 0:
            expert5_winner = 0
        else:
            continue

        chose_expert5_winner = float(int(row["response"]) == expert5_winner)
        # Averaging this score gives P(E5 winner | balanced) minus
        # P(E5 winner | imbalanced), since the schedule is balanced.
        interaction_scores.append(condition_sign * chose_expert5_winner)

    if len(interaction_scores) == 0:
        return float("nan")
    return float(np.mean(interaction_scores))
```

**Observed (real) value:** 0.0721 (var=0.0052)
**Previous candidate values (this loop):**
  - iter 1: -0.0942 (var=0.0034) (Δ vs real -0.1663)
  - iter 2: -0.0471 (var=0.0032) (Δ vs real -0.1192)
  - iter 3: -0.0535 (var=0.0023) (Δ vs real -0.1256)
  - iter 4: -0.0869 (var=0.0021) (Δ vs real -0.1590)
  - iter 5 (most recent): -0.0623 (var=0.0018) (Δ vs real -0.1344)
**Other theories' values on this metric (for reference):**
- pi_1: -0.0008 (var=0.0015)
- pi_3: -0.3629 (var=0.0033)
- pi_2: -0.1762 (var=0.0033)
- pi_4: 0.0050 (var=0.0001)
- pi_5: 0.1125 (var=0.0053)
- pi_6: -0.0462 (var=0.0019)
- pi_7: 0.0358 (var=0.0025)
- pi_8: -0.0956 (var=0.0027)
- pi_9: 0.0273 (var=0.0071)
- pi_10: 0.0312 (var=0.0143)

### Experiment 4
**Design**
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[0, 0, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 1, 1, 1]
  A=[0, 1, 0, 1, 1, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 1, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 1, 1]  B=[1, 0, 0, 1, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 1, 1, 1]
  A=[1, 0, 0, 1, 1, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 0]  B=[1, 0, 1, 0, 1, 1]
  A=[1, 0, 1, 0, 1, 1]  B=[0, 1, 0, 1, 0, 0]
  A=[0, 0, 1, 1, 0, 0]  B=[1, 1, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 1, 1]  B=[0, 0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    def subject_score(df):
        if len(df) == 0:
            return np.nan

        a = np.stack(df["option_a_ratings"].apply(lambda x: np.asarray(x, dtype=float)).to_numpy())
        b = np.stack(df["option_b_ratings"].apply(lambda x: np.asarray(x, dtype=float)).to_numpy())
        response = df["response"].to_numpy(dtype=int)

        # Expert 5 is uniquely most valid, so its favored option is the
        # Take-The-Best winner in this design.
        ttb_winner = (b[:, 4] > a[:, 4]).astype(int)
        chose_ttb_winner = (response == ttb_winner).astype(float)

        # Whether Expert 1 favors the same option as Expert 5.
        expert1_winner = (b[:, 0] > a[:, 0]).astype(int)
        expert1_supports = expert1_winner == ttb_winner

        if not np.any(expert1_supports) or not np.any(~expert1_supports):
            return np.nan

        crossover = (chose_ttb_winner[expert1_supports].mean() -
                     chose_ttb_winner[~expert1_supports].mean())

        # Classify a subject as showing a substantively sized primacy
        # crossover. The 0.12 margin suppresses chance sampling contrasts
        # around TTB's population prediction of exactly zero.
        return float(crossover > 0.12)

    if "subject_id" in data.columns and data["subject_id"].nunique() > 1:
        scores = [subject_score(g) for _, g in data.groupby("subject_id", sort=False)]
        scores = np.asarray(scores, dtype=float)
        scores = scores[np.isfinite(scores)]
        return float(scores.mean()) if scores.size else np.nan

    return subject_score(data)

```

**Observed (real) value:** 0.0000 (var=0.0000)
**Previous candidate values (this loop):**
  - iter 1: 0.6000 (var=0.2400) (Δ vs real +0.6000)
  - iter 2: 0.7400 (var=0.1924) (Δ vs real +0.7400)
  - iter 3: 0.4400 (var=0.2464) (Δ vs real +0.4400)
  - iter 4: 0.6200 (var=0.2356) (Δ vs real +0.6200)
  - iter 5 (most recent): 0.5800 (var=0.2436) (Δ vs real +0.5800)
**Other theories' values on this metric (for reference):**
- pi_3: 1.0000 (var=0.0000)
- pi_1: 0.0400 (var=0.0384)
- pi_2: 0.0600 (var=0.0564)
- pi_4: 0.0000 (var=0.0000)
- pi_5: 0.0000 (var=0.0000)
- pi_6: 0.2400 (var=0.1824)
- pi_7: 0.2200 (var=0.1716)
- pi_8: 0.2200 (var=0.1716)
- pi_9: 0.3800 (var=0.2356)
- pi_10: 0.0000 (var=0.0000)

### Experiment 5
**Design**
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 1, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 1, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Proportion of choices that follow the stable-order winner among the tied top cues."""
    if len(data) == 0:
        return float("nan")

    follows_top = []
    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=float)
        b = np.asarray(row["option_b_ratings"], dtype=float)

        # Feature 0 is consulted first under the communicated validity order.
        if a[0] > b[0]:
            top_choice = 0
        elif b[0] > a[0]:
            top_choice = 1
        else:
            continue

        follows_top.append(float(int(row["response"]) == top_choice))

    if len(follows_top) == 0:
        return float("nan")
    return float(np.mean(follows_top))
```

**Observed (real) value:** 0.7900 (var=0.0184)
**Previous candidate values (this loop):**
  - iter 1: 0.6950 (var=0.0052) (Δ vs real -0.0950)
  - iter 2: 0.7148 (var=0.0050) (Δ vs real -0.0752)
  - iter 3: 0.7617 (var=0.0057) (Δ vs real -0.0283)
  - iter 4: 0.7650 (var=0.0058) (Δ vs real -0.0250)
  - iter 5 (most recent): 0.8037 (var=0.0060) (Δ vs real +0.0137)
**Other theories' values on this metric (for reference):**
- pi_1: 0.8244 (var=0.0081)
- pi_4: 0.0179 (var=0.0002)
- pi_2: 0.1456 (var=0.0074)
- pi_3: 0.6381 (var=0.0031)
- pi_5: 0.8223 (var=0.0088)
- pi_6: 0.7727 (var=0.0071)
- pi_7: 0.8063 (var=0.0071)
- pi_8: 0.7033 (var=0.0264)
- pi_9: 0.6785 (var=0.0080)
- pi_10: 0.7412 (var=0.0190)

### Experiment 6
**Design**
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1, 0, 0]
  A=[0, 1, 1, 1, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Difference in adherence to the highest-validity cue between
    # one-opponent and multi-opponent coalitions.
    lone_top_choices = []
    multi_top_choices = []

    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=float)
        b = np.asarray(row["option_b_ratings"], dtype=float)

        # Feature 0 is the uniquely highest-validity expert in this design.
        top_direction = np.sign(b[0] - a[0])  # +1 means B is top-cue winner
        if top_direction == 0:
            continue

        lower_directions = np.sign(b[1:] - a[1:])
        n_opponents = int(np.sum(lower_directions * top_direction < 0))
        chose_top_winner = float(
            int(row["response"]) == (1 if top_direction > 0 else 0)
        )

        if n_opponents == 1:
            lone_top_choices.append(chose_top_winner)
        elif n_opponents >= 2:
            multi_top_choices.append(chose_top_winner)

    # The fixed schedule supplies both classes for every subject. These
    # fallbacks keep the function scalar-valued on unexpected partial data.
    if len(lone_top_choices) == 0 or len(multi_top_choices) == 0:
        return 0.0

    return float(np.mean(lone_top_choices) - np.mean(multi_top_choices))
```

**Observed (real) value:** -0.5450 (var=0.0462)
**Previous candidate values (this loop):**
  - iter 1: -0.2462 (var=0.0120) (Δ vs real +0.2988)
  - iter 2: -0.0881 (var=0.0152) (Δ vs real +0.4569)
  - iter 3: -0.2344 (var=0.0150) (Δ vs real +0.3106)
  - iter 4: -0.1713 (var=0.0164) (Δ vs real +0.3738)
  - iter 5 (most recent): -0.1734 (var=0.0128) (Δ vs real +0.3716)
**Other theories' values on this metric (for reference):**
- pi_4: 0.5559 (var=0.0104)
- pi_1: 0.0103 (var=0.0049)
- pi_2: 0.3781 (var=0.0114)
- pi_3: -0.3150 (var=0.0123)
- pi_5: -0.5416 (var=0.0261)
- pi_6: -0.1356 (var=0.0077)
- pi_7: -0.3969 (var=0.0200)
- pi_8: -0.2550 (var=0.0318)
- pi_9: -0.3984 (var=0.0281)
- pi_10: -0.4419 (var=0.0602)

### Experiment 7
**Design**
  A=[0, 0, 0, 0, 1, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 1, 0, 1]  B=[1, 1, 1, 0, 0, 0, 1]
  A=[1, 1, 1, 0, 0, 0, 1]  B=[0, 0, 0, 0, 1, 0, 1]
  A=[0, 0, 0, 0, 1, 1, 0]  B=[1, 1, 1, 0, 0, 1, 0]
  A=[1, 1, 1, 0, 0, 1, 0]  B=[0, 0, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 1, 1]
  A=[1, 1, 1, 0, 0, 1, 1]  B=[0, 0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0, 0]
  A=[0, 1, 0, 1, 0, 0, 1]  B=[1, 0, 1, 1, 0, 0, 1]
  A=[1, 0, 1, 1, 0, 0, 1]  B=[0, 1, 0, 1, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Post-exposure diagnostic minus control adherence to the top-validity cue."""
    if data is None or len(data) == 0:
        return float("nan")

    def subject_score(df):
        diagnostic = {False: [], True: []}
        control = {False: [], True: []}
        occurrence = {}

        for _, row in df.iterrows():
            a = np.asarray(row["option_a_ratings"], dtype=float)
            b = np.asarray(row["option_b_ratings"], dtype=float)
            if a.size < 5 or b.size < 5:
                continue

            direction = np.sign(b - a)
            if direction[0] == 0:
                continue

            anchor_b = bool(direction[0] > 0)
            followed_anchor = float(int(row["response"]) == int(anchor_b))

            # Diagnostic trials have Expert 5 opposing the validity anchor.
            is_diagnostic = direction[4] == -direction[0]
            # Control trials instead have Expert 2 opposing the anchor.
            is_control = direction[4] == 0 and direction[1] == -direction[0]

            if is_diagnostic:
                # Use repetitions 3--8 of each exact ordered stimulus. This
                # removes acquisition trials while preserving equal numbers
                # of A- and B-anchor trials through the reversal pairs.
                key = (tuple(a.tolist()), tuple(b.tolist()))
                prior = occurrence.get(key, 0)
                occurrence[key] = prior + 1
                if prior >= 2:
                    diagnostic[anchor_b].append(followed_anchor)
            elif is_control:
                control[anchor_b].append(followed_anchor)

        if any(len(diagnostic[s]) == 0 or len(control[s]) == 0
               for s in (False, True)):
            return float("nan")

        diag_balanced = 0.5 * (
            float(np.mean(diagnostic[False])) +
            float(np.mean(diagnostic[True]))
        )
        control_balanced = 0.5 * (
            float(np.mean(control[False])) +
            float(np.mean(control[True]))
        )
        return diag_balanced - control_balanced

    if "subject_id" in data.columns:
        scores = []
        for _, subj_df in data.groupby("subject_id", sort=False):
            score = subject_score(subj_df)
            if np.isfinite(score):
                scores.append(score)
        return float(np.mean(scores)) if scores else float("nan")

    return subject_score(data)

```

**Observed (real) value:** 0.0052 (var=0.0075)
**Previous candidate values (this loop):**
  - iter 1: 0.0862 (var=0.0173) (Δ vs real +0.0810)
  - iter 2: 0.0334 (var=0.0085) (Δ vs real +0.0283)
  - iter 3: 0.0265 (var=0.0167) (Δ vs real +0.0213)
  - iter 4: 0.0641 (var=0.0145) (Δ vs real +0.0589)
  - iter 5 (most recent): 0.0541 (var=0.0091) (Δ vs real +0.0489)
**Other theories' values on this metric (for reference):**
- pi_1: -0.0058 (var=0.0071)
- pi_5: -0.1060 (var=0.0121)
- pi_2: -0.0056 (var=0.0083)
- pi_3: 0.0227 (var=0.0111)
- pi_4: 0.0025 (var=0.0020)
- pi_6: 0.0092 (var=0.0215)
- pi_7: -0.0589 (var=0.0212)
- pi_8: 0.0404 (var=0.0151)
- pi_9: 0.1459 (var=0.0178)
- pi_10: -0.0074 (var=0.0135)

### Experiment 8
**Design**
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 0, 1, 0, 1, 0]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 0, 0, 1]
  A=[0, 0, 1, 0, 0, 1]  B=[1, 0, 0, 1, 0, 0]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 0, 1, 0, 0, 1]
  A=[0, 0, 0, 1, 0, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[0, 0, 0, 1, 0, 0]  B=[1, 1, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    def subject_score(df: pd.DataFrame) -> float:
        # Encode every response as adherence to Expert 1, which is the TTB
        # winner on all trials, and group A/B reversals into invariant cue
        # profiles by orienting each profile toward Expert 1's direction.
        groups = {}
        for _, row in df.iterrows():
            a = np.asarray(row["option_a_ratings"], dtype=float)
            b = np.asarray(row["option_b_ratings"], dtype=float)
            d = np.sign(b - a).astype(int)
            if d.size == 0 or d[0] == 0:
                continue

            orientation = int(d[0])
            profile = tuple((d * orientation).tolist())
            ttb_response = 1 if d[0] > 0 else 0
            adherence = float(int(row["response"]) == ttb_response)
            groups.setdefault(profile, []).append(adherence)

        # The intended design supplies six profiles with many observations
        # each. Requiring at least two observations permits an unbiased
        # estimate of each profile mean's sampling variance.
        usable = [np.asarray(v, dtype=float) for v in groups.values() if len(v) >= 2]
        k = len(usable)
        if k < 2:
            return 0.0

        means = np.asarray([np.mean(v) for v in usable], dtype=float)

        # Observed population variance of profile-specific TTB-adherence
        # rates. Under TTB all profiles have the same latent rate, but its
        # finite-sample value is positive because of response noise.
        observed_profile_variance = float(np.var(means, ddof=0))

        # For Bernoulli observations, p_hat*(1-p_hat)/(n-1) is an unbiased
        # estimator of Var(p_hat). Subtract the exact contribution of these
        # estimation errors to the population variance across k profiles.
        mean_sampling_variances = []
        for v, p_hat in zip(usable, means):
            n = len(v)
            mean_sampling_variances.append(
                float(p_hat * (1.0 - p_hat) / float(n - 1))
            )
        noise_bias = (1.0 - 1.0 / float(k)) * float(
            np.mean(mean_sampling_variances)
        )

        return observed_profile_variance - noise_bias

    if len(data) == 0:
        return 0.0
    if "subject_id" in data.columns:
        scores = [
            subject_score(g)
            for _, g in data.groupby("subject_id", sort=False)
        ]
        return float(np.mean(scores)) if scores else 0.0
    return subject_score(data)

```

**Observed (real) value:** 0.0070 (var=0.0002)
**Previous candidate values (this loop):**
  - iter 1: 0.0101 (var=0.0002) (Δ vs real +0.0031)
  - iter 2: 0.0064 (var=0.0001) (Δ vs real -0.0006)
  - iter 3: 0.0031 (var=0.0001) (Δ vs real -0.0039)
  - iter 4: 0.0096 (var=0.0002) (Δ vs real +0.0026)
  - iter 5 (most recent): 0.0031 (var=0.0000) (Δ vs real -0.0039)
**Other theories' values on this metric (for reference):**
- pi_5: 0.0058 (var=0.0001)
- pi_1: 0.0002 (var=0.0000)
- pi_2: 0.0206 (var=0.0003)
- pi_3: 0.0317 (var=0.0005)
- pi_4: 0.0000 (var=0.0000)
- pi_6: 0.0018 (var=0.0001)
- pi_7: 0.0062 (var=0.0001)
- pi_8: 0.0072 (var=0.0002)
- pi_9: 0.0115 (var=0.0002)
- pi_10: -0.0002 (var=0.0000)

### Experiment 9
**Design**
  A=[0, 0, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[1, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 0, 0, 0, 1]
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 0, 1]
  A=[1, 1, 0, 1, 1]  B=[0, 0, 1, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 1]  B=[1, 0, 1, 1, 0]
  A=[0, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0]
  A=[0, 0, 0, 0, 1]  B=[1, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    if data is None or len(data) == 0:
        return 0.5

    def subject_score(subj):
        anchor_choices = []

        for _, row in subj.iterrows():
            a = np.asarray(row["option_a_ratings"], dtype=float)
            b = np.asarray(row["option_b_ratings"], dtype=float)
            if a.size < 5 or b.size < 5:
                continue

            directions = np.sign(b - a)
            active = set(np.flatnonzero(directions != 0).tolist())

            # The two isolated-anchor target classes and their A/B reversals.
            is_outer_target = active == {0, 3, 4}
            is_middle_target = active == {1, 2, 4}
            if not (is_outer_target or is_middle_target):
                continue

            lower = [0, 3] if is_outer_target else [1, 2]
            coalition_is_concordant = directions[lower[0]] == directions[lower[1]]
            coalition_opposes_anchor = directions[lower[0]] == -directions[4]
            if not (coalition_is_concordant and coalition_opposes_anchor):
                continue

            anchor_response = 1 if directions[4] > 0 else 0
            anchor_choices.append(float(int(row["response"]) == anchor_response))

        if len(anchor_choices) == 0:
            return np.nan
        return float(np.mean(anchor_choices))

    if "subject_id" in data.columns:
        scores = [subject_score(subj) for _, subj in data.groupby("subject_id", sort=False)]
        scores = [x for x in scores if np.isfinite(x)]
        return float(np.mean(scores)) if len(scores) > 0 else 0.5

    score = subject_score(data)
    return float(score) if np.isfinite(score) else 0.5

```

**Observed (real) value:** 0.7250 (var=0.0723)
**Previous candidate values (this loop):**
  - iter 1: 0.3625 (var=0.0296) (Δ vs real -0.3625)
  - iter 2: 0.6238 (var=0.0350) (Δ vs real -0.1012)
  - iter 3: 0.4606 (var=0.0360) (Δ vs real -0.2644)
  - iter 4: 0.5038 (var=0.0405) (Δ vs real -0.2212)
  - iter 5 (most recent): 0.4725 (var=0.0462) (Δ vs real -0.2525)
**Other theories' values on this metric (for reference):**
- pi_6: 0.8094 (var=0.0121)
- pi_5: 0.5687 (var=0.0166)
- pi_1: 0.8600 (var=0.0122)
- pi_2: 0.1737 (var=0.0171)
- pi_3: 0.2675 (var=0.0088)
- pi_4: 0.9844 (var=0.0007)
- pi_7: 0.7512 (var=0.0113)
- pi_8: 0.5850 (var=0.0117)
- pi_9: 0.7538 (var=0.0365)
- pi_10: 0.7481 (var=0.1072)

### Experiment 10
**Design**
  A=[0, 0, 1, 0, 1, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[1, 1, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 1]  B=[1, 0, 0, 1, 1, 0]
  A=[0, 1, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 0, 1, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 1]
  A=[1, 1, 0, 1, 1, 1]  B=[0, 0, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[1, 0, 0, 1, 1, 0]  B=[0, 1, 1, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    def subject_score(subj):
        followed = []

        for _, row in subj.iterrows():
            a = np.asarray(row['option_a_ratings'], dtype=int)
            b = np.asarray(row['option_b_ratings'], dtype=int)
            if a.shape[0] != 6 or b.shape[0] != 6:
                continue

            directions = np.sign(b - a)

            # Diagnostic compact opposition: Experts 3 and 5 oppose the
            # unique validity anchor (trial-pair 1 and its reversal).
            compact_diagnostic = (
                np.array_equal(np.abs(directions),
                               np.array([1, 0, 1, 0, 1, 0]))
                and directions[2] == directions[4]
                and directions[0] == -directions[2]
            )

            # Singleton diagnostic dissent: Expert 3 alone opposes all five
            # other discriminating experts (trial-pair 3 and its reversal).
            singleton_diagnostic = (
                np.all(np.abs(directions) == 1)
                and directions[2] == -directions[0]
                and directions[1] == directions[0]
                and directions[3] == directions[0]
                and directions[4] == directions[0]
                and directions[5] == directions[0]
            )

            if not (compact_diagnostic or singleton_diagnostic):
                continue

            anchor_response = 1 if directions[0] > 0 else 0
            followed.append(float(int(row['response']) == anchor_response))

        if len(followed) == 0:
            return np.nan
        return float(np.mean(followed))

    scores = []
    for _, subj in data.groupby('subject_id', sort=False):
        value = subject_score(subj)
        if np.isfinite(value):
            scores.append(value)

    if len(scores) == 0:
        return np.nan
    return float(np.mean(scores))
```

**Observed (real) value:** 0.4462 (var=0.0224)
**Previous candidate values (this loop):**
  - iter 1: 0.5525 (var=0.0151) (Δ vs real +0.1063)
  - iter 2: 0.7669 (var=0.0145) (Δ vs real +0.3206)
  - iter 3: 0.6150 (var=0.0236) (Δ vs real +0.1688)
  - iter 4: 0.5969 (var=0.0211) (Δ vs real +0.1506)
  - iter 5 (most recent): 0.6550 (var=0.0171) (Δ vs real +0.2088)
**Other theories' values on this metric (for reference):**
- pi_5: 0.4656 (var=0.0070)
- pi_6: 0.7306 (var=0.0084)
- pi_1: 0.8250 (var=0.0150)
- pi_2: 0.5275 (var=0.0076)
- pi_3: 0.7612 (var=0.0061)
- pi_4: 0.9844 (var=0.0006)
- pi_7: 0.4644 (var=0.0059)
- pi_8: 0.6150 (var=0.0107)
- pi_9: 0.5681 (var=0.0203)
- pi_10: 0.6106 (var=0.0980)

### Experiment 11
**Design**
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 1]  B=[1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 1]  B=[1, 0, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 1]  B=[1, 1, 0, 1, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 1, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    high_count_anchor_choices = []
    two_opponent_anchor_choices = []

    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=float)
        b = np.asarray(row["option_b_ratings"], dtype=float)
        if a.size < 8 or b.size < 8:
            continue

        directions = np.sign(b - a)
        anchor_direction = int(directions[7])
        if anchor_direction == 0:
            continue

        # Retain isolated-expert-8 profiles and count cues opposing it.
        other_directions = directions[:7]
        if np.any(other_directions == anchor_direction):
            continue
        opponent_count = int(np.sum(other_directions == -anchor_direction))

        anchor_response = 1 if anchor_direction > 0 else 0
        chose_anchor = float(int(row["response"]) == anchor_response)

        if opponent_count == 2:
            two_opponent_anchor_choices.append(chose_anchor)
        elif opponent_count >= 3:
            high_count_anchor_choices.append(chose_anchor)

    if not high_count_anchor_choices or not two_opponent_anchor_choices:
        return float("nan")

    return float(
        np.mean(high_count_anchor_choices)
        - np.mean(two_opponent_anchor_choices)
    )
```

**Observed (real) value:** 0.1093 (var=0.0652)
**Previous candidate values (this loop):**
  - iter 1: 0.0050 (var=0.0082) (Δ vs real -0.1043)
  - iter 2: 0.2033 (var=0.0126) (Δ vs real +0.0940)
  - iter 3: -0.0100 (var=0.0064) (Δ vs real -0.1193)
  - iter 4: -0.0047 (var=0.0084) (Δ vs real -0.1140)
  - iter 5 (most recent): -0.0215 (var=0.0059) (Δ vs real -0.1308)
**Other theories' values on this metric (for reference):**
- pi_7: 0.6688 (var=0.0308)
- pi_5: 0.0092 (var=0.0107)
- pi_1: 0.0137 (var=0.0129)
- pi_2: -0.0240 (var=0.0079)
- pi_3: -0.0033 (var=0.0095)
- pi_4: -0.0368 (var=0.0015)
- pi_6: -0.0085 (var=0.0107)
- pi_8: 0.1107 (var=0.0194)
- pi_9: 0.0435 (var=0.0122)
- pi_10: 0.1185 (var=0.1286)

### Experiment 12
**Design**
  A=[0, 1, 1, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 1, 0, 1, 0]
  A=[0, 1, 1, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 1, 1, 1, 0]
  A=[0, 1, 0, 1, 1, 0, 0, 0]  B=[1, 0, 1, 0, 0, 0, 1, 0]
  A=[0, 1, 0, 1, 1, 0, 0, 0]  B=[1, 0, 1, 0, 0, 1, 1, 0]
  A=[0, 1, 0, 1, 0, 0, 1, 0]  B=[1, 0, 1, 0, 1, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 0, 1, 0]  B=[1, 0, 1, 0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 1, 0, 1, 0]  B=[0, 1, 1, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 1, 1, 1, 0]  B=[0, 1, 1, 1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0, 1, 0]  B=[0, 1, 0, 1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 1, 1, 0]  B=[0, 1, 0, 1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 1, 0, 0, 1, 0]
  A=[1, 0, 1, 0, 1, 1, 0, 0]  B=[0, 1, 0, 1, 0, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Expert-6 activation effect on choosing the Expert-4 anchor option."""
    if len(data) == 0:
        return float("nan")

    anchor_choices = []
    expert6_on = []

    for a_cell, b_cell, response in zip(
        data["option_a_ratings"],
        data["option_b_ratings"],
        data["response"],
    ):
        a = np.asarray(a_cell, dtype=float)
        b = np.asarray(b_cell, dtype=float)

        # Expert 4 (zero-based index 3) defines the designated anchor option.
        if a[3] > b[3]:
            anchor_response = 0
        elif b[3] > a[3]:
            anchor_response = 1
        else:
            continue

        anchor_choices.append(float(int(response) == anchor_response))
        expert6_on.append(bool(a[5] != b[5]))

    anchor_choices = np.asarray(anchor_choices, dtype=float)
    expert6_on = np.asarray(expert6_on, dtype=bool)

    if not np.any(expert6_on) or not np.any(~expert6_on):
        return float("nan")

    return float(
        np.mean(anchor_choices[expert6_on])
        - np.mean(anchor_choices[~expert6_on])
    )
```

**Observed (real) value:** 0.3533 (var=0.0427)
**Previous candidate values (this loop):**
  - iter 1: 0.3025 (var=0.0118) (Δ vs real -0.0508)
  - iter 2: 0.1892 (var=0.0199) (Δ vs real -0.1642)
  - iter 3: 0.3679 (var=0.0134) (Δ vs real +0.0146)
  - iter 4: 0.4208 (var=0.0184) (Δ vs real +0.0675)
  - iter 5 (most recent): 0.2217 (var=0.0116) (Δ vs real -0.1317)
**Other theories' values on this metric (for reference):**
- pi_5: -0.0208 (var=0.0079)
- pi_7: 0.2908 (var=0.0147)
- pi_1: 0.0083 (var=0.0081)
- pi_2: -0.3271 (var=0.0169)
- pi_3: 0.0450 (var=0.0087)
- pi_4: -0.5246 (var=0.0081)
- pi_6: 0.2700 (var=0.0168)
- pi_8: 0.3488 (var=0.0128)
- pi_9: 0.1708 (var=0.0122)
- pi_10: 0.3358 (var=0.1291)

### Experiment 13
**Design**
  A=[0, 0, 1, 0, 0, 1]  B=[1, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 1, 1]  B=[1, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 0, 1, 0, 1, 0]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 0, 1, 0, 0, 1]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 1, 1, 0, 0, 1]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[1, 0, 0, 1, 1, 0]  B=[0, 0, 1, 0, 1, 1]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    anchor_choices = []

    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=float)
        b = np.asarray(row["option_b_ratings"], dtype=float)
        if a.size <= 5 or b.size <= 5:
            continue

        # Expert 6 (index 5) is the unique 95%-validity anchor.
        anchor_direction = np.sign(b[5] - a[5])
        if anchor_direction == 0:
            continue

        response = int(row["response"])
        chose_anchor = (
            (anchor_direction > 0 and response == 1)
            or (anchor_direction < 0 and response == 0)
        )
        anchor_choices.append(float(chose_anchor))

    if len(anchor_choices) == 0:
        return 0.5
    return float(np.mean(anchor_choices))
```

**Observed (real) value:** 0.3275 (var=0.0184)
**Previous candidate values (this loop):**
  - iter 1: 0.4371 (var=0.0124) (Δ vs real +0.1096)
  - iter 2: 0.6206 (var=0.0117) (Δ vs real +0.2931)
  - iter 3: 0.4602 (var=0.0133) (Δ vs real +0.1327)
  - iter 4: 0.4329 (var=0.0143) (Δ vs real +0.1054)
  - iter 5 (most recent): 0.6202 (var=0.0098) (Δ vs real +0.2927)
**Other theories' values on this metric (for reference):**
- pi_8: 0.5044 (var=0.0026)
- pi_5: 0.3144 (var=0.0091)
- pi_1: 0.8431 (var=0.0109)
- pi_2: 0.4846 (var=0.0035)
- pi_3: 0.6629 (var=0.0048)
- pi_4: 0.9952 (var=0.0001)
- pi_6: 0.5269 (var=0.0032)
- pi_7: 0.4956 (var=0.0025)
- pi_9: 0.4288 (var=0.0042)
- pi_10: 0.2969 (var=0.0404)

### Experiment 14
**Design**
  A=[0, 0, 0, 0, 1, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 1, 0, 0, 1, 0]  B=[1, 1, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 0, 1]  B=[0, 1, 0, 0, 1, 0]
  A=[0, 0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0, 1]
  A=[1, 0, 1, 0, 0, 1]  B=[0, 0, 1, 0, 1, 0]
  A=[0, 0, 0, 1, 1, 0]  B=[1, 0, 0, 1, 0, 1]
  A=[1, 0, 0, 1, 0, 1]  B=[0, 0, 0, 1, 1, 0]
  A=[0, 1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 0, 1]
  A=[1, 1, 1, 1, 0, 1]  B=[0, 1, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 1]
  A=[0, 0, 1, 0, 0, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[1, 0, 1, 0, 0, 1]
  A=[1, 0, 1, 0, 0, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 0]  B=[0, 0, 1, 1, 0, 1]
  A=[0, 0, 1, 1, 0, 1]  B=[0, 1, 0, 1, 0, 0]
  A=[0, 1, 0, 0, 1, 0]  B=[0, 0, 1, 0, 1, 1]
  A=[0, 0, 1, 0, 1, 1]  B=[0, 1, 0, 0, 1, 0]
  A=[1, 1, 0, 1, 1, 0]  B=[1, 0, 1, 1, 1, 1]
  A=[1, 0, 1, 1, 1, 1]  B=[1, 1, 0, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    def subject_score(df):
        diagnostic = []
        control = []

        for _, row in df.iterrows():
            a = np.asarray(row["option_a_ratings"], dtype=float)
            b = np.asarray(row["option_b_ratings"], dtype=float)
            d = np.sign(b - a)
            active = set(np.flatnonzero(d != 0).tolist())

            if active == {0, 4} and d[0] == -d[4]:
                anchor_choice = float(int(row["response"]) == int(d[0] > 0))
                diagnostic.append(anchor_choice)
            elif active == {0, 1} and d[0] == -d[1]:
                anchor_choice = float(int(row["response"]) == int(d[0] > 0))
                control.append(anchor_choice)

        def late_minus_early(values):
            x = np.asarray(values, dtype=float)
            if x.size < 2:
                return np.nan
            half = x.size // 2
            return float(np.mean(x[-half:]) - np.mean(x[:half]))

        diag_change = late_minus_early(diagnostic)
        control_change = late_minus_early(control)
        if not np.isfinite(diag_change) or not np.isfinite(control_change):
            return np.nan
        return float(diag_change - control_change)

    if "subject_id" in data.columns and data["subject_id"].nunique() > 1:
        scores = [subject_score(g) for _, g in data.groupby("subject_id", sort=False)]
        scores = np.asarray(scores, dtype=float)
        scores = scores[np.isfinite(scores)]
        return float(np.mean(scores)) if scores.size else np.nan

    return subject_score(data)

```

**Observed (real) value:** 0.0200 (var=0.1946)
**Previous candidate values (this loop):**
  - iter 1: 0.0700 (var=0.2276) (Δ vs real +0.0500)
  - iter 2: -0.0100 (var=0.1174) (Δ vs real -0.0300)
  - iter 3: -0.0950 (var=0.3172) (Δ vs real -0.1150)
  - iter 4: 0.0600 (var=0.2339) (Δ vs real +0.0400)
  - iter 5 (most recent): -0.0750 (var=0.1756) (Δ vs real -0.0950)
**Other theories' values on this metric (for reference):**
- pi_5: 0.3050 (var=0.1632)
- pi_8: -0.1050 (var=0.1227)
- pi_1: 0.0200 (var=0.1196)
- pi_2: -0.0600 (var=0.2064)
- pi_3: 0.1000 (var=0.2775)
- pi_4: 0.0050 (var=0.0062)
- pi_6: -0.0300 (var=0.2041)
- pi_7: -0.0400 (var=0.2234)
- pi_9: 0.0900 (var=0.2244)
- pi_10: 0.0200 (var=0.0696)

### Experiment 15
**Design**
  A=[1, 0, 0, 0, 0, 1, 1, 0]  B=[0, 1, 1, 1, 0, 1, 0, 1]
  A=[0, 1, 1, 1, 0, 1, 0, 1]  B=[1, 0, 0, 0, 0, 1, 1, 0]
  A=[1, 0, 1, 0, 0, 1, 0, 0]  B=[0, 1, 1, 1, 1, 0, 0, 1]
  A=[0, 1, 1, 1, 1, 0, 0, 1]  B=[1, 0, 1, 0, 0, 1, 0, 0]
  A=[1, 1, 0, 0, 1, 0, 0, 0]  B=[0, 1, 1, 1, 0, 1, 0, 1]
  A=[0, 1, 1, 1, 0, 1, 0, 1]  B=[1, 1, 0, 0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 1, 1, 0, 1]  B=[0, 1, 1, 1, 0, 1, 0, 0]
  A=[0, 1, 1, 1, 0, 1, 0, 0]  B=[1, 0, 0, 0, 1, 1, 0, 1]
  A=[1, 0, 0, 0, 0, 1, 1, 1]  B=[0, 1, 1, 1, 0, 0, 1, 0]
  A=[0, 1, 1, 1, 0, 0, 1, 0]  B=[1, 0, 0, 0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 1, 0, 1, 1]  B=[0, 1, 1, 1, 1, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 0, 0, 0]  B=[1, 0, 0, 0, 1, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    if data is None or len(data) == 0:
        return float('nan')

    cue1_choices = []

    for _, row in data.iterrows():
        a = np.asarray(row['option_a_ratings'], dtype=float)
        b = np.asarray(row['option_b_ratings'], dtype=float)
        if a.ndim != 1 or b.ndim != 1 or a.size < 8 or b.size < 8:
            continue

        direction = np.sign(b - a)

        # Critical displays are those on which Experts 1 and 8 both
        # discriminate but recommend opposite products.
        if direction[0] == 0 or direction[7] == 0:
            continue
        if direction[0] == direction[7]:
            continue

        cue1_response = 1 if direction[0] > 0 else 0
        cue1_choices.append(float(int(row['response']) == cue1_response))

    if len(cue1_choices) == 0:
        return float('nan')

    return float(np.mean(cue1_choices))
```

**Observed (real) value:** 0.8475 (var=0.0129)
**Previous candidate values (this loop):**
  - iter 1: 0.8608 (var=0.0060) (Δ vs real +0.0133)
  - iter 2: 0.7788 (var=0.0064) (Δ vs real -0.0687)
  - iter 3: 0.9083 (var=0.0034) (Δ vs real +0.0608)
  - iter 4: 0.9046 (var=0.0039) (Δ vs real +0.0571)
  - iter 5 (most recent): 0.9087 (var=0.0042) (Δ vs real +0.0612)
**Other theories' values on this metric (for reference):**
- pi_9: 0.8521 (var=0.0068)
- pi_5: 0.1762 (var=0.0116)
- pi_1: 0.1567 (var=0.0166)
- pi_2: 0.1533 (var=0.0142)
- pi_3: 0.7188 (var=0.0093)
- pi_4: 0.0096 (var=0.0002)
- pi_6: 0.4733 (var=0.0064)
- pi_7: 0.4275 (var=0.0052)
- pi_8: 0.6492 (var=0.0078)
- pi_10: 0.8496 (var=0.0084)

### Experiment 16
**Design**
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 1, 0, 1]  B=[0, 1, 0, 1, 1, 0, 1]
  A=[0, 1, 0, 1, 1, 0, 1]  B=[1, 1, 0, 0, 1, 0, 1]
  A=[1, 0, 1, 0, 0, 1, 0]  B=[0, 0, 1, 1, 0, 1, 0]
  A=[0, 0, 1, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 1, 0, 1]  B=[1, 1, 0, 1, 1, 0, 0]
  A=[1, 1, 0, 1, 1, 0, 0]  B=[1, 1, 0, 0, 1, 0, 1]
  A=[0, 0, 1, 0, 0, 1, 1]  B=[0, 0, 1, 1, 0, 1, 0]
  A=[0, 0, 1, 1, 0, 1, 0]  B=[0, 0, 1, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    def subject_score(df):
        early_opponent = []
        late_opponent = []
        novice_anchor = []
        mature_anchor = []
        exposure_count = {"early": 0, "late": 0}

        for _, row in df.iterrows():
            a = np.asarray(row["option_a_ratings"], dtype=float)
            b = np.asarray(row["option_b_ratings"], dtype=float)
            if a.size < 7 or b.size < 7:
                continue

            active = set(np.flatnonzero(a != b).tolist())
            if active == {0, 3}:
                condition = "early"
            elif active == {3, 6}:
                condition = "late"
            else:
                continue

            if a[3] == b[3]:
                continue
            anchor_response = 0 if a[3] > b[3] else 1
            anchor_chosen = float(int(row["response"]) == anchor_response)

            rank = exposure_count[condition]
            exposure_count[condition] += 1

            if condition == "early":
                early_opponent.append(anchor_chosen)
            else:
                late_opponent.append(anchor_chosen)

            # Before four prior condition-specific observations, ADCG's
            # anti-concurrence estimate is still strongly pseudocount- and
            # confidence-limited. At eight or more it is comparatively mature.
            if rank < 4:
                novice_anchor.append(anchor_chosen)
            elif rank >= 8:
                mature_anchor.append(anchor_chosen)

        order_contrast = 0.0
        if early_opponent and late_opponent:
            order_contrast = float(np.mean(late_opponent) - np.mean(early_opponent))

        learning_contrast = 0.0
        if novice_anchor and mature_anchor:
            learning_contrast = float(np.mean(novice_anchor) - np.mean(mature_anchor))

        return order_contrast + 0.75 * learning_contrast

    if len(data) == 0:
        return 0.0
    if "subject_id" not in data.columns:
        return float(subject_score(data))

    scores = [subject_score(df) for _, df in data.groupby("subject_id", sort=False)]
    return float(np.mean(scores)) if scores else 0.0
```

**Observed (real) value:** 0.0263 (var=0.0299)
**Previous candidate values (this loop):**
  - iter 1: -0.0399 (var=0.0204) (Δ vs real -0.0662)
  - iter 2: 0.0097 (var=0.0176) (Δ vs real -0.0166)
  - iter 3: 0.0443 (var=0.0164) (Δ vs real +0.0180)
  - iter 4: -0.0215 (var=0.0225) (Δ vs real -0.0478)
  - iter 5 (most recent): -0.0152 (var=0.0225) (Δ vs real -0.0415)
**Other theories' values on this metric (for reference):**
- pi_5: 0.1532 (var=0.0330)
- pi_9: 0.0106 (var=0.0320)
- pi_1: -0.0078 (var=0.0146)
- pi_2: 0.0011 (var=0.0351)
- pi_3: -0.2768 (var=0.0329)
- pi_4: 0.0055 (var=0.0008)
- pi_6: -0.0259 (var=0.0278)
- pi_7: -0.0118 (var=0.0177)
- pi_8: -0.0081 (var=0.0183)
- pi_10: 0.0006 (var=0.0082)

### Experiment 17
**Design**
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[0, 0, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 0]  B=[1, 1, 1, 0, 0, 1]
  A=[1, 1, 1, 0, 0, 1]  B=[0, 0, 0, 1, 1, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 1, 0]  B=[1, 1, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 0, 1]  B=[0, 0, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Code every response as choosing the option endorsed by Expert 6,
    # the uniquely most-valid expert.
    records = []
    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=int)
        b = np.asarray(row["option_b_ratings"], dtype=int)
        if a.size != 6 or b.size != 6:
            continue

        # Expert 6's anchor option is A when its A rating is 1, otherwise B.
        anchor_response = 0 if a[5] == 1 else 1
        anchor_choice = float(int(row["response"]) == anchor_response)

        # Cue identities opposing Expert 6 are invariant under A/B reversal.
        opponents = tuple(np.flatnonzero(a[:5] != a[5]).tolist())
        records.append((opponents, anchor_choice))

    if not records:
        return 0.0

    frame = pd.DataFrame(records, columns=["opponents", "anchor_choice"])

    # Compact, high-validity opposition profiles: {1,2} and {1,2,3}.
    compact_sets = {(0, 1), (0, 1, 2)}
    # High-multiplicity profiles: {1,2,3,4} and {1,2,3,4,5}.
    recovery_sets = {(0, 1, 2, 3), (0, 1, 2, 3, 4)}

    compact = frame.loc[
        frame["opponents"].apply(lambda x: x in compact_sets),
        "anchor_choice"
    ]
    recovery = frame.loc[
        frame["opponents"].apply(lambda x: x in recovery_sets),
        "anchor_choice"
    ]

    if len(compact) == 0 or len(recovery) == 0:
        return 0.0

    return float(recovery.mean() - compact.mean())
```

**Observed (real) value:** 0.5600 (var=0.0288)
**Previous candidate values (this loop):**
  - iter 1: 0.1856 (var=0.0274) (Δ vs real -0.3744)
  - iter 2: 0.3088 (var=0.0348) (Δ vs real -0.2513)
  - iter 3: 0.1512 (var=0.0279) (Δ vs real -0.4088)
  - iter 4: 0.2069 (var=0.0343) (Δ vs real -0.3531)
  - iter 5 (most recent): 0.1600 (var=0.0167) (Δ vs real -0.4000)
**Other theories' values on this metric (for reference):**
- pi_9: 0.4031 (var=0.0261)
- pi_10: -0.0069 (var=0.0030)
- pi_1: -0.0006 (var=0.0092)
- pi_2: -0.5300 (var=0.0308)
- pi_3: -0.1925 (var=0.0135)
- pi_4: -0.0381 (var=0.0022)
- pi_5: 0.0344 (var=0.0146)
- pi_6: -0.0106 (var=0.0189)
- pi_7: 0.1544 (var=0.0156)
- pi_8: 0.0325 (var=0.0124)

### Experiment 18
**Design**
  A=[1, 0, 0, 0, 0, 0, 1, 0]  B=[0, 0, 1, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 1, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0, 1]  B=[0, 0, 1, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 1, 0, 0]  B=[0, 0, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0, 1, 0]  B=[0, 0, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 1, 0]
  A=[0, 0, 1, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 1, 1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 1, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 1, 0, 0]
  A=[0, 0, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    def subject_contrast(df):
        broad_choices = []
        nonbroad_choices = []

        for _, row in df.iterrows():
            a = np.asarray(row["option_a_ratings"], dtype=int)
            b = np.asarray(row["option_b_ratings"], dtype=int)
            direction = np.sign(b - a).astype(int)

            # Expert 4 (zero-based index 3) is the unique-validity anchor.
            anchor_direction = int(direction[3])
            if anchor_direction == 0:
                continue

            opposition = np.flatnonzero(direction == -anchor_direction)
            if opposition.size != 2:
                continue

            opposition_span = int(np.max(opposition) - np.min(opposition))
            is_broad = opposition_span >= 6

            response = int(row["response"])
            anchor_chosen = float(
                response == (1 if anchor_direction > 0 else 0)
            )

            if is_broad:
                broad_choices.append(anchor_chosen)
            else:
                nonbroad_choices.append(anchor_chosen)

        if len(broad_choices) == 0 or len(nonbroad_choices) == 0:
            return 0.0
        return float(np.mean(broad_choices) - np.mean(nonbroad_choices))

    if "subject_id" in data.columns:
        contrasts = [
            subject_contrast(df)
            for _, df in data.groupby("subject_id", sort=False)
        ]
        return float(np.mean(contrasts)) if len(contrasts) else 0.0

    return subject_contrast(data)

```

**Observed (real) value:** 0.0092 (var=0.0117)
**Previous candidate values (this loop):**
  - iter 1: 0.0062 (var=0.0080) (Δ vs real -0.0029)
  - iter 2: -0.0162 (var=0.0068) (Δ vs real -0.0254)
  - iter 3: -0.0038 (var=0.0092) (Δ vs real -0.0129)
  - iter 4: -0.0221 (var=0.0061) (Δ vs real -0.0313)
  - iter 5 (most recent): 0.0038 (var=0.0109) (Δ vs real -0.0054)
**Other theories' values on this metric (for reference):**
- pi_10: 0.5554 (var=0.0321)
- pi_9: -0.0196 (var=0.0100)
- pi_1: -0.0033 (var=0.0050)
- pi_2: -0.0013 (var=0.0100)
- pi_3: -0.0792 (var=0.0037)
- pi_4: -0.0050 (var=0.0103)
- pi_5: 0.0125 (var=0.0050)
- pi_6: 0.0146 (var=0.0103)
- pi_7: 0.0029 (var=0.0081)
- pi_8: 0.0279 (var=0.0087)

## PREVIOUS CANDIDATE (this loop)
The RUNNING-BEST (last ACCEPTED) candidate in this critique loop — i.e. the source the loop's accept gate kept as the best base so far. If your most recent attempt was REJECTED by the gate, this is NOT that attempt; it is the previously-accepted base the gate rolled back to. Iterate on this source — the next critic feedback should be applied on top of it.

**Description**
Continuous Reliability-Gated Reason Competition with Bounded Embedded Leverage (CRGRC-BEL) claims that communicated validities are continuously compressed into reliability evidence and accumulated within option-specific coalitions under divisive redundancy. Credible sparse opposition receives a graded diagnosticity gain, whereas weak opposition is filtered by a smooth credibility threshold. Diagnosticity declines with effective opponent multiplicity, after which a smooth restoration process can recover an isolated, high-validity anchor. For uniquely strongest anchors embedded in a coalition, the effect of coalition composition on the final normalized margin is bounded according to anchor identity share. This prevents one additional aligned cue from generating a spurious primacy crossover without imposing feature-count or cue-index rules. Serial accessibility remains restricted to actual or psychologically indistinguishable top-validity ties and is selectively strengthened by balanced coalition competition. The model is strictly history-invariant.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"CRGRC expects state with shape (2, n_features); got {stim.shape}."
        )

    n_features = stim.shape[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} != n_features {n_features}."
        )

    # CRGRC deliberately performs no learning in this feedback-free task.
    _ = history

    validity_compression = float(parameters["validity_compression"])
    redundancy = float(parameters["redundancy"])
    sparse_dissent = float(parameters["sparse_dissent"])
    dissent_saturation = float(parameters["dissent_saturation"])
    credibility_threshold = float(parameters["credibility_threshold"])
    credibility_slope = float(parameters["credibility_slope"])
    embedded_margin_floor = float(parameters["embedded_margin_floor"])
    restoration_threshold = float(parameters["restoration_threshold"])
    restoration_strength = float(parameters["restoration_strength"])
    tie_width = float(parameters["tie_width"])
    tie_order_weight = float(parameters["tie_order_weight"])
    beta = float(parameters["beta"])
    lapse = float(parameters["lapse"])
    trait_correlation = float(parameters["trait_correlation"])

    # A single stable orientation induces correlated random effects. Positive
    # values preserve communicated-validity differences, increase redundancy,
    # restoration, and precision, and reduce dissent and serial reliance.
    z = trait_correlation
    validity_compression *= np.exp(0.32 * z)
    redundancy *= np.exp(0.22 * z)
    sparse_dissent *= np.exp(-0.42 * z)
    restoration_strength *= np.exp(0.28 * z)
    tie_order_weight *= np.exp(-0.24 * z)
    beta *= np.exp(0.18 * z)

    restoration_strength = float(np.clip(restoration_strength, 0.0, 0.98))
    tie_order_weight = float(np.clip(tie_order_weight, 0.0, 0.95))

    def sigmoid(x):
        x = float(np.clip(x, -60.0, 60.0))
        return 1.0 / (1.0 + np.exp(-x))

    # Positive directions favor B and negative directions favor A.
    directions = np.sign(stim[1] - stim[0])
    active = np.flatnonzero(directions != 0)
    if active.size == 0:
        return np.array([0.5, 0.5], dtype=np.float64)

    # Communicated validity is converted to reliability evidence and compressed
    # continuously relative to the strongest currently relevant expert.
    v = np.clip(validities, 0.500001, 0.999999)
    reliability = np.log(v / (1.0 - v))
    active_reference = float(np.max(reliability[active]))
    cue_weight = np.exp(
        validity_compression * (reliability - active_reference)
    )

    a_cues = np.flatnonzero(directions < 0)
    b_cues = np.flatnonzero(directions > 0)

    def effective_multiplicity(indices):
        if indices.size == 0:
            return 0.0
        w = np.asarray(cue_weight[indices], dtype=float)
        total = float(np.sum(w))
        return (total * total) / max(float(np.sum(w * w)), 1e-12)

    def coalition_support(indices):
        if indices.size == 0:
            return 0.0
        w = np.asarray(cue_weight[indices], dtype=float)
        raw = float(np.sum(w))
        effective_n = effective_multiplicity(indices)

        # Divisive redundancy is based on effective evidence multiplicity.
        # It therefore responds to coalition validity composition without using
        # cue indices, spatial dispersion, or exact nominal display size.
        excess = max(effective_n - 1.0, 0.0)
        divisor = 1.0 + redundancy * (excess ** 1.20)
        return raw / max(divisor, 1e-12)

    support_a = coalition_support(a_cues)
    support_b = coalition_support(b_cues)

    active_v = validities[active]
    descending = np.sort(active_v)[::-1]
    best_v = float(descending[0])
    second_v = float(descending[1]) if descending.size > 1 else 0.5
    top_gap = max(best_v - second_v, 0.0)

    # Ambiguity and uniqueness are complementary continuous gates. Exact ties
    # have ambiguity one; a clearly unique maximum has ambiguity near zero.
    scaled_gap = top_gap / max(tie_width, 1e-8)
    top_ambiguity = float(np.exp(-0.5 * scaled_gap * scaled_gap))
    unique_strength = 1.0 - top_ambiguity

    top_cues = active[np.isclose(active_v, best_v, atol=1e-12)]
    anchor_cue = int(np.min(top_cues))
    anchor_direction = float(directions[anchor_cue])

    if anchor_direction > 0:
        anchor_indices = b_cues
        opponent_indices = a_cues
        anchor_support = support_b
        opponent_support = support_a
    else:
        anchor_indices = a_cues
        opponent_indices = b_cues
        anchor_support = support_a
        opponent_support = support_b

    anchor_effective_n = effective_multiplicity(anchor_indices)
    opponent_effective_n = effective_multiplicity(opponent_indices)

    if anchor_indices.size > 0:
        anchor_weights = np.asarray(cue_weight[anchor_indices], dtype=float)
        anchor_identity_share = float(np.max(anchor_weights)) / max(
            float(np.sum(anchor_weights)), 1e-12
        )
    else:
        anchor_identity_share = 0.0

    if opponent_indices.size > 0:
        opponent_weights = np.asarray(cue_weight[opponent_indices], dtype=float)
        strongest_opponent = float(np.max(opponent_weights))
        mean_opponent = float(np.mean(opponent_weights))

        # Credibility combines the strongest opposing reason and the typical
        # opposing reason. A smooth threshold protects anchors from genuinely
        # weak opposition without suppressing credible intermediate coalitions.
        opposition_credibility = np.sqrt(
            np.clip(strongest_opponent * mean_opponent, 0.0, 1.0)
        )
        credibility_gate = sigmoid(
            credibility_slope
            * (opposition_credibility - credibility_threshold)
        )

        # Sparse diagnosticity decays continuously with effective multiplicity.
        # Isolation is likewise continuous: an anchor embedded in a coalition
        # receives less challenge amplification than a lone anchor.
        sparse_profile = 1.0 / (
            1.0
            + (opponent_effective_n / max(dissent_saturation, 1e-8)) ** 2
        )
        isolation = anchor_identity_share ** 1.5
        challenge_gain = (
            sparse_dissent
            * unique_strength
            * credibility_gate
            * sparse_profile
            * isolation
        )
        opponent_support *= 1.0 + challenge_gain

    total_support = anchor_support + opponent_support
    if total_support <= 1e-12:
        core_evidence = 0.0
    else:
        anchor_margin = (anchor_support - opponent_support) / total_support
        core_evidence = anchor_direction * anchor_margin

    # Under a unique maximum, embedding bounds the leverage of coalition
    # composition on the normalized margin. Isolated anchors are unchanged.
    embedded_leverage = (
        embedded_margin_floor
        + (1.0 - embedded_margin_floor) * anchor_identity_share
    )
    leverage_gate = 1.0 - unique_strength * (1.0 - embedded_leverage)
    core_evidence *= leverage_gate

    # Restoration grows smoothly only after opposition becomes sufficiently
    # numerous in effective-evidence terms. It is strongest for a credible,
    # isolated, uniquely best anchor and saturates below complete determinism.
    anchor_quality = np.clip((best_v - 0.5) / 0.5, 0.0, 1.0)
    count_restoration = sigmoid(
        4.0 * (opponent_effective_n - restoration_threshold)
    )
    restoration_gate = (
        restoration_strength
        * unique_strength
        * (anchor_identity_share ** 1.7)
        * (anchor_quality ** 1.3)
        * count_restoration
    )
    restoration_gate = float(np.clip(restoration_gate, 0.0, 0.97))
    restored_evidence = (
        (1.0 - restoration_gate) * core_evidence
        + restoration_gate * anchor_direction
    )

    # Serial accessibility is calculated only through the continuous top-tie
    # gate. Serial rank among active cues is meaningful presentation order, not
    # spatial span. Reliability closeness prevents clearly inferior cues from
    # acting as serial anchors even when they occur early.
    serial_numerator = 0.0
    serial_denominator = 0.0
    for rank, cue in enumerate(active):
        closeness = np.exp(
            -(best_v - validities[cue]) / max(tie_width, 1e-8)
        )
        accessibility = closeness * np.exp(-float(rank) / 0.70)
        serial_numerator += accessibility * float(directions[cue])
        serial_denominator += accessibility

    if serial_denominator <= 1e-12:
        serial_evidence = 0.0
    else:
        serial_evidence = serial_numerator / serial_denominator

    # Balanced reason competition selectively strengthens tied-top order
    # resolution while retaining the previous imbalanced-profile baseline.
    prechallenge_total = support_a + support_b
    if prechallenge_total <= 1e-12:
        coalition_balance = 1.0
    else:
        coalition_balance = (
            2.0 * min(support_a, support_b) / prechallenge_total
        )
    balance_gate = 0.45 + 0.85 * coalition_balance
    serial_gate = float(np.clip(
        tie_order_weight * top_ambiguity * balance_gate, 0.0, 0.95
    ))

    choice_evidence = (
        (1.0 - serial_gate) * restored_evidence
        + serial_gate * serial_evidence
    )

    logits = beta * np.array(
        [-0.5 * choice_evidence, 0.5 * choice_evidence], dtype=np.float64
    )
    logits = logits - np.max(logits)
    probs = np.exp(logits)
    probs /= probs.sum()

    probs = (1.0 - lapse) * probs + lapse * np.array(
        [0.5, 0.5], dtype=np.float64
    )
    probs = np.clip(probs, 0.0, None)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        return np.array([0.5, 0.5], dtype=np.float64)
    probs /= total
    return probs.astype(np.float64)


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
- validity_compression: [0.16, 0.48]
- redundancy: [0.10, 0.38]
- sparse_dissent: [2.8, 6.2]
- dissent_saturation: [1.20, 2.25]
- credibility_threshold: [0.60, 0.74]
- credibility_slope: [9.0, 16.0]
- embedded_margin_floor: [0.30, 0.55]
- restoration_threshold: [2.85, 3.55]
- restoration_strength: [0.74, 0.97]
- tie_width: [0.004, 0.022]
- tie_order_weight: [0.58, 0.86]
- beta: [2.0, 4.8]
- lapse: [0.0, 0.10]
- trait_correlation: [-1.0, 1.0]

`rationale`: This is a targeted edit of the accepted CRGRC base. First, linear opposition credibility is replaced by a smooth threshold, selectively protecting anchors from weak opposition as required by Experiment 9 while leaving genuinely credible intermediate coalitions able to override in Experiments 2, 6, 10, and 13. Second, a continuous anchor-identity-share leverage bound attenuates composition-driven margins only when a unique anchor is embedded. This directly targets the non-serial Experiment 4 crossover without any cue-index, feature-count, or display-size exception; isolated anchors remain unchanged. Third, restoration receives only a modestly steeper onset and slightly stronger range, intermediate between the accepted and rejected calibrations, to improve high-count recovery in Experiments 11 and 17 without broadly overprotecting anchors. Finally, the balanced component of the tie-order gate is increased while its imbalanced baseline and overall tie-order range are retained. This separately targets the sign of Experiment 3 without repeating the rejected global increase in serial reliance. All other weighting, redundancy, history invariance, geometry independence, policy, and probability calculations are unchanged.

## PRIOR FEEDBACK ITERATIONS
The critic's verdicts on each previous in-loop candidate, in order. Each block ends with an **Outcome of this advice** line saying whether the candidate the proposer produced AFTER this advice was ACCEPTED (loss strictly beat the running best) or REJECTED (the gate discarded it). Address the most recent iteration's feedback in your next edit, but down-weight past advice whose candidates were REJECTED.

### Iteration 1
Verdict: regenerate
Interpretation: CRGRC is faithful to the prescribed history-invariant reliability-gated competition family and captures several important qualitative constraints: Experiment 1 is exact, the geometry null in Experiment 18 is exact, coalition/profile sensitivity in Experiment 8 is close, the activation effect in Experiment 12 is reasonably close, Experiment 15 is excellent, and the nominal learning contrasts in Experiments 14 and 16 remain near zero. Nevertheless, the aggregate fit is not yet experiment-invariant. The largest contradiction is Experiment 4: despite claiming that serial accessibility vanishes under a unique maximum, the candidate predicts a large primacy crossover (0.600 versus 0.000). Tied-order adherence is also too weak in Experiment 5 (0.695 versus 0.790), while the balance interaction has the wrong sign in Experiment 3 (-0.094 versus 0.072). Coalition competition is too favorable to the anchor in Experiments 2, 6, 10, and 13: predicted anchor/highest-cue adherence is too high, and the one-versus-many reduction in Experiment 6 is much too shallow (-0.246 versus -0.545). Conversely, isolated-anchor protection and high-count restoration are too weak in Experiment 9 (0.363 versus 0.725), Experiment 11 (0.005 versus 0.109), and especially Experiment 17 (0.186 versus 0.560). Thus the required nonmonotonic multiplicity response is present but insufficiently shaped: intermediate credible coalitions do not override strongly enough, while restoration at genuinely high multiplicity does not rise sharply enough. Several observed between-subject variances, especially in Experiments 9, 11, and 12, are also substantially underestimated.
Rationale: Retain CRGRC's mechanism family but recalibrate its gates. First, eliminate the Experiment 4 leakage by making the ambiguity gate substantially narrower or more sharply decaying and by restricting serial evidence to cues within the actual top-validity tie set; then increase tied-order weight conditional on that stricter gate to recover Experiment 5 without recreating a unique-maximum crossover. Recheck the balance modulation because its current interaction produces the wrong sign in Experiment 3. Second, make the multiplicity curve more distinctly U-shaped: strengthen credible two-to-three-cue coalition competition, for example through less divisive redundancy and a more composition-sensitive diagnosticity gain, while making restoration steeper and closer to saturation only at high effective multiplicity. Raising validity resolution while making diagnosticity more nonlinear in opposition credibility may help weak opposition preserve the anchor in Experiment 9 without preventing strong, credible coalitions from overriding it in Experiments 2, 6, 10, and 13. A steeper high-count restoration gate with stronger upper asymptote should target Experiments 11 and 17 without relying on exact count rules. Finally, implement the recommended correlated random effects more literally: the current single `trait_correlation` value is a common orientation rather than a correlation structure, and it leaves restoration threshold and saturation essentially homogeneous. Modest correlated variation in restoration threshold, redundancy, and dissent saturation could improve the markedly underestimated subject variance while remaining within the prescribed continuous, history-invariant theory.

**Outcome of this advice:** iter 1 candidate loss=0.2039 -> iter 2 candidate loss=0.2224 -> the gate marked it REJECTED.

### Iteration 2
Verdict: regenerate
Interpretation: The current candidate remains faithful to the prescribed continuous, history-invariant reliability-gated competition family, and it retains exact or close fits for Experiment 1, the geometry null in Experiment 18, profile sensitivity in Experiment 8, and the null history contrasts in Experiments 14 and 16. However, it was rejected by the accept gate because the broad recalibration worsened aggregate loss from 0.2039 to 0.2224. The principal trade-off is clear: stronger validity compression, quadratic credibility, and aggressive restoration improved isolated-anchor protection in Experiment 9 (0.624 versus the prior 0.363) and recovery in Experiments 11 and 17, but made the model much too anchor-favoring at intermediate coalition sizes. Errors consequently grew sharply in Experiments 2 (0.625 versus 0.324), 6 (-0.088 versus -0.545), 10 (0.767 versus 0.446), and 13 (0.621 versus 0.328). The activation effect in Experiment 12 also deteriorated from 0.303 to 0.189 versus 0.353, and Experiment 15 moved away from an excellent fit. Experiment 4 became still worse, predicting a primacy-crossover prevalence of 0.740 despite an observed value of zero. Because the serial ambiguity gate is already extremely narrow under a unique maximum, this Experiment 4 failure is unlikely to be residual serial leakage; it is more plausibly generated by the core coalition/challenge computation, where the position of Expert 1 relative to the anchor changes coalition support enough to create subject-level crossovers. Tied-order behavior improved only modestly: Experiment 5 remains low and the Experiment 3 interaction remains negative. Thus the rejected package overprotected unique anchors broadly rather than selectively distinguishing weak opposition, credible intermediate coalitions, and genuinely high-count restoration.
Rationale: Build the next candidate on the unchanged iteration-1 accepted base, not by repeating the rejected broad push. In particular, do not retain the simultaneous increase in validity compression, quadratic credibility suppression, and near-ceiling steep restoration: that combination caused the large regressions in Experiments 2, 6, 10, 12, 13, and 15. Instead, make a smaller, more isolated in-family adjustment. Preserve the base validity weighting and use a credibility transform with a sharper threshold between weak and genuinely credible opposition, rather than squaring all bounded credibility values; this should protect the anchor against the weak coalition in Experiment 9 without suppressing the credible intermediate coalitions needed to override it in Experiments 2, 6, 10, and 13. If redundancy is reduced, take only a modest step from the accepted-base range and leave the other coalition parameters fixed so its effect can be identified. Add only an intermediate-strength restoration adjustment—between iterations 1 and 2 in onset and asymptote—because iteration 1 underpredicted Experiments 11 and 17 whereas iteration 2 overshot Experiment 11 while still undershooting Experiment 17. For Experiment 4, target the core unique-maximum challenge calculation rather than narrowing the serial gate again: cap the leverage of one additional aligned or opposing cue on the normalized margin while allowing effective multiplicity to accumulate smoothly, thereby reducing subject-level Expert-1 crossovers without blocking multi-cue coalition override. Finally, tune tied-order behavior separately by increasing the contrast between the balanced and imbalanced serial gates, not the overall tie-order weight; the rejected global increase raised Experiment 5 only slightly and failed to reverse Experiment 3. Keep strict history invariance and the geometry-free representation unchanged.

**Outcome of this advice:** iter 2 candidate loss=0.2224 -> iter 3 candidate loss=0.1853 -> the gate marked it ACCEPTED.

### Iteration 3
Verdict: regenerate
Interpretation: The accepted iteration is a genuine aggregate improvement (loss 0.1853 versus 0.2039), and the prior advice to use selective credibility gating, bounded embedded leverage, and separately balanced tie gating was productive. The candidate is also faithful to the prescribed family: it is continuous, history-invariant, geometry-free, and uses validity-weighted coalition competition. It fits Experiment 1 exactly; is close on tied-order adherence in Experiment 5; captures the null/profile results in Experiments 7, 8, 16, and 18; and now fits the activation effect in Experiment 12 very well. Nevertheless, the model is not yet experiment-invariant. The largest failures remain Experiment 4, where 44% of simulated subjects show a unique-maximum primacy crossover despite an observed prevalence of zero, and Experiment 17, where high-multiplicity recovery is far too weak (0.151 versus 0.560). The same recovery deficit appears in Experiment 11 (-0.010 versus 0.109). At intermediate multiplicities the model remains too favorable to the anchor: highest-cue adherence is too high in Experiments 2 (0.530 versus 0.324), 10 (0.615 versus 0.446), and 13 (0.460 versus 0.328), while the many-opponent reduction in Experiment 6 is much too shallow (-0.234 versus -0.545). Conversely, weak opposition still receives too much leverage in Experiment 9, producing insufficient isolated-anchor protection (0.461 versus 0.725). Thus the required response is still insufficiently nonmonotonic: weak opposition should be filtered more, credible intermediate coalitions should override more, and genuinely high effective multiplicity should trigger substantially sharper restoration. The tied-cue balance interaction also remains wrong-signed in Experiment 3 (-0.054 versus 0.072), despite the successful improvement in overall tied-order adherence. Between-subject variance is generally too low in several key experiments, especially Experiments 3, 5, 6, 9, 11, 12, and 13.
Rationale: Retain the current accepted candidate as the basis, since its targeted changes improved aggregate fit, but tune distinct gates rather than making another broad validity/restoration shift. First, sharpen the existing credibility threshold modestly so genuinely weak opposition in Experiment 9 falls below the gate, while credible opposition remains above it; pair this with stronger challenge gain only above threshold to lower anchor adherence in Experiments 2, 6, 10, and 13. Do not repeat the rejected global increase in validity compression or broad credibility suppression. Second, expose and tune the currently fixed restoration sigmoid slope. A steeper transition localized around high effective multiplicity is preferable to a general increase in restoration strength: restoration should remain negligible for the intermediate coalitions but rise much more abruptly for the high-count profiles in Experiments 11 and 17. Third, the Experiment 4 edit is directionally successful but incomplete. Multiplying the entire margin by `embedded_leverage` reduces confidence without directly removing composition-dependent differences and therefore still permits sampling-defined crossovers. Revise this normalization so that, under a clear unique maximum, the marginal contribution of cues allied with an embedded anchor is smoothly capped before the anchor-versus-opponent margin is formed. This remains bounded embedded leverage and should eliminate the crossover without suppressing opposition from a genuinely multi-cue coalition. Finally, diagnose the Experiment 3 sign before further increasing serial weight. Restrict serial evidence to the psychologically tied top-validity set rather than allowing every active cue a nonzero closeness weight, and tune the balanced-versus-imbalanced gate after that correction; a further global increase risks overshooting the now-close Experiment 5. Preserve strict history invariance and the geometry-free representation. Only after these mean-pattern corrections, add modest correlated variation in credibility/restoration thresholds or response precision to address the systematically underestimated subject variance.

**Outcome of this advice:** iter 3 candidate loss=0.1853 -> iter 4 candidate loss=0.1960 -> the gate marked it REJECTED.

### Iteration 4
Verdict: regenerate
Interpretation: The current candidate remains faithful to the prescribed continuous, history-invariant, geometry-free reliability-gated competition family, but it was rejected by the accept gate: loss rose from 0.1853 to 0.1960. The rejected package produced a few useful local movements—Experiments 2, 9, 10, 13, and 17 moved toward the observations—but these were outweighed by broad regressions. Most importantly, the pre-margin allied-support cap worsened rather than fixed the unique-maximum crossover in Experiment 4, raising its prevalence from 0.440 to 0.620 against an observed 0.000. It also coincided with loss of the exact Experiment 1 fit and an overshoot of the previously excellent Experiment 12 activation effect. The steeper restoration transition modestly raised Experiment 17 recovery from 0.151 to 0.207, but remains far below 0.560 and did essentially nothing for Experiment 11 (-0.005 versus 0.109); meanwhile, the many-opponent contrast in Experiment 6 deteriorated from -0.234 to -0.171 versus -0.545. Restricting serial evidence to the tied set did not repair the balance interaction: Experiment 3 became more negative (-0.087 versus 0.072), while Experiment 5 was already close and barely changed. Thus the latest cap, restoration-slope, and serial-set edits do not provide an experiment-invariant improvement. The accepted iteration-3 base still has the central substantive problem: weak opposition is insufficiently filtered, credible intermediate coalitions are insufficiently influential, and high-count recovery is too weak, but the current attempt shows that simultaneously sharpening all three components destabilizes other successful effects.
Rationale: Because this candidate was rejected, the next attempt should use the unchanged iteration-3 accepted base and should not repeat the current package. In particular, do not retain the asymmetric pre-margin allied cap, do not further steepen restoration, and do not make another global serial-weight or tied-set adjustment. The prior recommendation to combine those edits was rejected by the gate, and the directions of the Experiment 4 and Experiment 3 changes show that those implementations were counterproductive. Try a smaller, identifiable in-family change centered on coalition normalization. For Experiment 4, replace identity-dependent treatment of the anchor coalition with a symmetric bounded transform of lower-cue evidence: separate the uniquely best anchor from all nonanchor evidence, aggregate the latter by validity-weighted directional coalitions under divisive redundancy, and smoothly bound the signed nonanchor contribution regardless of whether a given lower cue is allied with or opposed to the anchor. This should reduce Expert-1-dependent crossovers without selectively weakening only allied support or suppressing genuine multi-cue opposition. Separately, the modestly favorable movements in Experiments 2, 9, 10, and 13 suggest that selective credibility gating is still promising, but isolate it: take a smaller threshold/slope step than in the rejected candidate while leaving validity compression, redundancy, restoration, and serial parameters at the accepted-base settings. For later high-count recovery, use a different knob rather than another slope increase: gate restoration with a smooth credible-opponent-mass or participation statistic that preserves the distinction between two or three strong opponents and four or five contributing opponents when Kish effective multiplicity saturates. Test that separately, since the current effective-multiplicity sigmoid failed to improve Experiment 11 and harmed Experiment 6. Preserve strict history invariance and index-free geometry throughout.

**Outcome of this advice:** iter 4 candidate loss=0.1960 -> iter 5 candidate loss=0.2322 -> the gate marked it REJECTED.

### Iteration 5 (most recent — address this)
Verdict: regenerate
Interpretation: The current candidate is faithful in broad terms to the prescribed history-invariant, geometry-free reliability-gated competition family, but it was decisively rejected by the gate: loss increased from the accepted iteration-3 value of 0.1853 to 0.2322. The symmetric lower-reason bounding proposed in the previous critique did not work. It increased the Experiment 4 crossover prevalence from 0.440 in the accepted base to 0.580, rather than moving it toward the observed zero. It also broadly overprotected anchors: Experiment 2 rose to 0.606 versus 0.324, Experiment 10 to 0.655 versus 0.446, and Experiment 13 to 0.620 versus 0.328. The previously excellent Experiment 12 activation effect deteriorated from 0.368 to 0.222 versus 0.353. High-count restoration remains much too weak in Experiments 11 (-0.022 versus 0.109) and 17 (0.160 versus 0.560), and the multiplicity effect in Experiment 6 is still far too shallow (-0.173 versus -0.545). Weak-opposition anchor protection is also inadequate in Experiment 9 (0.473 versus 0.725). The candidate does retain exact or close results for Experiments 1, 5, 8, 15, 16, and 18, and remains appropriately history-invariant, but these successes do not compensate for the systematic failures of the multiplicity curve and the large Experiment 4 crossover. The Experiment 3 balance interaction also remains wrong-signed (-0.062 versus 0.072), while subject variance is generally underestimated.
Rationale: Return to the unchanged accepted iteration-3 base. Do not retain the current symmetric lower-reason bounding or its credibility-threshold edit: the gate rejected that recommendation, and the resulting movements in Experiments 2, 4, 10, 12, and 13 were clearly counterproductive. After several failed attempts to repair Experiment 4 through allied caps, whole-margin attenuation, and symmetric lower-evidence bounds, do not make another embedded-anchor bounding change in the next iteration. Instead, make one identifiable, still in-family adjustment to the restoration input. Kish effective multiplicity appears to saturate when opponent weights are unequal, preventing the model from distinguishing a genuinely broad coalition from two or three strong opponents. For restoration only, replace it with a smooth credible-participation statistic, such as summing continuous participation gates based on each opponent's weight relative to the strongest opponent. Keep the accepted-base challenge, credibility, redundancy, serial, and response parameters fixed. Calibrate a smooth restoration threshold so that two-to-three-contributor intermediate coalitions receive negligible restoration, while broadly participating coalitions cross the gate without any exact-count or display-size rule. This should strengthen recovery in Experiments 11 and 17 and make Experiment 6 more negative, while avoiding the severe anchor overprotection in Experiments 10 and 13. Preserve the existing unique-anchor, isolation, and anchor-quality gates so the change does not create restoration for tied or embedded profiles. Defer further Experiment 3 serial tuning and variance expansion until this multiplicity adjustment is evaluated separately; previous serial-set edits were rejected and should not be repeated.

**Outcome of this advice:** iter 5 candidate loss=0.2322 -> next candidate accept-status=PENDING (this is the advice you are addressing now).


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
  "theory": "Continuous Reliability-Gated Reason Competition with Bounded Embedded Leverage and Credible Participation (CRGRC-BEL-CP) claims that communicated validities are continuously compressed into reliability evidence and accumulated within option-specific coalitions under divisive redundancy. Credible sparse opposition receives a graded diagnosticity gain, whereas weak opposition is filtered by a smooth credibility threshold. Diagnosticity declines with effective opponent multiplicity. Restoration of an isolated, high-validity anchor depends separately on credible participation: each opposing reason contributes continuously according to its weight relative to the coalition's strongest opponent, allowing broadly participating coalitions to cross the restoration threshold even when Kish effective multiplicity saturates. For uniquely strongest anchors embedded in a coalition, the effect of coalition composition on the final normalized margin remains bounded according to anchor identity share. Serial accessibility remains restricted to actual or psychologically indistinguishable top-validity ties and is selectively strengthened by balanced coalition competition. The model is strictly history-invariant.",
  "predict": "def predict(parameters, state, history):\n    stim = np.asarray(state, dtype=float)\n    if stim.ndim != 2 or stim.shape[0] != 2:\n        raise ValueError(\n            f\"CRGRC expects state with shape (2, n_features); got {stim.shape}.\"\n        )\n\n    n_features = stim.shape[1]\n    validities = np.asarray(parameters[\"validities\"], dtype=float)\n    if validities.ndim != 1 or validities.size != n_features:\n        raise ValueError(\n            f\"validities length {validities.size} != n_features {n_features}.\"\n        )\n\n    # CRGRC deliberately performs no learning in this feedback-free task.\n    _ = history\n\n    validity_compression = float(parameters[\"validity_compression\"])\n    redundancy = float(parameters[\"redundancy\"])\n    sparse_dissent = float(parameters[\"sparse_dissent\"])\n    dissent_saturation = float(parameters[\"dissent_saturation\"])\n    credibility_threshold = float(parameters[\"credibility_threshold\"])\n    credibility_slope = float(parameters[\"credibility_slope\"])\n    embedded_margin_floor = float(parameters[\"embedded_margin_floor\"])\n    restoration_threshold = float(parameters[\"restoration_threshold\"])\n    restoration_participation_cutoff = float(\n        parameters[\"restoration_participation_cutoff\"]\n    )\n    restoration_strength = float(parameters[\"restoration_strength\"])\n    tie_width = float(parameters[\"tie_width\"])\n    tie_order_weight = float(parameters[\"tie_order_weight\"])\n    beta = float(parameters[\"beta\"])\n    lapse = float(parameters[\"lapse\"])\n    trait_correlation = float(parameters[\"trait_correlation\"])\n\n    # A single stable orientation induces correlated random effects. Positive\n    # values preserve communicated-validity differences, increase redundancy,\n    # restoration, and precision, and reduce dissent and serial reliance.\n    z = trait_correlation\n    validity_compression *= np.exp(0.32 * z)\n    redundancy *= np.exp(0.22 * z)\n    sparse_dissent *= np.exp(-0.42 * z)\n    restoration_strength *= np.exp(0.28 * z)\n    tie_order_weight *= np.exp(-0.24 * z)\n    beta *= np.exp(0.18 * z)\n\n    restoration_strength = float(np.clip(restoration_strength, 0.0, 0.98))\n    tie_order_weight = float(np.clip(tie_order_weight, 0.0, 0.95))\n\n    def sigmoid(x):\n        x = float(np.clip(x, -60.0, 60.0))\n        return 1.0 / (1.0 + np.exp(-x))\n\n    # Positive directions favor B and negative directions favor A.\n    directions = np.sign(stim[1] - stim[0])\n    active = np.flatnonzero(directions != 0)\n    if active.size == 0:\n        return np.array([0.5, 0.5], dtype=np.float64)\n\n    # Communicated validity is converted to reliability evidence and compressed\n    # continuously relative to the strongest currently relevant expert.\n    v = np.clip(validities, 0.500001, 0.999999)\n    reliability = np.log(v / (1.0 - v))\n    active_reference = float(np.max(reliability[active]))\n    cue_weight = np.exp(\n        validity_compression * (reliability - active_reference)\n    )\n\n    a_cues = np.flatnonzero(directions < 0)\n    b_cues = np.flatnonzero(directions > 0)\n\n    def effective_multiplicity(indices):\n        if indices.size == 0:\n            return 0.0\n        w = np.asarray(cue_weight[indices], dtype=float)\n        total = float(np.sum(w))\n        return (total * total) / max(float(np.sum(w * w)), 1e-12)\n\n    def coalition_support(indices):\n        if indices.size == 0:\n            return 0.0\n        w = np.asarray(cue_weight[indices], dtype=float)\n        raw = float(np.sum(w))\n        effective_n = effective_multiplicity(indices)\n\n        # Divisive redundancy is based on effective evidence multiplicity.\n        # It therefore responds to coalition validity composition without using\n        # cue indices, spatial dispersion, or exact nominal display size.\n        excess = max(effective_n - 1.0, 0.0)\n        divisor = 1.0 + redundancy * (excess ** 1.20)\n        return raw / max(divisor, 1e-12)\n\n    support_a = coalition_support(a_cues)\n    support_b = coalition_support(b_cues)\n\n    active_v = validities[active]\n    descending = np.sort(active_v)[::-1]\n    best_v = float(descending[0])\n    second_v = float(descending[1]) if descending.size > 1 else 0.5\n    top_gap = max(best_v - second_v, 0.0)\n\n    # Ambiguity and uniqueness are complementary continuous gates. Exact ties\n    # have ambiguity one; a clearly unique maximum has ambiguity near zero.\n    scaled_gap = top_gap / max(tie_width, 1e-8)\n    top_ambiguity = float(np.exp(-0.5 * scaled_gap * scaled_gap))\n    unique_strength = 1.0 - top_ambiguity\n\n    top_cues = active[np.isclose(active_v, best_v, atol=1e-12)]\n    anchor_cue = int(np.min(top_cues))\n    anchor_direction = float(directions[anchor_cue])\n\n    if anchor_direction > 0:\n        anchor_indices = b_cues\n        opponent_indices = a_cues\n        anchor_support = support_b\n        opponent_support = support_a\n    else:\n        anchor_indices = a_cues\n        opponent_indices = b_cues\n        anchor_support = support_a\n        opponent_support = support_b\n\n    anchor_effective_n = effective_multiplicity(anchor_indices)\n    opponent_effective_n = effective_multiplicity(opponent_indices)\n\n    if anchor_indices.size > 0:\n        anchor_weights = np.asarray(cue_weight[anchor_indices], dtype=float)\n        anchor_identity_share = float(np.max(anchor_weights)) / max(\n            float(np.sum(anchor_weights)), 1e-12\n        )\n    else:\n        anchor_identity_share = 0.0\n\n    credible_participation = 0.0\n    if opponent_indices.size > 0:\n        opponent_weights = np.asarray(cue_weight[opponent_indices], dtype=float)\n        strongest_opponent = float(np.max(opponent_weights))\n        mean_opponent = float(np.mean(opponent_weights))\n\n        # Restoration uses a smooth participation count rather than Kish\n        # multiplicity. Every opponent contributes in proportion to whether\n        # its weight is credible relative to the strongest opposing reason.\n        relative_opponent_weights = opponent_weights / max(\n            strongest_opponent, 1e-12\n        )\n        participation_gates = 1.0 / (\n            1.0 + np.exp(-12.0 * (\n                relative_opponent_weights - restoration_participation_cutoff\n            ))\n        )\n        credible_participation = float(np.sum(participation_gates))\n\n        # Credibility combines the strongest opposing reason and the typical\n        # opposing reason. A smooth threshold protects anchors from genuinely\n        # weak opposition without suppressing credible intermediate coalitions.\n        opposition_credibility = np.sqrt(\n            np.clip(strongest_opponent * mean_opponent, 0.0, 1.0)\n        )\n        credibility_gate = sigmoid(\n            credibility_slope\n            * (opposition_credibility - credibility_threshold)\n        )\n\n        # Sparse diagnosticity decays continuously with effective multiplicity.\n        # Isolation is likewise continuous: an anchor embedded in a coalition\n        # receives less challenge amplification than a lone anchor.\n        sparse_profile = 1.0 / (\n            1.0\n            + (opponent_effective_n / max(dissent_saturation, 1e-8)) ** 2\n        )\n        isolation = anchor_identity_share ** 1.5\n        challenge_gain = (\n            sparse_dissent\n            * unique_strength\n            * credibility_gate\n            * sparse_profile\n            * isolation\n        )\n        opponent_support *= 1.0 + challenge_gain\n\n    total_support = anchor_support + opponent_support\n    if total_support <= 1e-12:\n        core_evidence = 0.0\n    else:\n        anchor_margin = (anchor_support - opponent_support) / total_support\n        core_evidence = anchor_direction * anchor_margin\n\n    # Under a unique maximum, embedding bounds the leverage of coalition\n    # composition on the normalized margin. Isolated anchors are unchanged.\n    embedded_leverage = (\n        embedded_margin_floor\n        + (1.0 - embedded_margin_floor) * anchor_identity_share\n    )\n    leverage_gate = 1.0 - unique_strength * (1.0 - embedded_leverage)\n    core_evidence *= leverage_gate\n\n    # Restoration grows only when many opponents credibly participate. Unlike\n    # Kish multiplicity, this statistic does not collapse a broad coalition\n    # merely because some contributing reasons are moderately less reliable.\n    anchor_quality = np.clip((best_v - 0.5) / 0.5, 0.0, 1.0)\n    count_restoration = sigmoid(\n        4.0 * (credible_participation - restoration_threshold)\n    )\n    restoration_gate = (\n        restoration_strength\n        * unique_strength\n        * (anchor_identity_share ** 1.7)\n        * (anchor_quality ** 1.3)\n        * count_restoration\n    )\n    restoration_gate = float(np.clip(restoration_gate, 0.0, 0.97))\n    restored_evidence = (\n        (1.0 - restoration_gate) * core_evidence\n        + restoration_gate * anchor_direction\n    )\n\n    # Serial accessibility is calculated only through the continuous top-tie\n    # gate. Serial rank among active cues is meaningful presentation order, not\n    # spatial span. Reliability closeness prevents clearly inferior cues from\n    # acting as serial anchors even when they occur early.\n    serial_numerator = 0.0\n    serial_denominator = 0.0\n    for rank, cue in enumerate(active):\n        closeness = np.exp(\n            -(best_v - validities[cue]) / max(tie_width, 1e-8)\n        )\n        accessibility = closeness * np.exp(-float(rank) / 0.70)\n        serial_numerator += accessibility * float(directions[cue])\n        serial_denominator += accessibility\n\n    if serial_denominator <= 1e-12:\n        serial_evidence = 0.0\n    else:\n        serial_evidence = serial_numerator / serial_denominator\n\n    # Balanced reason competition selectively strengthens tied-top order\n    # resolution while retaining the previous imbalanced-profile baseline.\n    prechallenge_total = support_a + support_b\n    if prechallenge_total <= 1e-12:\n        coalition_balance = 1.0\n    else:\n        coalition_balance = (\n            2.0 * min(support_a, support_b) / prechallenge_total\n        )\n    balance_gate = 0.45 + 0.85 * coalition_balance\n    serial_gate = float(np.clip(\n        tie_order_weight * top_ambiguity * balance_gate, 0.0, 0.95\n    ))\n\n    choice_evidence = (\n        (1.0 - serial_gate) * restored_evidence\n        + serial_gate * serial_evidence\n    )\n\n    logits = beta * np.array(\n        [-0.5 * choice_evidence, 0.5 * choice_evidence], dtype=np.float64\n    )\n    logits = logits - np.max(logits)\n    probs = np.exp(logits)\n    probs /= probs.sum()\n\n    probs = (1.0 - lapse) * probs + lapse * np.array(\n        [0.5, 0.5], dtype=np.float64\n    )\n    probs = np.clip(probs, 0.0, None)\n    total = float(probs.sum())\n    if not np.isfinite(total) or total <= 0.0:\n        return np.array([0.5, 0.5], dtype=np.float64)\n    probs /= total\n    return probs.astype(np.float64)",
  "policy": "def policy(probs):\n    probs = np.asarray(probs, dtype=np.float64)\n    probs = np.clip(probs, 0.0, None)\n    total = float(probs.sum())\n    if not np.isfinite(total) or total <= 0.0:\n        probs = np.ones(len(probs), dtype=np.float64) / float(len(probs))\n    else:\n        probs /= total\n    return int(np.random.choice(len(probs), p=probs))",
  "parameters": {
    "validities": "validities",
    "validity_compression": "[0.16, 0.48]",
    "redundancy": "[0.10, 0.38]",
    "sparse_dissent": "[2.8, 6.2]",
    "dissent_saturation": "[1.20, 2.25]",
    "credibility_threshold": "[0.60, 0.74]",
    "credibility_slope": "[9.0, 16.0]",
    "embedded_margin_floor": "[0.30, 0.55]",
    "restoration_threshold": "[3.25, 3.65]",
    "restoration_participation_cutoff": "[0.52, 0.68]",
    "restoration_strength": "[0.74, 0.97]",
    "tie_width": "[0.004, 0.022]",
    "tie_order_weight": "[0.58, 0.86]",
    "beta": "[2.0, 4.8]",
    "lapse": "[0.0, 0.10]",
    "trait_correlation": "[-1.0, 1.0]"
  },
  "rationale": "This is an isolated restoration-input edit to the accepted iteration-3 candidate. The challenge, credibility, redundancy, embedded-leverage, serial-accessibility, and response equations are unchanged. Only restoration replaces Kish effective multiplicity with a smooth credible-participation sum. Each opponent contributes continuously according to its reliability weight relative to the strongest opponent, so no exact cue count, feature count, cue identity, or spatial rule is introduced. The adjusted restoration-threshold range keeps two- and most three-contributor coalitions below restoration while allowing broadly participating coalitions to cross it. This should preserve intermediate coalition override while increasing isolated-anchor recovery in Experiments 11 and 17 and making the Experiment 6 one-versus-many contrast more negative. The new participation cutoff provides interpretable stable heterogeneity in how much relative reliability a reason needs to count toward broad-coalition saturation. All mechanisms remain history-invariant."
}
```

## Usage

```json
{
  "input_tokens": 45914,
  "output_tokens": 4442
}
```
