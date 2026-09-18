# Round 3 — Theories

**Verdict:** `new_theory` (slot 2 replaced)

## Starting theories

### slot 1 — `pi_5` — SURVIVED ✓

**Description:** Uncertain-Credibility Normalized Voting theory proposes that people do not treat instructed expert validities as precisely known reliabilities. In the absence of feedback, each communicated validity is shrunk toward a shared, moderately credible prototype. Consequently, every discriminating expert supplies one dominant categorical vote, while the incompletely trusted deviation of that expert's validity from the prototype supplies only a residual adjustment. Extreme communicated deviations are compressed smoothly because participants regard unusually high or low precision claims as especially uncertain, while still retaining limited distinctions among the most credible experts. These residual adjustments are accumulated cue by cue, preserving expert identity, but their total is divisively normalized and increasingly bounded once a clear tally coalition exists. Residual reliability is also contextually gated: it is strongly discounted in exact tally ties, where conflicting reliability claims provide no categorical direction, while otherwise retaining its ordinary residual weight without a special margin-one amplification. Before saturation, total evidence undergoes a moderately convex magnitude transformation, making small vote margins comparatively uncertain while preserving confidence for large coalitions. The resulting evidence is passed through a saturating response transformation, so additional agreement has diminishing effects once evidence is decisive. Between-person differences arise in reliability shrinkage, response sensitivity, and lapse rate. Because choices reveal no correctness information, the representation is not updated from choice history.

**Rationale:** This is a localized extension of the accepted iteration-9 response transformation. All cue-wise reliability accumulation, shrinkage, deviation compression, exact-tie attenuation, quadratic coalition protection, and subject-level parameter ranges are unchanged. Response curvature increases only from 1.20 to 1.28, further compressing the low total-evidence conflicts responsible for the excessive tally decisiveness in Experiment 1 and strengthening the margin profile measured in Experiment 2. The saturation scale is changed from the previous analytically implied value of about 4.15 to 4.50. This calibrates confidence against the lower total evidence actually produced on margin-five conflicts after an opposing residual reliability adjustment, rather than against an unattained raw evidence value of exactly five. The modestly broader scale should lower the excessive Experiment 4 tally rate while the convex transformation preserves comparatively strong confidence for the large, reliability-supported coalitions in Experiment 6. No rejected global reliability amplification, coalition-protection release, or sensitivity-range widening is repeated.

