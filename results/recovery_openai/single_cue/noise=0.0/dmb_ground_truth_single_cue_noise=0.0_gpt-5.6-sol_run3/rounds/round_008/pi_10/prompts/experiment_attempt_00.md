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
**Description:** Coalition-Level Skeptical Consensus theory proposes that people do not compare communicated validities expert by expert. They first construct a representation of each option's endorsing coalition from three attributes: its mean assertiveness, its breadth, and its internal coherence. Mean assertiveness increases smoothly with communicated validity from 50% through 100%, without endpoint bonuses, notches, or categorical boundaries. Repeated similarly assertive endorsements strengthen the coalition representation according to a sublinear consensus function, whereas heterogeneous coalitions are represented less coherently. The contrast between the two coalition representations is additionally normalized by total conflict breadth and compositional mixture. In narrow conflicts, reactance is further normalized when both coalitions make substantive claims or when neither coalition approaches the maximum of the same smooth assertiveness continuum. This leaves a maximal 100%-versus-50% contrast intact while attenuating moderate and bilateral narrow conflicts without creating an endpoint bonus or threshold. People pragmatically react against the coalition making the stronger aggregate claim, so the coalition contrast enters choice with a skeptical sign. This reactance is continuous across individuals and can be weak rather than defining discrete skeptic classes. A smooth breadth-dependent gain makes isolated conflicts less reactance-provoking than repeated consensus, while preserving compression in very broad conflicts. A separate categorical tally channel ignores validity and increases nonlinearly with the absolute vote margin. It is weak enough at ties and one-vote margins to permit anti-validity reversals, but gradually protects decisive majorities without forcing ceiling-level tally choices. A shared continuous reactance trait modulates margin curvature. This modulation is centered and analytically mean-corrected, so it preserves the population-average tally function while producing increasingly large individual differences at large margins. Independent continuous variation in tally sensitivity and decision noise supplies further subject heterogeneity. Because choices receive no correctness feedback, coalition construction is history independent; because all evidence is expressed as signed option contrasts, the model is exactly invariant to swapping A and B.

**Parameters:**
- consensus_exponent: [0.68, 0.84]
- coherence_scale: [0.025, 0.090]
- coherence_floor: [0.42, 0.68]
- breadth_normalization: [0.05, 0.14]
- composition_normalization: [0.8, 2.2]
- bilateral_narrow_normalization: [2.0, 4.0]
- submaximal_narrow_normalization: [1.0, 2.0]
- breadth_reinforcement_floor: [0.62, 0.76]
- coalition_accumulation: [1.15, 1.75]
- reactance_strength: [2.4, 3.7]
- reactance_trait: [0, 1]
- tally_sensitivity: [0.20, 0.38]
- tally_trait: [0, 1]
- margin_exponent: [1.15, 1.40]
- reactance_margin_coupling: [-0.50, 0.60]
- choice_sensitivity: [0.78, 1.24]
- noise_trait: [0, 1]
- lapse_rate: [0.0, 0.08]
- validities: validities

