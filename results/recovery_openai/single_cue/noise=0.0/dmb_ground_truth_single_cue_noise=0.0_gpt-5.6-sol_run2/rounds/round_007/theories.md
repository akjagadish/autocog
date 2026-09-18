# Round 7 — Theories

**Verdict:** `new_theory` (slot 1 replaced)

## Starting theories

### slot 1 — `pi_8` — KILLED ✗

**Description:** Contextual Reliability-Region Compression proposes that people integrate every discriminating expert rating into an exchangeable option-level coalition while representing advertised validities on a strongly compressed reliability-region scale. Coalition evidence grows sublinearly, and stable count calibration can make a third cue either corroborative or partially redundant. Redundancy is order-specific in cardinality but not spatial position: two-cue coalitions receive only a smooth joint-diagnostic composition discount, whereas coalitions of three or more undergo a contextual topology operation. In the latter operation, two cues occupying nearly the same represented reliability region are compressed toward one informational unit when another cue occupies a distinct region. In equal-cardinality contests between multi-cue coalitions, people additionally compare the coalitions' topology relationally. This relational comparison is moderately concave: modest clustered-versus-distributed differences are transmitted approximately linearly, whereas larger differences receive stronger diminishing amplification. The comparison fades smoothly when coalition cardinalities differ, preserving independently calibrated count judgments. Topology sensitivity is stable and heterogeneous across subjects, while pair-composition sensitivity is comparatively narrow. Stable, zero-centered idiosyncratic cue salience permits individual configuration preferences without population-level onset, closure, recency, adjacency, entry, or exit effects. Because subjects receive no outcome feedback, these representations remain fixed across trials.

**Rationale:** This is an isolated one-line functional edit to the accepted iteration-9 model. The curvature coefficient in the slope-preserving transform tanh(k*d)/k is increased modestly from 1.5 to 1.8. Because the derivative at zero remains exactly one, small topology contrasts such as those implicated in Experiment 2 remain approximately linear. Larger contrasts, especially the one driving Experiment 12's overshoot, are attenuated somewhat more strongly. Absolute triadic compression, count calibration, topology-sensitivity dispersion, pair composition, salience, and response parameters are unchanged, preserving the exact Experiment-6 result, the close Experiment-1 fit, and the nearly correct Experiment-12 variance. Experiment 11 is deliberately left for a later isolated dyadic adjustment rather than confounding this topology test.

**Parameters:**
  - `validities`: `validities`
  - `cue_salience_profile`: `[(-1.0, 1.0)] * n_features`
  - `validity_compression`: `[0.16, 0.32]`
  - `validity_reliance`: `[0.025, 0.070]`
  - `salience_strength`: `[0.12, 0.27]`
  - `coalition_saturation`: `[0.74, 0.84]`
  - `count_calibration`: `[-0.75, 0.25]`
  - `count_calibration_strength`: `[0.36, 0.48]`
  - `pair_composition_sensitivity`: `[2.10, 2.65]`
  - `topology_sensitivity`: `[0.40, 8.00]`
  - `topology_contrast_gain`: `[1.50, 2.75]`
  - `cluster_bandwidth`: `[0.018, 0.040]`
  - `context_scale`: `[0.025, 0.060]`
  - `beta`: `[1.02, 1.30]`
  - `epsilon`: `[0.03, 0.08]`

**`predict(parameters, stimulus, history)`:**
```python
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
```

**`policy(probs)`:**
```python
def policy(probs) -> int:
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.maximum(probs, 0.0)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        probs = np.ones(len(probs), dtype=np.float64) / float(len(probs))
    else:
        probs /= total
    return int(np.random.choice(len(probs), p=probs))
```


### slot 2 — `pi_9` — SURVIVED ✓

**Description:** Reliability-Space Credit Sharing proposes that people interpret agreement among experts through an inferred dependence network defined entirely in represented reliability space. Advertised validities have two related but distinct cognitive representations: a strongly compressed representation determines each cue's direct evidential weight, while a separately calibrated fixed-anchor representation determines inferred dependence. Within any option-supporting coalition, every expert shares informational credit with similarly represented experts according to a smooth, sharply localized similarity kernel. An expert surrounded by reliability-near neighbors therefore contributes less independent evidence, whereas reliability-distant experts contribute nearly undiluted evidence. The steep but continuous kernel concentrates redundancy around extremely similar reliability representations, producing a strong equality penalty without a broad dyadic reliability-gap gradient. Credit sharing applies at every coalition size, without an equality detector, dyadic/triadic switch, spatial grouping rule, or duplicate-pair-in-context operation. Because additional coalition members create multiple possible similarity relations, local dependence can accumulate nonlinearly in larger coalitions even when its effect on a single nonidentical pair is weak. Effective evidence is additionally subject to generic sublinear count growth. Stable subject-level dependence sensitivity, overlap curvature, compressed validity reliance, and exchangeable zero-centered cue salience generate individual differences without population-level serial-position effects. Choices arise from response sensitivity plus an independent lapse process, and representations remain fixed because no outcome feedback is provided.