**Parameters:**
  - `reliability_shrinkage`: `[0.58, 0.84]`
  - `choice_sensitivity`: `[2.20, 2.70]`
  - `lapse_rate`: `[0.0, 0.12]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history):
    # Uncertain-Credibility Normalized Voting. History is intentionally ignored:
    # without outcome feedback, previous choices cannot identify expert accuracy.
    stimulus = np.asarray(state, dtype=np.float64)
    if stimulus.ndim != 2 or stimulus.shape[0] != 2:
        raise ValueError(
            f"Expected state with shape (2, n_features); got {stimulus.shape}."
        )

    n_features = stimulus.shape[1]
    validities = np.asarray(parameters["validities"], dtype=np.float64)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} does not match "
            f"n_features {n_features}."
        )

    # A difference of +1 is an endorsement of A and -1 an endorsement of B.
    # Nondiscriminating experts contribute neither a vote nor reliability evidence.
    signed_endorsements = np.sign(stimulus[0] - stimulus[1])
    discriminating = signed_endorsements != 0.0
    tally_evidence = float(np.sum(signed_endorsements))

    # Map validity onto above-chance diagnostic strength. The reference value
    # zero corresponds to a common validity of .75. Lower-tail deviations are
    # winsorized, while upper-tail deviations are smoothly compressed so that
    # very credible experts remain distinguishable without receiving full weight.
    v = np.clip(validities, 0.5, 1.0)
    communicated_strength = 2.0 * (v - 0.5)
    raw_deviation = communicated_strength - 0.5
    lower_bounded = np.maximum(raw_deviation, -0.25)
    upper_excess = np.maximum(lower_bounded - 0.25, 0.0)
    reliability_deviation = (
        np.minimum(lower_bounded, 0.25)
        + 0.13 * np.tanh(upper_excess / 0.10)
    )

    # Strong shrinkage leaves only a small fraction of communicated deviations.
    # Deviations are nevertheless summed expert by expert, unlike a summary of
    # the two endorsing groups. Divisive normalization bounds their joint impact.
    shrinkage = float(parameters["reliability_shrinkage"])
    retained_precision = 1.0 - shrinkage
    active_deviations = reliability_deviation[discriminating]
    active_signs = signed_endorsements[discriminating]

    if active_deviations.size == 0:
        reliability_adjustment = 0.0
    else:
        signed_sum = float(np.dot(active_signs, active_deviations))
        deviation_mass = float(np.sum(np.abs(active_deviations)))
        coalition_protection = 0.12 * max(abs(tally_evidence) - 1.0, 0.0) ** 2
        reliability_adjustment = (
            4.0 * retained_precision * signed_sum
            / (1.0 + retained_precision * deviation_mass + coalition_protection)
        )

        # Reliability is least trusted when the categorical tally is exactly
        # tied. Outside exact ties it receives its ordinary residual weight;
        # there is no separate amplification at a one-vote margin.
        absolute_tally = abs(tally_evidence)
        tie_gate = 1.0 - 0.94 * np.exp(-((absolute_tally / 0.35) ** 2))
        reliability_adjustment *= tie_gate

    total_evidence_for_a = tally_evidence + reliability_adjustment

    # Slightly stronger convexity compresses low evidence further. The revised
    # scale is calibrated to residual-shifted large-margin evidence rather than
    # to a raw tally of exactly five.
    response_curvature = 1.28
    saturation_scale = 4.50
    curved_evidence = np.sign(total_evidence_for_a) * (
        abs(total_evidence_for_a) / saturation_scale
    ) ** response_curvature
    normalized_evidence = np.tanh(curved_evidence)
    sensitivity = float(parameters["choice_sensitivity"])
    decision_variable = sensitivity * normalized_evidence

    logits = np.array(
        [0.5 * decision_variable, -0.5 * decision_variable],
        dtype=np.float64,
    )
    logits -= np.max(logits)
    p_core = np.exp(logits)
    p_core /= p_core.sum()

    lapse = float(parameters["lapse_rate"])
    probabilities = (1.0 - lapse) * p_core + lapse * 0.5
    probabilities = np.clip(probabilities, 0.0, 1.0)
    probabilities /= probabilities.sum()
    return probabilities
```

**`policy(probs)`:**
```python
def policy(probs):
    probabilities = np.asarray(probs, dtype=np.float64)
    probabilities = np.clip(probabilities, 0.0, None)
    total = float(np.sum(probabilities))
    if not np.isfinite(total) or total <= 0.0:
        probabilities = np.full(
            probabilities.size, 1.0 / probabilities.size, dtype=np.float64
        )
    else:
        probabilities /= total
    return int(np.random.choice(probabilities.size, p=probabilities))
```


### slot 2 — `pi_4` — KILLED ✗

**Description:** Compressed-Reliability Consensus theory holds that people represent every discriminating expert primarily as one categorical vote and encode communicated reliability through a separate, bounded comparison of the two endorsing groups. For each option, attention is biased moderately toward its more reliable endorsers, but their reliabilities are summarized as a softmax-weighted mean rather than accumulated expert by expert. Net evidence is therefore the full signed tally plus an identity-sensitive contrast between the two bounded group summaries. Agreement additionally amplifies confidence as the absolute tally margin grows, with amplification saturating after a decisive coalition has formed. This representation permits expert identity to determine equal-tally choices, preserves substantial influence for near-chance experts, and allows sufficiently numerous weak experts to override the strongest expert. Reliability sensitivity, consensus amplification, choice sensitivity, and lapse rate vary across subjects. Because the task provides no correctness feedback, choices are reversal-symmetric and independent of history.

**Rationale:** The accepted iteration-5 model is retained except for the reliability-combination block. Instead of adding a reliability bonus from every discriminating expert, the revision preserves the complete signed tally and adds a bounded contrast between option-level reliability summaries. Within each side, a fixed moderate softmax temperature of 4 emphasizes more reliable endorsers without becoming a hard maximum; taking a weighted mean keeps each side's reliability signal bounded. This should increase strongest-expert leverage in ordinary conflicts and equal tallies without allowing several medium-validity bonuses to accumulate. It can also flatten Experiment 2's margin-consistency gradient because reliability can support tally winners even at small margins. The six-expert baseline coalition remains fully represented in Experiment 4, while the accepted margin-five consensus cap, choice-sensitivity range, lapse range, and all hierarchical parameter variation remain unchanged.

