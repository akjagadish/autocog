# experiment_attempt_00

## System Prompt

You are a renowned cognitive scientist designing an experiment in the Decision Making (Binary Features) domain.

Your goal is to be an adversarial collaborator: propose a design whose outcomes would be predicted by your advocated theory but NOT by the competing theory. Both are provided below.

A useful proposal targets a *quantitative* dissociation between the two theories — how they respond differently to specific stimuli in addition to differences in overall performance.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

A multi-attribute decision-making experiment. On each trial the subject sees two options (A, B), each described by `n_features` integer expert ratings (`n_features` is set by the length of `validities` you propose). Choose `validities` — one per feature, each in [0.5, 1.0], order free — to fix each expert's advertised accuracy; subjects are told these values up front. Then choose `trial_a_ratings/trial_b_ratings` (each rating value in [0, 1]) so that the intended decision-making theories make distinguishable predictions: avoid degenerate pairs where every theory agrees, and prefer pairs that maximally dissociate the candidate theories. Validities and the trial ratings together define the design; they are fixed across all trials in this experiment. No trial-by-trial correctness feedback. The total number of trials per subject is held at roughly 96: each unique pair is repeated K = max(1, 96 // n_unique_pairs) times in an independently-randomized order per subject.

Subjects see the following instructions:
In this experiment you will repeatedly choose between two fictitious products, A and B. On every trial you will see `n_features` expert ratings for each product (the number of experts is fixed across all trials and is set by the length of `validities`).

Each rating is an integer in [0, 1]. The ratings are displayed as a horizontal filled bar with the numeric value (e.g. "0/1") shown next to it. Higher = more positive.

The same experts (in the same order) provide ratings for both products on every trial. Each expert's accuracy (their validity expressed as a percentage, e.g. "Expert 1 (80%)") is shown next to their rating on every trial AND is also listed up front in an "Expert accuracies" panel.

On each trial, decide which product is of higher quality and press A for product A or B for product B. There is no time limit and no feedback. Note that for the first ~`min_rt_ms` of each trial the answer prompt is hidden and the keys are locked, so subjects first see the full ratings and can answer once the A / B prompt appears — design pairs that actually require comparing the ratings.

Total trials per subject is roughly `MAX_TRIALS`: each unique pair you propose is repeated `K = max(1, MAX_TRIALS // n_unique_pairs)` times in an independently-randomized order per subject.

## ADVOCATED THEORY
**Description:** Adaptive Distinctive Coalition Gating (ADCG) proposes that binary-feature decisions arise from task-adaptive cue weights combining communicated validity, presentation prominence, distributional rarity, and learned cue dependence. Directionally concordant cues are compressed as potentially redundant, while sparse dissent can dominate when its cues have reliably and repeatedly opposed the anchor's cues. Learned anti-concurrence is reliability-sensitive: disagreement near chance is strongly suppressed, whereas well-observed disagreement above a subject-specific threshold receives a bounded nonlinear gain. A profile-driven gate interpolates between coalition comparison and a lexicographic anchor, preserving anchoring against large redundant coalitions while permitting diagnostic opposition to suppress it. For compact opposition, gate suppression is controlled by a selective summary of the strongest reliably learned opposing relationship rather than an indiscriminate average across all cue pairs; larger coalitions retain mean aggregation and strong size decay. In addition, a unique, early-presented validity anchor loses accessibility within the coalition core when it faces compact, reliably anti-concurrent opposition. This attenuation targets residual anchoring without increasing dissent support and vanishes for tied-validity anchors, late anchors, and large opposing coalitions. When top validities are tied, presentation order supplies a bounded anchor but the distinctive-coalition core is attenuated by a stable subject-specific amount. Stable variation in validity attention, order prominence, anti-concurrence threshold and gain, diagnostic selectivity, anchor attenuation, tied-top attenuation, redundancy, gating, and temperature produces structured individual differences without experiment-specific strategies.

**Parameters:**
- validities: validities
- validity_attention: [0.2, 0.9]
- order_prominence: [0.15, 0.7]
- distribution_attention: [0.8, 1.8]
- distinctiveness: [0.35, 0.9]
- dissent_bonus: [1.0, 2.2]
- anti_concurrence_attention: [1.0, 4.8]
- anti_concurrence_threshold: [0.62, 0.76]
- diagnostic_selectivity: [2.0, 8.0]
- anchor_attenuation: [0.8, 3.2]
- redundancy: [0.68, 1.15]
- lex_strength: [0.7, 1.4]
- gate_sharpness: [4.0, 11.0]
- gate_rarity: [1.0, 4.0]
- tie_gate_ceiling: [0.55, 0.85]
- tie_core_attenuation: [0.7, 0.95]
- beta: [0.6, 3.4]

