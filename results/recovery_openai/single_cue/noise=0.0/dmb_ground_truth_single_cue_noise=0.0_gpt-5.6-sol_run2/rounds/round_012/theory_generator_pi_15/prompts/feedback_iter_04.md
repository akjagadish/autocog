# feedback_iter_04

## System Prompt

You are a renowned cognitive scientist critiquing a freshly proposed candidate theory and model in the Decision Making (Binary Features) domain.

The candidate has been simulated on every previously run experiment. For each experiment you are shown the design, the metric, the value the metric takes on real data, and the value it takes on the candidate's simulated data.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the feedback is to SURFACE theories that are EXPERIMENT-INVARIANT: that is,theories that explain data across multiple experiments. 
Your task is to determine whether the candidate captures the human/real behavior well enough across these experiments. Return a verdict:
  * "continue"   — the candidate is good enough; carry on.
  * "regenerate" — the candidate fails to capture the empirical pattern; the proposing agent must produce a new candidate, taking your rationale into account.

Justify the verdict with a concrete diagnosis (which experiments fail, in what direction, what mechanism is likely missing or miscalibrated).

## SCOPE OF YOUR CRITIQUE — STAY INSIDE THE ARBITER'S MECHANISM FAMILY
When an "## ARBITER RECOMMENDATION" block is present below, the proposer was explicitly instructed to implement the mechanism family the arbiter prescribed. Your job is to grade FIT QUALITY *within that prescribed family*, not to relitigate which family should be used — that is the arbiter's call, made one level above this loop.

Concretely:
  * If the candidate misses the data, you may push for MINOR ADJUSTMENTS that keep the prescribed mechanism intact: tightening / widening parameter ranges, adding a temperature, swapping a normalization scheme, fixing a softmax / distance metric, re-balancing attention weights, fixing a learning-rate sign, correcting a bug in the gating or recurrence, etc.
  * You MUST NOT recommend switching to a different mechanism family. Such a switch is the arbiter's prerogative; recommending it here will mislead the proposer into oscillating between families across iterations.
  * Also grade FAITHFULNESS to the recommendation explicitly: if the candidate has clearly drifted into a different family than the one prescribed, say so in the rationale and ask for a return to the prescribed family — again, with minor adjustments, not a re-design.

## ACCEPT GATE — HOW THE LOOP DECIDES WHAT TO BUILD ON NEXT
This propose-loop has a programmatic accept gate. After every iteration the candidate's `aggregate_loss` is compared against the running-best loss (`accepted_loss`):
  * `loss < accepted_loss` → ACCEPTED. The candidate becomes the new running-best base; the next iteration's proposer will build on THIS candidate.
  * `loss >= accepted_loss` → REJECTED. The base is unchanged; the next iteration's proposer will build on the SAME `accepted` candidate again, with your new feedback on top. Rejected candidates are discarded — the loop guarantees the base never regresses, so you do NOT need to ask the proposer to "revert" anything; that already happens for free.

Two consequences for your verdict:
  * If the candidate you are grading was REJECTED by the gate, returning `"continue"` is silently downgraded to `"regenerate"` (returning a worse candidate would defeat the gate). Spend your rationale on a NEW direction the proposer should try on top of the unchanged accepted base, not on defending the rejected attempt.
  * If the candidate was ACCEPTED, you can return `"continue"` to stop the loop and ship this candidate, or `"regenerate"` to keep tuning further.