**Parameters:**
  - `reliability_sensitivity`: `[0.65, 1.05]`
  - `consensus_amplification`: `[0.03, 0.07]`
  - `choice_sensitivity`: `[0.13, 0.30]`
  - `lapse_rate`: `[0.0, 0.08]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history):
    # Compressed-Reliability Consensus model. History is intentionally ignored
    # because the task supplies no outcome feedback from which to recalibrate.
    stimulus = np.asarray(state, dtype=np.float64)
    if stimulus.ndim != 2 or stimulus.shape[0] != 2:
        raise ValueError(
            f"Expected state with shape (2, n_features); got {stimulus.shape}."
        )

    n_features = stimulus.shape[1]
    validities = np.asarray(parameters["validities"], dtype=np.float64)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} does not match "
            f"n_features {n_features}."
        )

    # Every discriminating expert contributes a full baseline vote through the
    # signed tally. Reliability is encoded separately as a bounded summary of
    # each endorsing side, preventing identity increments from accumulating
    # without bound as a coalition grows.
    v = np.clip(validities, 0.5, 1.0)
    reliability_code = np.tanh(3.0 * (v - 0.5)) / np.tanh(1.5)

    difference = stimulus[0] - stimulus[1]
    a_endorsers = difference > 0.0
    b_endorsers = difference < 0.0
    tally_margin = float(np.sum(a_endorsers) - np.sum(b_endorsers))

    def side_reliability(mask):
        values = reliability_code[mask]
        if values.size == 0:
            return 0.0
        attention_logits = 4.0 * values
        attention_logits = attention_logits - np.max(attention_logits)
        attention = np.exp(attention_logits)
        attention /= attention.sum()
        return float(np.dot(attention, values))

    reliability_contrast = (
        side_reliability(a_endorsers) - side_reliability(b_endorsers)
    )
    alpha = float(parameters["reliability_sensitivity"])
    weighted_balance = tally_margin + alpha * reliability_contrast

    # Agreement is represented separately by the unweighted vote margin.
    # It changes confidence but does not erase which experts supplied the
    # votes. Leaving margin-one and tied tallies unamplified preserves
    # uncertainty in sparse conflicts and identity effects in equal tallies.
    # Amplification saturates at the level reached by a margin-five coalition.
    excess_consensus = max(abs(tally_margin) - 1.0, 0.0)
    consensus_gain = float(parameters["consensus_amplification"])
    confidence_multiplier = 1.0 + consensus_gain * min(excess_consensus ** 1.5, 8.0)
    evidence_for_a = weighted_balance * confidence_multiplier

    sensitivity = float(parameters["choice_sensitivity"])
    logits = np.array(
        [0.5 * sensitivity * evidence_for_a,
         -0.5 * sensitivity * evidence_for_a],
        dtype=np.float64,
    )
    logits = logits - np.max(logits)
    probabilities = np.exp(logits)
    probabilities /= probabilities.sum()

    lapse = float(parameters["lapse_rate"])
    probabilities = (1.0 - lapse) * probabilities + lapse * 0.5
    probabilities = np.clip(probabilities, 0.0, 1.0)
    probabilities /= probabilities.sum()
    return probabilities
```

**`policy(probs)`:**
```python
def policy(probs):
    probabilities = np.asarray(probs, dtype=np.float64)
    probabilities = np.clip(probabilities, 0.0, None)
    total = float(np.sum(probabilities))
    if not np.isfinite(total) or total <= 0.0:
        probabilities = np.full(probabilities.size, 1.0 / probabilities.size)
    else:
        probabilities /= total
    return int(np.random.choice(probabilities.size, p=probabilities))
```


## Replacement

### `pi_6` → slot 2 (via `new_theory`)