**`predict source code`:**
```python
def predict(parameters, state, history):
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"ADCG expects a (2, n_features) stimulus; got shape {stim.shape}."
        )

    n_features = stim.shape[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    if validities.ndim != 1 or validities.shape[0] != n_features:
        raise ValueError(
            f"validities length {validities.shape[0]} != n_features {n_features}."
        )

    # Positive directions favor B; negative directions favor A.
    directions = np.sign(stim[1] - stim[0])
    active = np.flatnonzero(directions != 0)
    if active.size == 0:
        return np.array([0.5, 0.5], dtype=np.float64)

    validity_attention = float(parameters["validity_attention"])
    order_prominence = float(parameters["order_prominence"])
    distribution_attention = float(parameters["distribution_attention"])
    distinctiveness = float(parameters["distinctiveness"])
    dissent_bonus = float(parameters["dissent_bonus"])
    anti_concurrence_attention = float(parameters["anti_concurrence_attention"])
    anti_concurrence_threshold = float(parameters["anti_concurrence_threshold"])
    diagnostic_selectivity = float(parameters["diagnostic_selectivity"])
    anchor_attenuation = float(parameters["anchor_attenuation"])
    redundancy = float(parameters["redundancy"])
    lex_strength = float(parameters["lex_strength"])
    gate_sharpness = float(parameters["gate_sharpness"])
    gate_rarity = float(parameters["gate_rarity"])
    tie_gate_ceiling = float(parameters["tie_gate_ceiling"])
    tie_core_attenuation = float(parameters["tie_core_attenuation"])
    beta = float(parameters["beta"])

    # Communicated validity is represented on a reliability-evidence scale.
    v = np.clip(validities, 0.500001, 0.999999)
    reliability = np.log(v / (1.0 - v))
    reliability = (reliability - np.mean(reliability)) / (
        np.std(reliability) + 0.35
    )

    # Estimate how often each cue discriminates and how often cue pairs
    # concur. Symmetric pseudocounts make the model well-defined early in
    # the block while allowing randomized task experience to update weights.
    past_a = history.get("option_a_ratings", [])
    past_b = history.get("option_b_ratings", [])
    n_past = min(len(past_a), len(past_b))

    discr_count = np.ones(n_features, dtype=float) * 2.0
    pair_both = np.ones((n_features, n_features), dtype=float) * 2.0
    pair_same = np.ones((n_features, n_features), dtype=float)

    for i in range(n_past):
        pa = np.asarray(past_a[i], dtype=float)
        pb = np.asarray(past_b[i], dtype=float)
        if pa.shape[0] != n_features or pb.shape[0] != n_features:
            continue
        s = np.sign(pb - pa)
        on = np.flatnonzero(s != 0)
        discr_count[on] += 1.0
        for q, j in enumerate(on):
            for k in on[q + 1:]:
                pair_both[j, k] += 1.0
                pair_both[k, j] += 1.0
                if s[j] == s[k]:
                    pair_same[j, k] += 1.0
                    pair_same[k, j] += 1.0

    discr_rate = discr_count / float(n_past + 4.0)
    reference_rate = float(np.mean(discr_rate))
    rarity = np.clip(reference_rate / discr_rate, 0.35, 3.5)

    # Learned anti-concurrence is high only for cue pairs that repeatedly
    # discriminate in opposite directions. Pair-specific observation counts
    # determine reliability, and a steep subject-specific threshold removes
    # weak or chance-level disagreement while retaining systematic dissent.
    anti_concurrence = np.clip(1.0 - pair_same / pair_both, 0.0, 1.0)
    pair_observations = np.maximum(pair_both - 2.0, 0.0)
    pair_confidence = pair_observations / (pair_observations + 2.0)
    pair_confidence *= np.clip((pair_observations - 1.0) / 3.0, 0.0, 1.0)
    threshold_baseline = 1.0 / (
        1.0 + np.exp(-18.0 * (0.5 - anti_concurrence_threshold))
    )
    thresholded_anti = 1.0 / (
        1.0 + np.exp(-18.0 * (anti_concurrence - anti_concurrence_threshold))
    )
    thresholded_anti = np.clip(
        (thresholded_anti - threshold_baseline)
        / max(1.0 - threshold_baseline, 1e-12),
        0.0,
        1.0,
    )
    learned_anti = pair_confidence * thresholded_anti

    # Baseline cue accessibility combines instructed validity, serial
    # prominence, and learned distributional rarity.
    if n_features > 1:
        position = 1.0 - np.arange(n_features, dtype=float) / (n_features - 1.0)
    else:
        position = np.ones(1, dtype=float)
    cue_weight = np.exp(
        validity_attention * reliability
        + order_prominence * position
        + distribution_attention * np.log(rarity)
    )

    # Cues that historically concur with their current coalition partners
    # are treated as less independent. A cue with no partner is not given
    # this historical redundancy penalty.
    for j in active:
        partners = [
            int(k) for k in active
            if k != j and directions[k] == directions[j]
        ]
        if partners:
            concurrence = [pair_same[j, k] / pair_both[j, k] for k in partners]
            corr_load = float(np.mean(concurrence))
            cue_weight[j] /= 1.0 + redundancy * corr_load

    a_cues = np.flatnonzero(directions < 0)
    b_cues = np.flatnonzero(directions > 0)
    n_a = int(a_cues.size)
    n_b = int(b_cues.size)

    # Lexicographic anchor: highest communicated validity among currently
    # discriminating cues, with stable presentation order breaking ties.
    active_validity = validities[active]
    best_validity = float(np.max(active_validity))
    best_candidates = active[np.isclose(active_validity, best_validity, atol=1e-10)]
    lex_cue = int(np.min(best_candidates))
    lex_direction = float(directions[lex_cue])

    # A global top-validity tie attenuates profile-based singleton
    # amplification, preventing the first cue from receiving both a strong
    # order anchor and a full distinctiveness bonus.
    sorted_v = np.sort(validities)[::-1]
    if sorted_v.size >= 2:
        top_gap = float(sorted_v[0] - sorted_v[1])
        global_top_tie = float(np.exp(-80.0 * top_gap))
    else:
        global_top_tie = 1.0
    tie_core_multiplier = 1.0 - tie_core_attenuation * global_top_tie

    # Current-profile distinctiveness: members of the smaller directional
    # coalition stand out, while each coalition's accumulated contribution
    # is divided by a redundancy term.
    if n_a > 0 and n_b > 0:
        if n_a < n_b:
            cue_weight[a_cues] *= (float(n_b) / float(n_a)) ** (
                distinctiveness * tie_core_multiplier
            )
        elif n_b < n_a:
            cue_weight[b_cues] *= (float(n_a) / float(n_b)) ** (
                distinctiveness * tie_core_multiplier
            )

        # Sparse evidence opposing the validity-defined anchor receives its
        # ordinary bounded bonus. Additional influence is restricted to
        # dissenting cues with reliably learned above-threshold opposition.
        dissent_cues = a_cues if lex_direction > 0 else b_cues
        anchor_cues = b_cues if lex_direction > 0 else a_cues
        n_dissent = int(dissent_cues.size)
        if n_dissent > 0:
            for j in dissent_cues:
                learned_diagnosticity = 0.0
                if anchor_cues.size > 0:
                    learned_diagnosticity = float(
                        np.mean(learned_anti[j, anchor_cues])
                    )
                bonus = 1.0 + (dissent_bonus / float(n_dissent)) * (
                    1.0
                    + anti_concurrence_attention * learned_diagnosticity
                )
                cue_weight[j] *= bonus

            # A unique and presentation-prominent validity anchor becomes
            # less accessible in the coalition core when compact opposition
            # has a reliably learned anti-concurrent relationship with it.
            # Active-cue validity uniqueness leaves tied-top profiles intact;
            # squared prominence and size decay protect late anchors and
            # anchors facing large, plausibly redundant coalitions.
            if active_validity.size >= 2:
                sorted_active_v = np.sort(active_validity)[::-1]
                active_gap = float(sorted_active_v[0] - sorted_active_v[1])
                anchor_uniqueness = 1.0 - np.exp(-80.0 * active_gap)
            else:
                anchor_uniqueness = 1.0
            anchor_diagnosticity = float(
                np.max(learned_anti[dissent_cues, lex_cue])
            )
            compact_decay = np.exp(-1.5 * float(n_dissent - 1))
            anchor_signal = (
                anchor_uniqueness
                * float(position[lex_cue] ** 2)
                * anchor_diagnosticity
                * compact_decay
            )
            cue_weight[lex_cue] *= np.exp(
                -anchor_attenuation * anchor_signal
            )

    support_a = 0.0
    support_b = 0.0
    if n_a > 0:
        support_a = float(np.sum(cue_weight[a_cues])) / (float(n_a) ** redundancy)
    if n_b > 0:
        support_b = float(np.sum(cue_weight[b_cues])) / (float(n_b) ** redundancy)

    scale = support_a + support_b
    core_evidence = (support_b - support_a) / max(scale, 1e-12)

    # A near tie among the two globally strongest instructed validities
    # raises the stable-order gate, but anchoring has a subject-specific
    # ceiling rather than becoming obligatorily lexicographic.
    tied_top_gate = tie_gate_ceiling * global_top_tie

    # Profile-driven anchoring occurs when the earliest discriminating cue
    # is on an isolated minority side. It is attenuated when a sparse cue in
    # the opposing coalition is historically rare or reliably
    # anti-concurrent, while a large opposition remains interpretable as
    # redundant evidence.
    first_cue = int(active[0])
    first_side_count = n_b if directions[first_cue] > 0 else n_a
    other_side_count = n_a if directions[first_cue] > 0 else n_b
    if first_side_count > 0 and other_side_count > 0:
        isolation = 1.0 - float(first_side_count) / float(other_side_count)
        minority_first = float(first_side_count < other_side_count)
        opposing_cues = a_cues if directions[first_cue] > 0 else b_cues
        first_side_cues = b_cues if directions[first_cue] > 0 else a_cues
        opposing_rarity = float(np.max(np.maximum(np.log(rarity[opposing_cues]), 0.0)))
        opposing_distinctiveness = opposing_rarity / (
            np.log(3.5) * np.sqrt(float(other_side_count))
        )

        # For compact opposition, a reliability-weighted soft maximum lets
        # one strongly diagnostic relation disengage the anchor without
        # being diluted by weak pairings. Larger coalitions retain mean
        # aggregation, and all configurations retain exponential size decay.
        opposition_relations = learned_anti[
            np.ix_(opposing_cues, first_side_cues)
        ].reshape(-1)
        if other_side_count <= 3 and opposition_relations.size > 1:
            select_logits = diagnostic_selectivity * (
                opposition_relations - np.max(opposition_relations)
            )
            select_weights = np.exp(select_logits)
            select_weights /= np.sum(select_weights)
            learned_opposition = float(
                np.sum(select_weights * opposition_relations)
            )
        else:
            learned_opposition = float(np.mean(opposition_relations))
        learned_opposition *= np.exp(-1.5 * float(other_side_count - 1))
        opposing_distinctiveness += (
            anti_concurrence_attention * learned_opposition
        )
    else:
        isolation = 0.0
        minority_first = 0.0
        opposing_distinctiveness = 0.0

    profile_gate = minority_first / (
        1.0 + np.exp(-gate_sharpness * (isolation - 0.30))
    )
    profile_gate *= np.exp(-gate_rarity * opposing_distinctiveness)
    gate = 1.0 - (1.0 - tied_top_gate) * (1.0 - profile_gate)
    gate = float(np.clip(gate, 0.0, 1.0))

    choice_evidence = (
        (1.0 - gate) * core_evidence
        + gate * lex_strength * lex_direction
    )

    logits = beta * np.array([-0.5 * choice_evidence, 0.5 * choice_evidence])
    logits = logits - np.max(logits)
    probs = np.exp(logits)
    probs /= probs.sum()
    return probs.astype(np.float64)
```