## LEARN FROM YOUR OWN PAST ADVICE
When a "## YOUR PRIOR CRITIQUES" block is present below, each prior iteration ends with an "Outcome of your advice" line that says whether the next candidate the proposer produced was ACCEPTED (your advice helped — its loss strictly beat the running best) or REJECTED (your advice didn't help — the proposer discarded the result and reset to the previous accepted base). This is the loop's ground-truth signal on whether *your own previous critique was good*. Use it explicitly:
  * If a previous piece of advice was ACCEPTED, it is OK to repeat / extend it. Reinforce in the same direction.
  * If a previous piece of advice was REJECTED, do NOT repeat the same recommendation; in your new rationale, briefly acknowledge that the previous push in that direction was rejected by the gate and try a different in-family knob (or a smaller step in the same direction) instead.
  * If you find yourself oscillating (e.g. iter 1 said "increase α", iter 2 said "decrease α", iter 3 about to say "increase α" again), STOP and recommend a value between the two flanking iterations instead.
  * The "## LOSS TRAJECTORY" block at the top of the user prompt summarises the same information at the loop level — consult it before issuing a new regenerate-with-direction recommendation.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## ARBITER RECOMMENDATION (mechanism family the proposer was told to implement)
The arbiter labelled this round's two theories in its recommendation as follows:
- THEORY 1 = `pi_11`
- THEORY 2 = `pi_14`
- The recommendation below acts on THEORY 2 (= `pi_14`).

Replace pi_14 with a theory of Capacity-Gated Local Source Individuation. Its core claim should be that source dependence is inferred locally among the closest reliability neighbors, while larger coalitions are evaluated through bounded, nontransitive evidence accounts rather than through a globally coherent latent partition. Exact equality should strongly activate a common-source tag and discount duplicate evidence. A small nonzero gap should release that tag and provide local independence credit, producing the near-over-exact effect in Experiment 24. For dyads, that credit should decline once the gap becomes too broad, capturing Experiment 26. Crucially, this dyadic Goldilocks function must not become a coalition-wide span penalty: in tetrads and larger coalitions, local links should be capacity-limited and nonaccumulating, while distinct reliability regions can still contribute separate bounded accounts. This should allow diffuse coalitions to beat compact duplicate-heavy coalitions in Experiment 1 and Experiments 14–16 and 18, while preventing chains from accumulating a large advantage in Experiments 20 and 22.

The new theory should include an explicit cardinality gate: dyads permit fine metric comparison of reliability gaps; at three or more cues, observers increasingly compress reliability into a few contextual codes and use bounded account coverage plus duplicate penalties. Any two-to-three release should be weak and empirically constrained, because Experiment 17 is near zero, and the model must reproduce the cardinality profile in Experiment 19 rather than imposing a generic triadic bonus. Reliability weighting should remain compressed but consequential, and duplicate penalties should accumulate by locally tagged group as in the successful portion of pi_11. Do not add a generic global coherence, total-span, or strongest-stratum-link term.

The model should also distinguish choice sensitivity from structural valuation so that near-chance means and subject-threshold metrics are not forced to move together. Stable subject heterogeneity may vary duplicate tolerance, local-gap resolution, reliability compression, and response sensitivity, but these distributions must be shared across experiments rather than selected per design. Retain exchangeable cue salience and avoid population-level recency, onset, adjacency, or closure gradients, given the repeated null results for those mechanisms. During development, jointly calibrate against all experiments, with hard qualitative checks that the model simultaneously produces: dispersed preference in Experiment 1; approximately chance compact choice in Experiment 2; near-over-exact preference in Experiment 24; broad-dyad avoidance in Experiment 26; approximately chance chain choice in Experiments 20 and 22; duplicate avoidance in Experiments 12 and 18; and distributed-coalition preference in Experiments 14–16. It should additionally incorporate a coalition-level normalization or contrast process capable of addressing the shared failures in Experiments 4, 5, 8, and 25, without invoking unsupported serial-position effects.


## CANDIDATE THEORY
Capacity-Gated Local Source Individuation proposes that observers do not infer a globally coherent partition of experts into latent sources. They inspect a capacity-limited set of nearest reliability relations. Exact equality activates a categorical common-source tag, while dyads permit fine metric comparison through a localized Goldilocks function: narrow positive gaps earn independence credit, moderately broad gaps incur uncertainty, and very large gaps recover toward reliability-weighted baseline. At cardinalities of three or more, reliability is compressed into bounded contextual evidence accounts. Triads permit only a weak, capped release from one sampled resolvable link. At four or more cues, account coverage is licensed by a steep threshold on sampled local resolution, preventing weak broad links from accumulating into chain evidence. Duplicate penalties remain additive across locally tagged equality groups, with a small extra cost for representing multiple distinct duplicate groups. Structural valuation is separated from response sensitivity, with a stable subject-specific overload criterion governing unequal three-versus-two choices. Reliability compression, duplicate tolerance, local-gap resolution, overload criterion, and response sensitivity vary across subjects from distributions shared across experiments. Cue salience remains exchangeable, with no population-level recency, onset, adjacency, or closure gradient.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history) -> np.ndarray:
    stim = np.asarray(state, dtype=np.float64)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Capacity-Gated Local Source Individuation expects shape "
            f"(2, n_features); got {stim.shape}."
        )

    a, b = stim[0], stim[1]
    n_features = int(stim.shape[1])

    v = np.asarray(parameters["validities"], dtype=np.float64)
    if v.ndim != 1 or v.size != n_features:
        raise ValueError(
            f"validities length {v.size} != n_features {n_features}."
        )
    v = np.clip(v, 0.500001, 0.999999)

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
    equality_resolution = float(parameters["equality_resolution"])
    dyad_gap_resolution = float(parameters["dyad_gap_resolution"])
    dyad_broad_scale = float(parameters["dyad_broad_scale"])
    dyad_independence_gain = float(parameters["dyad_independence_gain"])
    dyad_duplicate_penalty = float(parameters["dyad_duplicate_penalty"])
    dyad_trough_strength = float(parameters["dyad_trough_strength"])
    dyad_trough_center = float(parameters["dyad_trough_center"])
    dyad_trough_width = float(parameters["dyad_trough_width"])
    code_resolution = int(parameters["code_resolution"])
    account_capacity = float(parameters["account_capacity"])
    account_normalization = float(parameters["account_normalization"])
    coverage_gain = float(parameters["coverage_gain"])
    large_coalition_gate = float(parameters["large_coalition_gate"])
    local_link_gain = float(parameters["local_link_gain"])
    local_link_capacity = int(parameters["local_link_capacity"])
    coalition_duplicate_penalty = float(
        parameters["coalition_duplicate_penalty"]
    )
    duplicate_group_saturation = float(
        parameters["duplicate_group_saturation"]
    )
    count_curvature = float(parameters["count_curvature"])
    contrast_normalization = float(parameters["contrast_normalization"])
    contrast_scale = float(parameters["contrast_scale"])
    overload_criterion = float(parameters["overload_criterion"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    # Communicated reliability remains compressed but consequential.
    log_odds = np.log(v / (1.0 - v))
    compressed = np.power(np.maximum(log_odds, 1e-12), validity_compression)
    compressed /= max(float(np.mean(compressed)), 1e-12)
    reliability_quality = (
        (1.0 - validity_reliance)
        + validity_reliance * compressed
    )

    # Subject-specific cue salience is centered and exchangeable.
    centered_salience = raw_salience - float(np.mean(raw_salience))
    attention = np.exp(
        np.clip(salience_strength * centered_salience, -10.0, 10.0)
    )
    attention /= max(float(np.mean(attention)), 1e-12)

    cue_quality = reliability_quality * attention
    cue_quality /= max(float(np.mean(cue_quality)), 1e-12)

    # Coarse contextual codes are bounded evidence accounts, not latent
    # transitive source partitions.
    unique_v, inverse_levels = np.unique(v, return_inverse=True)
    n_levels = int(unique_v.size)
    actual_codes = max(1, min(code_resolution, n_levels))
    if n_levels == 1:
        level_codes = np.zeros(1, dtype=np.int64)
    else:
        level_codes = np.floor(
            np.arange(n_levels, dtype=np.float64)
            * float(actual_codes)
            / float(n_levels)
        ).astype(np.int64)
        level_codes = np.minimum(level_codes, actual_codes - 1)
    cue_codes = level_codes[inverse_levels]

    difference = a - b
    a_support = np.flatnonzero(difference > 0.0)
    b_support = np.flatnonzero(difference < 0.0)

    if a_support.size == 0 and b_support.size == 0:
        return np.array([0.5, 0.5], dtype=np.float64)

    def goldilocks_credit(gap):
        gap = float(max(gap, 0.0))
        if gap <= equality_resolution:
            return 0.0

        release = 1.0 - np.exp(
            -gap / max(dyad_gap_resolution, 1e-12)
        )
        broad_decay = np.exp(
            -gap / max(dyad_broad_scale, 1e-12)
        )
        return float(np.clip(release * broad_decay, 0.0, 1.0))

    def duplicate_load(indices):
        idx = np.asarray(indices, dtype=np.int64)
        if idx.size <= 1:
            return 0.0

        levels = inverse_levels[idx]
        counts = np.bincount(levels, minlength=n_levels).astype(np.float64)
        duplicate_counts = counts[counts > 1.0]
        load = 0.0
        for count in duplicate_counts:
            excess = float(count - 1.0)
            load += excess / (
                1.0 + duplicate_group_saturation * excess
            )

        # Maintaining more than one separately tagged equality group consumes
        # an additional bounded account slot. This does not increase the cost
        # of a single large exact block relative to a broad chain.
        load += 0.30 * float(max(int(duplicate_counts.size) - 1, 0))
        return float(load)

    def coalition_value(indices):
        idx = np.asarray(indices, dtype=np.int64)
        n = int(idx.size)
        if n == 0:
            return 0.0
        if n == 1:
            return float(cue_quality[idx[0]])

        qualities = cue_quality[idx]
        coalition_v = v[idx]

        if n == 2:
            gap = abs(float(coalition_v[0] - coalition_v[1]))
            base = float(np.sum(qualities)) / (
                2.0 ** account_normalization
            )

            if gap <= equality_resolution:
                structural_factor = np.exp(-dyad_duplicate_penalty)
            else:
                credit = goldilocks_credit(gap)
                localized_trough = np.exp(
                    -0.5
                    * ((gap - dyad_trough_center)
                       / max(dyad_trough_width, 1e-12)) ** 2
                )
                structural_factor = (
                    1.0
                    + dyad_independence_gain * credit
                    - dyad_trough_strength * localized_trough
                )
                structural_factor = max(structural_factor, 0.05)

            return float(
                np.power(max(base, 1e-12), count_curvature)
                * structural_factor
            )

        codes = cue_codes[idx]
        occupied_codes = np.unique(codes)
        account_values = []
        for code in occupied_codes:
            members = np.flatnonzero(codes == code)
            m = int(members.size)
            mean_quality = float(np.mean(qualities[members]))
            if m == 1:
                represented_mass = 1.0
            else:
                represented_mass = 1.0 + account_capacity * (
                    1.0
                    - np.exp(
                        -float(m - 1) / max(account_capacity, 1e-12)
                    )
                )
            account_values.append(mean_quality * represented_mass)

        coverage = int(len(account_values))
        account_total = float(np.sum(account_values))
        normalized_accounts = account_total / (
            float(max(coverage, 1)) ** account_normalization
        )

        bounded_coverage = float(min(max(coverage - 1, 0), 1))
        load_gate = 1.0 / (
            1.0 + large_coalition_gate * float(max(n - 3, 0))
        )

        # Only a bounded set of nearest positive links is inspected.
        order = np.argsort(coalition_v)
        sorted_v = coalition_v[order]
        adjacent_gaps = np.diff(sorted_v)
        positive_gaps = adjacent_gaps[adjacent_gaps > equality_resolution]
        if positive_gaps.size == 0:
            local_credit = 0.0
        else:
            nearest = np.sort(positive_gaps)[:local_link_capacity]
            credits = np.asarray(
                [goldilocks_credit(g) for g in nearest],
                dtype=np.float64,
            )
            local_credit = float(np.mean(credits)) if credits.size else 0.0

        # Triads receive only a weak release from the sampled relation. At
        # higher cardinalities, local credit must cross a resolution threshold
        # before it licenses another account. The activation is bounded and
        # nonaccumulating, so broad chains cannot profit from many weak links.
        if n == 3:
            coverage_activation = 1.0
            link_activation = np.sqrt(local_credit)
        else:
            resolved_link = np.clip(
                (local_credit - 0.10) / 0.25, 0.0, 1.0
            )
            coverage_activation = resolved_link ** 3
            link_activation = resolved_link ** 3

        coverage_factor = 1.0 + (
            coverage_gain
            * bounded_coverage
            * load_gate
            * coverage_activation
        )
        if n == 3:
            effective_link_gain = local_link_gain + 0.5 * coverage_gain
        else:
            effective_link_gain = local_link_gain
        local_factor = 1.0 + (
            effective_link_gain * link_activation * load_gate
        )

        dup_load = duplicate_load(idx)
        duplicate_factor = np.exp(
            -coalition_duplicate_penalty * dup_load
        )

        represented = np.power(
            max(normalized_accounts, 1e-12), count_curvature
        )
        return float(
            represented
            * coverage_factor
            * local_factor
            * duplicate_factor
        )

    value_a = coalition_value(a_support)
    value_b = coalition_value(b_support)

    comparison_scale = (
        1.0 + 0.5 * (abs(value_a) + abs(value_b))
    ) ** contrast_normalization
    normalized_difference = (value_a - value_b) / max(
        comparison_scale, 1e-12
    )

    structural_contrast = contrast_scale * np.tanh(
        normalized_difference / max(contrast_scale, 1e-12)
    )

    # A stable response-stage overload criterion applies only to unequal
    # three-versus-two conflicts. Its heterogeneous distribution can change
    # subject-threshold measures without imposing a generic triad valuation
    # bonus or penalty on equal-cardinality comparisons.
    sizes = {int(a_support.size), int(b_support.size)}
    if sizes == {2, 3}:
        larger_side = float(np.sign(a_support.size - b_support.size))
        structural_contrast -= overload_criterion * larger_side

    logits = np.array(
        [0.5 * beta * structural_contrast,
         -0.5 * beta * structural_contrast],
        dtype=np.float64,
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
- cue_salience_profile: [(-1.0, 1.0)] * n_features
- validity_compression: [0.16, 0.34]
- validity_reliance: [0.06, 0.15]
- salience_strength: [0.04, 0.18]
- equality_resolution: [0.0000001, 0.00001]
- dyad_gap_resolution: [0.0025, 0.0055]
- dyad_broad_scale: [0.0045, 0.0090]
- dyad_independence_gain: [0.45, 1.05]
- dyad_duplicate_penalty: [0.85, 1.55]
- dyad_trough_strength: [0.18, 0.52]
- dyad_trough_center: [0.011, 0.017]
- dyad_trough_width: [0.0035, 0.0065]
- code_resolution: {2, 3}
- account_capacity: [0.85, 1.65]
- account_normalization: [0.50, 0.72]
- coverage_gain: [0.10, 0.42]
- large_coalition_gate: [0.85, 1.80]
- local_link_gain: [0.08, 0.30]
- local_link_capacity: {1, 2}
- coalition_duplicate_penalty: [0.18, 0.48]
- duplicate_group_saturation: [0.45, 1.05]
- count_curvature: [0.72, 0.90]
- contrast_normalization: [0.35, 0.70]
- contrast_scale: [0.55, 1.15]
- overload_criterion: [0.10, 0.90]
- beta: [0.85, 2.20]
- epsilon: [0.025, 0.085]

`rationale`:
This is a narrow extension of the accepted iteration. The localized dyadic trough, contextual accounts, additive duplicate penalties, and response-stage cardinality criterion are retained. Four targeted edits address the latest diagnosis. First, the overload-criterion distribution is shifted upward and widened, increasing heterogeneity and reducing excessive three-cue endorsement in unequal 3-versus-2 choices without directly changing equal-cardinality Experiment 15. Second, triads receive a weak square-root release from one sampled local link; this can offset the excessive negative triad-minus-dyad shift and recover part of the Experiment 17 cardinality profile without adding a generic triadic bonus. Third, the former squared large-coalition link activation is replaced by a steep bounded resolution threshold. Narrow resolvable links can license account coverage, whereas broad-chain links below threshold receive essentially no coverage or link multiplier. This targets Experiments 18, 20, 23, and 26 while preserving distributed effects supported by genuinely local relations. Fourth, a small surcharge is applied only when multiple distinct equality groups must be represented, strengthening the one-versus-two-group contrasts in Experiments 16 and 25 without increasing the penalty on a single exact block relative to a chain. The dyadic equality penalty is also modestly increased to address Experiment 10 while leaving the recovering broad-gap trough intact for Experiments 24 and 26. No global span, coherence, transitive source partition, or serial-position mechanism is introduced.

## LOSS TRAJECTORY (this propose-loop)
Aggregate loss across iterations of THIS propose-loop (lower = better, 0 = perfect, `+inf` = unscorable). The ACCEPTED / REJECTED tag is the loop's programmatic accept-gate decision: `loss < accepted_loss` -> ACCEPTED (becomes new base), else REJECTED (base unchanged). Use this together with the per-experiment values below to grade fit-quality AND your own past advice (see `## YOUR PRIOR CRITIQUES` below).

- iter 1: loss=0.2308 -> ACCEPTED
- iter 2: loss=0.2572 -> REJECTED
- iter 3: loss=0.2328 -> REJECTED
- iter 4: loss=0.2085 -> ACCEPTED
- iter 5 (current candidate you are grading): loss=0.2279 -> REJECTED
Running-best (last accepted) base: iter 4 at loss=0.2085.

## EXPERIMENTAL RESULTS (candidate vs real, per experiment)
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
**Candidate trajectory (this loop):**
  - iter 1: -0.2617 (var=0.0144) (Δ vs real -0.1400)
  - iter 2: -0.0346 (var=0.0087) (Δ vs real +0.0871)
  - iter 3: -0.1875 (var=0.0086) (Δ vs real -0.0658)
  - iter 4: -0.2313 (var=0.0132) (Δ vs real -0.1096)
  - iter 5 (current): -0.2104 (var=0.0173) (Δ vs real -0.0887)
**Other theories' values on this metric (for reference):**
- pi_1: 0.7129 (var=0.0389)
- pi_2: -0.6354 (var=0.0266)
- pi_3: -0.1033 (var=0.0092)
- pi_4: -0.1246 (var=0.0114)
- pi_5: -0.1179 (var=0.0105)
- pi_6: -0.0779 (var=0.0176)
- pi_7: -0.3083 (var=0.0280)
- pi_8: -0.1358 (var=0.0111)
- pi_9: -0.2600 (var=0.0153)
- pi_10: -0.1767 (var=0.0260)
- pi_11: -0.2383 (var=0.0360)
- pi_12: -0.3588 (var=0.0139)
- pi_13: -0.4079 (var=0.0298)
- pi_14: -0.1487 (var=0.0343)

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
**Candidate trajectory (this loop):**
  - iter 1: 0.0054 (var=0.0093) (Δ vs real +0.2696)
  - iter 2: 0.0083 (var=0.0088) (Δ vs real +0.2725)
  - iter 3: 0.0533 (var=0.0075) (Δ vs real +0.3175)
  - iter 4: 0.0321 (var=0.0091) (Δ vs real +0.2963)
  - iter 5 (current): 0.0367 (var=0.0128) (Δ vs real +0.3008)
**Other theories' values on this metric (for reference):**
- pi_2: -0.0008 (var=0.0102)
- pi_1: 0.7221 (var=0.0226)
- pi_3: -0.1892 (var=0.0123)
- pi_4: -0.2667 (var=0.0120)
- pi_5: -0.2217 (var=0.0089)
- pi_6: -0.2321 (var=0.0159)
- pi_7: -0.0892 (var=0.0075)
- pi_8: -0.2221 (var=0.0114)
- pi_9: -0.0008 (var=0.0090)
- pi_10: 0.0396 (var=0.0103)
- pi_11: 0.0096 (var=0.0132)
- pi_12: 0.0117 (var=0.0092)
- pi_13: 0.0375 (var=0.0119)
- pi_14: 0.0617 (var=0.0113)

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
**Candidate trajectory (this loop):**
  - iter 1: -0.0016 (var=0.0002) (Δ vs real +0.0394)
  - iter 2: 0.0035 (var=0.0003) (Δ vs real +0.0445)
  - iter 3: 0.0000 (var=0.0002) (Δ vs real +0.0410)
  - iter 4: 0.0011 (var=0.0003) (Δ vs real +0.0421)
  - iter 5 (current): 0.0035 (var=0.0003) (Δ vs real +0.0445)
**Other theories' values on this metric (for reference):**
- pi_3: 0.0860 (var=0.0002)
- pi_2: -0.0017 (var=0.0001)
- pi_1: 0.0899 (var=0.0009)
- pi_4: -0.0260 (var=0.0002)
- pi_5: -0.0237 (var=0.0003)
- pi_6: -0.0366 (var=0.0003)
- pi_7: -0.0224 (var=0.0002)
- pi_8: -0.0376 (var=0.0003)
- pi_9: 0.0012 (var=0.0003)
- pi_10: 0.0007 (var=0.0004)
- pi_11: 0.0039 (var=0.0005)
- pi_12: 0.0144 (var=0.0003)
- pi_13: 0.0037 (var=0.0003)
- pi_14: 0.0059 (var=0.0003)

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
**Candidate trajectory (this loop):**
  - iter 1: 0.4909 (var=0.0043) (Δ vs real -0.0178)
  - iter 2: 0.5018 (var=0.0044) (Δ vs real -0.0069)
  - iter 3: 0.4888 (var=0.0037) (Δ vs real -0.0199)
  - iter 4: 0.5016 (var=0.0035) (Δ vs real -0.0071)
  - iter 5 (current): 0.4870 (var=0.0044) (Δ vs real -0.0216)
**Other theories' values on this metric (for reference):**
- pi_2: 0.5017 (var=0.0041)
- pi_3: 0.6281 (var=0.0049)
- pi_1: 0.1476 (var=0.0116)
- pi_4: 0.5061 (var=0.0029)
- pi_5: 0.4957 (var=0.0036)
- pi_6: 0.5046 (var=0.0065)
- pi_7: 0.4932 (var=0.0039)
- pi_8: 0.4759 (var=0.0052)
- pi_9: 0.5033 (var=0.0044)
- pi_10: 0.4788 (var=0.0086)
- pi_11: 0.4771 (var=0.0066)
- pi_12: 0.5132 (var=0.0055)
- pi_13: 0.5116 (var=0.0099)
- pi_14: 0.4938 (var=0.0036)

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
**Candidate trajectory (this loop):**
  - iter 1: 0.4931 (var=0.0033) (Δ vs real -0.0090)
  - iter 2: 0.5096 (var=0.0025) (Δ vs real +0.0075)
  - iter 3: 0.4935 (var=0.0030) (Δ vs real -0.0085)
  - iter 4: 0.4983 (var=0.0021) (Δ vs real -0.0037)
  - iter 5 (current): 0.4956 (var=0.0034) (Δ vs real -0.0065)
**Other theories' values on this metric (for reference):**
- pi_3: 0.5692 (var=0.0021)
- pi_4: 0.3798 (var=0.0029)
- pi_1: 0.1575 (var=0.0119)
- pi_2: 0.4992 (var=0.0023)
- pi_5: 0.5098 (var=0.0033)
- pi_6: 0.5123 (var=0.0025)
- pi_7: 0.5052 (var=0.0023)
- pi_8: 0.4940 (var=0.0029)
- pi_9: 0.4973 (var=0.0028)
- pi_10: 0.4923 (var=0.0026)
- pi_11: 0.5060 (var=0.0029)
- pi_12: 0.4983 (var=0.0020)
- pi_13: 0.5056 (var=0.0030)
- pi_14: 0.4821 (var=0.0030)

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
**Candidate trajectory (this loop):**
  - iter 1: 1.0000 (var=0.0000) (Δ vs real +0.5600)
  - iter 2: 0.9800 (var=0.0196) (Δ vs real +0.5400)
  - iter 3: 0.7800 (var=0.1716) (Δ vs real +0.3400)
  - iter 4: 0.8400 (var=0.1344) (Δ vs real +0.4000)
  - iter 5 (current): 0.6400 (var=0.2304) (Δ vs real +0.2000)
**Other theories' values on this metric (for reference):**
- pi_4: 0.9800 (var=0.0196)
- pi_3: 0.0000 (var=0.0000)
- pi_1: 1.0000 (var=0.0000)
- pi_2: 1.0000 (var=0.0000)
- pi_5: 0.3200 (var=0.2176)
- pi_6: 0.3600 (var=0.2304)
- pi_7: 0.3200 (var=0.2176)
- pi_8: 0.5000 (var=0.2500)
- pi_9: 0.1600 (var=0.1344)
- pi_10: 0.0600 (var=0.0564)
- pi_11: 0.1600 (var=0.1344)
- pi_12: 0.8400 (var=0.1344)
- pi_13: 0.7400 (var=0.1924)
- pi_14: 0.1600 (var=0.1344)

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
**Candidate trajectory (this loop):**
  - iter 1: -0.0071 (var=0.0077) (Δ vs real -0.0290)
  - iter 2: -0.0073 (var=0.0130) (Δ vs real -0.0291)
  - iter 3: -0.0141 (var=0.0145) (Δ vs real -0.0360)
  - iter 4: 0.0094 (var=0.0115) (Δ vs real -0.0125)
  - iter 5 (current): -0.0110 (var=0.0122) (Δ vs real -0.0329)
**Other theories' values on this metric (for reference):**
- pi_5: 0.2360 (var=0.0123)
- pi_4: 0.0009 (var=0.0095)
- pi_1: 0.0069 (var=0.0048)
- pi_2: -0.0035 (var=0.0050)
- pi_3: -0.0376 (var=0.0081)
- pi_6: 0.0257 (var=0.0065)
- pi_7: -0.0108 (var=0.0126)
- pi_8: 0.0088 (var=0.0097)
- pi_9: -0.0034 (var=0.0107)
- pi_10: -0.0065 (var=0.0117)
- pi_11: 0.0143 (var=0.0064)
- pi_12: -0.0353 (var=0.0117)
- pi_13: 0.0113 (var=0.0089)
- pi_14: -0.0001 (var=0.0100)

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
**Candidate trajectory (this loop):**
  - iter 1: 0.0375 (var=0.0064) (Δ vs real +0.0258)
  - iter 2: -0.0008 (var=0.0075) (Δ vs real -0.0125)
  - iter 3: -0.0429 (var=0.0095) (Δ vs real -0.0546)
  - iter 4: 0.0158 (var=0.0071) (Δ vs real +0.0042)
  - iter 5 (current): 0.0033 (var=0.0068) (Δ vs real -0.0083)
**Other theories' values on this metric (for reference):**
- pi_4: 0.2729 (var=0.0146)
- pi_5: -0.0100 (var=0.0101)
- pi_1: 0.7325 (var=0.0409)
- pi_2: -0.0042 (var=0.0038)
- pi_3: -0.4775 (var=0.0097)
- pi_6: -0.0154 (var=0.0165)
- pi_7: -0.0021 (var=0.0101)
- pi_8: -0.0042 (var=0.0116)
- pi_9: 0.0033 (var=0.0081)
- pi_10: -0.0167 (var=0.0081)
- pi_11: -0.0054 (var=0.0118)
- pi_12: 0.0358 (var=0.0069)
- pi_13: 0.0233 (var=0.0214)
- pi_14: 0.0179 (var=0.0084)

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
**Candidate trajectory (this loop):**
  - iter 1: 0.4910 (var=0.0027) (Δ vs real -0.0048)
  - iter 2: 0.5054 (var=0.0023) (Δ vs real +0.0096)
  - iter 3: 0.4969 (var=0.0022) (Δ vs real +0.0010)
  - iter 4: 0.5204 (var=0.0029) (Δ vs real +0.0246)
  - iter 5 (current): 0.4921 (var=0.0039) (Δ vs real -0.0038)
**Other theories' values on this metric (for reference):**
- pi_5: 0.6108 (var=0.0033)
- pi_6: 0.4996 (var=0.0028)
- pi_1: 0.4104 (var=0.0015)
- pi_2: 0.4985 (var=0.0025)
- pi_3: 0.6115 (var=0.0020)
- pi_4: 0.6271 (var=0.0029)
- pi_7: 0.4946 (var=0.0027)
- pi_8: 0.5056 (var=0.0026)
- pi_9: 0.4960 (var=0.0023)
- pi_10: 0.4925 (var=0.0029)
- pi_11: 0.5090 (var=0.0024)
- pi_12: 0.4890 (var=0.0018)
- pi_13: 0.4948 (var=0.0023)
- pi_14: 0.5110 (var=0.0027)

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
**Candidate trajectory (this loop):**
  - iter 1: 0.3436 (var=0.0047) (Δ vs real +0.1713)
  - iter 2: 0.3289 (var=0.0055) (Δ vs real +0.1566)
  - iter 3: 0.4443 (var=0.0043) (Δ vs real +0.2719)
  - iter 4: 0.3388 (var=0.0048) (Δ vs real +0.1665)
  - iter 5 (current): 0.3165 (var=0.0058) (Δ vs real +0.1442)
**Other theories' values on this metric (for reference):**
- pi_6: 0.2057 (var=0.0035)
- pi_5: 0.5023 (var=0.0031)
- pi_1: 0.8796 (var=0.0067)
- pi_2: 0.4978 (var=0.0039)
- pi_3: 0.5414 (var=0.0029)
- pi_4: 0.3753 (var=0.0039)
- pi_7: 0.1814 (var=0.0023)
- pi_8: 0.1646 (var=0.0019)
- pi_9: 0.2645 (var=0.0031)
- pi_10: 0.3205 (var=0.0042)
- pi_11: 0.2817 (var=0.0060)
- pi_12: 0.3006 (var=0.0042)
- pi_13: 0.3822 (var=0.0076)
- pi_14: 0.4606 (var=0.0076)

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
**Candidate trajectory (this loop):**
  - iter 1: 0.0892 (var=0.0147) (Δ vs real +0.0575)
  - iter 2: 0.0946 (var=0.0076) (Δ vs real +0.0629)
  - iter 3: 0.0017 (var=0.0107) (Δ vs real -0.0300)
  - iter 4: 0.0858 (var=0.0087) (Δ vs real +0.0542)
  - iter 5 (current): 0.0983 (var=0.0091) (Δ vs real +0.0667)
**Other theories' values on this metric (for reference):**
- pi_7: 0.2729 (var=0.0090)
- pi_6: 0.0217 (var=0.0086)
- pi_1: 0.0167 (var=0.0064)
- pi_2: -0.0292 (var=0.0133)
- pi_3: 0.1604 (var=0.0061)
- pi_4: 0.0054 (var=0.0079)
- pi_5: 0.0146 (var=0.0117)
- pi_8: 0.0125 (var=0.0063)
- pi_9: 0.1046 (var=0.0086)
- pi_10: 0.0933 (var=0.0083)
- pi_11: 0.1204 (var=0.0114)
- pi_12: 0.1071 (var=0.0100)
- pi_13: 0.1450 (var=0.0154)
- pi_14: 0.0250 (var=0.0090)

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
**Candidate trajectory (this loop):**
  - iter 1: 0.5654 (var=0.0028) (Δ vs real -0.1038)
  - iter 2: 0.5315 (var=0.0032) (Δ vs real -0.1377)
  - iter 3: 0.5727 (var=0.0038) (Δ vs real -0.0965)
  - iter 4: 0.5579 (var=0.0032) (Δ vs real -0.1113)
  - iter 5 (current): 0.5627 (var=0.0046) (Δ vs real -0.1065)
**Other theories' values on this metric (for reference):**
- pi_6: 0.4883 (var=0.0028)
- pi_7: 0.5575 (var=0.0028)
- pi_1: 0.1550 (var=0.0096)
- pi_2: 0.5073 (var=0.0027)
- pi_3: 0.6663 (var=0.0014)
- pi_4: 0.5715 (var=0.0020)
- pi_5: 0.5602 (var=0.0027)
- pi_8: 0.7031 (var=0.0082)
- pi_9: 0.6831 (var=0.0036)
- pi_10: 0.7271 (var=0.0030)
- pi_11: 0.6735 (var=0.0042)
- pi_12: 0.6571 (var=0.0061)
- pi_13: 0.5746 (var=0.0084)
- pi_14: 0.5206 (var=0.0047)

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
**Candidate trajectory (this loop):**
  - iter 1: 0.1050 (var=0.0105) (Δ vs real -0.2192)
  - iter 2: 0.0242 (var=0.0096) (Δ vs real -0.3000)
  - iter 3: 0.1583 (var=0.0161) (Δ vs real -0.1658)
  - iter 4: 0.1221 (var=0.0158) (Δ vs real -0.2021)
  - iter 5 (current): 0.1171 (var=0.0109) (Δ vs real -0.2071)
**Other theories' values on this metric (for reference):**
- pi_8: 0.5346 (var=0.0171)
- pi_6: 0.0158 (var=0.0163)
- pi_1: -0.6938 (var=0.0472)
- pi_2: 0.0129 (var=0.0129)
- pi_3: 0.6592 (var=0.0081)
- pi_4: 0.2250 (var=0.0097)
- pi_5: 0.2188 (var=0.0122)
- pi_7: 0.3412 (var=0.0162)
- pi_9: 0.3688 (var=0.0124)
- pi_10: 0.4242 (var=0.0096)
- pi_11: 0.3646 (var=0.0242)
- pi_12: 0.3475 (var=0.0228)
- pi_13: 0.1496 (var=0.0263)
- pi_14: -0.0279 (var=0.0164)

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
**Candidate trajectory (this loop):**
  - iter 1: 0.5328 (var=0.0051) (Δ vs real -0.0541)
  - iter 2: 0.4913 (var=0.0047) (Δ vs real -0.0956)
  - iter 3: 0.5378 (var=0.0025) (Δ vs real -0.0491)
  - iter 4: 0.5241 (var=0.0047) (Δ vs real -0.0628)
  - iter 5 (current): 0.5206 (var=0.0041) (Δ vs real -0.0663)
**Other theories' values on this metric (for reference):**
- pi_6: 0.5012 (var=0.0028)
- pi_8: 0.6616 (var=0.0045)
- pi_1: 0.1222 (var=0.0090)
- pi_2: 0.5122 (var=0.0043)
- pi_3: 0.6784 (var=0.0035)
- pi_4: 0.6269 (var=0.0040)
- pi_5: 0.6112 (var=0.0040)
- pi_7: 0.5816 (var=0.0036)
- pi_9: 0.5988 (var=0.0038)
- pi_10: 0.6191 (var=0.0035)
- pi_11: 0.5844 (var=0.0036)
- pi_12: 0.5878 (var=0.0035)
- pi_13: 0.5269 (var=0.0058)
- pi_14: 0.4959 (var=0.0038)

### Experiment 15
**Design**
  A=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 0, 0, 1, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 1, 0]  B=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 1, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 1]  B=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 1, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 1, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 1, 0, 0]
  A=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Triadic onset in preference for reliability-separated coalitions."""
    dyad_choices = []
    triad_choices = []

    for row in data.itertuples(index=False):
        a = np.asarray(row.option_a_ratings, dtype=np.int8)
        b = np.asarray(row.option_b_ratings, dtype=np.int8)
        d = a - b

        a_support = np.flatnonzero(d > 0)
        b_support = np.flatnonzero(d < 0)
        if a_support.size != b_support.size or a_support.size not in (2, 3):
            continue

        # The reliability-separated pair uses cues 4:8 (validities .65 and
        # .7666667); the matched pair uses two cues 0:4 (validity .70).
        a_mid = int(np.sum((a_support >= 4) & (a_support < 8)))
        b_mid = int(np.sum((b_support >= 4) & (b_support < 8)))
        a_equal = int(np.sum(a_support < 4))
        b_equal = int(np.sum(b_support < 4))

        if a_mid == 2 and b_equal == 2:
            separated_is_a = True
        elif b_mid == 2 and a_equal == 2:
            separated_is_a = False
        else:
            continue

        response = int(row.response)
        chose_separated = float(
            (separated_is_a and response == 0)
            or ((not separated_is_a) and response == 1)
        )

        if a_support.size == 2:
            dyad_choices.append(chose_separated)
        else:
            triad_choices.append(chose_separated)

    if len(dyad_choices) == 0 or len(triad_choices) == 0:
        return float("nan")

    return float(np.mean(triad_choices) - np.mean(dyad_choices))
```

**Observed (real) value:** 0.0142 (var=0.0045)
**Candidate trajectory (this loop):**
  - iter 1: -0.1221 (var=0.0109) (Δ vs real -0.1362)
  - iter 2: -0.1650 (var=0.0104) (Δ vs real -0.1792)
  - iter 3: -0.0104 (var=0.0124) (Δ vs real -0.0246)
  - iter 4: -0.1021 (var=0.0114) (Δ vs real -0.1162)
  - iter 5 (current): -0.1517 (var=0.0099) (Δ vs real -0.1658)
**Other theories' values on this metric (for reference):**
- pi_8: 0.2675 (var=0.0085)
- pi_9: -0.0350 (var=0.0068)
- pi_1: -0.3600 (var=0.0100)
- pi_2: -0.0133 (var=0.0099)
- pi_3: -0.0054 (var=0.0075)
- pi_4: -0.1288 (var=0.0113)
- pi_5: 0.0125 (var=0.0091)
- pi_6: -0.0029 (var=0.0108)
- pi_7: 0.0317 (var=0.0068)
- pi_10: 0.0337 (var=0.0098)
- pi_11: -0.0717 (var=0.0091)
- pi_12: -0.1379 (var=0.0071)
- pi_13: -0.1233 (var=0.0085)
- pi_14: -0.0237 (var=0.0095)

### Experiment 16
**Design**
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]  B=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Mirror-corrected probability of choosing a single-duplicate coalition
    # (features 8:16) over a double-duplicate coalition (features 0:8).
    chosen_single = []
    single_on_a = []

    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=np.float64)
        b = np.asarray(row["option_b_ratings"], dtype=np.float64)
        if a.size < 16 or b.size < 16:
            continue

        a_is_single = float(np.sum(a[8:16])) > float(np.sum(a[0:8]))
        b_is_single = float(np.sum(b[8:16])) > float(np.sum(b[0:8]))
        if a_is_single == b_is_single:
            continue

        response = int(row["response"])
        chose_single = ((response == 0 and a_is_single) or
                         (response == 1 and b_is_single))
        chosen_single.append(float(chose_single))
        single_on_a.append(bool(a_is_single))

    if not chosen_single:
        return float("nan")

    y = np.asarray(chosen_single, dtype=np.float64)
    side = np.asarray(single_on_a, dtype=bool)

    # Give the two mirror orientations equal weight, canceling stable A/B bias.
    if np.any(side) and np.any(~side):
        return float(0.5 * (np.mean(y[side]) + np.mean(y[~side])))
    return float(np.mean(y))

```

**Observed (real) value:** 0.6779 (var=0.0032)
**Candidate trajectory (this loop):**
  - iter 1: 0.5237 (var=0.0029) (Δ vs real -0.1542)
  - iter 2: 0.5175 (var=0.0030) (Δ vs real -0.1604)
  - iter 3: 0.6004 (var=0.0036) (Δ vs real -0.0775)
  - iter 4: 0.5229 (var=0.0022) (Δ vs real -0.1550)
  - iter 5 (current): 0.5408 (var=0.0030) (Δ vs real -0.1371)
**Other theories' values on this metric (for reference):**
- pi_9: 0.6575 (var=0.0035)
- pi_8: 0.5031 (var=0.0031)
- pi_1: 0.8390 (var=0.0107)
- pi_2: 0.5010 (var=0.0023)
- pi_3: 0.8723 (var=0.0016)
- pi_4: 0.6344 (var=0.0024)
- pi_5: 0.6090 (var=0.0024)
- pi_6: 0.4815 (var=0.0033)
- pi_7: 0.6562 (var=0.0033)
- pi_10: 0.6777 (var=0.0028)
- pi_11: 0.6365 (var=0.0053)
- pi_12: 0.7210 (var=0.0079)
- pi_13: 0.5477 (var=0.0053)
- pi_14: 0.5260 (var=0.0041)

### Experiment 17
**Design**
  A=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Signed, inverse-variance-weighted cardinality profile of choices for the
    # reliability-diverse coalition. The duplicate pair identifying each
    # cardinality is fixed by this experimental design.
    duplicate_pair = {2: (0, 1), 3: (4, 5), 4: (10, 11)}
    weights = {2: -1.00, 3: 0.53, 4: -0.51}

    def subject_score(df):
        chosen_diverse = {2: [], 3: [], 4: []}

        for _, row in df.iterrows():
            a = np.asarray(row["option_a_ratings"], dtype=float)
            b = np.asarray(row["option_b_ratings"], dtype=float)
            d = a - b
            cardinality = int(np.sum(d > 0))
            if cardinality not in duplicate_pair:
                continue

            i, j = duplicate_pair[cardinality]
            if d[i] > 0 and d[j] > 0:
                # The duplicate coalition supports A, so B is diverse.
                y = float(int(row["response"]) == 1)
            elif d[i] < 0 and d[j] < 0:
                # The duplicate coalition supports B, so A is diverse.
                y = float(int(row["response"]) == 0)
            else:
                continue
            chosen_diverse[cardinality].append(y)

        if any(len(chosen_diverse[k]) == 0 for k in (2, 3, 4)):
            return np.nan

        rates = {k: float(np.mean(chosen_diverse[k])) for k in (2, 3, 4)}
        return float(sum(weights[k] * (rates[k] - 0.5) for k in (2, 3, 4)))

    scores = []
    for _, subj_df in data.groupby("subject_id", sort=False):
        value = subject_score(subj_df)
        if np.isfinite(value):
            scores.append(value)

    if len(scores) == 0:
        return float("nan")
    return float(np.mean(scores))
```

**Observed (real) value:** -0.3486 (var=0.0131)
**Candidate trajectory (this loop):**
  - iter 1: -0.1494 (var=0.0114) (Δ vs real +0.1992)
  - iter 2: -0.2003 (var=0.0155) (Δ vs real +0.1483)
  - iter 3: 0.0021 (var=0.0155) (Δ vs real +0.3507)
  - iter 4: -0.1568 (var=0.0148) (Δ vs real +0.1918)
  - iter 5 (current): -0.1858 (var=0.0117) (Δ vs real +0.1628)
**Other theories' values on this metric (for reference):**
- pi_10: -0.1210 (var=0.0132)
- pi_9: -0.2371 (var=0.0104)
- pi_1: 0.0290 (var=0.0066)
- pi_2: 0.0005 (var=0.0172)
- pi_3: -0.1762 (var=0.0147)
- pi_4: -0.1228 (var=0.0094)
- pi_5: 0.0260 (var=0.0189)
- pi_6: -0.0595 (var=0.0208)
- pi_7: -0.3008 (var=0.0082)
- pi_8: -0.0731 (var=0.0163)
- pi_11: -0.1886 (var=0.0173)
- pi_12: -0.2260 (var=0.0128)
- pi_13: -0.1662 (var=0.0141)
- pi_14: -0.0326 (var=0.0166)

### Experiment 18
**Design**
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Equal-weighted, mirror-corrected probability of choosing the chain coalition."""
    if data is None or len(data) == 0:
        return float("nan")

    records = []
    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=float)
        b = np.asarray(row["option_b_ratings"], dtype=float)
        if a.size < 20 or b.size != a.size:
            continue

        d = a - b
        chain_direction = float(np.sum(d[:10]))
        if abs(chain_direction) < 1e-12:
            continue

        # Positive means that A is supported by one of the two chain blocks;
        # negative means that B is supported by a chain block.
        chain_is_a = chain_direction > 0.0
        response = int(row["response"])
        chain_chosen = float((response == 0 and chain_is_a) or
                             (response == 1 and not chain_is_a))

        # Identify the crossed chain/comparison configuration independently
        # of whether it was displayed in its original or mirrored orientation.
        chain_block = int(np.sum(np.abs(d[5:10])) > np.sum(np.abs(d[0:5])))
        comparison_block = int(
            np.sum(np.abs(d[15:20])) > np.sum(np.abs(d[10:15]))
        )
        family = 2 * chain_block + comparison_block
        records.append((row["subject_id"], family, chain_chosen))

    if not records:
        return float("nan")

    scored = pd.DataFrame(records, columns=["subject_id", "family", "score"])
    # Equal weighting of the four crossed configurations prevents stable cue
    # salience or an uneven number of usable repetitions from dominating.
    family_rates = scored.groupby(["subject_id", "family"])["score"].mean()
    subject_rates = family_rates.groupby(level=0).mean()
    return float(subject_rates.mean())