**`predict source code`:**
```python
def predict(parameters, state, history):
    # Coalition-Level Skeptical Consensus model. Choice history is deliberately
    # ignored because no outcome feedback is available for learning validity.
    stimulus = np.asarray(state, dtype=np.float64)
    if stimulus.ndim != 2 or stimulus.shape[0] != 2:
        raise ValueError(
            f"Expected state with shape (2, n_features); got {stimulus.shape}."
        )

    validities = np.asarray(parameters["validities"], dtype=np.float64)
    n_features = stimulus.shape[1]
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} does not match "
            f"n_features {n_features}."
        )

    # +1 denotes a discriminating endorsement of A and -1 an endorsement of B.
    signed_votes = np.sign(stimulus[0] - stimulus[1])
    active = signed_votes != 0.0
    tally_margin = float(np.sum(signed_votes))

    # Assertiveness is completely smooth and monotone on the communicated
    # validity scale. In particular, 90%, 95%, and 100% receive neighboring
    # values on the same linear continuum.
    validity = np.clip(validities, 0.5, 1.0)
    assertiveness = 2.0 * (validity - 0.5)

    def coalition_summary(side):
        members = assertiveness[active & (signed_votes == side)]
        breadth = int(members.size)
        if breadth == 0:
            return 0.0, 0.0, 0

        mean_assertiveness = float(np.mean(members))
        dispersion = float(np.mean((members - mean_assertiveness) ** 2))

        # Similar members form a coherent aggregate claim. Mixed validity
        # compositions reduce coherence continuously rather than triggering an
        # exception for any particular validity or coalition size.
        coherence_scale = float(parameters["coherence_scale"])
        coherence_floor = float(parameters["coherence_floor"])
        coherence = coherence_floor + (1.0 - coherence_floor) * np.exp(
            -dispersion / coherence_scale
        )

        # Repetition reinforces consensus, but with diminishing returns. This
        # differs from allocating a fixed attentional pool among individual
        # claims: adding a similar endorser always increases the summary.
        consensus_exponent = float(parameters["consensus_exponent"])
        consensus = float(breadth) ** consensus_exponent
        summary = mean_assertiveness * consensus * coherence
        return float(summary), dispersion, breadth

    summary_a, dispersion_a, breadth_a = coalition_summary(1.0)
    summary_b, dispersion_b, breadth_b = coalition_summary(-1.0)
    raw_coalition_contrast = summary_a - summary_b
    total_breadth = breadth_a + breadth_b

    if total_breadth == 0:
        contextual_contrast = 0.0
    else:
        # Broad conflicts compress pragmatic contrast. Internal mixture adds a
        # second coalition-level normalizer, weighted by coalition breadth.
        excess_breadth = max(total_breadth - 2, 0)
        breadth_normalizer = 1.0 + float(
            parameters["breadth_normalization"]
        ) * np.log1p(float(excess_breadth))

        pooled_dispersion = (
            breadth_a * dispersion_a + breadth_b * dispersion_b
        ) / float(total_breadth)
        composition_normalizer = 1.0 + float(
            parameters["composition_normalization"]
        ) * float(total_breadth) * pooled_dispersion

        contextual_contrast = raw_coalition_contrast / (
            breadth_normalizer * composition_normalizer + 1e-12
        )

        # Narrow conflicts are additionally normalized when both coalition
        # summaries are substantive or when the strongest summary remains
        # below the top of the smooth assertiveness scale. Both effects decay
        # continuously with conflict breadth. A maximal singleton contrast of
        # 100% against 50% has zero added normalization.
        narrow_weight = np.exp(-float(excess_breadth) / 2.0)
        bilateral_mass = min(abs(summary_a), abs(summary_b))
        strongest_summary = min(max(abs(summary_a), abs(summary_b)), 1.0)
        submaximal_gap = 1.0 - strongest_summary
        narrow_normalizer = 1.0 + narrow_weight * (
            float(parameters["bilateral_narrow_normalization"])
            * bilateral_mass
            + float(parameters["submaximal_narrow_normalization"])
            * submaximal_gap ** 2
        )
        contextual_contrast /= float(narrow_normalizer)

        # A singleton conflict evokes less coalition-level reactance than a
        # repeated consensus. The gain rises smoothly with breadth and remains
        # distinct from the broad-conflict normalization above.
        reinforcement_floor = float(parameters["breadth_reinforcement_floor"])
        reinforcement_gain = reinforcement_floor + (
            1.0 - reinforcement_floor
        ) * (1.0 - np.exp(-float(excess_breadth) / 2.0))
        contextual_contrast *= float(reinforcement_gain)

    # A continuous trait controls skeptical construal. It also contributes to
    # margin curvature below, permitting correlated heterogeneity without a
    # categorical skeptic/conventional mixture.
    reactance_trait = float(parameters["reactance_trait"])
    reactance_strength = float(parameters["reactance_strength"]) * (
        0.65 + 0.70 * reactance_trait
    )
    accumulated_contrast = np.tanh(
        float(parameters["coalition_accumulation"]) * contextual_contrast
    )
    skeptical_evidence = -reactance_strength * float(accumulated_contrast)

    # The raw tally is represented independently of communicated validity. Its
    # mildly superlinear margin function leaves a one-vote lead vulnerable but
    # lets decisive margins gradually dominate bounded reactance without
    # producing near-deterministic tally choices.
    tally_trait = float(parameters["tally_trait"])
    tally_sensitivity = float(parameters["tally_sensitivity"]) * (
        0.70 + 0.60 * tally_trait
    )
    base_margin_exponent = float(parameters["margin_exponent"])
    margin_coupling = float(parameters["reactance_margin_coupling"])
    exponent_deviation = margin_coupling * (reactance_trait - 0.5)
    margin_exponent = base_margin_exponent + exponent_deviation

    if abs(tally_margin) < 1e-12:
        tally_evidence = 0.0
    else:
        margin_magnitude = abs(tally_margin)

        # Centering the exponent deviation preserves one-vote evidence exactly.
        # For larger margins, divide by its analytic population mean under the
        # continuous uniform reactance trait. Thus widening the coupling adds
        # heterogeneity that grows with margin without changing the accepted
        # population-average tally curve.
        mean_span = 0.5 * margin_coupling * np.log(margin_magnitude)
        if abs(mean_span) < 1e-8:
            heterogeneity_correction = 1.0
        else:
            heterogeneity_correction = float(np.sinh(mean_span) / mean_span)

        tally_evidence = (
            tally_sensitivity
            * np.sign(tally_margin)
            * margin_magnitude ** margin_exponent
            / heterogeneity_correction
        )

    total_evidence = tally_evidence + skeptical_evidence

    # Decision noise varies continuously and independently across subjects.
    noise_trait = float(parameters["noise_trait"])
    choice_sensitivity = float(parameters["choice_sensitivity"]) * (
        0.65 + 0.70 * noise_trait
    )
    decision_variable = choice_sensitivity * total_evidence

    # Positive evidence favors A. Symmetric logits guarantee exact option-swap
    # symmetry, including on tied and mirrored trials.
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

**`policy source code`:**
```python
def policy(probs):
    probabilities = np.asarray(probs, dtype=np.float64)
    probabilities = np.clip(probabilities, 0.0, None)
    total = float(np.sum(probabilities))
    if not np.isfinite(total) or total <= 0.0:
        probabilities = np.full(
            probabilities.size,
            1.0 / probabilities.size,
            dtype=np.float64,
        )
    else:
        probabilities /= total
    return int(np.random.choice(probabilities.size, p=probabilities))
