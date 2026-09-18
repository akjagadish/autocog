# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_7" and "pi_4") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_7" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_4" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_7
Polarity-Anchored Dual-Timescale Margin Integration theory: subjects maintain a stable semantic interpretation of whether binary marks are adverse or beneficial. Conditional on that interpretation, tally evidence depends only on the signed absolute count margin, never on display density or the number of discriminating cues. A rapidly compressing accumulator supplies strong evidence at the first nonzero margin, while a very small logarithmic tail preserves continued but sharply diminishing growth across moderate and large margins. Count-residualized validity evidence remains continuously available but is softly standardized and subject to a later, steeper capacity curve that slightly reduces average validity influence at 11 features, preserves relatively more influence at 15 features, and strongly attenuates it by 19 and 37 features. Stable subject differences in count strength, compression, validity attention, semantic polarity, precision, and lapses produce persistent behavioral heterogeneity.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Polarity-Anchored Dual-Timescale Margin Integration expects "
            f"shape (2, n_features); got {stim.shape}."
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
    margin = abs(count_difference)

    # The count representation depends exclusively on the raw tally margin.
    # A dominant fast component makes the first nonzero margin informative
    # and then compresses rapidly. A much smaller logarithmic tail preserves
    # continued but diminishing growth at moderate and large margins.
    if margin > 0.0:
        fast_component = float(parameters["count_gain"]) * np.tanh(
            margin / float(parameters["fast_margin_scale"])
        )
        slow_component = float(parameters["log_tail_gain"]) * np.log1p(margin)
        count_magnitude = fast_component + slow_component
        count_signal = float(np.sign(count_difference)) * count_magnitude
    else:
        count_signal = 0.0

    # Centering removes the portion of validity-weighted evidence that merely
    # restates which option has more marks. The resulting reliability residual
    # remains available at every margin, including exact count ties.
    centered_validities = validities - float(np.mean(validities))
    raw_validity_residual = float(np.dot(centered_validities, difference))

    # Soft shrinkage standardization avoids disproportionately amplifying
    # low-energy reliability profiles while retaining meaningful differences
    # in reliability dispersion. It uses no trial-specific density or conflict.
    profile_energy = float(np.sqrt(np.dot(
        centered_validities, centered_validities
    )))
    standardization_exponent = float(
        parameters["reliability_standardization"]
    )
    shrinkage_scale = np.sqrt(
        float(parameters["reliability_shrinkage"])
        + profile_energy ** 2
    )
    validity_units = raw_validity_residual / (
        shrinkage_scale ** standardization_exponent
    )

    # Reliability inspection decreases continuously with display complexity.
    # The later, steeper knee preserves relatively more access near 15 cues
    # than the previous curve while retaining strong attenuation by 19 and 37.
    capacity = float(parameters["validity_capacity"])
    load_exponent = float(parameters["display_load_exponent"])
    attention_factor = 1.0 / (
        1.0 + (float(n_features) / capacity) ** load_exponent
    )
    validity_signal = (
        float(parameters["validity_attention"])
        * attention_factor
        * validity_units
    )

    markedness_evidence = float(parameters["response_precision"]) * (
        count_signal + validity_signal
    )

    # Positive markedness means that A carries more adverse evidence and hence
    # favors B under the adverse semantic interpretation.
    adverse_logits = np.array(
        [-0.5 * markedness_evidence, 0.5 * markedness_evidence],
        dtype=float,
    )
    adverse_logits -= np.max(adverse_logits)
    adverse_probs = np.exp(adverse_logits)
    adverse_probs /= adverse_probs.sum()

    # A stable alternative interpretation treats marks as beneficial and
    # reverses the entire integrated evidence distribution.
    beneficial_probs = adverse_probs[::-1]
    polarity = float(parameters["adverse_polarity_confidence"])
    core_probs = (
        polarity * adverse_probs
        + (1.0 - polarity) * beneficial_probs
    )

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