**`policy source code`:**
```python
def policy(probs):
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        probs = np.ones(len(probs), dtype=np.float64) / float(len(probs))
    else:
        probs /= total
    return int(np.random.choice(len(probs), p=probs))
```


## COMPETING THEORY
**Description:** Static Configuration-Contingent Integration (SCCI) claims that people form a fixed, instruction-based representation of cue reliability and apply it to the directional evidence profile on each trial. Each discriminating cue contributes reliability-weighted evidence, so independently supporting cues accumulate, while concordant cues are compressed as potentially redundant. This compression increases moderately convexly with coalition size, reflecting the declining informational value of each additional concordant cue. A bounded configuration gate supplements integration: strong protection of a uniquely most-valid cue is restricted to profiles in which that cue is isolated, has a sufficiently large communicated-validity advantage, and faces multiple concordant opponents. Cue uniqueness functions primarily as a tie detector, while a separate raw validity-gap criterion determines whether restoration is warranted. The transition to restoration is sharp, allowing an isolated anchor to be weak against one credible challenger but strongly protected against a redundant multi-cue bloc. Compact challenge amplification is strictly limited to isolated anchors and therefore cannot create general primacy effects when the anchor has allies. When the most-valid discriminating cues have equal communicated validity, they remain exchangeable in the integrator, but stable display order supplies a bounded tie-breaking anchor. Choices are history-invariant because concurrence, anti-concurrence, and discrimination frequency are not learned without correctness feedback. Stable profile heterogeneity arises from subject-level variation in validity sensitivity, coalition integration, redundancy, isolated-anchor challenge and restoration, tie-order bias, temperature, and lapse.