```


## COMPETING THEORY
**Description:** Contextual Anti-Reliability Arbitration theory proposes that communicated validity numbers are interpreted partly as pragmatic claims whose assertiveness can undermine their credibility. Every above-chance claim therefore generates continuous evidence against the option endorsed by that expert, rather than being categorically reversed by a special subgroup. The magnitude of this anti-reliability response varies continuously across people. Near-perfect claims additionally evoke endpoint distrust because unusually strong assurances are perceived as especially suspicious. When an endpoint cue faces a substantive opposing claim, both its ordinary and endpoint-specific distrust contributions are attenuated; against a genuinely neutral cue, both remain intact. Claims around 95% are more strongly compressed in the ordinary channel and do not receive the endpoint bonus, separating near-endpoint skepticism from distrust of literal certainty. Anti-reliability evidence is accumulated separately from the raw vote tally and divisively normalized by coalition breadth, within-side compositional heterogeneity, and sparse across-side claim mismatch. The latter detects heterogeneous singleton conflicts that within-side dispersion cannot detect, while exempting an isolated certainty claim opposed by a neutral cue. A small smooth boost preserves moderate-claim distrust in broad but not maximally dense coalitions. Its influence is strongest when the validity contrast is concentrated and the tally is tied or weak, while it decays smoothly as the absolute tally margin grows. Raw tally evidence additionally receives a continuously heterogeneous, intermediate-margin decision-temperature adjustment. The mechanism remains continuous, option-swap symmetric, and history independent because choices are followed by no accuracy feedback.

**Parameters:**
- anti_reliability_strength: [3.0, 5.6]
- anti_accumulation: [2.0, 3.5]
- endpoint_distrust: [1.10, 2.05]
- coalition_dilution_exponent: [0.46, 0.72]
- composition_dilution: [0.8, 2.4]
- across_composition_dilution: [1.0, 3.5]
- concentration_floor: [0.38, 0.62]
- margin_protection_scale: [1.55, 2.25]
- margin_protection_power: [2.2, 3.4]
- evidence_scale: [2.2, 3.0]
- choice_sensitivity: [1.45, 2.65]
- margin_temperature_gain: [0.0, 0.32]
- lapse_rate: [0.0, 0.10]
- validities: validities

**`predict source code`:**
```python
def predict(parameters, state, history):
    # Contextual Anti-Reliability Arbitration. History is intentionally ignored:
    # without outcome feedback, prior choices cannot reveal expert accuracy.
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

    # Positive endorsements favor A and negative endorsements favor B.
    signed_votes = np.sign(stimulus[0] - stimulus[1])
    active = signed_votes != 0.0
    tally_margin = float(np.sum(signed_votes))
    active_count = int(np.count_nonzero(active))

    # Encode the assertiveness of every communicated above-chance claim.
    # Moderate claims already carry pragmatic suspicion. The ordinary channel
    # is strongly compressed near 95%, preventing near-endpoint claims from
    # behaving like literal-certainty claims.
    v = np.clip(validities, 0.5, 1.0)
    above_chance = np.clip(2.0 * (v - 0.5), 0.0, 1.0)
    ordinary_base = np.power(above_chance, 0.82)

    def logistic(x):
        if x >= 0.0:
            return 1.0 / (1.0 + np.exp(-x))
        ex = np.exp(x)
        return ex / (1.0 + ex)

    upper_compression = np.array(
        [logistic(50.0 * (float(x) - 0.86)) for x in above_chance],
        dtype=np.float64,
    )
    ordinary_claim = ordinary_base * (1.0 - 0.55 * upper_compression)

    # Endpoint distrust is reserved for claims extremely close to certainty.
    endpoint_low = logistic(100.0 * (0.0 - 0.98))
    endpoint_high = logistic(100.0 * (1.0 - 0.98))
    endpoint_curve = np.array(
        [
            (logistic(100.0 * (float(x) - 0.98)) - endpoint_low)
            / (endpoint_high - endpoint_low)
            for x in above_chance
        ],
        dtype=np.float64,
    )
    endpoint_curve = np.clip(endpoint_curve, 0.0, 1.0)

    if active_count == 0:
        anti_reliability = 0.0
    else:
        active_signs = signed_votes[active]
        active_ordinary = ordinary_claim[active]
        active_endpoint = endpoint_curve[active]
        active_above_chance = above_chance[active]

        # Endpoint distrust is preserved against a neutral 50% opponent, but
        # attenuated by the smooth maximum ordinary strength on the opposing
        # side. The attenuation applies to the endpoint cue's total distrust,
        # not merely to its endpoint bonus.
        nonendpoint_ordinary = active_ordinary * (1.0 - active_endpoint)
        endpoint_focus = np.ones(active_count, dtype=np.float64)
        for i in range(active_count):
            opposing = nonendpoint_ordinary[active_signs != active_signs[i]]
            if opposing.size > 0:
                attention_logits = 6.0 * opposing
                attention_logits -= np.max(attention_logits)
                attention = np.exp(attention_logits)
                attention /= attention.sum()
                opposing_peak = float(np.dot(attention, opposing))
                endpoint_focus[i] = 1.0 / (
                    1.0 + 3.0 * opposing_peak ** 1.4
                )

        focused_endpoint = active_endpoint * endpoint_focus
        active_claims = (
            active_ordinary * (1.0 - active_endpoint)
            + (
                active_ordinary
                + float(parameters["endpoint_distrust"])
            ) * focused_endpoint
        )
        signed_claim_contrast = float(np.dot(active_signs, active_claims))
        total_claim_mass = float(np.sum(active_claims))

        # Relative contrast measures whether distrust is directionally
        # concentrated rather than spread across two similarly assertive sides.
        concentration = abs(signed_claim_contrast) / (total_claim_mass + 1e-12)
        concentration = float(np.clip(concentration, 0.0, 1.0))
        focus_floor = float(parameters["concentration_floor"])
        focus = focus_floor + (1.0 - focus_floor) * concentration ** 1.35

        # Estimate heterogeneity within each endorsing coalition. Mixing claims
        # of substantially different strength on the same side makes their
        # pragmatic interpretation less coherent and hence more strongly diluted.
        positive_claims = active_claims[active_signs > 0.0]
        negative_claims = active_claims[active_signs < 0.0]

        def side_dispersion(values):
            if values.size <= 1:
                return 0.0
            mean_value = float(np.mean(values))
            return float(np.mean((values - mean_value) ** 2))

        positive_dispersion = side_dispersion(positive_claims)
        negative_dispersion = side_dispersion(negative_claims)
        within_dispersion = (
            positive_claims.size * positive_dispersion
            + negative_claims.size * negative_dispersion
        ) / float(active_count)

        breadth_exponent = float(parameters["coalition_dilution_exponent"])
        breadth_normalizer = float(active_count) ** breadth_exponent
        heterogeneity_normalizer = 1.0 + (
            float(parameters["composition_dilution"])
            * float(active_count)
            * within_dispersion
        )

        # Within-side dispersion is exactly zero when each option has only one
        # active endorser. Across-active dispersion therefore supplies a second,
        # smoothly sparse-weighted composition diagnostic. It is switched off
        # for a literal endpoint claim against a neutral claim, preserving the
        # isolated 100%-versus-50% distrust response.
        across_dispersion = float(np.mean((active_claims - np.mean(active_claims)) ** 2))
        sparse_weight = (2.0 / float(active_count)) ** 2
        endpoint_neutral_exemption = float(np.max(active_endpoint)) * (
            1.0 - float(np.max(nonendpoint_ordinary))
        )
        across_gate = 1.0 - np.clip(endpoint_neutral_exemption, 0.0, 1.0)
        across_normalizer = 1.0 + (
            float(parameters["across_composition_dilution"])
            * sparse_weight
            * across_gate
            * across_dispersion
        )

        contextual_contrast = (
            signed_claim_contrast * focus
            / (
                breadth_normalizer
                * heterogeneity_normalizer
                * across_normalizer
                + 1e-12
            )
        )

        # Moderate pragmatic claims receive a small accumulation boost in broad
        # but not maximally dense coalitions. The smooth validity and breadth
        # gates avoid strengthening sparse 95%-claim conflicts or dense diffuse
        # conflicts indiscriminately.
        strongest_assertiveness = float(np.max(active_above_chance))
        moderate_gate = logistic(12.0 * (0.72 - strongest_assertiveness))
        breadth_peak = (
            (1.0 - np.exp(-max(active_count - 2, 0) / 2.0))
            * np.exp(-((active_count - 7.0) / 4.0) ** 2)
        )
        contextual_contrast *= float(
            1.0 + 0.15 * moderate_gate * breadth_peak
        )

        # The anti-reliability signal is bounded and continuously heterogeneous
        # across subjects. Its sign opposes the communicated validity contrast.
        accumulated = np.tanh(
            float(parameters["anti_accumulation"]) * contextual_contrast
        )
        anti_reliability = -float(parameters["anti_reliability_strength"]) * float(accumulated)

        # A smooth arbitration function cedes control to the tally as its margin
        # becomes decisive; there are no exact-tie or one-margin special cases.
        margin_scale = float(parameters["margin_protection_scale"])
        margin_power = float(parameters["margin_protection_power"])
        margin_gate = 1.0 / (
            1.0 + (abs(tally_margin) / margin_scale) ** margin_power
        )
        anti_reliability *= float(margin_gate)

    # Raw votes retain their categorical status but saturate gradually, limiting
    # overconfidence while preserving dominance by large vote coalitions.
    tally_evidence = 4.5 * np.tanh(tally_margin / 4.5)
    total_evidence = tally_evidence + anti_reliability

    evidence_scale = float(parameters["evidence_scale"])
    normalized_evidence = float(np.tanh(total_evidence / evidence_scale))
    decision_variable = float(parameters["choice_sensitivity"]) * normalized_evidence

    # Confidence separates most strongly at intermediate margins. The bounded
    # gain is zero through margin one and decreases again for very large margins,
    # increasing heterogeneous margin sensitivity without indiscriminately
    # sharpening every decisive coalition.
    margin_excess = max(abs(tally_margin) - 1.0, 0.0)
    intermediate_margin_shape = (
        0.5 * margin_excess * np.exp(1.0 - margin_excess / 2.0)
        if margin_excess > 0.0 else 0.0
    )
    margin_temperature = 1.0 + float(parameters["margin_temperature_gain"]) * intermediate_margin_shape
    decision_variable *= float(margin_temperature)

    # Positive evidence favors A. Symmetric logits guarantee that swapping the
    # displayed options swaps their probabilities exactly.
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