**Description:** Latent Validity-Construal Tally theory proposes that participants first encode each discriminating expert as one categorical vote and form an unweighted vote margin. Communicated validities are represented separately as monotonic diagnostic-strength codes whose signed sum is compressed into bounded reliability evidence. Crucially, participants differ in their interpretation of the communicated validity scale. The dominant latent construal treats lower stated values as safer or more diagnostic, reversing the direction of reliability evidence. Small subgroups either disregard the validity information or interpret it conventionally. Because reliability evidence is bounded, the dominant reversed construal can overturn a one-vote tally or resolve an exact tally, but it cannot overturn a decisive many-versus-few coalition. When reliability opposes a one-vote tally, its influence is selectively attenuated if that tally advantage arises from a compact, proportionally coherent coalition; reliability remains nearly unchanged in diffuse many-versus-many conflicts. Reliability-based commitment applies only when validity overturns a nonzero tally; exact-tally decisions remain graded rather than receiving the same categorical amplification. In exact tallies, reliability is further gated by its relative salience: the absolute signed validity imbalance is compared with the total encoded validity strength on both sides. Diffuse conflicts between two substantial coalitions receive little reliability influence, whereas endpoint contrasts involving a near-chance expert remain salient. The raw tally is also smoothly saturated, reducing excessive confidence differences between moderate and large margins while retaining its dominance in decisive coalitions. The model is reversal-symmetric and history-independent because no outcome feedback is available.

**Rationale:** This is a minimal edit to the accepted iteration-5 model. The successful exact-tally relative-salience gate and all previously calibrated validity, tally-saturation, construal-mixture, commitment, sensitivity, and lapse mechanisms are retained. The only computational addition is a bounded gate applied when reliability opposes an exactly one-vote, nonzero tally. Its input is relative consensus, |margin| divided by the number of discriminating experts. Compact 2-versus-1 conflicts therefore attenuate reversed reliability enough to restore tally choices in Experiments 1 and 3, while diffuse one-vote conflicts involving many experts receive little attenuation, preserving the reversed-validity pattern in Experiment 7. The gate is restricted to one-vote conflicts, so Experiment 2's margins of 2, 3, 5, and 7 retain exactly the accepted model's confidence profile rather than repeating the rejected additive-consensus edit that inflated its Bayes factor. Exact ties are unchanged, protecting Experiments 5 and 8, and decisive margins are unchanged, protecting Experiments 4 and 6. The tunable floor permits subject-level differences in coalition protection without broadening the core orientation or response parameters.