**Parameters:**
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

**`predict source code`:**
```python
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
```

**`policy source code`:**
```python
def policy(probs):
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        probs = np.ones(len(probs), dtype=np.float64) / float(len(probs))
    else:
        probs /= total
    return int(np.random.choice(len(probs), p=probs))
```


## ALREADY-EXPLORED EXPERIMENTS (do not repeat)
[0] Eight experts have strictly ordered, widely separated validities. Every pair creates a conflict between Take The Best and Tallying: the highest-validity discriminating expert favors one option, while the majority of discriminating experts favors the other. The design orthogonally balances whether A or B is favored by the decisive expert and manipulates the opposing tally margin. In trials where Expert 1 discriminates, the tally margins are 2, 4, and 6; where Expert 1 ties and Expert 2 is the first discriminating expert, the margins are 1, 3, and 5. Take The Best therefore predicts the same choice probability for the option favored by the first discriminating expert on every trial: epsilon/2 + (1-epsilon)*sigmoid(beta), invariant to both cue rank and tally margin. Tallying predicts that this option is chosen below chance, with probability epsilon/2 + (1-epsilon)*sigmoid(-beta*m), and predicts a systematic decrease as the opposing margin m increases. Thus, the critical dissociation is both directional and quantitative: invariant support for the top-cue winner under TTB versus increasingly strong rejection of it under Tallying. Swapping A and B for each evidence pattern controls response-side preferences. The 12 unique pairs yield exactly 96 trials with eight repetitions per pair.