**`policy source code`:**
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


## ALREADY-EXPLORED EXPERIMENTS (do not repeat)
[0] This 16-pair, 96-trial design creates both directional and quantitative dissociations. In each of the first eight pairs, the highest-validity discriminating cue favors A; the remaining eight pairs are exact A/B reversals. Therefore Take The Best predicts the same choice probability for its lexicographic winner on every trial: epsilon/2 + (1-epsilon)*sigmoid(beta), regardless of which cue is first discriminating or how many lower-validity cues oppose it. Pairs 1-4 manipulate the rank of the first discriminating cue while producing equal tallies (one cue for each option). Tallying must predict exactly 0.5 on these pairs, whereas Take The Best predicts a systematic preference. In pairs 5-8, the lexicographic winner loses the tally by respective score gaps of 1, 2, 3, and 5. Take The Best continues to predict an invariant preference for that winner, while Tallying predicts the opposite option with monotonically increasing confidence as the gap grows. Exact reversals balance response side and preserve every theoretical contrast. With 16 unique pairs, each is repeated six times.

[1] This design isolates a quantitative confidence signature without relying on opposite directional choices. The highest-validity expert (feature 5, validity 0.95) discriminates on every trial, so Take The Best always stops immediately and predicts the same probability for its winner on all eight pairs: epsilon/2 + (1-epsilon)*sigmoid(beta). The tally winner is always the same option as the Take-The-Best winner, but its feature-win margin is systematically manipulated across four conditions: 4-3 (gap 1), 5-2 (gap 3), 6-1 (gap 5), and 7-0 (gap 7), with two tied features in every condition. Tallying therefore predicts winner probabilities epsilon/2 + (1-epsilon)*sigmoid(beta*d) for d in {1,3,5,7}, producing a strictly increasing choice-consistency gradient except at practical saturation. Take The Best cannot produce this within-subject margin gradient because its binary score difference is always one. Each condition has an exact A/B reversal, balancing response side while preserving the theoretical contrast. There are eight unique pairs, so each is repeated 12 times for approximately 96 trials.

[2] Each base pair gives A one feature win and B two feature wins; the final eight pairs are exact A/B reversals. Tallying therefore predicts exactly the same B-choice probability on all eight base pairs because its tally margin is always 2-1, and the same mirrored A-choice probability on all reversals. Communicated-Reliability Accumulation instead distinguishes the identities of the winning experts. At representative parameter values (gamma about 1.035 and reliability_floor about 0.12), net evidence for A across the eight base pairs is approximately 2.71, 1.80, 1.00, 0.43, -0.10, -0.34, -0.71, and -1.40. Thus it predicts a strong, ordered choice gradient and a crossover from choosing the one-cue minority A to choosing the two-cue majority B. This ordering and crossover are robust over the advocated parameter ranges, whereas no setting of Tallying's beta or epsilon can produce stimulus-specific differences among pairs having the same tally margin. Exact reversals balance response side and should mirror the gradient. With 16 unique pairs, each pair is repeated six times for 96 trials.