## THEORY 2 — pi_4
Semantic-Polarity Smooth Integration theory: people first interpret what the marked binary state means rather than assuming that 1 is intrinsically desirable. Each subject forms a stable posterior belief that a mark is adverse or suspicious. Conditional on either the adverse interpretation or its residual beneficial alternative, the subject smoothly integrates two continuous signals: the difference in total marks and a partially count-residualized validity-weighted difference. The count signal normally dominates, while the weighted signal supplies graded sensitivity to which experts carry the marks on every trial. The two semantic interpretations generate opposite choice distributions, which are averaged according to the subject's polarity confidence. A small lapse process captures stimulus-independent errors.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Semantic-Polarity Smooth Integration expects shape "
            f"(2, n_features); got {stim.shape}."
        )

    a, b = stim[0], stim[1]
    n_features = stim.shape[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} != n_features {n_features}."
        )

    # Positive differences mean that A contains more marked states than B.
    count_difference = float(np.sum(a - b))
    partial_centering = float(parameters["partial_centering"])
    effective_validities = validities - partial_centering * float(np.mean(validities))
    weighted_difference = float(np.dot(effective_validities, a - b))

    # There is no count gate: validity contributes continuously on every
    # discriminating trial. Partial centering limits the count component
    # embedded in the weighted sum without removing it completely.
    integrated_markedness = (
        float(parameters["count_weight"]) * count_difference
        + float(parameters["validity_weight"]) * weighted_difference
    )

    adverse_logits = np.array(
        [-0.5 * integrated_markedness, 0.5 * integrated_markedness],
        dtype=float,
    )
    adverse_logits = adverse_logits - np.max(adverse_logits)
    adverse_probs = np.exp(adverse_logits)
    adverse_probs /= adverse_probs.sum()

    # The beneficial interpretation reverses the semantic polarity while
    # preserving the same smooth evidence-integration computation.
    beneficial_probs = adverse_probs[::-1]
    polarity_confidence = float(parameters["adverse_polarity_confidence"])
    core_probs = (
        polarity_confidence * adverse_probs
        + (1.0 - polarity_confidence) * beneficial_probs
    )

    lapse = float(parameters["lapse_rate"])
    probs = (1.0 - lapse) * core_probs + lapse * np.array([0.5, 0.5])
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


## EXPERIMENT 1 (proposed by pi_7)

### DESIGN
**Validities (n_features=37):** [0.99, 0.98, 0.97, 0.96, 0.95, 0.94, 0.93, 0.92, 0.91, 0.9, 0.89, 0.88, 0.87, 0.86, 0.85, 0.84, 0.83, 0.82, 0.75, 0.51, 0.52, 0.53, 0.54, 0.55, 0.56, 0.57, 0.58, 0.59, 0.6, 0.61, 0.62, 0.63, 0.64, 0.65, 0.66, 0.67, 0.68]

**Trial pairs (n=12):**
  trial 1: A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  trial 2: A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  trial 3: A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  trial 4: A=[1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  trial 5: A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  trial 6: A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]
  trial 7: A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  trial 8: A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  trial 9: A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  trial 10: A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  trial 11: A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  trial 12: A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]

**Rationale:** This 37-feature design isolates the advocated theory's steep display-load attenuation of validity evidence while eliminating count evidence in both theories. The validity profile is symmetric around 0.75: 18 high-validity experts (0.99 to 0.82), one mean-validity expert, and 18 low-validity experts (0.51 to 0.68). In every trial A and B have exactly the same number of marks, so the count difference is zero. Across six base conditions, A is marked by the first m high-validity experts and B by their symmetrically matched low-validity experts, for m = 1, 2, 4, 7, 11, and 18. The resulting count-residualized validity differences are +0.48, +0.94, +1.80, +2.94, +4.18, and +5.58. All pairs are also A/B reversed. Smooth Integration therefore predicts a pronounced monotonic increase in choices of the option whose marks are concentrated on low-validity experts. At the strongest endpoint its evidence is at least 0.7*5.58 = 3.906; even with its lowest adverse-polarity confidence and highest lapse rate, it predicts approximately P(validity-favored option) >= 0.74. The advocated theory applies a 37-feature attention factor no larger than 1/(1+(37/16)^5), leaving endpoint evidence below approximately 0.22 even under maximal validity attention and response precision. It consequently predicts P(validity-favored option) below approximately 0.555 and an almost flat, near-indifferent profile. Thus the diagnostic result is a large graded validity effect under Smooth Integration versus severe compression toward chance under the advocated load-capacity theory. Twelve unique pairs repeated eight times yield exactly 96 trials.

**Computed schedule:** 12 unique pairs × 8 reps = 96 trials per subject.



