# Round 7 — Theories

**Verdict:** `new_theory` (slot 2 replaced)

## Starting theories

### slot 1 — `pi_3` — SURVIVED ✓

**Description:** Recency-Gated Reason Overwrite with Processing Fatigue. People inspect cues sequentially in descending order of instructed validity and continue after finding a discriminating cue. An attended discriminating cue establishes a provisional choice, and each subsequently attended discriminating cue can overwrite that choice. Consequently, the final attended reason has disproportionate control. Occasional failures to attend a cue preserve an earlier reason, while response lapses dilute strong recency effects. In addition, processing more than two discriminating reasons produces task-invariant update fatigue: the retained decision is expressed with progressively lower reliability as the discriminating-cue count increases. This preserves strong second-reason overwrite on short conflicts while moderating near-deterministic last-reason control on longer sequences.

**Rationale:** This is a minimal extension of the accepted recency-overwrite model. The cue scan and overwrite equations are unchanged. The only mechanistic addition is a discriminating-cue-count fatigue gate that begins after the second reason, together with a broader and slightly lower lapse range. Two-reason trials therefore retain the strong overwrite needed for Experiment 2, whereas long reason sequences are pulled modestly toward uncertainty, reducing the excessive Experiment-1 contrast. Lower average lapse simultaneously strengthens anti-TTB behavior in Experiment 2. Broad subject-level ranges for fatigue and lapse should also increase the previously underestimated between-subject variability. The gate is task-invariant and depends only on processing load, not experiment identity or stimulus-specific switches.

**Parameters:**
  - `validities`: `validities`
  - `cue_attention`: `[0.95, 1.0]`
  - `overwrite_rate`: `[0.95, 1.0]`
  - `update_fatigue`: `[0.06, 0.17]`
  - `lapse_rate`: `[0.15, 0.41]`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history):
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Recency-Gated Reason Overwrite expects shape (2, n_features); got {stim.shape}."
        )

    n_features = stim.shape[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} != n_features {n_features}."
        )

    attention = float(parameters["cue_attention"])
    overwrite = float(parameters["overwrite_rate"])
    fatigue = float(parameters["update_fatigue"])
    lapse = float(parameters["lapse_rate"])

    # Stable sorting represents the displayed high-to-low validity scan;
    # ties retain their display order.
    cue_order = np.argsort(-validities, kind="stable")
    diff = stim[0] - stim[1]

    # Exact marginal distribution over the provisional state:
    # A selected, B selected, or no discriminating cue encoded yet.
    p_a, p_b, p_uncommitted = 0.0, 0.0, 1.0
    discriminating_count = 0

    for j in cue_order:
        direction = diff[j]
        if direction == 0:
            continue

        discriminating_count += 1
        old_a, old_b, old_u = p_a, p_b, p_uncommitted

        if direction > 0:
            # An attended A cue initializes an uncommitted decision and
            # overwrites a conflicting B decision with the overwrite rate.
            p_a = old_a + attention * overwrite * old_b + attention * old_u
            p_b = old_b * (1.0 - attention * overwrite)
            p_uncommitted = old_u * (1.0 - attention)
        else:
            p_b = old_b + attention * overwrite * old_a + attention * old_u
            p_a = old_a * (1.0 - attention * overwrite)
            p_uncommitted = old_u * (1.0 - attention)

    # If no discriminating cue was encoded, either response is an equal guess.
    p_core = np.array([
        p_a + 0.5 * p_uncommitted,
        p_b + 0.5 * p_uncommitted
    ], dtype=np.float64)

    # Processing the first reason and its immediate successor is reliable.
    # Additional discriminating updates progressively weaken expression of
    # the retained choice without disrupting the crucial second-cue reversal.
    excess_updates = max(0, discriminating_count - 2)
    retention = (1.0 - fatigue) ** excess_updates
    p_core = retention * p_core + (1.0 - retention) * np.array([0.5, 0.5])

    # Independent execution/inattention lapse.
    probs = (1.0 - lapse) * p_core + lapse * np.array([0.5, 0.5])
    probs = np.clip(probs, 0.0, None)
    probs /= probs.sum()
    return probs