[1] This design targets the parameter-free prediction of Tallying on exactly balanced evidence. On every trial, A and B win on the same number of discriminating features, so Tallying predicts P(A)=P(B)=0.5 for every beta and epsilon. Nevertheless, each pair has a uniquely defined first discriminating expert in descending-validity order. Take The Best therefore predicts choice of that expert's favored option with probability epsilon/2 + (1-epsilon)*sigmoid(beta), which is strictly above chance throughout the stated parameter ranges. The six underlying evidence patterns vary both the rank of the first discriminating expert (1, 3, or 5) and the total number of discriminating experts (2, 4, 6, or 8), while preserving an exactly tied tally. Take The Best predicts the same above-chance preference across these manipulations, whereas Tallying remains exactly at chance. Each pattern is paired with an A/B reversal, controlling response-side bias. Thus the critical statistic is the probability of choosing the option favored by the first discriminating expert: exactly 0.5 under Tallying versus a common value above 0.5 under Take The Best. The 12 unique pairs are repeated eight times for 96 trials.

[2] The design exploits a sharp conflict-gated crossover unique to CGRDA while holding Take The Best's decisive cue constant. Expert 5 has the highest validity (0.95) and always discriminates in favor of the designated TTB winner. Each family contains an exactly balanced 2-versus-2 trial and a matched 3-versus-1 trial differing only in Expert 1's direction. On balanced trials, the final discriminating expert (Expert 6) opposes Expert 5. TTB therefore chooses Expert 5's option with the same probability q = epsilon/2 + (1-epsilon)*sigmoid(beta) on every trial. CGRDA instead predicts the Expert-6 option on every balanced trial throughout its parameter ranges: tally balance fully opens the recency gate, and recency_strength is at least 1.15 while normalized core evidence is bounded in magnitude by 1. On matched imbalanced trials, reversing Expert 1 creates three endorsements for the TTB winner versus one final endorsement for its opponent. The imbalance of two suppresses recency by at least exp(-5), while the early Expert-1 endorsement and two additional concordant endorsements make CGRDA favor the TTB winner. Thus, the critical statistic is the probability of choosing the Expert-5 winner: TTB predicts invariance between balanced and imbalanced conditions, whereas CGRDA predicts a crossover from below chance on balanced trials to above chance on imbalanced trials. Moving the second pro-TTB endorsement across Experts 2, 3, and 4 provides an additional serial-position manipulation: TTB remains invariant, while CGRDA's integrated evidence changes with primacy. Exact A/B reversals control response-side bias. The 12 unique pairs are each repeated eight times, yielding 96 trials.

[3] This design isolates CGRDA's serial-position weighting and redundancy discounting while holding constant every determinant of Take The Best. All six cues discriminate, Expert 5 (index 4) is uniquely most valid at 0.95, and it always favors the designated TTB winner. Every trial also has the same 4-versus-2 endorsement tally, and the final cue always favors the TTB winner. TTB therefore predicts one common probability q = epsilon/2 + (1-epsilon)*sigmoid(beta) of selecting the designated winner across all patterns. The two cues opposing that winner are moved among the first four serial positions. CGRDA predicts a sharp position-dependent reversal: when the compact opposing pair includes the highly reliable first-position cue (sets {1,2}, {1,3}, or {1,4} in one-based numbering), primacy and redundancy discounting allow those two early endorsements to defeat four later, partly redundant endorsements, producing below-chance selection of the TTB winner. When the opposing pair excludes the first cue ({2,3}, {2,4}, or {3,4}), the TTB winner receives the dominant first-position endorsement and should be selected above chance. This is not a recency-gate effect: the tally imbalance is always two, limiting the gate to exp(-5) or less, and the last cue's direction is fixed. Thus the critical quantitative statistic is the change in TTB-winner choice probability depending on whether Expert 1 opposes or supports that winner: TTB predicts exactly zero change, whereas CGRDA predicts a large crossover. Exact A/B reversals control response-side preference. The 12 unique pairs are repeated eight times for 96 trials.