[3] This six-pair design makes tally margin increase while communicated-reliability evidence decreases and ultimately reverses direction. In the first three pairs, A's tally margins are respectively 1, 3, and 5: A wins 1-0, 3-0, and 6-1 features. Tallying therefore predicts a strictly increasing A-choice gradient, with probabilities epsilon/2 + (1-epsilon)*sigmoid(beta*d) for d in {1,3,5}. Reliability accumulation predicts the opposite quantitative pattern because the larger tallies are built from progressively weaker experts. At representative parameters (gamma=1.035 and reliability_floor=0.12), its evidence for A is approximately 3.18, 2.44, and -1.04. These evidence values remain ordered across the specified parameter ranges, and the third remains negative: there, Tallying favors A by a five-feature margin, whereas reliability accumulation favors B because the 95%-valid expert outweighs six weak experts. The final three pairs are exact A/B reversals, balancing response side and mirroring both theories' predictions. Thus the critical signatures are an increasing choice-consistency gradient under Tallying versus a decreasing gradient and directional crossover under reliability accumulation. With six unique pairs, each is repeated 16 times for 96 trials.

[4] This eight-pair design holds the signed tally at exactly zero while varying coalition size and composition. In the four base pairs, A is endorsed by one 95%-valid expert plus respectively 0, 1, 2, or 3 near-chance (51%) experts; B is endorsed by respectively 1, 2, 3, or 4 experts of 73.5% validity. Because both sides have equal numbers of endorsers within every pair, the advocated model's common reliability floor cancels. Across its parameter range, its evidence for A is approximately 1.99–2.09, 1.01–1.10, 0.02–0.11, and -0.96–-0.88. It therefore predicts a steep decline in A choices and a robust directional crossover on the fourth condition, where four moderately reliable experts cumulatively outweigh the high expert and three weak experts. Compressed-Reliability Consensus instead assigns every condition a tied tally and compares bounded group summaries. Softmax attention keeps A's group summary dominated by the 95% expert: its reliability contrast remains positive at approximately 0.295, 0.273, 0.252, and 0.232. It consequently predicts A above chance in all four conditions, with only a shallow decline and no crossover. Thus the critical dissociation is a large accumulation-driven gradient ending below chance versus a near-flat, uniformly above-chance consensus pattern. The final four pairs are exact A/B reversals, balancing response side and requiring both patterns to mirror. Eight unique pairs are each repeated 12 times for 96 trials.

[5] This design targets both a robust confidence dissociation and a secondary composition-sensitive gradient. Every base pair gives A seven discriminating endorsements and B two, producing the same tally margin of five. Five of A's endorsements always come from 50%-valid experts. Compressed-Reliability Consensus treats these as full categorical votes and applies its saturated margin-five consensus multiplier; it therefore predicts substantially above-chance A choice. Even at its least confident parameter settings, its predicted A probability is approximately 0.67 or greater. Communicated-Reliability Accumulation gives each 50%-valid expert only the reliability floor, so these five endorsements contribute total evidence of only 5c = 0.50–0.70. The remaining two-versus-two coalitions were selected to have approximately equal summed transformed log-odds weights throughout the accumulation model's narrow gamma range. Consequently, accumulation predicts a nearly invariant and much weaker A preference, approximately 0.53–0.60 across base pairs. The four conditions also increase the dispersion of A's two non-chance reliabilities while preserving their accumulated weight: from 69%/80% to 51%/90%, opposed by two experts near 75%. Softmax compression increasingly emphasizes A's high-reliability member, moving the advocated model's reliability contrast from slightly negative to positive and producing an increasing choice-confidence gradient. Accumulation predicts essentially no such condition gradient because the transformed-weight sums are matched. Exact reversals balance response side and require mirrored predictions. There are eight unique pairs, each repeated 12 times for 96 trials.

[6] This 12-pair design isolates expert-by-expert residual accumulation from bounded group summarization while holding the categorical tally fixed. In each of the six base pairs, A is endorsed by m high-validity (95%) experts and B by m-1 near-chance (51%) experts, for m = 2,...,7. Thus A's tally margin is always exactly one, and both options always have at least one endorser. Compressed-Reliability Consensus predicts the same response probability in every base condition: because each coalition is homogeneous, its softmax-weighted summaries are always the 95% and 51% reliability codes, respectively; the reliability contrast is therefore constant, the tally is always +1, and consensus amplification is inactive. Across its parameter ranges, it predicts an approximately 0.55-0.64 A-choice probability with no coalition-size gradient. Uncertain-Credibility Normalized Voting instead preserves each expert's identity and accumulates residual deviations cue by cue. Every added 95% endorsement for A contributes a positive residual, while every added 51% endorsement for B also shifts residual evidence toward A because that weak B vote is discounted relative to the shared prototype. Divisive normalization slows but does not eliminate this accumulation. Its total evidence for A rises monotonically from approximately 1.54-2.17 at m=2 to 2.58-3.52 at m=7, yielding a substantial within-subject increase in A-choice consistency. The critical signature is therefore a strong monotonic coalition-size gradient under the advocated theory versus an exactly flat profile under the competing theory, despite an identical one-vote tally and identical within-side reliability summaries. The final six pairs are exact A/B reversals, balancing response side and requiring the gradient to mirror. With 12 unique pairs, each is repeated eight times for 96 trials.

[7] This 12-pair design targets the competing theory's exact-tally reliability gate. Every trial has exactly one expert endorsing A and one endorsing B, so the categorical tally is zero. In the six base pairs, A's endorser has validity 0.60, 0.80, or 1.00, whereas B's endorser always has validity 0.50. Each reliability contrast appears in two nuisance contexts: all nondiscriminating experts rate both products 0 or all rate both products 1. Compressed-Reliability Consensus leaves reliability contrasts active in exact ties and therefore predicts an ordered increase in A choices as A's endorser rises from 60% to 80% to 100%. Its softmax group summaries reduce to the two individual endorsers, making the two nuisance contexts exactly equivalent. Uncertain-Credibility Normalized Voting multiplies reliability evidence by only 0.06 in an exact tally tie and then further compresses the resulting tiny evidence through its convex response transformation. It consequently predicts choices extremely close to chance at all three reliability levels and an almost negligible gradient; at 60% versus 50%, lower-tail winsorization makes its signed reliability adjustment exactly zero. Thus the critical quantitative signature is a visible reliability-contrast gradient, reaching a meaningful above-chance preference in the 100%-versus-50% condition, under the advocated theory versus an essentially flat chance-level profile under the competing theory. The final six pairs are exact A/B reversals, balancing response side and requiring the gradient to mirror. With 12 unique pairs, each is repeated eight times for 96 trials.