**Parameters:**
  - `construal_quantile`: `[0, 1]`
  - `orientation_strength`: `[1.9, 2.4]`
  - `reliability_accumulation`: `[1.8, 3.2]`
  - `exact_tie_salience_threshold`: `[0.45, 0.60]`
  - `exact_tie_salience_slope`: `[12, 18]`
  - `conflict_consensus_floor`: `[0.35, 0.60]`
  - `evidence_scale`: `[2.3, 2.9]`
  - `choice_sensitivity`: `[1.55, 2.15]`
  - `construal_commitment`: `[2.1, 2.5]`
  - `lapse_rate`: `[0.0, 0.08]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history):
    # Latent Validity-Construal Tally model. History is intentionally ignored:
    # choices without correctness feedback cannot reveal expert accuracy.
    stimulus = np.asarray(state, dtype=np.float64)
    if stimulus.ndim != 2 or stimulus.shape[0] != 2:
        raise ValueError(
            f"Expected state with shape (2, n_features); got {stimulus.shape}."
        )

    n_features = stimulus.shape[1]
    validities = np.asarray(parameters["validities"], dtype=np.float64)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} does not match "
            f"n_features {n_features}."
        )

    # +1 denotes an expert uniquely endorsing A, -1 an expert uniquely
    # endorsing B, and zero a nondiscriminating expert.
    signed_votes = np.sign(stimulus[0] - stimulus[1])
    tally_margin = float(np.sum(signed_votes))

    # The communicated scale is encoded monotonically before its psychological
    # direction is selected. Near-chance experts retain a categorical vote but
    # supply little reliability evidence. Extreme values are compressed.
    v = np.clip(validities, 0.5, 1.0)
    validity_code = np.tanh(3.0 * (v - 0.5)) / np.tanh(1.5)
    signed_validity_sum = float(np.dot(signed_votes, validity_code))

    # Accumulation is cue-by-cue but saturates, so validity can settle a weak
    # conflict without growing enough to defeat a large tally coalition.
    accumulation = float(parameters["reliability_accumulation"])
    bounded_reliability = float(np.tanh(accumulation * signed_validity_sum))

    # In an exact tally, distinguish a concentrated diagnostic imbalance from
    # a diffuse conflict between two substantial endorsing coalitions. The
    # normalization is used only at exact ties, leaving every nonzero-tally
    # prediction and its successful margin profile unchanged.
    if abs(tally_margin) < 1e-12:
        total_validity_strength = float(
            np.dot(np.abs(signed_votes), validity_code)
        )
        if total_validity_strength > 1e-12:
            relative_salience = np.clip(
                abs(signed_validity_sum) / total_validity_strength, 0.0, 1.0
            )
        else:
            relative_salience = 0.0

        threshold = float(parameters["exact_tie_salience_threshold"])
        slope = float(parameters["exact_tie_salience_slope"])
        raw_gate = 1.0 / (
            1.0 + np.exp(-slope * (relative_salience - threshold))
        )
        endpoint_gate = 1.0 / (
            1.0 + np.exp(-slope * (1.0 - threshold))
        )
        bounded_reliability *= float(raw_gate / endpoint_gate)

    # The continuous latent index implements a task-invariant population
    # mixture. Nearly all participants reverse the instructed scale; very small
    # groups ignore it or use its conventional direction.
    construal_quantile = float(parameters["construal_quantile"])
    if construal_quantile < 0.99:
        validity_orientation = -1.0
    elif construal_quantile < 0.998:
        validity_orientation = 0.0
    else:
        validity_orientation = 1.0

    orientation_strength = float(parameters["orientation_strength"])
    reliability_evidence = (
        validity_orientation * orientation_strength * bounded_reliability
    )

    # In a nonzero one-vote conflict, coalition structure regulates only the
    # opposing reliability signal. A compact proportional majority protects
    # its tally, whereas a diffuse many-versus-many margin leaves validity
    # almost unchanged. Larger tally margins and aligned reliability are not
    # modified, preserving the established margin-confidence profile.
    discriminating_count = int(np.count_nonzero(signed_votes))
    if (
        discriminating_count > 0
        and 0.5 < abs(tally_margin) < 1.5
        and reliability_evidence * tally_margin < 0.0
    ):
        relative_consensus = abs(tally_margin) / float(discriminating_count)
        coherent_conflict = 1.0 / (
            1.0 + np.exp(-24.0 * (relative_consensus - 0.25))
        )
        conflict_floor = float(parameters["conflict_consensus_floor"])
        conflict_gate = 1.0 - (1.0 - conflict_floor) * coherent_conflict
        reliability_evidence *= float(conflict_gate)

    # Smoothly saturating the raw tally reduces excessive margin-dependent
    # confidence while preserving its sign and its dominance for large margins.
    tally_evidence = 3.8 * np.tanh(tally_margin / 3.8)
    total_evidence = tally_evidence + reliability_evidence

    # A reliability-based construal that reverses a weak nonzero tally is
    # treated as a categorical resolution. Exact-tally reliability choices are
    # left graded, avoiding excessive amplification in balanced coalitions.
    reliability_controls = False
    if abs(total_evidence) > 1e-12 and abs(reliability_evidence) > 1e-12:
        if abs(tally_margin) >= 1e-12:
            if np.sign(total_evidence) != np.sign(tally_margin):
                reliability_controls = True

    evidence_scale = float(parameters["evidence_scale"])
    normalized_evidence = float(np.tanh(total_evidence / evidence_scale))
    decision_variable = (
        float(parameters["choice_sensitivity"]) * normalized_evidence
    )
    if reliability_controls:
        decision_variable *= float(parameters["construal_commitment"])

    # Positive evidence favors A. Construct symmetric logits to preserve exact
    # invariance under swapping the two displayed options.
    logits = np.array(
        [0.5 * decision_variable, -0.5 * decision_variable],
        dtype=np.float64,
    )
    logits -= np.max(logits)
    probabilities = np.exp(logits)
    probabilities /= probabilities.sum()

    lapse = float(parameters["lapse_rate"])
    probabilities = (1.0 - lapse) * probabilities + 0.5 * lapse
    probabilities = np.clip(probabilities, 0.0, 1.0)
    probabilities /= probabilities.sum()
    return probabilities
```

**`policy(probs)`:**
```python
def policy(probs):
    probabilities = np.asarray(probs, dtype=np.float64)
    probabilities = np.clip(probabilities, 0.0, None)
    total = float(np.sum(probabilities))
    if not np.isfinite(total) or total <= 0.0:
        probabilities = np.full(
            probabilities.size, 1.0 / probabilities.size, dtype=np.float64
        )
    else:
        probabilities /= total
    return int(np.random.choice(probabilities.size, p=probabilities))
```