```

**`policy(probs)`:**
```python
def policy(probs):
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))
```


### slot 2 — `pi_9` — KILLED ✗

**Description:** Distribution-Calibrated Competitive Accumulation with Susceptibility-Dominant Context Learning. People inspect discriminating cues in descending instructed-validity order and encode each attended cue as signed evidence in a continuously evolving competitive accumulator. Opposing evidence inhibits the active commitment, while a continuous experiment-level task set controls retention and overwrite. The task set is learned primarily from how readily opposing runs reverse a reference accumulator across the experiment's sequence families. Coarse ordinal properties such as terminal singletons, two-run structure, and reversal-location concentration provide only weak, centered calibration rather than directly producing overwrite. Reliability-weighted coalitions can reverse the sequential state, but their access to choice is proportional to normalized evidence margin. Physical gaps are not represented, and reliability depends on conflict geometry and evidence margin rather than discriminating-cue count.

**Rationale:** This is a minimal edit of the accepted iteration-7 candidate. The arithmetic model-implied reversal-susceptibility statistic, reference accumulator, learning rate, bounded current-trial contribution, static validity weighting, coalition-margin gate, local competition rule, response mapping, parameter ranges, and exclusion of physical gaps are unchanged. Only the context-score mapping is revised. The direct coefficients on terminal-singleton rate, reversal concentration, and two-run frequency are reduced from 3.0, 3.0, and 2.0 to 1.2, 1.2, and 0.8; entropy and switch-density effects are also conservatively reduced. These coarse statistics are centered around neutral reference values, with a 1.30 intercept preserving the accepted model's typical operating level rather than causing a global collapse in overwrite. Consequently, merely having a two-block or terminal-singleton display should no longer create excessive overwrite in Experiments 6 and 8 or a large within-task contrast in Experiment 5. Cross-experiment differentiation is instead carried more proportionally by the already accepted reversal-susceptibility term, which asks whether opposing runs are strong enough to overcome an incumbent in sequential evidence units. No upper-tail or terminal-weighted aggregation is introduced because that change was rejected. The edit therefore targets context miscalibration without globally changing terminal competition or risking the accepted fits in Experiments 7, 10, 12, and 14.

**Parameters:**
  - `validities`: `validities`
  - `attention_rate`: `[0.88, 1.0]`
  - `integration_retention`: `[0.84, 0.97]`
  - `overwrite_retention`: `[0.14, 0.36]`
  - `conflict_inhibition`: `[0.35, 1.20]`
  - `coalition_weight`: `[0.30, 0.62]`
  - `validity_sensitivity`: `[0.15, 0.45]`
  - `context_sensitivity`: `[1.4, 2.4]`
  - `context_threshold`: `[1.0, 1.6]`
  - `context_learning_rate`: `[0.05, 0.12]`
  - `susceptibility_coupling`: `[0.60, 1.10]`
  - `response_gain`: `[1.8, 3.8]`
  - `lapse_rate`: `[0.04, 0.15]`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history) -> np.ndarray:
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Competitive accumulation expects shape (2, n_features); got {stim.shape}."
        )

    n_features = stim.shape[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} != n_features {n_features}."
        )

    attention = float(parameters["attention_rate"])
    integration_retention = float(parameters["integration_retention"])
    overwrite_retention = float(parameters["overwrite_retention"])
    conflict_inhibition = float(parameters["conflict_inhibition"])
    coalition_weight = float(parameters["coalition_weight"])
    validity_sensitivity = float(parameters["validity_sensitivity"])
    context_sensitivity = float(parameters["context_sensitivity"])
    context_threshold = float(parameters["context_threshold"])
    learning_rate = float(parameters["context_learning_rate"])
    susceptibility_coupling = float(parameters["susceptibility_coupling"])
    response_gain = float(parameters["response_gain"])
    lapse = float(parameters["lapse_rate"])

    cue_order = np.argsort(-validities, kind="stable")

    def ordinal_summary(a, b):
        a = np.asarray(a, dtype=float)
        b = np.asarray(b, dtype=float)
        if a.ndim != 1 or b.ndim != 1 or a.size != b.size:
            return None
        d = a - b
        ordered_idx = [int(j) for j in cue_order if j < d.size and d[j] != 0]
        if not ordered_idx:
            return None
        directions = np.asarray([np.sign(d[j]) for j in ordered_idx], dtype=float)
        m = directions.size
        switches = np.flatnonzero(directions[1:] != directions[:-1]) + 1

        run_lengths = []
        run = 1
        for k in range(1, m):
            if directions[k] == directions[k - 1]:
                run += 1
            else:
                run_lengths.append(run)
                run = 1
        run_lengths.append(run)

        if switches.size:
            reversal_fractions = switches.astype(float) / float(m)
        else:
            reversal_fractions = np.asarray([], dtype=float)

        # Estimate reversal susceptibility with the same signed evidence units
        # used by the decision process. At every run boundary, compare the
        # incoming opposing run with the reference-retained incumbent. The
        # smooth score records both actual reversals and near reversals.
        local_v = np.clip(validities, 0.5001, 0.999)
        local_reliability = np.log(local_v / (1.0 - local_v))
        local_scale = float(np.mean(local_reliability[local_reliability > 0.0]))
        if not np.isfinite(local_scale) or local_scale <= 0.0:
            local_scale = 1.0
        local_normalized = np.clip(local_reliability / local_scale, 0.15, 6.0)
        local_strength = np.power(local_normalized, validity_sensitivity)
        ordered_strength = np.asarray(
            [attention * float(local_strength[j]) for j in ordered_idx],
            dtype=float
        )

        reference_retention = 0.55
        reference_accumulator = 0.0
        susceptibility_scores = []
        k = 0
        while k < m:
            run_direction = float(directions[k])
            run_end = k + 1
            while run_end < m and directions[run_end] == run_direction:
                run_end += 1

            run_evidence = ordered_strength[k:run_end]
            run_length = int(run_end - k)
            if reference_accumulator != 0.0 and np.sign(reference_accumulator) != run_direction:
                retained_incumbent = abs(reference_accumulator) * (
                    reference_retention ** run_length
                )
                attack = 0.0
                for strength in run_evidence:
                    attack = reference_retention * attack + float(strength)
                normalized_advantage = (
                    attack - retained_incumbent
                ) / max(attack + retained_incumbent, 1e-9)
                smooth_reversal = 1.0 / (
                    1.0 + np.exp(-4.0 * np.clip(normalized_advantage, -15.0, 15.0))
                )
                susceptibility_scores.append(float(smooth_reversal))

            for strength in run_evidence:
                reference_accumulator = (
                    reference_retention * reference_accumulator
                    + run_direction * float(strength)
                )
            k = run_end

        if susceptibility_scores:
            reversal_susceptibility = float(np.mean(susceptibility_scores))
        else:
            reversal_susceptibility = 0.35

        return {
            "m": float(m),
            "directions": directions,
            "reversal_fractions": reversal_fractions,
            "terminal_singleton": float(run_lengths[-1] == 1 and len(run_lengths) > 1),
            "two_run": float(len(run_lengths) == 2),
            "switch_density": float(switches.size) / float(max(1, m - 1)),
            "reversal_susceptibility": reversal_susceptibility
        }

    # Learn the task set from ordinal scan sequences only. Physical indices,
    # distances between cues, and nondiscriminating gaps never enter these
    # statistics. Exponential weighting implements continuous contextual
    # learning while retaining a weak neutral prior early in the block.
    summaries = []
    past_a = history.get("option_a_ratings", [])
    past_b = history.get("option_b_ratings", [])
    n_past = min(len(past_a), len(past_b))
    for i in range(n_past):
        s = ordinal_summary(past_a[i], past_b[i])
        if s is not None:
            summaries.append(s)

    current_summary = ordinal_summary(stim[0], stim[1])
    if current_summary is None:
        return np.array([0.5, 0.5], dtype=np.float64)
    summaries.append(current_summary)

    ages = np.arange(len(summaries) - 1, -1, -1, dtype=float)
    weights = np.power(np.clip(1.0 - learning_rate, 1e-6, 1.0), ages)
    # The current stimulus can update calibration, but once context exists it
    # receives a bounded weight and cannot sharply change the experiment-level
    # task set solely because of its own conflict geometry.
    if len(summaries) > 1:
        weights[-1] *= 0.35
    weights /= max(float(weights.sum()), 1e-12)

    terminal_singleton_rate = float(np.sum([
        w * s["terminal_singleton"] for w, s in zip(weights, summaries)
    ]))
    two_run_rate = float(np.sum([
        w * s["two_run"] for w, s in zip(weights, summaries)
    ]))
    switch_density = float(np.sum([
        w * s["switch_density"] for w, s in zip(weights, summaries)
    ]))
    reversal_susceptibility = float(np.sum([
        w * s["reversal_susceptibility"] for w, s in zip(weights, summaries)
    ]))

    # A five-bin distribution represents reversal locations in ordinal scan
    # time, not their physical screen positions. Concentrated sequence
    # families provide only weak contextual calibration; whether opposing
    # runs can actually reverse accumulated evidence is the primary signal.
    reversal_hist = np.zeros(5, dtype=float)
    reversal_mass = 0.0
    for w, s in zip(weights, summaries):
        fractions = s["reversal_fractions"]
        if fractions.size == 0:
            continue
        contribution = w / float(fractions.size)
        for fraction in fractions:
            bin_index = min(4, max(0, int(np.floor(5.0 * float(fraction)))))
            reversal_hist[bin_index] += contribution
            reversal_mass += contribution

    if reversal_mass > 0.0:
        reversal_distribution = reversal_hist / reversal_mass
        concentration = float(np.sum(reversal_distribution ** 2))
        positive = reversal_distribution[reversal_distribution > 0.0]
        reversal_entropy = float(
            -np.sum(positive * np.log(positive)) / np.log(5.0)
        )
    else:
        concentration = 0.2
        reversal_entropy = 1.0

    # Validity-profile steepness can alter task calibration, but only weakly;
    # this allows the same ordinal sequence to generalize differently under a
    # changed reliability profile without turning validity into a hard rule.
    clipped_v = np.clip(validities, 0.5001, 0.999)
    reliability = np.log(clipped_v / (1.0 - clipped_v))
    mean_rel = max(float(np.mean(reliability)), 1e-8)
    validity_gradient = float(np.std(reliability) / mean_rel)
    validity_gradient = float(np.clip(validity_gradient, 0.0, 2.0))

    # Coarse geometry terms are shrunken and centered around neutral task
    # values. They can adjust calibration but no longer directly force high
    # overwrite merely because a task contains two-run or singleton displays.
    # The accepted process-derived susceptibility statistic carries the main
    # cross-task signal while the centering preserves the prior operating
    # level of the continuous task set.
    context_score = (
        1.30
        + 1.20 * (terminal_singleton_rate - 0.30)
        + 1.20 * (concentration - 0.30)
        + 0.80 * (two_run_rate - 0.50)
        - 1.50 * (reversal_entropy - 0.70)
        - 0.70 * (switch_density - 0.25)
        - 0.20 * validity_gradient
        + susceptibility_coupling * (reversal_susceptibility - 0.35)
    )
    context_logit = context_sensitivity * (context_score - context_threshold)
    context_logit = float(np.clip(context_logit, -60.0, 60.0))
    overwrite_task_set = 1.0 / (1.0 + np.exp(-context_logit))

    # The latent task set continuously interpolates between integration and
    # overwrite. It never selects a discrete primacy or terminal policy.
    base_retention = (
        (1.0 - overwrite_task_set) * integration_retention
        + overwrite_task_set * overwrite_retention
    )
    base_retention = float(np.clip(base_retention, 0.01, 0.999))

    diff = stim[0] - stim[1]
    discriminating = [int(j) for j in cue_order if diff[j] != 0]
    directions = np.asarray([np.sign(diff[j]) for j in discriminating], dtype=float)

    mean_positive_rel = float(np.mean(reliability[reliability > 0.0]))
    if not np.isfinite(mean_positive_rel) or mean_positive_rel <= 0.0:
        mean_positive_rel = 1.0
    normalized_rel = np.clip(reliability / mean_positive_rel, 0.15, 6.0)
    cue_strength = np.power(normalized_rel, validity_sensitivity)

    accumulator = 0.0
    coalition = 0.0
    current_run_strength = 0.0
    previous_direction = 0.0

    for j, direction in zip(discriminating, directions):
        evidence = attention * float(cue_strength[j]) * float(direction)
        coalition += evidence

        if previous_direction == 0.0 or direction == previous_direction:
            current_run_strength += abs(evidence)
        else:
            current_run_strength = abs(evidence)

        retention = base_retention
        if accumulator != 0.0 and np.sign(accumulator) != direction:
            # Opposition inhibits the existing commitment in proportion to
            # the new reason's strength relative to the active commitment.
            relative_attack = abs(evidence) / (abs(accumulator) + abs(evidence) + 1e-9)
            run_attack = current_run_strength / (abs(accumulator) + current_run_strength + 1e-9)
            inhibition = conflict_inhibition * overwrite_task_set
            retention *= np.exp(-inhibition * (0.65 * relative_attack + 0.35 * run_attack))

        accumulator = retention * accumulator + evidence
        previous_direction = float(direction)

    # A reliability-weighted coalition has strong access only when it has a
    # substantial normalized margin. Near balance, sequential opposition can
    # determine the sign; clear early majorities remain protected by global
    # coalition evidence. This is continuous evidence gating, not policy mixing.
    total_input = float(np.sum([
        attention * float(cue_strength[j]) for j in discriminating
    ]))
    coalition_margin = abs(coalition) / max(total_input, 1e-9)
    coalition_margin = float(np.clip(coalition_margin, 0.0, 1.0))
    margin_access = 0.10 + 0.90 * coalition_margin / (coalition_margin + 0.20)
    effective_coalition_weight = (
        coalition_weight * (1.0 - overwrite_task_set) * margin_access
    )
    decision_evidence = (
        (1.0 - effective_coalition_weight) * accumulator
        + effective_coalition_weight * coalition
    )

    # Confidence follows the final evidence margin. There is deliberately no
    # fatigue or count penalty, allowing coherent long reversals to remain
    # reliable while balanced conflict naturally remains uncertain.
    margin = abs(decision_evidence) / max(total_input, 1e-9)
    geometry_gain = 0.75 + 0.50 * np.sqrt(np.clip(margin, 0.0, 1.0))
    decision_variable = response_gain * geometry_gain * decision_evidence
    decision_variable = float(np.clip(decision_variable, -60.0, 60.0))

    p_a = 1.0 / (1.0 + np.exp(-decision_variable))
    core = np.array([p_a, 1.0 - p_a], dtype=np.float64)
    probs = (1.0 - lapse) * core + lapse * np.array([0.5, 0.5], dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        return np.array([0.5, 0.5], dtype=np.float64)
    return probs / total
```