[4] The validity profile contains four validity-matched cue pairs but remains broad enough to force DCSC into its compensatory regime. Using the most dominance-favoring allowed profile-shape weight, the profile's dominance score is approximately 0.212, still below the minimum dominance threshold of 0.285; hence the dominance gate is at most about 0.006. On every trial, the two highest-validity experts discriminate in opposite directions. Because their validities are tied, Take The Best uses its stable ordering rule and follows Expert 1, predicting the same probability q = epsilon/2 + (1-epsilon)*sigmoid(beta) for Expert 1's option on every trial. DCSC instead averages the opposing tied anchors, making anchor evidence exactly zero. One or more lower-validity experts then unanimously support Expert 2's option, so DCSC's coalition evidence always points against the TTB winner and predicts selection of the TTB winner below chance. Nested conditions increase the size of this opposing coalition from one to six lower experts, providing a graded DCSC signature while TTB remains exactly invariant. The two single-supporter conditions also contrast a relatively reliable lower expert (82%) with a weaker one (65%), testing DCSC's compressed reliability weighting without affecting TTB. Each pattern has an exact A/B reversal, controlling response-side preference. The 12 unique pairs are repeated eight times, yielding 96 trials.

[5] The broad validity profile forces DCSC into its compensatory regime while preserving a unique highest-validity cue. With diagnosticities [0.70, 0.64, 0.58, 0.52, 0.46, 0.40, 0.34, 0.20], the maximum DCSC dominance score is approximately 0.215, below the minimum dominance threshold of 0.285; even at the least decisive allowed gap sensitivity, the dominance gate is below 0.008. In every underlying pattern, Expert 1 discriminates for a designated top-cue winner, so Take The Best always selects that option with the same probability q = epsilon/2 + (1-epsilon)*sigmoid(beta), regardless of all lower cues. DCSC predicts a distinctive crossover. When only one lower expert opposes Expert 1, the top-cue winner remains weakly favored because its reliability weight is larger. This preference should be stronger when the lone opponent is the weakest expert (Expert 8) rather than Expert 2, directly testing compressed reliability weighting. Once two or more lower experts form the opposing coalition, DCSC predicts the coalition's option above chance, with increasingly strong but diminishing support as the coalition grows from two to three, five, and seven experts. Thus TTB predicts complete invariance, whereas DCSC predicts both a directional crossover between one- and multi-opponent trials and a nonlinear coalition-size gradient. Unlike the previously explored tied-anchor design, the highest-validity anchor is unique here and DCSC initially agrees with TTB before lower-cue accumulation overturns it. Exact A/B reversals control response-side preferences. The 12 unique pairs are repeated eight times, yielding 96 trials.

[6] This design targets ADCG's history-dependent learning of selective anti-concurrence, a mechanism entirely absent from Take The Best. Expert 1 is the unique validity anchor (95%) and favors the designated TTB winner in every pair, so TTB predicts one constant probability q = epsilon/2 + (1-epsilon)*sigmoid(beta) of choosing that option, invariant across stimulus type, repetition, and trial position. Five diagnostic-opposition patterns share directions [anchor, anchor, anchor, tie, dissent, tie, tie]: the late Expert 5 repeatedly opposes Experts 1–3 whenever it discriminates. A control pattern has directions [anchor, dissent, anchor, tie, tie, tie, tie]: Expert 2 opposes the anchor there but concurs with it throughout the five diagnostic patterns. Across the randomized block, Expert 5 therefore acquires strong, well-observed anti-concurrence with the anchor coalition, whereas Expert 2's occasional opposition remains below ADCG's anti-concurrence threshold because it usually concurs with that coalition. Experts 2 and 5 have identical advertised validity (72%), and the diagnostic dissenter is presented later, making its predicted learned advantage conservative rather than a simple validity or order effect. ADCG predicts an experience-dependent reduction in choices of the Expert-1 winner on diagnostic-opposition trials: learned diagnostic gain amplifies Expert 5, attenuates the unique early anchor, and suppresses residual anchoring. The corresponding change should be much smaller on control trials and can produce a growing diagnostic-versus-control gap, potentially including below-chance selection of the TTB winner late in the block. TTB predicts exactly zero condition difference and zero early-to-late change. The five diagnostic pairs differ only in values shared by A and B on nondiscriminating cues, so ADCG treats their current directional evidence identically while their multiplicity establishes the intended 5:1 history distribution. Exact A/B reversals control response-side preferences. The 12 unique pairs are repeated eight times, yielding 96 trials; the critical analysis is the probability of choosing the Expert-1 winner by condition and experience bin.