[8] This eight-pair design targets the theories' opposite use of communicated validity while holding A's categorical tally advantage fixed at 7 endorsements versus 6. The first seven experts have validity .95 and the last seven validity .50. Across the four base pairs, the high-validity endorsement imbalance favoring A is +7, +3, -3, and -6. Under Uncertain-Credibility Normalized Voting, the corresponding signed residual-deviation sums are approximately +4.07, +1.60, -2.10, and -3.96. Its total evidence for A therefore decreases from approximately 2.58–3.53 to 1.62–1.99, then to approximately -0.30–0.19, and finally to -1.50–-0.55 over the reliability-shrinkage range. It predicts a steep conventional-validity gradient: strong A choice in the first conditions, near-chance choice in the third, and a B preference in the fourth despite A's one-vote tally advantage. The competing theory's dominant latent construal reverses validity direction. Its bounded reliability signal is nearly saturated whenever the high-validity imbalance is nonzero; hence it predicts the opposite gradient—B choices for the +7 and +3 conditions because reversed reliability overturns A's weak tally, but confident A choices for the -3 and -6 conditions because reversed reliability aligns with A's tally. The conflicts involve 13 discriminating experts, so the competing theory's compact-coalition attenuation is essentially inactive. Thus the theories predict oppositely signed condition gradients and opposite majority choices at both ends, not merely different overall accuracy. The final four pairs are exact A/B reversals, balancing response side and requiring mirrored effects. Eight unique pairs are each repeated 12 times for 96 trials.

[9] This eight-pair design isolates the advocated theory's exact-tally relative-salience gate while holding both the categorical tally and the signed validity imbalance constant. In each of the four base pairs, A and B receive equal numbers of endorsements. A always has one unmatched 100%-valid endorser and B one unmatched 50%-valid endorser, producing the same signed validity sum favoring A. Conditions 2-4 add one, two, or three canceling pairs of 100%-valid endorsers—one for A and one for B per pair. These additions leave the tally at zero and leave the signed validity sum unchanged, but increase total encoded validity strength. Consequently, relative salience under the advocated model falls exactly from 1 to 1/3, 1/5, and 1/7. For the dominant reversed-validity construal, the endpoint condition should therefore produce a substantial B preference despite A owning the 100%-valid endorsement, approximately 0.72-0.79 B choice across typical parameter combinations. Adding one balanced high-validity pair sharply gates this reliability evidence, and the 1/5 and 1/7 conditions should be close to chance. This predicts a pronounced nonlinear endpoint-versus-diffuse gradient even though raw reliability imbalance is identical. Uncertain-Credibility Normalized Voting instead applies its 0.06 exact-tie gate in every condition and then convexly compresses the already tiny residual evidence. It should remain extremely close to chance throughout, with at most a minute conventional preference for A and no sizable endpoint effect. Thus the critical dissociation is a strong reversed-validity choice in the concentrated 1-versus-1 endpoint condition followed by collapse toward chance under diffuse balanced coalitions, versus an essentially flat chance-level profile under the competing theory. The final four pairs are exact A/B reversals, balancing response side. Eight unique pairs are each repeated 12 times for 96 trials.

[10] This eight-pair design holds the categorical tally at a one-vote advantage for A while manipulating coalition size and proportional coherence. In the four base pairs, A receives m endorsements from 70%-valid experts and B receives m-1 endorsements from 50%-valid experts, for m = 2, 3, 4, and 5. Under Credibility-Claim Skepticism, a 70% claim has positive net weight throughout the full skepticism range: its weight is 0.4 - 0.128*claim_skepticism, or approximately 0.093 to 0.362. The 50% claims have zero claim weight but still contribute categorical votes. Thus both the fixed +1 tally and normalized claim evidence favor A in every base condition. As m increases, the normalization floor becomes less consequential, claim evidence and its share of total evidence increase, and the advocated theory predicts a monotonic increase in already substantial A-choice consistency. The competing theory's dominant reversed construal makes the accumulated 70% validity signal oppose A's tally. Critically, its special one-vote conflict gate protects the compact 2-versus-1 coalition because its relative consensus is 1/3, but progressively removes that protection for the diffuse 3-versus-2, 4-versus-3, and 5-versus-4 coalitions. For m >= 3, even the competing theory's weakest reversed reliability signal robustly overturns the +1 tally, invokes construal commitment, and predicts a B preference. It therefore predicts a sharply decreasing A-choice profile and a crossover toward B as coalition size grows, whereas the advocated theory predicts an increasing A-choice profile and no crossover. The final four pairs are exact A/B reversals, balancing response side and requiring both quantitative profiles to mirror. With eight unique pairs, each is repeated 12 times for approximately 96 trials.

[11] This 16-pair design creates a robust directional dissociation and a coalition-size gradient while keeping the categorical tally exactly zero. In the first six base pairs, A receives m endorsements from 70%-valid experts and B receives m endorsements from 50%-valid experts, for m = 1,...,6. For the competing theory, a 70% claim has net weight 0.4 - 0.128*claim_skepticism, which remains strictly positive (approximately 0.093 to 0.362) across its entire parameter range. With no tally evidence, it therefore predicts A above chance in every moderate-validity condition; divisive normalization also predicts increasing A-choice consistency as m grows and the normalization floor becomes less consequential. The advocated theory's dominant reversed construal gives the opposite prediction: the positive signed validity sum favoring A is interpreted as evidence for B. Relative salience equals one because the opposing 50% experts have zero encoded validity strength, so the exact-tie gate does not attenuate this signal. It predicts B above chance, increasing toward a bounded plateau with coalition size. Conditions 7 and 8 replace the moderate A coalition with one or three 95%-valid experts. They provide a secondary signature: the advocated theory remains monotonic and predicts at least as much B choice for 95% as for size-matched 70% coalitions, whereas the competing theory's extreme-claim correction changes the 95% net weight to 0.9 - 1.458*claim_skepticism and can reverse its direction when skepticism exceeds about 0.617. Thus the primary result is an oppositely directed coalition-size profile for guaranteed-positive 70% claims, supplemented by a theory-specific moderate-versus-extreme validity contrast. The final eight pairs are exact A/B reversals, balancing response side. With 16 unique pairs, each is repeated six times for 96 trials.