**`policy(probs)`:**
```python
def policy(probs) -> int:
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        probs = np.ones(len(probs), dtype=np.float64) / float(len(probs))
    else:
        probs /= total
    return int(np.random.choice(len(probs), p=probs))
```


## Replacement

### `pi_10` → slot 2 (via `new_theory`)

**Description:** Reliability-Gated Decision-Object Arbitration with Prefix-Coherence-Conditioned Terminal Access. People construct at most three bounded objects from each display: an initial high-validity commitment, a reliability-weighted summary of the visible coalition, and a privileged terminal reason or terminal directional run. Arbitration is stimulus-local and history-free. Terminal evidence has a genuine recency advantage, but weak terminal evidence receives reliable access only when it constitutes the sole coherent reversal against a unified prefix at manageable load. A terminal reason following an already fragmented prefix receives no such accessibility floor and may be mildly discounted. Very short conflicts provide too little separation for a strongly privileged counterargument, whereas seven-or-more-reason conflicts reduce access through object competition rather than general count fatigue. The initial commitment remains a weak but non-negligible fallback, coalition evidence saturates, and unanimous evidence experiences only a modest vigilance decline. Stable variation in coherent-terminal accessibility, terminal susceptibility, coalition reliance, attention, and lapses produces heterogeneous conflict choices without learned context.