### METRIC
Rationale:
This is the proportion of choices favoring the option whose marks come from the lower-validity experts, restricted to the three strongest validity conflicts (m=7, 11, and 18). It pools 48 repeated trials per subject and folds the A/B reversals into the same orientation, providing substantially lower sampling variance than a single-condition contrast. Smooth Integration predicts a large preference for this option because its unattenuated validity evidence is already strong at these levels. The advocated load-capacity theory predicts choices much closer to 0.5 because 37-feature display load sharply attenuates the same validity residual. Excluding the weak m=1, 2, and 4 conditions increases the expected theory gap while retaining enough trials for a stable subject-level estimate.

Source:
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

### RESULTS
- Predicted under pi_7 (simulated): 0.5038 (var=0.0050)
- Predicted under pi_4 (simulated): 0.8542 (var=0.0061)
- Observed on real data: 0.8442 (var=0.0078)

## EXPERIMENT 2 (proposed by pi_4)

### DESIGN
**Validities (n_features=15):** [0.99, 0.95, 0.9, 0.85, 0.8, 0.51, 0.55, 0.6, 0.65, 0.7, 0.75, 0.75, 0.75, 0.75, 0.75]

**Trial pairs (n=12):**
  trial 1: A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  trial 2: A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  trial 3: A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0]  B=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  trial 4: A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0]  B=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  trial 5: A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0]  B=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  trial 6: A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  trial 7: A=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  trial 8: A=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0]
  trial 9: A=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0]
  trial 10: A=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0]
  trial 11: A=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0]
  trial 12: A=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1]

**Rationale:** This 15-feature design creates a conflict between a fixed validity residual and count margins of 0, 1, 2, 3, 4, and 5. The validity profile has mean 0.75. In every base trial, A is marked by four low-validity experts (0.55, 0.60, 0.65, 0.70), while B is marked by their four high-validity counterparts (0.95, 0.90, 0.85, 0.80). This produces a constant centered-validity residual of -1.00 and an initially tied count. Successive conditions add marks to A on up to five exactly mean-validity experts. These marks increase the A-minus-B count margin without changing the competitor's centered-validity signal. Under Semantic-Polarity Smooth Integration, markedness evidence is exactly -validity_weight + d*[count_weight + 0.75*(1-partial_centering)*validity_weight], where d is the count margin. Its evidence therefore increases linearly at every step, with a slope between 0.7475 and 2.265; it is necessarily positive by margin 2 and rises by at least 2.99 evidence units from margin 1 to margin 5. The competing theory instead predicts an abrupt reversal from the negative validity signal at margin 0 to positive markedness at margin 1: even its weakest first-margin count component exceeds its strongest possible opposing validity component at 15 features. Thereafter its tanh count accumulator is nearly saturated. From margin 1 to margin 5, its unscaled count signal can increase by no more than about 0.16, while its validity signal remains exactly fixed. Thus the critical quantitative signature is a strong, sustained margin-1-to-margin-5 increase in choices of B under Smooth Integration versus an early margin-1 step followed by an almost flat profile under Dual-Timescale Margin Integration. All six pairs are also A/B reversed. The 12 unique pairs repeated eight times yield exactly 96 trials.

**Computed schedule:** 12 unique pairs × 8 reps = 96 trials per subject.



### METRIC
Rationale:
The metric is the within-subject linear slope of orientation-corrected, adverse-aligned choices across absolute count margins 1 through 5. Smooth Integration predicts a sizable positive slope because its evidence continues increasing at every added mean-validity mark. Dual-Timescale Integration predicts a slope near zero because its count accumulator has already nearly saturated at margin 1 while the centered-validity residual remains fixed. Using all five margins and both A/B orientations yields a lower-variance estimate than an endpoint difference, and the balanced repetitions make the pooled estimate directly comparable to the per-subject estimates.

Source:
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

### RESULTS
- Predicted under pi_7 (simulated): -0.0020 (var=0.0013)
- Predicted under pi_4 (simulated): 0.0704 (var=0.0014)
- Observed on real data: 0.0793 (var=0.0131)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
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
**Predicted under pi_7:** -0.3760 (var=0.0198)
**Predicted under pi_4:** -0.3570 (var=0.0237)

### Experiment 4
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
**Predicted under pi_7:** 0.0000 (var=0.0000)
**Predicted under pi_4:** 0.0000 (var=0.0000)

### Experiment 5
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
**Predicted under pi_7:** 0.7817 (var=0.0222)
**Predicted under pi_4:** 0.7317 (var=0.0354)