[12] This six-pair design holds the competing theory's complete decision-relevant summary constant while changing the advocated theory's pragmatic claim signal. In every base pair, A receives two endorsements and B receives one, so the tally margin is +1 and the discriminating count is three. The opponent validities were chosen to make the competing theory's signed validity sum identical across conditions: tanh(1.2) = tanh(1.35) - tanh(3*(0.51347-0.5)) = tanh(1.5) - tanh(3*(0.52387-0.5)), up to rounding. Thus its bounded reliability evidence, compact-coalition attenuation, reversal commitment, and predicted A-choice probability are effectively identical for the 90%, 95%, and 100% conditions, for every latent construal orientation. Contextual Anti-Reliability Arbitration instead predicts a pronounced 95% notch. The ordinary distrust claim is strong at 90% but sharply compressed at 95%; the small opposing 51.347% claim further cancels part of the already compressed 95% contrast. Literal certainty then activates endpoint distrust in the 100% condition, while its very weak 52.387% opponent produces little endpoint attenuation. Consequently, the advocated theory predicts substantially more A choices at 95% than at 90%, followed by a renewed decrease in A choices at 100% relative to 95%. The critical result is this nonmonotonic, endpoint-rebounding profile versus the competing theory's quantitatively flat profile. The final three pairs are exact A/B reversals, balancing response side. Six unique pairs are each repeated 16 times for 96 trials.

[13] This 12-pair design isolates dilution by coalition breadth and compositional heterogeneity while holding the advocated theory's complete reliability calculation constant. In each of the six base pairs, A has one 100%-valid endorser plus m-1 endorsers with 50% validity, while B has m endorsers with 50% validity, for m=1,...,6. Thus the categorical tally is exactly tied in every condition. For Latent Validity-Construal Tally, 50%-valid experts retain categorical votes but contribute exactly zero validity strength. Consequently, every base pair has the same signed validity sum favoring A, the same total encoded validity strength, relative salience exactly one, and the same bounded reliability evidence. The dominant reversed construal therefore predicts a substantial B preference that is quantitatively flat across coalition sizes; the rare conventional and validity-ignoring construals are likewise flat. Contextual Anti-Reliability Arbitration instead assigns the certainty claim a large endpoint-distrust signal but increasingly embeds that single nonzero claim among active neutral claims. As m rises, its breadth normalizer grows and the A coalition becomes increasingly heterogeneous because it mixes one endpoint claim with more zero-strength claims. Endpoint-versus-neutral protection leaves the endpoint signal intact locally, so the predicted reduction specifically arises during coalition arbitration: the B preference should decline monotonically toward chance from m=1 to m=6. The critical dissociation is therefore a flat, sizable reversed-validity preference under the advocated theory versus a strong coalition-size attenuation gradient under the competing theory, despite identical tally, signed validity imbalance, and exact-tie salience for the advocated model. The final six pairs are exact A/B reversals, balancing response side and requiring mirrored profiles. With 12 unique pairs, each is repeated eight times for 96 trials.

[14] This eight-pair design tests the advocated theory's condition-specific attenuation of endpoint distrust. In each base pair, the 100%-valid expert endorses A and exactly one opposing expert endorses B; the opponent's validity increases across 50%, 70%, 80%, and 90%. The categorical tally is always tied 1-1. Contextual Anti-Reliability Arbitration predicts a qualitative crossover. Against the 50% cue, the endpoint-versus-neutral exemption preserves the 100% expert's full ordinary and endpoint-specific distrust, producing a strong preference for B. A 70% opponent should still leave the endpoint claim more distrusted, whereas the 80% condition should approach the transition. Against the substantive 90% opponent, attentional focusing attenuates the endpoint cue's total distrust enough that the 90% claim becomes more distrusted than the 100% claim; the model therefore predicts a preference for A. Thus, paradoxically, strengthening the expert opposed to the endpoint cue should move choices from rejecting A to favoring A, crossing chance between the low- and high-validity conditions. Finite-Pool Pragmatic Claim Competition cannot produce this within-person crossover. With one endorser per side, both claims receive the same attention because their pairwise competition loads are identical, so allocated claim contrast is attention times [1-(2v_B-1)], which remains positive whenever v_B<1. A skeptical construal consequently favors B in every condition, merely declining toward chance as the opponent approaches 100%; a weak conventional construal favors A throughout and also cannot switch signs. The critical planned contrast is therefore endpoint-endorsed choice below chance for the 50%/70% opponents but above chance for the 90% opponent, rather than only a monotonic confidence reduction. The last four pairs are exact A/B reversals, balancing response side while preserving this interaction. Eight unique pairs are each repeated 12 times for approximately 96 trials.

[15] This six-pair design holds the categorical tally exactly tied at 4-4 while manipulating only the dispersion of B's claim validities. In every base pair, A is endorsed by four homogeneous 75%-valid experts (assertiveness 0.50 each). B's four endorsements have the same mean assertiveness of 0.70 in all three conditions: four 85% experts; 80%/82.5%/87.5%/90% experts; or 77.5%/82.5%/87.5%/92.5% experts. Finite-Pool Pragmatic Claim Competition predicts increasing A choice as B's coalition becomes more dispersed. Homogeneous B claims strongly compete with one another, whereas dispersion releases especially assertive B claims from similarity-based competition, making the allocated contrast increasingly favor B; the predominant skeptical construal reverses that contrast into stronger evidence for A. Contextual Anti-Reliability Arbitration predicts the opposite gradient. B has greater ordinary claim mass than A throughout, so anti-reliability initially favors A, but increasing within-B dispersion divisively dilutes that signal; the most dispersed condition also includes a smoothly compressed 92.5% claim, further reducing A-favoring anti-reliability evidence. It therefore predicts decreasing A choice toward chance. The critical test is the sign of the within-subject dispersion slope under an invariant 4-4 tally and invariant mean linear validity contrast. The last three pairs are exact option reversals. Six unique pairs are each repeated 16 times for 96 trials.