```

**Observed (real) value:** 0.4983 (var=0.0018)
**Candidate trajectory (this loop):**
  - iter 1: 0.6250 (var=0.0049) (Δ vs real +0.1267)
  - iter 2: 0.6183 (var=0.0035) (Δ vs real +0.1200)
  - iter 3: 0.6352 (var=0.0030) (Δ vs real +0.1369)
  - iter 4: 0.6187 (var=0.0045) (Δ vs real +0.1204)
  - iter 5 (current): 0.6646 (var=0.0073) (Δ vs real +0.1662)
**Other theories' values on this metric (for reference):**
- pi_9: 0.7094 (var=0.0054)
- pi_10: 0.2913 (var=0.0022)
- pi_1: 0.1706 (var=0.0080)
- pi_2: 0.4950 (var=0.0026)
- pi_3: 0.1296 (var=0.0016)
- pi_4: 0.3533 (var=0.0025)
- pi_5: 0.3854 (var=0.0022)
- pi_6: 0.5079 (var=0.0037)
- pi_7: 0.4525 (var=0.0026)
- pi_8: 0.5229 (var=0.0036)
- pi_11: 0.4998 (var=0.0039)
- pi_12: 0.4948 (var=0.0035)
- pi_13: 0.5371 (var=0.0037)
- pi_14: 0.6452 (var=0.0049)

### Experiment 19
**Design**
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0]  B=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    narrow_choices = []
    wide_choices = []

    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=float)
        b = np.asarray(row["option_b_ratings"], dtype=float)
        response = int(row["response"])

        a_support = np.flatnonzero(a > b)
        b_support = np.flatnonzero(b > a)

        # Features 0--3 form the two narrow-gap target dyads;
        # features 4--7 form the two wide-gap target dyads.
        a_narrow = np.any(a_support < 4)
        b_narrow = np.any(b_support < 4)
        a_wide = np.any((a_support >= 4) & (a_support < 8))
        b_wide = np.any((b_support >= 4) & (b_support < 8))

        if a_narrow and not b_narrow:
            narrow_choices.append(float(response == 0))
        elif b_narrow and not a_narrow:
            narrow_choices.append(float(response == 1))
        elif a_wide and not b_wide:
            wide_choices.append(float(response == 0))
        elif b_wide and not a_wide:
            wide_choices.append(float(response == 1))

    if len(narrow_choices) == 0 or len(wide_choices) == 0:
        return float("nan")

    return float(np.mean(wide_choices) - np.mean(narrow_choices))
```