**Rationale:** This is a narrow edit to the accepted iteration-3 model. The early, coalition, confidence, vigilance, load-window, and history-free mechanisms are unchanged. The only substantive change is inside the existing terminal reliability gate. In five- or six-reason conflicts, a singleton or short terminal run now receives a bounded subject-specific accessibility floor when all preceding reasons form one coherent opposing coalition. This targets the weak low-validity reversal in Experiments 11 and 13 and should reduce erroneous majority following in Experiment 12 without globally increasing terminal susceptibility. A short terminal run following an already fragmented prefix receives a mild 12% accessibility discount, targeting excessive terminal agreement in Experiment 3 and the mixed-condition excess in Experiment 5. The discount does not apply to four-cue conflicts, protecting Experiment 4, and coherent seven-plus reversals receive neither the new floor nor the new penalty, protecting the accepted overload fit in Experiment 6. The new floor varies stably across subjects, expressing heterogeneity specifically where coherent terminal and coalition objects compete rather than broadening susceptibility in every condition.

**Parameters:**
  - `validities`: `validities`
  - `validity_compression`: `[0.18, 0.42]`
  - `early_commitment`: `[0.04, 0.22]`
  - `coalition_reliance`: `[0.20, 0.85]`
  - `terminal_susceptibility`: `[1.2, 8.3]`
  - `terminal_reliability_threshold`: `[0.28, 0.62]`
  - `terminal_reliability_sharpness`: `[0.06, 0.14]`
  - `coherent_access_floor`: `[0.58, 0.78]`
  - `terminal_run_bonus`: `[0.25, 0.95]`
  - `terminal_singleton_bonus`: `[0.40, 1.00]`
  - `conflict_moderation`: `[0.10, 0.65]`
  - `attentional_reliability`: `[0.82, 0.99]`
  - `choice_gain`: `[2.4, 4.8]`
  - `vigilance_decline`: `[0.12, 0.25]`
  - `lapse_rate`: `[0.03, 0.15]`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history) -> np.ndarray:
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Decision-object arbitration expects shape (2, n_features); got {stim.shape}."
        )

    n_features = stim.shape[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} != n_features {n_features}."
        )

    validity_compression = float(parameters["validity_compression"])
    early_commitment = float(parameters["early_commitment"])
    coalition_reliance = float(parameters["coalition_reliance"])
    terminal_susceptibility = float(parameters["terminal_susceptibility"])
    reliability_threshold = float(parameters["terminal_reliability_threshold"])
    reliability_sharpness = float(parameters["terminal_reliability_sharpness"])
    coherent_access_floor = float(parameters["coherent_access_floor"])
    terminal_run_bonus = float(parameters["terminal_run_bonus"])
    terminal_singleton_bonus = float(parameters["terminal_singleton_bonus"])
    conflict_moderation = float(parameters["conflict_moderation"])
    attentional_reliability = float(parameters["attentional_reliability"])
    choice_gain = float(parameters["choice_gain"])
    vigilance_decline = float(parameters["vigilance_decline"])
    lapse_rate = float(parameters["lapse_rate"])

    # Communicated validity determines psychological inspection order. Exact
    # ties retain display order, but physical gaps otherwise have no role.
    cue_order = np.argsort(-validities, kind="stable")
    diff = stim[0] - stim[1]
    discriminating = [int(j) for j in cue_order if diff[j] != 0.0]
    m = len(discriminating)
    if m == 0:
        return np.array([0.5, 0.5], dtype=np.float64)

    directions = np.asarray(
        [float(np.sign(diff[j])) for j in discriminating], dtype=float
    )

    # Convert instructed validities to reliability strengths. Compression
    # preserves whether a validity profile is flat or steep without allowing
    # one extreme cue to create an unbounded accumulator.
    clipped_v = np.clip(validities, 0.5001, 0.999)
    log_odds = np.log(clipped_v / (1.0 - clipped_v))
    positive = log_odds[log_odds > 0.0]
    scale = float(np.mean(positive)) if positive.size else 1.0
    if not np.isfinite(scale) or scale <= 0.0:
        scale = 1.0
    normalized = np.clip(log_odds / scale, 1e-4, 30.0)
    strengths_all = np.power(normalized, validity_compression)
    strengths = np.asarray(
        [float(strengths_all[j]) for j in discriminating], dtype=float
    )

    def sigmoid(x):
        x = float(np.clip(x, -60.0, 60.0))
        return 1.0 / (1.0 + np.exp(-x))

    # OBJECT 1: an early high-validity commitment. Its availability receives
    # a small boost only when the first reason is unusually reliable.
    first_direction = float(directions[0])
    first_strength = float(strengths[0])
    maximum_strength = max(float(np.max(strengths)), 1e-8)
    first_relative = first_strength / maximum_strength
    early_availability = 1.0 - np.exp(-first_strength)
    w_early = early_commitment * early_availability * (
        1.0 + 0.5 * first_relative
    )

    # OBJECT 2: a bounded reliability-weighted summary of the visible
    # coalition. Directional mass saturates; no sequential accumulator or
    # learned contextual state is constructed. Balance sensitivity is
    # compressed so the coalition does not duplicate the initial object.
    signed_support = float(np.sum(directions * strengths))
    total_support = max(float(np.sum(strengths)), 1e-12)
    coalition_balance = abs(signed_support) / total_support
    coalition_balance = float(np.clip(coalition_balance, 0.0, 1.0))
    coalition_direction = float(np.sign(signed_support))
    coalition_saturation = 1.0 - np.exp(-total_support / 2.0)
    if coalition_direction == 0.0:
        w_coalition = 0.0
    else:
        w_coalition = (
            coalition_reliance
            * coalition_saturation
            * (0.22 + 0.58 * coalition_balance)
        )

    # OBJECT 3: the final directional run in validity order. Run support is
    # represented as one chunk, and its length benefit rapidly saturates.
    terminal_direction = float(directions[-1])
    run_start = m - 1
    while run_start > 0 and directions[run_start - 1] == terminal_direction:
        run_start -= 1
    terminal_run_length = m - run_start
    terminal_run_strength = float(np.sum(strengths[run_start:]))
    run_saturation = 1.0 - np.exp(-terminal_run_strength)
    n_runs = 1 + int(np.sum(directions[1:] != directions[:-1]))

    # Terminal access depends on reliability relative to the strongest
    # currently visible reason. This creates nonuniform recency across
    # validity environments without learning an experiment-level overwrite
    # state. Even weak terminal reasons retain a small intrinsic privilege.
    terminal_relative = float(strengths[-1] / maximum_strength)
    terminal_access = sigmoid(
        (terminal_relative - reliability_threshold)
        / max(reliability_sharpness, 1e-6)
    )

    # A weak terminal counterargument is distinctly retrievable when it is a
    # short, sole reversal against a coherent prefix at manageable load. No
    # such floor is granted after a fragmented prefix; short terminal runs in
    # those displays receive only a mild local discount. Four-cue conflicts
    # and seven-plus coherent reversals are left unchanged.
    prefix = directions[:run_start]
    prefix_coherent = bool(
        prefix.size > 0
        and np.all(prefix == prefix[0])
        and prefix[0] != terminal_direction
    )
    short_terminal_run = terminal_run_length <= max(2, m // 2)
    if m in (5, 6) and prefix_coherent and short_terminal_run:
        singleton_boost = 0.08 * float(terminal_run_length == 1)
        terminal_access = max(
            terminal_access,
            min(0.92, coherent_access_floor + singleton_boost)
        )
    elif m >= 5 and terminal_run_length <= 2 and prefix.size > 1:
        prefix_fragmented = bool(np.any(prefix[1:] != prefix[:-1]))
        if prefix_fragmented:
            terminal_access *= 0.88

    reliability_gate = 0.08 + 0.92 * terminal_access

    # A coherent reversal is maximally accessible at manageable loads. The
    # smooth window weakens this privilege for very short conflicts and for
    # seven-or-more-reason overload without imposing general count fatigue.
    manageable_access = (
        sigmoid((float(m) - 3.5) / 0.35)
        * sigmoid((6.5 - float(m)) / 0.35)
    )
    geometry_multiplier = 1.0 + 0.25 * terminal_run_bonus * run_saturation
    if n_runs == 2:
        singleton = float(terminal_run_length == 1)
        coherent_access = 2.0 + terminal_singleton_bonus * singleton
        geometry_multiplier *= (
            1.0
            + terminal_run_bonus * manageable_access * coherent_access
        )
    elif n_runs >= 3:
        # Fragmented conflicts provide several competing retrieval boundaries;
        # their terminal reason remains privileged but is less diagnostic.
        fragmentation = min(2.0, float(n_runs - 2))
        geometry_multiplier /= (
            1.0 + 0.50 * terminal_run_bonus * fragmentation
        )
    w_terminal = (
        terminal_susceptibility
        * reliability_gate
        * (0.35 + 0.65 * attentional_reliability)
        * geometry_multiplier
    )

    # A conflicting coalition moderates, but cannot categorically erase, the
    # terminal object. Switch count and physical gaps do not enter this gate.
    if coalition_direction != 0.0 and coalition_direction != terminal_direction:
        opposing_advantage = coalition_balance * min(
            2.0, np.sqrt(float(m) / 2.0)
        )
        w_terminal /= 1.0 + conflict_moderation * opposing_advantage

    # Each object has a bounded probability of expressing its favored option.
    # Attentional reliability affects readout globally while the object
    # strengths determine confidence locally.
    early_confidence = sigmoid(
        choice_gain * attentional_reliability * (0.65 + 0.35 * early_availability)
    )
    coalition_confidence = sigmoid(
        choice_gain
        * attentional_reliability
        * (0.40 + 0.50 * coalition_balance)
    )
    terminal_confidence = sigmoid(
        choice_gain
        * attentional_reliability
        * (0.62 + 0.38 * run_saturation)
    )

    def p_a_from_object(direction, confidence):
        if direction > 0.0:
            return float(confidence)
        if direction < 0.0:
            return float(1.0 - confidence)
        return 0.5

    object_weights = np.asarray(
        [w_early, w_coalition, w_terminal], dtype=np.float64
    )
    object_predictions = np.asarray([
        p_a_from_object(first_direction, early_confidence),
        p_a_from_object(coalition_direction, coalition_confidence),
        p_a_from_object(terminal_direction, terminal_confidence)
    ], dtype=np.float64)

    weight_sum = float(np.sum(object_weights))
    if not np.isfinite(weight_sum) or weight_sum <= 0.0:
        p_a_core = 0.5
    else:
        p_a_core = float(np.dot(object_weights, object_predictions) / weight_sum)

    # Only coherent added evidence incurs a mild vigilance decrement. Because
    # all objects agree on such trials, evidence remains strong and the load
    # effect is much smaller than obligatory count fatigue.
    unanimous = bool(np.all(directions == directions[0]))
    extra_lapse = 0.0
    if unanimous:
        extra_lapse = vigilance_decline * min(
            1.0, max(0.0, float(m) - 2.0) / 8.0
        )
    effective_lapse = float(np.clip(lapse_rate + extra_lapse, 0.0, 0.45))

    p_a = (1.0 - effective_lapse) * p_a_core + effective_lapse * 0.5
    probs = np.array([p_a, 1.0 - p_a], dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        return np.array([0.5, 0.5], dtype=np.float64)
    return probs / total
```

**`policy(probs)`:**
```python
def policy(probs) -> int:
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        probs = np.ones(len(probs), dtype=np.float64) / float(len(probs))
    else:
        probs /= total
    return int(np.random.choice(len(probs), p=probs))
```