**Rationale:** This is a parameter-only edit of the accepted iteration-6 model. The rejected superlinear-overlap transform is not retained: pairwise similarities still combine through the accepted additive local-overlap rule. The dependence coordinate is made less compressed by increasing validity_compression, while the single super-Gaussian core is narrowed. Consequently, genuinely nonzero reliability gaps separate more rapidly on the fixed-anchor coordinate, which should suppress the excessive broad dyadic gradient in Experiment 11 and reduce the modest overshoots in Experiments 12–14. Exact matches remain at unit similarity regardless of bandwidth. A small increase in overlap curvature therefore strengthens their smooth dependence penalty for Experiment 10 without increasing global dependence sensitivity. The dependence-sensitivity range is slightly narrowed to limit subject-level variance. Direct validity compression, direct reliance, count saturation, response sensitivity, lapse, and exchangeable salience are otherwise unchanged, protecting the accepted separation of direct weighting from dependence inference and the established positional nulls.

**Parameters:**
  - `validities`: `validities`
  - `cue_salience_profile`: `[(-1.0, 1.0)] * n_features`
  - `validity_compression`: `[0.30, 0.34]`
  - `direct_validity_compression`: `[0.08, 0.14]`
  - `validity_reliance`: `[0.008, 0.025]`
  - `salience_strength`: `[0.12, 0.28]`
  - `coalition_saturation`: `[0.64, 0.72]`
  - `dependence_sensitivity`: `[2.90, 3.30]`
  - `similarity_bandwidth`: `[0.0045, 0.0065]`
  - `overlap_curvature`: `[0.88, 0.96]`
  - `beta`: `[1.12, 1.38]`
  - `epsilon`: `[0.03, 0.08]`

**`predict(parameters, stimulus, history)`:**
```python
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
```

**`policy(probs)`:**
```python
def policy(probs) -> int:
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.maximum(probs, 0.0)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        probs = np.ones(len(probs), dtype=np.float64) / float(len(probs))
    else:
        probs /= total
    return int(np.random.choice(len(probs), p=probs))
```


## Replacement

### `pi_10` → slot 1 (via `new_theory`)

**Description:** Categorical Source-Budget Inference proposes that people recode instructed expert reliabilities into a small number of latent information-source categories. Category membership is inferred locally: experts with exactly or nearly matching represented reliabilities are likely to be treated as exchangeable observations from one source, whereas this coassignment declines sharply outside a narrow subject-specific neighborhood. Within each option-supporting coalition, members assigned to one source draw from a shared evidence budget whose value grows as a strongly concave power of cluster membership. Exact reliability matches additionally invoke a categorical equality atom, producing an almost flat shared budget without changing how nonzero reliability gaps are partitioned. Budgets belonging to distinct inferred sources are added. A duplicate pair is therefore redundant in a dyad, an unrelated outsider adds a separate budget without changing that duplicate cost, and two duplicate clusters consume two separate budgets. The total is then subjected to generic nominal-coalition normalization and a separately calibrated saturating release that is concentrated between two and three effective sources. Instructed validity differences have little direct influence after strong compression. Stable, exchangeable, zero-centered cue salience permits individual configuration preferences but creates no population-level serial-position mechanism. With no correctness feedback, source assignments and cue salience remain fixed across trials.

**Rationale:** This is a surgical edit of the accepted iteration-2 model. The accepted hard-radius partition is retained for all nonzero reliability gaps, avoiding the rejected soft-prototype revision. The first change adds an equality-specific cluster curvature only after the existing partition has been formed. Exact duplicate clusters consequently receive an almost flat source budget, targeting the insufficient redundancy in Experiment 10 while leaving the nonzero-gap treatment—and therefore Experiments 11-15—nearly unchanged. The second change replaces the unbounded k^curvature multiplier with a bounded logistic count release centered between two and three effective sources. It supplies little extra credit at two sources, a meaningful increment at three, and no continuing growth for larger source counts. This directly targets the low three-versus-two subject-majority result in Experiment 6 while reducing, rather than increasing, the excessive large-coalition advantage in Experiment 1. Nominal normalization, local category assignment, direct validity compression, exchangeable salience, and the position-free response mechanism are otherwise unchanged.