**Observed (real) value:** -0.0283 (var=0.0129)
**Candidate trajectory (this loop):**
  - iter 1: 0.0075 (var=0.0088) (Δ vs real +0.0358)
  - iter 2: -0.0146 (var=0.0059) (Δ vs real +0.0138)
  - iter 3: -0.0092 (var=0.0081) (Δ vs real +0.0192)
  - iter 4: -0.0108 (var=0.0092) (Δ vs real +0.0175)
  - iter 5 (current): -0.0025 (var=0.0096) (Δ vs real +0.0258)
**Other theories' values on this metric (for reference):**
- pi_11: -0.0029 (var=0.0090)
- pi_9: 0.1900 (var=0.0096)
- pi_1: -0.0088 (var=0.0046)
- pi_2: 0.0033 (var=0.0099)
- pi_3: 0.0775 (var=0.0094)
- pi_4: 0.0067 (var=0.0102)
- pi_5: 0.0087 (var=0.0124)
- pi_6: 0.0029 (var=0.0113)
- pi_7: 0.0192 (var=0.0098)
- pi_8: -0.0146 (var=0.0165)
- pi_10: -0.0008 (var=0.0157)
- pi_12: -0.0354 (var=0.0045)
- pi_13: 0.0083 (var=0.0145)
- pi_14: 0.1217 (var=0.0113)