### Experiment 6
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
**Predicted under pi_7:** -0.6488 (var=0.0220)
**Predicted under pi_4:** -0.5396 (var=0.0205)

### Experiment 7
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
**Predicted under pi_7:** 0.1866 (var=0.0085)
**Predicted under pi_4:** 0.2053 (var=0.0075)

### Experiment 8
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
**Predicted under pi_7:** 0.2163 (var=0.0049)
**Predicted under pi_4:** 0.2086 (var=0.0061)

### Experiment 9
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
**Predicted under pi_7:** 0.4404 (var=0.0130)
**Predicted under pi_4:** 0.0925 (var=0.0089)

### Experiment 10
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
**Predicted under pi_7:** -18.0000 (var=45.2304)
**Predicted under pi_4:** -112.0000 (var=44.4224)

### Experiment 11
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
**Predicted under pi_7:** -0.8319 (var=0.4823)
**Predicted under pi_4:** 1.3194 (var=0.6212)

### Experiment 12
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
**Predicted under pi_7:** 0.8641 (var=0.0034)
**Predicted under pi_4:** 0.8800 (var=0.0062)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "pi_4 is the substantially better task-invariant account among the two, although it is not sufficient as a final theory. The two decisive experiments strongly reject central commitments of pi_7. In Experiment 1, validity information remains highly influential with 37 displayed features: observed 0.8442 is nearly identical to pi_4's 0.8542 but radically inconsistent with pi_7's 0.5038. Thus validity access is not strongly attenuated merely because the display contains 37 features. In Experiment 2, choices continue changing from count margins 1 through 5: observed slope 0.0793 closely matches pi_4's 0.0704 and contradicts pi_7's nearly flat -0.0020. Thus count evidence is not generally almost saturated at the first nonzero margin. The broader record reinforces this conclusion. pi_4 is closer in Experiments 5, 6, 7, 8, 9, and 12, ties pi_7 in Experiment 4, and is especially superior in Experiment 9, where pi_7 predicts an enormous margin-one discontinuity absent from the data. pi_7 is modestly better in Experiment 3 and clearly better in Experiment 10; it is also closer in Experiment 11, although both theories miss that near-null result. These exceptions reveal limitations of unrestricted smooth integration rather than rescuing pi_7's global load attenuation and first-margin saturation claims. In particular, pi_4 greatly exaggerates the effect measured in Experiment 10 (-112 predicted versus -28 observed), and neither account handles the near-zero density signature in Experiment 11. Across several experiments, observed between-subject variance also exceeds simulated variance, most conspicuously in Experiment 2, indicating more stable heterogeneity in evidence use than either implementation generates. Because the defining prose of pi_7 explicitly requires severe high-feature validity attenuation and rapid count compression, its failures in Experiments 1, 2, and 9 cannot be repaired by parameter-range adjustment without abandoning the theory itself.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Replace pi_7 with a Resource-Adaptive Diagnostic Integration theory that is a stronger competitor to pi_4. Retain stable semantic-polarity inference, but reject both a fixed feature-count capacity curve and universally smooth, context-free integration. The new theory should propose that attention is allocated according to diagnostic structure\u2014reliability contrast, organization/salience, redundancy, conflict, and the number or fraction of discriminating cues\u2014rather than total displayed feature count alone. Consequently, a structured high-versus-low validity contrast can remain strongly available even in a 37-feature display, as required by Experiment 1. Count evidence should accumulate smoothly across ordinary margins, as required by Experiment 2, but undergo divisive normalization or context-dependent compression in dense, extreme, or highly redundant displays, allowing the attenuated margin contrast in Experiment 10 without imposing pi_7's abrupt margin-one saturation. Validity and count evidence should be represented jointly so that adding a count cue can change normalization and conflict, but the theory should not impose the large discontinuity rejected by Experiment 9 or a systematic density effect rejected by Experiment 11. Include stable subject-level latent differences\u2014or a stable mixture between predominantly tally-oriented and reliability-sensitive integration policies\u2014to reproduce the elevated observed variances while preserving polarity across experiments. The replacement must make falsifiable cross-task predictions from common parameters and should be calibrated simultaneously to all experiments, not by separate feature-count-specific knees."
}
```

## Usage

```json
{
  "input_tokens": 28411,
  "output_tokens": 1491
}
```