**Parameters:**
  - `validities`: `validities`
  - `cue_salience_profile`: `[(-1.0, 1.0)] * n_features`
  - `direct_validity_compression`: `[0.08, 0.14]`
  - `validity_reliance`: `[0.006, 0.024]`
  - `salience_strength`: `[0.18, 0.40]`
  - `category_width`: `[0.008, 0.018]`
  - `category_boundary_shift`: `[-0.30, 0.30]`
  - `within_source_curvature`: `[0.08, 0.22]`
  - `equality_source_curvature`: `[0.00, 0.05]`
  - `coalition_normalization`: `[0.88, 0.98]`
  - `source_count_curvature`: `[0.18, 0.26]`
  - `source_count_midpoint`: `[2.45, 2.65]`
  - `source_count_slope`: `[7.0, 11.0]`
  - `beta`: `[1.45, 1.85]`
  - `epsilon`: `[0.03, 0.08]`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history) -> np.ndarray:
    stim = np.asarray(state, dtype=np.float64)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Categorical Source-Budget Inference expects shape "
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

    direct_validity_compression = float(
        parameters["direct_validity_compression"]
    )
    validity_reliance = float(parameters["validity_reliance"])
    salience_strength = float(parameters["salience_strength"])
    category_width = float(parameters["category_width"])
    category_boundary_shift = float(parameters["category_boundary_shift"])
    within_source_curvature = float(parameters["within_source_curvature"])
    equality_source_curvature = float(
        parameters["equality_source_curvature"]
    )
    coalition_normalization = float(parameters["coalition_normalization"])
    source_count_curvature = float(parameters["source_count_curvature"])
    source_count_midpoint = float(parameters["source_count_midpoint"])
    source_count_slope = float(parameters["source_count_slope"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    v = np.clip(validities, 0.500001, 0.999999)

    # Reliability has only a weak direct effect. Diagnosticity differences
    # are strongly compressed around a fixed .75 reference so the scale is
    # comparable across experiments.
    diagnosticity = np.log(v / (1.0 - v))
    reference = np.log(0.75 / 0.25)
    represented_direct = np.power(
        np.maximum(diagnosticity, 1e-12), direct_validity_compression
    )
    represented_direct /= max(
        float(reference ** direct_validity_compression), 1e-12
    )
    reliability_weight = (
        (1.0 - validity_reliance) * np.ones(n_features, dtype=np.float64)
        + validity_reliance * represented_direct
    )

    # Idiosyncratic salience is exchangeable across identities and explicitly
    # centered, so it cannot generate a common onset, recency, or closure rule.
    centered_salience = raw_salience - float(np.mean(raw_salience))
    attention = np.exp(
        np.clip(salience_strength * centered_salience, -10.0, 10.0)
    )
    attention /= max(float(np.mean(attention)), 1e-12)

    cue_weights = reliability_weight * attention
    cue_weights /= max(float(np.mean(cue_weights)), 1e-12)

    # Category uncertainty controls a narrow local coassignment radius.
    # Exact matches are always coassigned; nonidentical reliabilities are
    # coassigned only inside a sharply localized subject-specific region.
    coassignment_radius = category_width * np.exp(category_boundary_shift)

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

        # Infer a local source partition by joining only reliability-near
        # coalition members. Connected components are exchangeable in expert
        # identity and produce no repeated global boundary artifacts.
        parent = np.arange(n, dtype=np.int64)

        def find(i):
            while parent[i] != i:
                parent[i] = parent[parent[i]]
                i = int(parent[i])
            return i

        def union(i, j):
            root_i = find(i)
            root_j = find(j)
            if root_i != root_j:
                parent[root_j] = root_i

        coalition_v = v[idx]
        for i in range(n):
            for j in range(i + 1, n):
                if abs(float(coalition_v[i] - coalition_v[j])) <= coassignment_radius:
                    union(i, j)

        labels = np.asarray([find(i) for i in range(n)], dtype=np.int64)
        unique_labels = np.unique(labels)
        source_budget_total = 0.0

        # Experts assigned to one latent source share a cluster-level budget.
        # Exact reliability matches invoke a categorical equality atom with
        # near-flat membership growth. Nonidentical local clusters retain the
        # accepted model's original pooling curvature.
        for label in unique_labels:
            local_members = np.flatnonzero(labels == label)
            members = idx[local_members]
            membership = float(members.size)
            source_quality = float(np.mean(cue_weights[members]))
            local_validities = coalition_v[local_members]
            exact_match = (
                members.size > 1
                and float(np.max(local_validities) - np.min(local_validities))
                <= 1e-12
            )
            cluster_curvature = (
                equality_source_curvature
                if exact_match
                else within_source_curvature
            )
            source_budget_total += source_quality * (
                membership ** cluster_curvature
            )

        effective_source_count = float(unique_labels.size)

        # Source budgets already add independent-source evidence. The extra
        # count calibration is therefore bounded and releases primarily when
        # effective source count crosses from two to three, rather than
        # multiplying evidence by an unbounded second power of source count.
        release = 1.0 / (
            1.0
            + np.exp(
                -np.clip(
                    source_count_slope
                    * (effective_source_count - source_count_midpoint),
                    -50.0,
                    50.0,
                )
            )
        )
        count_factor = np.exp(source_count_curvature * release)
        nominal_normalizer = float(n) ** coalition_normalization
        signal = source_budget_total * count_factor / max(
            nominal_normalizer, 1e-12
        )
        return float(max(signal, 0.0))

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
```

**`policy(probs)`:**
```python
def policy(probs) -> int:
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.maximum(probs, 0.0)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        probs = np.ones(len(probs), dtype=np.float64) / float(len(probs))
    else:
        probs /= total
    return int(np.random.choice(len(probs), p=probs))
```