### Experiment 20
**Design**
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Score each response as 1 when the chain-validity coalition was chosen
    # and 0 when the exact-duplicate comparison coalition was chosen.
    chain_when_a = []
    chain_when_b = []

    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=np.float64)
        b = np.asarray(row["option_b_ratings"], dtype=np.float64)
        d = a - b

        # In this design, chain experts occupy indices 0:8. Exactly one side
        # is supported by four of these experts on every experimental trial.
        a_chain_support = int(np.sum(d[:8] > 0.0))
        b_chain_support = int(np.sum(d[:8] < 0.0))
        response = int(row["response"])

        if a_chain_support > b_chain_support:
            chain_when_a.append(float(response == 0))
        elif b_chain_support > a_chain_support:
            chain_when_b.append(float(response == 1))

    # Average the two response-side orientations separately so the statistic
    # is explicitly mirror-corrected rather than sensitive to side imbalance.
    orientation_means = []
    if len(chain_when_a) > 0:
        orientation_means.append(float(np.mean(chain_when_a)))
    if len(chain_when_b) > 0:
        orientation_means.append(float(np.mean(chain_when_b)))

    if len(orientation_means) == 0:
        return float("nan")
    return float(np.mean(orientation_means))
```

**Observed (real) value:** 0.5042 (var=0.0027)
**Candidate trajectory (this loop):**
  - iter 1: 0.6235 (var=0.0037) (Δ vs real +0.1194)
  - iter 2: 0.6221 (var=0.0036) (Δ vs real +0.1179)
  - iter 3: 0.6212 (var=0.0050) (Δ vs real +0.1171)
  - iter 4: 0.5900 (var=0.0045) (Δ vs real +0.0858)
  - iter 5 (current): 0.6338 (var=0.0052) (Δ vs real +0.1296)
**Other theories' values on this metric (for reference):**
- pi_9: 0.7292 (var=0.0039)
- pi_11: 0.5040 (var=0.0037)
- pi_1: 0.1427 (var=0.0067)
- pi_2: 0.5029 (var=0.0031)
- pi_3: 0.1819 (var=0.0027)
- pi_4: 0.3612 (var=0.0019)
- pi_5: 0.3902 (var=0.0029)
- pi_6: 0.5054 (var=0.0028)
- pi_7: 0.4792 (var=0.0023)
- pi_8: 0.6019 (var=0.0034)
- pi_10: 0.4062 (var=0.0025)
- pi_12: 0.5085 (var=0.0024)
- pi_13: 0.5681 (var=0.0054)
- pi_14: 0.6625 (var=0.0051)

### Experiment 21
**Design**
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]  B=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Fraction of subjects showing a supermajority preference for diverse coalitions."""
    if data is None or len(data) == 0:
        return 0.0

    records = []
    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=float)
        b = np.asarray(row["option_b_ratings"], dtype=float)
        if a.size != 16 or b.size != 16:
            continue

        diff = a - b
        a_support = np.flatnonzero(diff > 0)
        b_support = np.flatnonzero(diff < 0)

        # In this design, indices 0--7 form the two reliability-diverse
        # coalitions, whereas indices 8--15 form the exact-duplicate blocks.
        a_diverse = (a_support.size == 4 and np.all(a_support < 8))
        b_diverse = (b_support.size == 4 and np.all(b_support < 8))
        a_duplicate = (a_support.size == 4 and np.all(a_support >= 8))
        b_duplicate = (b_support.size == 4 and np.all(b_support >= 8))

        if a_diverse and b_duplicate:
            chose_diverse = int(row["response"] == 0)
        elif b_diverse and a_duplicate:
            chose_diverse = int(row["response"] == 1)
        else:
            continue

        records.append((row["subject_id"], chose_diverse))

    if len(records) == 0:
        return 0.0

    scored = pd.DataFrame(records, columns=["subject_id", "chose_diverse"])
    subject_rates = scored.groupby("subject_id")["chose_diverse"].mean()

    # A 2/3 threshold lies well above the competing theory's near-chance
    # prediction but below the advocated theory's predicted range.
    return float(np.mean(subject_rates >= (2.0 / 3.0)))
```