[7] This design targets ADCG's learned distributional-rarity weighting while holding learned anti-concurrence near chance, separating the proposed rarity mechanism from the anti-concurrence manipulation explored previously. Expert 1 is uniquely most valid (95%) and discriminates on every trial, so Take The Best always follows Expert 1 and predicts the same probability q = epsilon/2 + (1-epsilon)*sigmoid(beta) for its favored option across stimulus types and experience. The critical matched targets are patterns 1–2 and their A/B reversals. In both, Experts 1 and 3 support the TTB winner and one 72%-valid dissenter opposes them; the dissenter is Expert 2 in the common-dissenter target and Expert 5 in the rare-dissenter target. Across the complete block, Expert 2 discriminates in four of six underlying patterns, whereas Expert 5 discriminates in only two. Whenever either dissenter and the anchor coalition are jointly active, it concurs and opposes equally often, keeping pairwise anti-concurrence around 0.5 and below ADCG's threshold. Early in the block, before distributional frequencies are learned, ADCG predicts stronger opposition from Expert 2 because it is presented earlier than the equally valid Expert 5; hence fewer Expert-1-winner choices in the common-dissenter target. With experience, Expert 5 becomes approximately twice as rare as Expert 2. Even at the minimum distribution-attention setting, its rarity advantage outweighs Expert 2's maximum order-prominence advantage; rarity also selectively suppresses the profile gate that otherwise preserves the anchor. ADCG therefore predicts a reversal of the target contrast: late in the block, Expert-1-winner choices should be lower with the rare Expert-5 dissenter than with the common Expert-2 dissenter. The critical quantitative interaction is thus (rare minus common) by experience bin: TTB predicts exactly zero throughout, whereas ADCG predicts a change from positive early to negative late. The remaining patterns establish the intended discrimination frequencies and balance concurrence without feedback. Exact A/B reversals control response-side preference. Twelve unique pairs repeated eight times yield 96 trials.

[8] This design isolates ADCG's learned within-coalition dependence while SCCI remains history-invariant. Expert 5 is the unique 95%-valid anchor. Experts 1–4 all have validity 72%, arranged as an outer pair (Experts 1 and 4) and a middle pair (Experts 2 and 3). Across the four history-building patterns and their A/B reversals, Experts 1 and 4 always discriminate concordantly, whereas Experts 2 and 3 always discriminate in opposite directions. Each lower expert nevertheless concurs with the anchor on half of these patterns and opposes it on half, equating lower-cue validity, discrimination frequency, and relationships with the anchor. The two critical targets are configuration-matched: the anchor supports one product while either the outer pair or the middle pair unanimously supports the other; the unused pair is nondiscriminating. SCCI assigns identical evidence to these targets because both contain one isolated 95% anchor against two 72% opponents. Its large validity gap activates isolated-anchor restoration, and it predicts the same stable, above-chance preference for the anchor's product in both targets at every point in the experiment. ADCG instead learns that the outer pair is highly concurrent and therefore redundant, while the middle pair is usually anti-concurrent and receives little historical redundancy discount when it happens to agree on its target. Relationships between each target cue and the anchor remain approximately 60% opposing—below ADCG's anti-concurrence thresholds—and are matched across pairs, so the key difference is coalition dependence rather than diagnostic dissent. Distributional rarity is also matched: every lower expert discriminates on five of the six underlying patterns. Presentation positions are deliberately balanced in summed prominence (outer positions 1 and 4 versus middle positions 2 and 3); convex order weighting may make the outer coalition slightly stronger initially, but learned redundancy should decisively reverse that contrast. Thus ADCG predicts an experience-dependent increase in P(anchor choice | outer-pair target) relative to P(anchor choice | middle-pair target), potentially with the middle coalition defeating the anchor late in the block. SCCI predicts an exactly zero target contrast and zero experience interaction. Because the first active cue on either target belongs to the two-cue opposing coalition rather than the late anchor, ADCG's minority-first profile gate is closed, exposing the coalition-learning effect in its core comparison. Exact A/B reversals control response-side preference. The 12 unique pairs are repeated eight times, yielding 96 trials.

## RESPONSE FORMAT
Return a JSON object with the following fields:
- rationale: Reasoning behind this experimental design; used when interpreting results.
- validities: Per-expert validities, one per feature. Each must be in [0.5, 1.0]; order is free (no descending requirement — theories that depend on validity order re-sort internally). Length determines n_features for the whole experiment and must match the rating-list length in every trial pair. Pick a spread (at least one high validity and at least one low one) — uniform validities (e.g. all 0.7) make many candidate theories indistinguishable, so spread them out.
- trial_a_ratings: List of option-A rating vectors, one per trial. Each inner list has length equal to len(validities); each value is binary (0 or 1). `trial_a_ratings[i]` pairs with `trial_b_ratings[i]` on trial i.
- trial_b_ratings: List of option-B rating vectors, one per trial. Same length and shape constraints as `trial_a_ratings`. Pick trials that let the intended theories be dissociated; avoid trials where every theory agrees.


