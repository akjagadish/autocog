# Round 4 — Theories

**Verdict:** `new_theory` (slot 1 replaced)

## Starting theories

### slot 1 — `pi_5` — KILLED ✗

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


### slot 2 — `pi_6` — SURVIVED ✓

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


## Replacement

### `pi_7` → slot 1 (via `new_theory`)

**Description:** Credibility-Claim Skepticism with Composition-Sensitive Coalition Fallback proposes that participants distinguish ordinal validity from the credibility of the communicated numerical claim. Moderate above-chance claims receive weakly positive weight, whereas near-perfect claims invite an inflation correction and can receive negative net weight. This correction varies continuously across people. Claim evidence is divisively normalized over all discriminating experts and combined with a robust, mildly convex unweighted tally fallback. Response precision additionally depends smoothly on evidence composition: decisions dominated by the coarse tally are made with lower precision, whereas claim-dominated decisions retain the original sensitivity. This softens overly deterministic coalition choices without imposing exact-tie or margin-specific gates and preserves history independence and option-swap symmetry.

**Rationale:** This is a minimal edit to the accepted iteration-8 model. The cubic credibility correction, original divisive denominator, accepted 1.10 tally curvature, evidence transformation, and all existing parameter ranges are unchanged. The only mechanistic addition is a continuous claim-share interpolation of response sensitivity. Purely tally-led decisions receive 68–82% of the original sensitivity, while claim-dominated decisions approach the accepted model's full sensitivity. This should reduce excessive determinism in Experiments 1, 3, 4, and 6 and modestly lower Experiment 2's overshoot, while largely preserving claim-led endpoint reversals in Experiments 8 and 10. Because the modulation uses absolute evidence composition, it remains continuous and option-swap symmetric and does not introduce an exact-tie, tally-margin, or coalition-size gate. The rejected participation-ratio normalization is not retained.

**Parameters:**
  - `claim_skepticism`: `[0.3, 2.4]`
  - `normalization_floor`: `[0.20, 0.45]`
  - `claim_capacity`: `[2.0, 2.5]`
  - `tally_capacity`: `[2.6, 3.2]`
  - `evidence_scale`: `[2.50, 3.30]`
  - `choice_sensitivity`: `[3.6, 4.8]`
  - `tally_sensitivity_ratio`: `[0.68, 0.82]`
  - `lapse_rate`: `[0.0, 0.10]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history):
    # Credibility-Claim Skepticism with Coalition Fallback. History is
    # intentionally ignored because no outcome feedback is available.
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

    # +1 denotes an endorsement unique to A, -1 one unique to B, and zero a
    # nondiscriminating expert. This representation guarantees option-swap
    # symmetry throughout the computation.
    signed_votes = np.sign(stimulus[0] - stimulus[1])
    active = signed_votes != 0.0
    tally_margin = float(np.sum(signed_votes))

    # Ordinal diagnostic strength rises conventionally from chance. The cubic
    # term represents suspicion that extreme numerical reliability claims are
    # inflated. It is negligible for modest claims but can make near-perfect
    # claims carry negative net credibility. Skepticism varies continuously
    # between people rather than selecting a categorical scale orientation.
    v = np.clip(validities, 0.5, 1.0)
    stated_strength = 2.0 * (v - 0.5)
    skepticism = float(parameters["claim_skepticism"])
    net_claim_weight = (
        stated_strength - 2.0 * skepticism * stated_strength ** 3
    )

    # Pool all discriminating experts in one divisive-normalization field.
    # The numerator preserves expert identity and direction, while total
    # absolute claim activity supplies conflict-dependent normalization.
    # Consequently, sparse endpoint contrasts remain salient but claim
    # evidence cannot accumulate without bound in large coalitions.
    if np.any(active):
        active_weights = net_claim_weight[active]
        active_signs = signed_votes[active]
        signed_claim_sum = float(np.dot(active_signs, active_weights))
        total_claim_activity = float(np.sum(np.abs(active_weights)))
        normalization_floor = float(parameters["normalization_floor"])
        normalized_claim = signed_claim_sum / (
            normalization_floor + total_claim_activity
        )
    else:
        normalized_claim = 0.0

    claim_capacity = float(parameters["claim_capacity"])
    claim_evidence = claim_capacity * normalized_claim

    # The tally is the robust fallback. A very mild fixed convexity discounts
    # an isolated one-vote advantage while allowing margins above one to
    # strengthen rapidly. Saturation still bounds decisive coalitions, and
    # claim capacity remains below the tally's asymptotic capacity.
    tally_capacity = float(parameters["tally_capacity"])
    scaled_tally = np.sign(tally_margin) * (
        abs(tally_margin) / tally_capacity
    ) ** 1.10
    tally_evidence = tally_capacity * np.tanh(scaled_tally)
    total_evidence = tally_evidence + claim_evidence

    # A common bounded response mapping is used for ties, weak conflicts, and
    # large coalitions; there are no hand-built exact-tie or margin-one gates.
    evidence_scale = float(parameters["evidence_scale"])
    bounded_evidence = float(np.tanh(total_evidence / evidence_scale))

    # Tally-led judgments use a coarser response temperature, while sensitivity
    # approaches its original level continuously as claim evidence constitutes
    # more of the active evidence. This is composition based, not margin gated.
    evidence_mass = abs(claim_evidence) + abs(tally_evidence)
    claim_share = abs(claim_evidence) / (evidence_mass + 1e-12)
    tally_ratio = float(parameters["tally_sensitivity_ratio"])
    effective_sensitivity = float(parameters["choice_sensitivity"]) * (
        tally_ratio + (1.0 - tally_ratio) * claim_share
    )
    decision_variable = effective_sensitivity * bounded_evidence

    # Positive evidence favors A and negative evidence favors B.
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