**Observed (real) value:** 0.6400 (var=0.2304)
**Candidate trajectory (this loop):**
  - iter 1: 0.3600 (var=0.2304) (Δ vs real -0.2800)
  - iter 2: 0.0000 (var=0.0000) (Δ vs real -0.6400)
  - iter 3: 0.0600 (var=0.0564) (Δ vs real -0.5800)
  - iter 4: 0.1000 (var=0.0900) (Δ vs real -0.5400)
  - iter 5 (current): 0.1800 (var=0.1476) (Δ vs real -0.4600)
**Other theories' values on this metric (for reference):**
- pi_11: 1.0000 (var=0.0000)
- pi_12: 0.0000 (var=0.0000)
- pi_1: 0.9600 (var=0.0384)
- pi_2: 0.0000 (var=0.0000)
- pi_3: 0.0000 (var=0.0000)
- pi_4: 0.0000 (var=0.0000)
- pi_5: 0.0000 (var=0.0000)
- pi_6: 0.0000 (var=0.0000)
- pi_7: 1.0000 (var=0.0000)
- pi_8: 0.0000 (var=0.0000)
- pi_9: 1.0000 (var=0.0000)
- pi_10: 1.0000 (var=0.0000)
- pi_13: 0.8200 (var=0.1476)
- pi_14: 0.9000 (var=0.0900)

### Experiment 22
**Design**
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # In this fixed design, features 0--3 form the two near-duplicate
    # coalitions, whereas features 4--7 form the two exact-duplicate
    # coalitions. Every trial pits one type against the other.
    near_choices = []

    for row in data.itertuples(index=False):
        a = np.asarray(row.option_a_ratings, dtype=np.float64)
        b = np.asarray(row.option_b_ratings, dtype=np.float64)

        a_near_mass = float(np.sum(a[:4]))
        a_exact_mass = float(np.sum(a[4:8]))
        b_near_mass = float(np.sum(b[:4]))
        b_exact_mass = float(np.sum(b[4:8]))

        a_is_near = a_near_mass > a_exact_mass
        b_is_near = b_near_mass > b_exact_mass

        # Retain only the intended near-versus-exact diagnostic trials.
        if a_is_near == b_is_near:
            continue

        response = int(row.response)
        chose_near = a_is_near if response == 0 else b_is_near
        near_choices.append(float(chose_near))

    if len(near_choices) == 0:
        return 0.5
    return float(np.mean(near_choices))
```

**Observed (real) value:** 0.6817 (var=0.0026)
**Candidate trajectory (this loop):**
  - iter 1: 0.7008 (var=0.0038) (Δ vs real +0.0192)
  - iter 2: 0.6765 (var=0.0035) (Δ vs real -0.0052)
  - iter 3: 0.6977 (var=0.0048) (Δ vs real +0.0160)
  - iter 4: 0.6879 (var=0.0032) (Δ vs real +0.0062)
  - iter 5 (current): 0.6958 (var=0.0060) (Δ vs real +0.0142)
**Other theories' values on this metric (for reference):**
- pi_12: 0.7017 (var=0.0030)
- pi_11: 0.4998 (var=0.0029)
- pi_1: 0.8473 (var=0.0103)
- pi_2: 0.5046 (var=0.0017)
- pi_3: 0.4006 (var=0.0025)
- pi_4: 0.3654 (var=0.0023)
- pi_5: 0.4827 (var=0.0022)
- pi_6: 0.4890 (var=0.0027)
- pi_7: 0.5088 (var=0.0022)
- pi_8: 0.4983 (var=0.0026)
- pi_9: 0.7244 (var=0.0023)
- pi_10: 0.5156 (var=0.0026)
- pi_13: 0.6694 (var=0.0048)
- pi_14: 0.6856 (var=0.0112)

### Experiment 23
**Design**
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    if len(data) == 0:
        return float('nan')

    a = np.vstack([np.asarray(x, dtype=np.float64) for x in data['option_a_ratings']])
    b = np.vstack([np.asarray(x, dtype=np.float64) for x in data['option_b_ratings']])
    responses = data['response'].to_numpy(dtype=np.int64)

    # Features 8:16 comprise the two fully separated coalitions. Their signed
    # rating difference identifies whether the separated coalition is on A
    # (+1) or B (-1), independently of the particular coalition identities.
    separated_side = np.sign(np.sum(a[:, 8:16] - b[:, 8:16], axis=1))
    valid = (separated_side != 0) & ((responses == 0) | (responses == 1))
    if not np.any(valid):
        return float('nan')

    # +1 denotes choosing A and -1 choosing B. Multiplication mirror-corrects
    # every response so +1 always means choosing the separated coalition.
    chosen_side = 1.0 - 2.0 * responses[valid].astype(np.float64)
    return float(np.mean(chosen_side * separated_side[valid]))

```

**Observed (real) value:** -0.3542 (var=0.0111)
**Candidate trajectory (this loop):**
  - iter 1: 0.2071 (var=0.0171) (Δ vs real +0.5613)
  - iter 2: 0.2583 (var=0.0164) (Δ vs real +0.6125)
  - iter 3: 0.1846 (var=0.0169) (Δ vs real +0.5388)
  - iter 4: 0.2137 (var=0.0179) (Δ vs real +0.5679)
  - iter 5 (current): 0.2754 (var=0.0250) (Δ vs real +0.6296)
**Other theories' values on this metric (for reference):**
- pi_11: 0.0071 (var=0.0085)
- pi_13: 0.1104 (var=0.0254)
- pi_1: -0.7033 (var=0.0507)
- pi_2: -0.0025 (var=0.0119)
- pi_3: 0.5962 (var=0.0107)
- pi_4: 0.2871 (var=0.0068)
- pi_5: 0.2362 (var=0.0116)
- pi_6: -0.0187 (var=0.0122)
- pi_7: -0.0146 (var=0.0112)
- pi_8: 0.1246 (var=0.0138)
- pi_9: -0.0104 (var=0.0124)
- pi_10: 0.0008 (var=0.0095)
- pi_12: 0.0108 (var=0.0081)
- pi_14: -0.0804 (var=0.0180)

### Experiment 24
**Design**
  A=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    if data is None or len(data) == 0:
        return 0.0

    validities = np.asarray([
        0.55, 0.554, 0.56, 0.574, 0.58, 0.594, 0.6, 0.604,
        0.65, 0.67, 0.69, 0.71, 0.73, 0.75, 0.77, 0.79,
        0.81, 0.83, 0.85, 0.87, 0.89, 0.91, 0.93, 0.95
    ], dtype=float)

    broad_when_a = []
    broad_when_b = []

    def coalition_gap(ratings):
        x = np.asarray(ratings, dtype=float)
        idx = np.flatnonzero(x > 0.5)
        if idx.size != 2:
            return np.nan
        return float(abs(validities[idx[1]] - validities[idx[0]]))

    for _, row in data.iterrows():
        gap_a = coalition_gap(row["option_a_ratings"])
        gap_b = coalition_gap(row["option_b_ratings"])
        if not np.isfinite(gap_a) or not np.isfinite(gap_b):
            continue

        # The design contains narrow gaps of .004 and broad gaps of .014;
        # .009 is their fixed midpoint and does not depend on responses.
        a_is_broad = gap_a > 0.009
        b_is_broad = gap_b > 0.009
        if a_is_broad == b_is_broad:
            continue

        response = int(row["response"])
        chose_broad = float(
            (a_is_broad and response == 0) or
            (b_is_broad and response == 1)
        )

        if a_is_broad:
            broad_when_a.append(chose_broad)
        else:
            broad_when_b.append(chose_broad)

    # Average the two mirror orientations separately before combining them.
    # This exactly removes a stable A/B response tendency in the balanced
    # schedule and remains well-defined for a single subject.
    orientation_means = []
    if len(broad_when_a) > 0:
        orientation_means.append(float(np.mean(broad_when_a)))
    if len(broad_when_b) > 0:
        orientation_means.append(float(np.mean(broad_when_b)))

    if len(orientation_means) == 0:
        return 0.0
    return float(np.mean(orientation_means))

```

**Observed (real) value:** 0.3208 (var=0.0038)
**Candidate trajectory (this loop):**
  - iter 1: 0.4590 (var=0.0030) (Δ vs real +0.1381)
  - iter 2: 0.4713 (var=0.0031) (Δ vs real +0.1504)
  - iter 3: 0.3744 (var=0.0043) (Δ vs real +0.0535)
  - iter 4: 0.3729 (var=0.0037) (Δ vs real +0.0521)
  - iter 5 (current): 0.4037 (var=0.0041) (Δ vs real +0.0829)
**Other theories' values on this metric (for reference):**
- pi_13: 0.4952 (var=0.0056)
- pi_11: 0.7165 (var=0.0043)
- pi_1: 0.5023 (var=0.0008)
- pi_2: 0.5117 (var=0.0028)
- pi_3: 0.5012 (var=0.0019)
- pi_4: 0.4933 (var=0.0018)
- pi_5: 0.5035 (var=0.0025)
- pi_6: 0.4967 (var=0.0029)
- pi_7: 0.5267 (var=0.0024)
- pi_8: 0.4975 (var=0.0031)
- pi_9: 0.5210 (var=0.0033)
- pi_10: 0.5956 (var=0.0110)
- pi_12: 0.4994 (var=0.0025)
- pi_14: 0.3846 (var=0.0102)

### Experiment 25
**Design**
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]  B=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    def subject_score(df):
        compact_sides = []
        compact_choices = []

        for _, row in df.iterrows():
            a = np.asarray(row["option_a_ratings"], dtype=float)
            b = np.asarray(row["option_b_ratings"], dtype=float)
            a_support = np.flatnonzero(a > b)
            b_support = np.flatnonzero(b > a)

            a_is_compact = a_support.size > 0 and np.all(a_support < 8)
            b_is_compact = b_support.size > 0 and np.all(b_support < 8)
            if a_is_compact == b_is_compact:
                continue

            compact_side = 0 if a_is_compact else 1
            compact_sides.append(compact_side)
            compact_choices.append(int(row["response"]) == compact_side)

        if len(compact_choices) == 0:
            return 0.5

        compact_sides = np.asarray(compact_sides, dtype=int)
        compact_choices = np.asarray(compact_choices, dtype=float)

        side_rates = []
        for side in (0, 1):
            mask = compact_sides == side
            if np.any(mask):
                side_rates.append(float(np.mean(compact_choices[mask])))

        compact_rate = float(np.mean(side_rates))
        dispersed_rate = 1.0 - compact_rate

        if dispersed_rate > 0.5:
            return 1.0
        if dispersed_rate < 0.5:
            return 0.0
        return 0.5

    if len(data) == 0:
        return 0.5

    scores = [subject_score(df) for _, df in data.groupby("subject_id", sort=False)]
    return float(np.mean(scores))
```

**Observed (real) value:** 0.9200 (var=0.0736)
**Candidate trajectory (this loop):**
  - iter 1: 0.5400 (var=0.2384) (Δ vs real -0.3800)
  - iter 2: 0.1200 (var=0.0956) (Δ vs real -0.8000)
  - iter 3: 0.4300 (var=0.2401) (Δ vs real -0.4900)
  - iter 4: 0.6700 (var=0.1961) (Δ vs real -0.2500)
  - iter 5 (current): 0.3100 (var=0.1789) (Δ vs real -0.6100)