## Response

```json
{
  "rationale": "This design isolates ADCG's selective use of the strongest reliably learned opposing relationship in a compact two-cue coalition, together with diagnostic dissent gain and attenuation of an early unique anchor. Expert 1 is the unique 95%-valid anchor and discriminates on every trial. Experts 2, 3, 5, and 6 all have validity 72% and each discriminates in exactly five of the six underlying patterns, equating their advertised reliability and asymptotic rarity. The first two patterns are the critical targets. In the diagnostic target, Experts 3 and 5 oppose the anchor; in the control target, Experts 2 and 6 oppose it. Both targets therefore present exactly one 95% anchor against two 72% opponents. SCCI assigns them identical evidence and predicts an exactly zero target difference at every experience level because it ignores presentation position and history, and its isolated-anchor restoration depends only on the shared validity gap and coalition counts. Across the four history-building patterns, Expert 3 always opposes Expert 1, so their anti-concurrence approaches its reliable, above-threshold regime. Each of Experts 2, 5, and 6 instead opposes Expert 1 on only two of four builders; including its target occurrence, each has three oppositions and two concurrences with the anchor, leaving its smoothed anti-concurrence below ADCG's threshold. On the diagnostic target, ADCG's reliability-weighted selective maximum can consequently detect the strong Expert-3 relationship without diluting it by Expert 5's weak relationship. This suppresses the profile gate protecting the isolated early anchor, amplifies Expert 3's dissent, and attenuates Expert 1 in the coalition core. Neither control opponent receives these learned effects. Historical concurrence within the two target coalitions is matched: Experts 3 and 5 concur on three of their five joint observations, as do Experts 2 and 6. Thus learned within-coalition redundancy cannot explain the critical contrast. The main quantitative prediction is an experience-dependent decrease in anchor choices on the diagnostic target relative to the control target: the late-minus-early change in [P(anchor choice | diagnostic) - P(anchor choice | control)] should be negative under ADCG but exactly zero under SCCI. Any initial serial-position difference can be estimated in the early trials rather than mistaken for learning; the opposing pairs also have matched summed prominence. Exact A/B reversals preserve every cue relationship while controlling response-side bias. The 12 unique pairs are repeated eight times for 96 trials.",
  "validities": [
    0.95,
    0.72,
    0.72,
    0.55,
    0.72,
    0.72
  ],
  "trial_a_ratings": [
    [
      0,
      0,
      1,
      0,
      1,
      0
    ],
    [
      0,
      1,
      0,
      0,
      0,
      1
    ],
    [
      0,
      0,
      1,
      0,
      0,
      0
    ],
    [
      0,
      0,
      1,
      1,
      1,
      1
    ],
    [
      0,
      1,
      1,
      0,
      0,
      1
    ],
    [
      0,
      1,
      1,
      1,
      1,
      0
    ],
    [
      1,
      0,
      0,
      0,
      0,
      0
    ],
    [
      1,
      0,
      0,
      0,
      0,
      0
    ],
    [
      1,
      1,
      0,
      1,
      1,
      1
    ],
    [
      1,
      1,
      0,
      0,
      0,
      0
    ],
    [
      1,
      0,
      0,
      1,
      1,
      0
    ],
    [
      1,
      0,
      0,
      0,
      0,
      1
    ]
  ],
  "trial_b_ratings": [
    [
      1,
      0,
      0,
      0,
      0,
      0
    ],
    [
      1,
      0,
      0,
      0,
      0,
      0
    ],
    [
      1,
      1,
      0,
      1,
      1,
      1
    ],
    [
      1,
      1,
      0,
      0,
      0,
      0
    ],
    [
      1,
      0,
      0,
      1,
      1,
      0
    ],
    [
      1,
      0,
      0,
      0,
      0,
      1
    ],
    [
      0,
      0,
      1,
      0,
      1,
      0
    ],
    [
      0,
      1,
      0,
      0,
      0,
      1
    ],
    [
      0,
      0,
      1,
      0,
      0,
      0
    ],
    [
      0,
      0,
      1,
      1,
      1,
      1
    ],
    [
      0,
      1,
      1,
      0,
      0,
      1
    ],
    [
      0,
      1,
      1,
      1,
      1,
      0
    ]
  ]
}
```

## Usage

```json
{
  "input_tokens": 10935,
  "output_tokens": 4960
}
```