[16] This six-pair design holds the categorical tally, coalition breadth, and aggregate anti-reliability contrast approximately constant while manipulating only the internal dispersion of B's coalition. In every base pair, A is endorsed by four homogeneous 75%-valid experts. B is also endorsed by four experts, but its composition is either homogeneous (70%, 70%, 70%, 70%), moderately dispersed (60%, 65%, 75%, 81.3%), or strongly dispersed (50%, 70%, 80%, 85.6%). These compositions were chosen so that B's summed ordinary claim strength under Contextual Anti-Reliability Arbitration is approximately constant: each coalition sums to about four times 0.4^0.82. A's claim sum, the signed claim contrast, the 4-4 tally, and the eight-cue active breadth therefore remain fixed. The advocated theory predicts that increasing B-side claim dispersion enlarges its compositional normalizer and progressively dilutes anti-reliability evidence against the stronger A coalition. It consequently predicts an increasing A-choice profile toward chance from homogeneous to strongly dispersed B. Coalition-Level Skeptical Consensus predicts the opposite slope. Its B coalitions have nearly matched mean linear assertiveness, but their coherence falls sharply with dispersion. B's coalition summary therefore decreases, enlarging A's coalition-level advantage; skeptical reactance against A becomes stronger, so A choice should decrease as B becomes more dispersed. Thus the critical result is an oppositely signed within-subject dispersion gradient under an invariant tied tally and nearly invariant aggregate claim mass. The final three pairs are exact A/B reversals, balancing response side and requiring mirrored gradients. Six unique pairs are each repeated 16 times for 96 trials.

## RESPONSE FORMAT
Return a JSON object with the following fields:
- rationale: Reasoning behind this experimental design; used when interpreting results.
- validities: Per-expert validities, one per feature. Each must be in [0.5, 1.0]; order is free (no descending requirement — theories that depend on validity order re-sort internally). Length determines n_features for the whole experiment and must match the rating-list length in every trial pair. Pick a spread (at least one high validity and at least one low one) — uniform validities (e.g. all 0.7) make many candidate theories indistinguishable, so spread them out.
- trial_a_ratings: List of option-A rating vectors, one per trial. Each inner list has length equal to len(validities); each value is binary (0 or 1). `trial_a_ratings[i]` pairs with `trial_b_ratings[i]` on trial i.
- trial_b_ratings: List of option-B rating vectors, one per trial. Same length and shape constraints as `trial_a_ratings`. Pick trials that let the intended theories be dissociated; avoid trials where every theory agrees.


## Response

```json
{
  "rationale": "This design tests the theories' quantitatively different breadth laws while holding the categorical tally, validity composition, and mean assertiveness of each coalition fixed. In each base pair, A receives m endorsements from 80%-valid experts and B receives m endorsements from 55%-valid experts, for m = 1, 2, 4, or 6. Thus every trial has an exactly tied m-versus-m tally, and both coalitions are internally homogeneous at every breadth. Coalition-Level Skeptical Consensus predicts a pronounced increase in B choices with m: the stronger A coalition grows as m^consensus_exponent, the breadth-reinforcement gain rises above its singleton floor, and the special narrow-conflict normalization becomes less influential, while broad-conflict compression is only logarithmic. Skeptical reactance therefore strengthens substantially from the isolated 1-versus-1 conflict to repeated consensus. Contextual Anti-Reliability Arbitration also distrusts A, but predicts a much shallower, rapidly saturating breadth profile. Its linearly growing claim contrast is divided by active breadth raised to coalition_dilution_exponent and then passed through a relatively steep tanh accumulator; consequently, substantial anti-reliability is already present for the singleton conflict and additional identical endorsements yield limited incremental change. The critical planned contrast is the increase in choice of the lower-validity coalition from m=1 to m=6: large under Coalition-Level Skeptical Consensus but comparatively small and plateau-like under Contextual Anti-Reliability Arbitration. Exact option reversals balance response side and require mirrored breadth functions. Eight unique pairs are repeated 12 times each for 96 trials.",
  "validities": [
    0.8,
    0.8,
    0.8,
    0.8,
    0.8,
    0.8,
    0.55,
    0.55,
    0.55,
    0.55,
    0.55,
    0.55
  ],
  "trial_a_ratings": [
    [
      1,
      0,
      0,
      0,
      0,
      0,
      0,
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
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0
    ],
    [
      1,
      1,
      1,
      1,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0
    ],
    [
      1,
      1,
      1,
      1,
      1,
      1,
      0,
      0,
      0,
      0,
      0,
      0
    ],
    [
      0,
      0,
      0,
      0,
      0,
      0,
      1,
      0,
      0,
      0,
      0,
      0
    ],
    [
      0,
      0,
      0,
      0,
      0,
      0,
      1,
      1,
      0,
      0,
      0,
      0
    ],
    [
      0,
      0,
      0,
      0,
      0,
      0,
      1,
      1,
      1,
      1,
      0,
      0
    ],
    [
      0,
      0,
      0,
      0,
      0,
      0,
      1,
      1,
      1,
      1,
      1,
      1
    ]
  ],
  "trial_b_ratings": [
    [
      0,
      0,
      0,
      0,
      0,
      0,
      1,
      0,
      0,
      0,
      0,
      0
    ],
    [
      0,
      0,
      0,
      0,
      0,
      0,
      1,
      1,
      0,
      0,
      0,
      0
    ],
    [
      0,
      0,
      0,
      0,
      0,
      0,
      1,
      1,
      1,
      1,
      0,
      0
    ],
    [
      0,
      0,
      0,
      0,
      0,
      0,
      1,
      1,
      1,
      1,
      1,
      1
    ],
    [
      1,
      0,
      0,
      0,
      0,
      0,
      0,
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
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0
    ],
    [
      1,
      1,
      1,
      1,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0
    ],
    [
      1,
      1,
      1,
      1,
      1,
      1,
      0,
      0,
      0,
      0,
      0,
      0
    ]
  ]
}
```

## Usage

```json
{
  "input_tokens": 12729,
  "output_tokens": 3384
}
```