**Other theories' values on this metric (for reference):**
- pi_11: 1.0000 (var=0.0000)
- pi_14: 0.4100 (var=0.2369)
- pi_1: 1.0000 (var=0.0000)
- pi_2: 0.5700 (var=0.2301)
- pi_3: 1.0000 (var=0.0000)
- pi_4: 0.9800 (var=0.0196)
- pi_5: 0.9800 (var=0.0196)
- pi_6: 0.5600 (var=0.2264)
- pi_7: 1.0000 (var=0.0000)
- pi_8: 1.0000 (var=0.0000)
- pi_9: 1.0000 (var=0.0000)
- pi_10: 1.0000 (var=0.0000)
- pi_12: 0.6400 (var=0.2104)
- pi_13: 0.7900 (var=0.1509)

### Experiment 26
**Design**
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    scores = []

    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=float)
        b = np.asarray(row["option_b_ratings"], dtype=float)
        diff = a - b
        a_support = np.flatnonzero(diff > 0)
        b_support = np.flatnonzero(diff < 0)

        # Retain comparisons involving either of the two diffuse chains:
        # features 12:16 have spacing .014 and features 16:20 spacing .020.
        all_support = np.concatenate((a_support, b_support))
        diffuse_trial = np.any((all_support >= 12) & (all_support < 20))
        if not diffuse_trial:
            continue

        # The compact coalitions occupy features 0:8. Determine whether the
        # compact coalition supports A or B, making the score side-invariant.
        a_is_compact = (
            a_support.size > 0
            and np.all((a_support >= 0) & (a_support < 8))
        )
        b_is_compact = (
            b_support.size > 0
            and np.all((b_support >= 0) & (b_support < 8))
        )

        if a_is_compact == b_is_compact:
            continue

        response = int(row["response"])
        chose_compact = (response == 0) if a_is_compact else (response == 1)
        scores.append(float(chose_compact))

    if len(scores) == 0:
        return 0.5
    return float(np.mean(np.asarray(scores, dtype=float)))
```

**Observed (real) value:** 0.4956 (var=0.0045)
**Candidate trajectory (this loop):**
  - iter 1: 0.3872 (var=0.0042) (Δ vs real -0.1084)
  - iter 2: 0.3753 (var=0.0049) (Δ vs real -0.1203)
  - iter 3: 0.3744 (var=0.0042) (Δ vs real -0.1212)
  - iter 4: 0.3981 (var=0.0059) (Δ vs real -0.0975)
  - iter 5 (current): 0.4000 (var=0.0040) (Δ vs real -0.0956)
**Other theories' values on this metric (for reference):**
- pi_14: 0.4944 (var=0.0099)
- pi_11: 0.1512 (var=0.0035)
- pi_1: 0.1559 (var=0.0102)
- pi_2: 0.5059 (var=0.0033)
- pi_3: 0.1231 (var=0.0025)
- pi_4: 0.3738 (var=0.0032)
- pi_5: 0.3950 (var=0.0033)
- pi_6: 0.4984 (var=0.0036)
- pi_7: 0.4556 (var=0.0044)
- pi_8: 0.6169 (var=0.0076)
- pi_9: 0.1922 (var=0.0028)
- pi_10: 0.2525 (var=0.0091)
- pi_12: 0.5041 (var=0.0040)
- pi_13: 0.4075 (var=0.0084)

## YOUR PRIOR CRITIQUES (for this propose-loop)
Each block is one of YOUR previous critique iterations: the verdict you returned, the interpretation and rationale you wrote, and an **Outcome of your advice** line that says whether the candidate the proposer produced AFTER following your advice was ACCEPTED (your advice helped — its loss strictly beat the running-best) or REJECTED (your advice didn't help — the gate discarded the candidate). Use this self-history to (a) reinforce advice that was ACCEPTED, (b) avoid repeating advice that was REJECTED, and (c) detect your own oscillation across iterations.

### Iteration 1
Verdict: regenerate
Interpretation: The candidate is faithful in broad form to Capacity-Gated Local Source Individuation and improves several targeted phenomena: positional and closure nulls are close in Experiments 4, 5, 7, and 9; near-over-exact choice is captured in Experiment 22 (0.701 versus 0.682); and Experiment 19 is approximately null. However, it is not yet experiment-invariant. Its largest problem is that coalition-level contextual coverage and local-link credit still create an excessive diffuse/chain advantage. Chain choices remain too high in Experiments 18 and 20 (0.625 and 0.624 versus approximately 0.50), and broad tetrads are likewise overvalued in Experiment 26 (compact choice 0.387 versus 0.496). The sign is dramatically wrong in Experiment 23 (0.207 versus -0.354). At the same time, the model underproduces the intended distributed-over-duplicate effects in Experiments 12-14, 16, 21, and 25, especially Experiment 16 (0.524 versus 0.678), Experiment 21 (0.36 versus 0.64), and Experiment 25 (0.54 versus 0.92). Thus its diffuse preference is coming from the wrong component: chain/coverage credit rather than appropriately structured, group-local duplicate discounting. The cardinality gate is also miscalibrated. Experiment 6 is deterministically predicted to favor the three-cue coalition (1.00 versus 0.44), while Experiment 15 shows an excessive negative two-to-three change (-0.122 versus 0.014). Dyadic discrimination is directionally useful but too weak: exact coalitions are chosen too often in Experiment 10 (0.344 versus 0.172), and broad dyads are insufficiently avoided in Experiment 24 (0.459 versus 0.321). Finally, the model misses the opponent-relative balanced patterns in Experiments 2 and 3, predicting approximately zero where the observed metrics are negative.
Rationale: Retain the prescribed mechanism family, but rebalance which in-family components generate structural preferences. First, sharply attenuate or eliminate local-link credit at cardinality four and above and reduce bounded coverage credit there; the present load gate is not strong enough to stop chain advantages in Experiments 18, 20, and 26. Replace the global equal-rank code binning with genuinely local, gap-threshold-based contextual coding: rank bins depend on the full experiment-wide validity set and can create arbitrary region boundaries, likely contributing to the severe reversal in Experiment 23. Second, move distributed-over-duplicate discrimination toward local duplicate-group accounting. Increase the penalty for multiple separately tagged duplicate groups while increasing within-group saturation, so two duplicate groups can be penalized more than one large exact block without making every exact tetrad lose to a chain. This specifically targets Experiments 12, 16, 21, and 25 while protecting the chain nulls. Third, weaken the generic triad count advantage and allow heterogeneous account normalization to cross indifference, avoiding the unanimous prediction in Experiment 6. Simultaneously reduce dyadic independence gain and strengthen the exact-equality penalty enough to preserve near-over-exact choice; sharpen the Goldilocks decay around the narrow gap so Experiment 24 moves downward without introducing a coalition-wide span penalty. These changes should also bring the two-to-three contrast in Experiment 15 toward zero. Recalibrate jointly with hard constraints on Experiments 6, 15, 18, 20, 23, 24, 25, and 26 rather than increasing response noise globally, since several failures are structural sign or ordering errors rather than merely excessive sensitivity.

**Outcome of your advice:** iter 1 candidate loss=0.2308 -> iter 2 candidate loss=0.2572 -> the gate marked it REJECTED.

### Iteration 2
Verdict: regenerate
Interpretation: The current candidate is broadly faithful to Capacity-Gated Local Source Individuation, but it is not experiment-invariant and was correctly rejected by the accept gate: loss worsened from 0.2308 to 0.2572. Some targeted fits improved, including Experiments 4, 8, 10, 17, 19, and 22. However, the changes seriously weakened the central distributed-coalition phenomena. Relative to the accepted base, Experiment 12 fell from 0.565 to 0.532, Experiment 13 from 0.105 to 0.024, Experiment 14 from 0.533 to 0.491, Experiment 21 from 0.36 to 0.00, and Experiment 25 from 0.54 to 0.12. Experiment 23 also moved farther in the wrong direction, from 0.207 to 0.258 when the observed value is -0.354. Meanwhile, eliminating local-link credit at four or more cues did not solve the chain problem: Experiments 18 and 20 remain around 0.62 rather than 0.50, and Experiment 26 still favors the diffuse coalition too strongly. This shows that the chain advantage is now generated primarily by the unconditional exact-duplicate penalty and account representation, not by explicit local-link accumulation. The added triadic load cost was also counterproductive: Experiment 6 remains nearly deterministic at 0.98 versus 0.44, while Experiment 15 worsened from -0.122 to -0.165 versus an observed value near zero. Dyadic calibration remains inadequate: exact choice is still too high in Experiment 10, and broad-dyad choice in Experiment 24 moved away from the target. Finally, the sorted discontinuity procedure still constructs a transitive partition of each coalition, despite the theory's claim of bounded, nontransitive local accounts.
Rationale: Because the previous broad push to replace coding, strengthen the large-cardinality gate, and add a triadic load penalty was rejected, do not repeat or intensify those changes. Build on the unchanged accepted iteration-1 base and make narrower in-family edits. First, remove the generic triadic valuation penalty and instead use a cardinality-gated response-temperature or contrast compression specifically for unequal 3-versus-2 comparisons. This can generate the subject-level crossover required by Experiment 6 without structurally depressing triads and worsening Experiment 15. Second, revise large-coalition duplicate accounting so a single exact group at n>=4 receives only a small saturated penalty, whereas penalties rise mainly with the number of separately tagged duplicate groups. The current unconditional load makes chains beat single exact blocks in Experiments 18 and 20; a group-count contrast should preserve duplicate avoidance in Experiments 16, 21, and 25 without rewarding every chain. Third, leave the accepted base's account coding largely intact for the next iteration rather than attempting another wholesale local-coding replacement. If local coding is adjusted, make it genuinely capacity-limited and nontransitive—evaluate only a bounded set of local anchor relations rather than assigning every cue to a cumulative sorted-gap partition. Finally, change the dyadic Goldilocks function qualitatively rather than merely sharpening its decay: permit a narrow positive gap to exceed baseline, but allow sufficiently broad dyadic gaps to fall modestly below baseline. A decay that only returns to 1 cannot reliably produce the strong broad-dyad avoidance in Experiment 24 when reliability composition favors the broad pair. Jointly hard-check Experiments 6, 15, 18, 20, 21, 23, 24, 25, and 26 while preserving the already good near-over-exact result in Experiment 22 and the positional nulls.

**Outcome of your advice:** iter 2 candidate loss=0.2572 -> iter 3 candidate loss=0.2328 -> the gate marked it REJECTED.

### Iteration 3
Verdict: regenerate
Interpretation: The candidate remains broadly faithful to Capacity-Gated Local Source Individuation, and the narrow edits produced some useful local improvements: Experiment 6 moved from 1.00 to 0.78, Experiment 15 moved close to its near-zero target, Experiment 16 improved from 0.524 to 0.600, and broad-dyad avoidance in Experiment 24 improved substantially from 0.459 to 0.374. Near-over-exact preference remains good in Experiment 22, and the positional/closure nulls remain broadly intact. Nevertheless, the candidate was rejected by the gate and is not experiment-invariant. The single-exact-group exemption did not neutralize chains: Experiments 18 and 20 remain around 0.62-0.64 rather than 0.50, and Experiment 26 still overvalues the diffuse coalition. At the same time, that exemption damaged the threshold-based distributed effects, especially Experiment 21 (0.06 versus 0.64) and Experiment 25 (0.43 versus 0.92). The cardinality profile in Experiment 17 also collapsed to approximately zero instead of -0.349. The dyadic broad-gap limb is too indiscriminate: it improves Experiment 24 but makes the exact coalition much too attractive in Experiment 10 (0.444 versus 0.172), apparently because all sufficiently unequal alternatives receive an asymptotic broad-gap penalty. Major failures also remain in Experiment 2 (wrong sign, 0.053 versus -0.264), Experiment 23 (wrong sign, 0.185 versus -0.354), and the distributed-coalition effects in Experiments 12-14. Thus the model still treats contextual account coverage too generically across validity environments and does not use communicated reliability strongly enough to distinguish superficially similar tetrad designs.
Rationale: Build again on the unchanged accepted iteration-1 base. The previous response-temperature and 8% single-group exemption package was rejected, so do not repeat or intensify it. First, retain additive local duplicate-group penalties from the accepted base rather than nearly deleting the cost of one exact group. The fact that the exemption barely changed Experiments 18 and 20 shows that their chain advantage is generated mainly by unconditional account coverage, while its sharp deterioration of Experiments 21 and 25 shows that one-group duplicate discounting is still empirically needed in some validity contexts. Instead, make the existing n>=4 coverage credit contingent on the bounded strength of the sampled local links: an occupied second code should earn credit only when a capacity-limited nearest gap falls in a resolvable local range. Broad links should contribute little, and credits must remain averaged and nonaccumulating. This is a narrow adjustment to account normalization, not a global span penalty or a new partition mechanism. It should distinguish moderate distributed coalitions from broad chains and directly target Experiments 18, 20, 23, 25, and 26. Second, make communicated reliability more consequential within the existing compressed weighting scheme—raise validity reliance modestly and avoid normalizations that erase too much absolute/local reliability contrast. This is especially important because Experiments 20, 21, and 25 have similar coalition layouts but different validity environments; a rank-code premium alone predicts them too similarly. It may also help the wrong signs in Experiments 2 and 23. Third, replace the rejected blanket 3-versus-2 temperature with stable subject heterogeneity in a response-stage cardinality criterion or indifference threshold. A symmetric temperature cannot reliably move the fraction of subjects crossing 0.5 when nearly everyone has the same positive structural ordering. A shared, mean-near-zero overload criterion can produce the heterogeneous threshold result in Experiment 6 without imposing a triadic valuation penalty or disturbing the now-good Experiment 15. Finally, do not retain the monotone asymptotic dyadic broad penalty. Use a localized Goldilocks trough: narrow positive gaps receive independence credit, moderately broad gaps such as those in Experiment 24 fall below baseline, but much larger gaps recover toward reliability-weighted baseline. That should preserve Experiment 24 while avoiding the severe regression in Experiment 10. Jointly hard-check Experiments 2, 6, 10, 17, 18, 20-26, with particular emphasis on obtaining chain means near chance without sacrificing the distributed-coalition threshold effects.

**Outcome of your advice:** iter 3 candidate loss=0.2328 -> iter 4 candidate loss=0.2085 -> the gate marked it ACCEPTED.

### Iteration 4 (most recent)
Verdict: regenerate
Interpretation: Iteration 4 is a genuine aggregate improvement and remains broadly faithful to Capacity-Gated Local Source Individuation. The accepted changes helped in the intended direction: Experiment 20 moved toward chance (0.590 versus 0.504), Experiment 26 moved toward chance (compact choice 0.398 versus 0.496), Experiment 24 retained substantially improved broad-dyad avoidance (0.373 versus 0.321), Experiment 22 remains excellent (0.688 versus 0.682), and the positional/onset nulls in Experiments 4, 5, 7, and 8 remain close. Nevertheless, the candidate fails several of the arbiter's hard qualitative checks. Chain preference remains excessive in Experiments 18 and 20, and Experiment 23 has a severe sign reversal (0.214 versus -0.354). Distributed and duplicate-sensitive effects are too weak in Experiments 12-14, 16, 21, and 25; the largest failures are Experiment 21 (0.10 versus 0.64), Experiment 25 (0.67 versus 0.92), Experiment 16 (0.523 versus 0.678), and Experiment 13 (0.122 versus 0.324). The cardinality gate is also still wrong: Experiment 6 predicts too many subjects favoring the three-cue coalition (0.84 versus 0.44), Experiment 15 produces an excessive negative triad-minus-dyad shift (-0.102 versus 0.014), and Experiment 17 captures less than half of the observed cardinality profile. Dyadic equality discounting is insufficient in Experiment 10 (equal choice 0.339 versus 0.172), although the localized trough works reasonably well for Experiment 24. Finally, Experiment 2 remains approximately chance rather than showing the robust anti-highest-cue pattern (0.032 versus -0.264). Variances for the threshold outcomes in Experiments 6 and 21 are also too small, indicating insufficient structural heterogeneity rather than merely excessive response noise.
Rationale: Build on this accepted iteration rather than undoing its successful localized trough and link-contingent coverage changes. The previous advice leading to these changes improved the aggregate loss, so it should be extended cautiously. First, strengthen the response-stage overload criterion for unequal 3-versus-2 choices by shifting its shared distribution upward and widening it moderately. It currently leaves 84% of subjects above the threshold in Experiment 6 and produces too little between-subject variance. Because this criterion is restricted to 3-versus-2 conflicts, it can repair Experiment 6 without directly worsening Experiment 15. Second, add a weak, capped triadic local-release term tied to one sampled resolvable link, or use a separate triadic account normalization. This should bring Experiment 15 back toward zero and fit Experiment 17's cardinality profile without introducing a generic triadic bonus.

Third, revise duplicate load within the existing local-tag family. Use a nonzero cost per locally tagged equality group plus a strongly saturating within-group excess cost. The present excess-only formula makes one versus two duplicate groups too similar, explaining the weak effects in Experiments 16, 21, and 25. Modulate that duplicate cost by bounded local reliability mass, so high-quality exact repetition can be discounted more strongly; this may also improve Experiments 2, 10, and the sign failure in Experiment 23. To avoid worsening chains, gate the opponent-relative expression of this duplicate contrast by whether the rival has at least one genuinely resolvable, capacity-limited local account. A broad chain with only weak links should not automatically win because its opponent contains an exact group. This remains local duplicate accounting plus coalition-level contrast, not a global span or coherence mechanism.

Fourth, make the new link contingency sharper rather than simply increasing or decreasing coverage gain globally. Experiments 18 and 20 show that squaring mean Goldilocks credit still grants broad chains too much effective account value, whereas Experiments 12-14 need stronger credit for locally resolvable distributed coalitions. Use a thresholded or steeper bounded activation for the one or two sampled links and keep it nonaccumulating. Finally, modestly increase the dyadic exact-equality penalty while retaining the localized, recovering broad-gap trough; this targets Experiment 10 without repeating the rejected asymptotic broad-gap penalty and should preserve Experiments 22 and 24. Joint calibration should impose hard checks on Experiments 2, 6, 10, 15-18, and 20-26, especially requiring chance-level chains alongside strong duplicate avoidance and sufficient subject-level heterogeneity.

**Outcome of your advice:** iter 4 candidate loss=0.2085 -> CURRENT candidate loss=0.2279 -> the gate marked it REJECTED.

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of the model simulation results on existing experiments and how they do or do not support the proposed model/theory.
- verdict: Either 'regenerate' (regenerate a new model/theory) or 'continue' (keep the current model/theory).
- rationale: If verdict='regenerate', why the current predict / policy / parameter-ranges should be revised. If verdict='continue', a sketch of why the current theory should be kept.


## Response

```json
{
  "interpretation": "The current candidate is faithful to the prescribed Capacity-Gated Local Source Individuation family, but it was rejected by the accept gate and regresses from the accepted iteration 4 (loss 0.2279 versus 0.2085). The latest package improved the unequal-cardinality threshold in Experiment 6 (0.64 versus 0.84 previously, observed 0.44) and slightly strengthened duplicate avoidance in Experiments 10, 16, and 21. Those gains are outweighed by clear structural regressions. The new triadic release drives Experiment 15 farther from its near-zero target (-0.152 versus 0.014). The steep large-coalition activation worsens rather than suppresses chains: Experiment 18 rises to 0.665 and Experiment 20 to 0.634, both observed near 0.50. Experiment 23 develops an even larger wrong-sign preference (0.275 versus -0.354), and the subject-threshold effect in Experiment 25 collapses from 0.67 to 0.31 despite an observed 0.92. Broad tetrads remain overvalued in Experiment 26 (compact choice 0.400 versus 0.496). Distributed-coalition and duplicate-sensitive effects also remain too weak in Experiments 12\u201314, 16, and 21. The candidate continues to miss the robust anti-highest-cue pattern in Experiment 2 and the covariance pattern in Experiment 3. Thus the revised activation and duplicate-group surcharge do not distinguish useful local account separation from chain-like separation across reliability environments.",
  "verdict": "regenerate",
  "rationale": "Build on the unchanged accepted iteration-4 base. The previous recommendation to combine a stronger overload distribution, a square-root triadic release, a steep thresholded large-coalition activation, a multiple-group surcharge, and a stronger dyadic equality penalty was rejected; do not repeat or intensify that package. In particular, remove the generic triadic release and restore the iteration-4 triadic treatment, because it substantially worsened Experiment 15. Also restore the iteration-4 large-coalition activation and duplicate-load formulation: the new threshold and fixed 0.30 multi-group surcharge simultaneously increased chain choices and destroyed Experiment 25.\n\nTry a different in-family knob that was described previously but not actually implemented here: make the expression of duplicate discounting opponent-relative and reliability-mass-sensitive. Preserve local equality tags, but let their structural consequence depend on bounded compressed quality within the tagged group and on whether the rival possesses a genuinely resolved, capacity-limited local account. If the rival is merely a broad or weak chain, duplicate discounting should be strongly contrast-normalized toward indifference; if it contains a locally resolvable account in the relevant reliability region, the duplicate contrast can be expressed. This targets the needed separation between near-chance chains in Experiments 18, 20, 23, and 26 and strong duplicate avoidance in Experiments 12\u201314, 16, 21, and 25 without adding a global span or coherence term.\n\nImplement this through the existing coalition-level normalization/contrast stage rather than another discontinuous coverage multiplier. Use bounded absolute compressed reliability mass\u2014not experiment-wide rank-code occupancy\u2014to scale account contrast, because the current rank coding treats the distinct validity environments of Experiments 20, 21, 23, and 25 too similarly. Keep coverage and local-link contributions capped and nonaccumulating. Hold the overload criterion near its iteration-4 range for this attempt; although the latest upward shift helped Experiment 6, the full change was rejected, so cardinality tuning should be isolated later rather than bundled again. Likewise retain the iteration-4 localized dyadic trough, which already fit Experiment 24 reasonably well and preserved Experiment 22. Hard-check that the next candidate improves Experiments 18, 20, 23, 25, and 26 simultaneously and does not sacrifice the near-zero Experiment 15 result."
}
```

## Usage

```json
{
  "input_tokens": 55533,
  "output_tokens": 1428
}
```
