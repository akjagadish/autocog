# feedback_iter_08

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
- THEORY 1 = `pi_10`
- THEORY 2 = `pi_9`
- The recommendation below acts on THEORY 2 (= `pi_9`).

Replace pi_9 with a Reliability-Precision Gated Competition theory. The new theory should retain a density-invariant signed count accumulator but treat centered validity evidence as a noisy estimate whose precision depends jointly on residual magnitude, signed coherence, and the contrast of the active validity field. Reliability should be confidence-weighted: weak residuals remain partly available through a floor, increasing magnitude makes coherent identity bindings more diagnostic, and diffuse opposing contributions reduce posterior precision. This naturally produces the magnitude-by-coherence curvature observed in Experiment 2 without pi_9's fixed diffuse/coherent ratio. When count and reliability conflict, channels should compete according to their estimated precision; uncertain reliability is downweighted, yielding robust count following in Experiment 1, while strong coherent reliability can still dominate as in Experiment 13. Unlike pi_10, the theory should allow selective dilution when the same diagnostic contrast is distributed across many similarly informative active cues, as supported by Experiment 18. That dilution must depend on active-set signal-to-noise or validity contrast—not raw feature count or discriminating-cue count—so it predicts little generic sparse-versus-dense effect in Experiments 16 and 17 and avoids the strong trajectory rejected in Experiment 11. Use a smooth confidence-weighted competition rule rather than pi_10's explicit notch plus winner-enhancement construction, preserve stable semantic polarity and lapses, and include continuous subject-level variation in count weight, reliability precision, and response precision broad enough to reproduce the observed between-subject heterogeneity.


## CANDIDATE THEORY
Contrast-Calibrated Reliability-Precision Competition theory: people encode a binary-feature display through two stable-polarity evidence channels. The count channel accumulates only the signed difference in marks and is therefore invariant to additions that cancel in the tally. It saturates smoothly after relatively small margins, while retaining a substantial precision floor, so ordinary and large margins differ less sharply in confidence. The reliability channel computes centered validity evidence but treats that residual as an uncertain estimate. Its precision is inferred jointly from residual magnitude, signed coherence, and active-field validity contrast relative to the characteristic dispersion of the communicated validity profile. Weak residuals retain partial availability through a confidence-weighted precision floor: coherent residuals in a distinct validity field remain available, whereas diffuse weak residuals receive little precision. Reliability is selectively diluted when active validity contrast falls relative to the full validity field, rather than merely because more cues are active. Count and reliability estimates enter a smooth precision-weighted competition: count controls choices when reliability is uncertain, whereas sufficiently precise coherent reliability can dominate count or resolve count ties. Before competition, the upper tail of inferred reliability precision is smoothly regularized, reflecting diminishing certainty about exceptionally strong identity bindings without bounding the signed reliability estimate itself. Broad continuous subject variation in count weighting, relative channel precision, and response precision produces persistent heterogeneity without discrete strategy classes.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Contrast-Calibrated Reliability-Precision Competition expects "
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
    count_magnitude = abs(count_difference)

    # This accumulator depends only on signed tally margin. Adding equally
    # many marks to opposing sides leaves both its signal and precision fixed.
    # Its relatively fast saturation flattens small-to-large margin growth.
    count_scale = float(parameters["count_scale"])
    count_signal = (
        float(parameters["count_weight"])
        * count_scale
        * np.tanh(count_difference / count_scale)
    )

    # A substantial baseline precision makes tallying available at ordinary
    # margins without making precision grow excessively with margin size.
    count_access = count_magnitude / (
        count_magnitude + float(parameters["count_precision_half"]) + 1e-12
    )
    count_precision = float(parameters["count_precision"]) * (
        float(parameters["count_precision_floor"])
        + (1.0 - float(parameters["count_precision_floor"])) * count_access
    )

    # Centering removes the validity component redundant with ordinary count.
    centered_validities = validities - float(np.mean(validities))
    signed_components = centered_validities * difference
    reliability_residual = float(np.sum(signed_components))
    residual_magnitude = abs(reliability_residual)
    gross_support = float(np.sum(np.abs(signed_components)))

    if gross_support > 1e-12:
        coherence = residual_magnitude / gross_support
        coherence = float(np.clip(coherence, 0.0, 1.0))
    else:
        coherence = 0.0

    # Active contrast is interpreted relative to the characteristic dispersion
    # of the communicated profile. This dimensionless reference distinguishes
    # a genuinely weakening active field from a mere change in measurement
    # units, while introducing no direct cue-count or display-size penalty.
    active = np.abs(difference) > 0.5
    if np.any(active):
        active_deviations = centered_validities[active]
        active_contrast = float(np.sqrt(np.mean(active_deviations ** 2)))
    else:
        active_contrast = 0.0

    profile_contrast = float(
        np.sqrt(np.mean(centered_validities ** 2))
    )
    if profile_contrast > 1e-12:
        relative_contrast = active_contrast / profile_contrast
    else:
        relative_contrast = 0.0

    contrast_confidence = relative_contrast / (
        relative_contrast + float(parameters["contrast_half"]) + 1e-12
    )
    contrast_confidence = float(np.clip(contrast_confidence, 0.0, 1.0))

    # Selective dilution follows relative active-field signal quality, not raw
    # feature count. The smooth cubic mapping makes deliberately declining
    # contrast diagnostic while retaining the nonzero accessibility floor.
    dilution_floor = float(parameters["dilution_floor"])
    selective_dilution = (
        dilution_floor
        + (1.0 - dilution_floor) * contrast_confidence ** 3
    )

    # Reliability precision has smooth magnitude-by-coherence curvature. Weak
    # residuals remain partly available, while coherent large residuals become
    # disproportionately trustworthy. The softened coherence transformation
    # prevents an unrealistically extreme coherent/diffuse endpoint.
    magnitude_confidence = residual_magnitude / (
        residual_magnitude + float(parameters["magnitude_half"]) + 1e-12
    )
    magnitude_confidence = magnitude_confidence ** float(
        parameters["magnitude_power"]
    )
    coherence_confidence = coherence ** float(parameters["coherence_power"])
    coherence_term = (
        float(parameters["coherence_floor"])
        + (1.0 - float(parameters["coherence_floor"]))
        * coherence_confidence
    )

    diagnostic_confidence = (
        magnitude_confidence * coherence_term * selective_dilution
    )

    # The weak-residual floor is itself confidence weighted. Small coherent
    # residuals in a distinctive active field remain accessible, whereas weak
    # diffuse residuals no longer receive the same unconditional precision.
    reliability_floor = float(parameters["reliability_floor"])
    floor_confidence = coherence_term * selective_dilution
    reliability_quality = (
        reliability_floor * floor_confidence
        + (1.0 - reliability_floor) * diagnostic_confidence
    )

    if residual_magnitude <= 1e-12:
        reliability_precision = 0.0
        reliability_signal = 0.0
    else:
        reliability_precision = (
            float(parameters["reliability_precision"])
            * reliability_quality
        )
        reliability_signal = (
            float(parameters["reliability_gain"])
            * reliability_residual
        )

        # Ordinary uncertain estimates are nearly linear in raw precision,
        # while the highly coherent, high-magnitude tail has diminishing
        # competitive leverage. The signed estimate remains uncompressed.
        reliability_precision_cap = float(
            parameters["reliability_precision_cap"]
        )
        reliability_precision = reliability_precision_cap * (
            1.0 - np.exp(-reliability_precision / reliability_precision_cap)
        )

    # Precision-weighted averaging implements smooth competition without a
    # notch, hard strategy switch, or explicit winner-enhancement operation.
    # It applies identically to congruent and conflicting channel directions.
    total_precision = count_precision + reliability_precision
    if total_precision <= 1e-12:
        integrated_signal = 0.0
    else:
        integrated_signal = float(parameters["competition_scale"]) * (
            count_precision * count_signal
            + reliability_precision * reliability_signal
        ) / total_precision

    # A final bounded decision representation supplies diminishing returns but
    # does not alter the precision estimates used to arbitrate the channels.
    decision_bound = float(parameters["decision_bound"])
    integrated_signal = decision_bound * np.tanh(
        integrated_signal / decision_bound
    )
    markedness_evidence = (
        float(parameters["response_precision"]) * integrated_signal
    )

    # Positive evidence means A carries greater adverse markedness and favors B.
    adverse_logits = np.array(
        [-0.5 * markedness_evidence, 0.5 * markedness_evidence], dtype=float
    )
    adverse_logits -= np.max(adverse_logits)
    adverse_probs = np.exp(adverse_logits)
    adverse_probs /= adverse_probs.sum()

    # Semantic polarity remains fixed over the subject run.
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
- count_weight: [1.25, 1.90]
- count_scale: [2.8, 4.2]
- count_precision: [0.35, 3.10]
- count_precision_floor: [0.52, 0.82]
- count_precision_half: [0.80, 2.00]
- reliability_gain: [1.8, 4.4]
- reliability_precision: [0.15, 3.10]
- reliability_precision_cap: [2.6, 3.4]
- reliability_floor: [0.10, 0.28]
- magnitude_half: [0.08, 0.30]
- magnitude_power: [1.00, 1.70]
- coherence_floor: [0.15, 0.35]
- coherence_power: [0.85, 1.65]
- contrast_half: [0.55, 1.25]
- dilution_floor: [0.12, 0.42]
- competition_scale: [1.45, 2.45]
- decision_bound: [3.4, 6.8]
- response_precision: [0.40, 2.10]
- adverse_polarity_confidence: [0.82, 0.99]
- lapse_rate: [0.0, 0.12]

`rationale`:
This is a one-factor edit of the accepted iteration-3 candidate. All count equations, reliability-quality calculations, relative-contrast normalization, cubic selective-dilution pathway, linear reliability estimate, response mapping, and existing parameter ranges are unchanged. The only mechanistic addition is a smooth upper-tail transform of raw reliability precision before competition: p_eff = p_cap * (1 - exp(-p_raw / p_cap)). Its relatively high, narrow cap leaves weak and ordinary reliability estimates close to their prior influence but regularizes the exceptionally precise coherent estimates implicated in the unstable Experiment 18 curvature. Unlike the rejected reliability-signal compression, this preserves the magnitude and sign of the reliability estimate; unlike rejected residual normalizations, it does not alter active-field contrast or introduce cue-count dependence. It should therefore retain the accepted Experiment 13 and 16 dilution effects while damping excessive high-magnitude competitive leverage in Experiments 8 and 18.

## LOSS TRAJECTORY (this propose-loop)
Aggregate loss across iterations of THIS propose-loop (lower = better, 0 = perfect, `+inf` = unscorable). The ACCEPTED / REJECTED tag is the loop's programmatic accept-gate decision: `loss < accepted_loss` -> ACCEPTED (becomes new base), else REJECTED (base unchanged). Use this together with the per-experiment values below to grade fit-quality AND your own past advice (see `## YOUR PRIOR CRITIQUES` below).

- iter 1: loss=0.1826 -> ACCEPTED
- iter 2: loss=0.1221 -> ACCEPTED
- iter 3: loss=0.0911 -> ACCEPTED
- iter 4: loss=0.1175 -> REJECTED
- iter 5: loss=0.1172 -> REJECTED
- iter 6: loss=0.1367 -> REJECTED
- iter 7: loss=0.1398 -> REJECTED
- iter 8: loss=0.1056 -> REJECTED
- iter 9 (current candidate you are grading): loss=0.1581 -> REJECTED
Running-best (last accepted) base: iter 3 at loss=0.0911.

## EXPERIMENTAL RESULTS (candidate vs real, per experiment)
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
**Candidate trajectory (this loop):**
  - iter 1: -0.3708 (var=0.0174) (Δ vs real +0.0648)
  - iter 2: -0.4007 (var=0.0291) (Δ vs real +0.0348)
  - iter 3: -0.3742 (var=0.0198) (Δ vs real +0.0613)
  - iter 4: -0.3743 (var=0.0212) (Δ vs real +0.0613)
  - iter 5: -0.3727 (var=0.0242) (Δ vs real +0.0628)
  - iter 6: -0.3795 (var=0.0232) (Δ vs real +0.0560)
  - iter 7: -0.3495 (var=0.0240) (Δ vs real +0.0860)
  - iter 8: -0.3892 (var=0.0264) (Δ vs real +0.0463)
  - iter 9 (current): -0.3935 (var=0.0236) (Δ vs real +0.0420)
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
- pi_10: -0.2765 (var=0.0166)

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
**Candidate trajectory (this loop):**
  - iter 1: 0.0000 (var=0.0000) (Δ vs real +0.0000)
  - iter 2: 0.0000 (var=0.0000) (Δ vs real +0.0000)
  - iter 3: 0.0000 (var=0.0000) (Δ vs real +0.0000)
  - iter 4: 0.0000 (var=0.0000) (Δ vs real +0.0000)
  - iter 5: 0.0000 (var=0.0000) (Δ vs real +0.0000)
  - iter 6: 0.0000 (var=0.0000) (Δ vs real +0.0000)
  - iter 7: 0.0000 (var=0.0000) (Δ vs real +0.0000)
  - iter 8: 0.0000 (var=0.0000) (Δ vs real +0.0000)
  - iter 9 (current): 0.0000 (var=0.0000) (Δ vs real +0.0000)
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
- pi_10: 0.0000 (var=0.0000)

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
**Candidate trajectory (this loop):**
  - iter 1: 0.7483 (var=0.0299) (Δ vs real +0.0117)
  - iter 2: 0.7517 (var=0.0210) (Δ vs real +0.0150)
  - iter 3: 0.6800 (var=0.0290) (Δ vs real -0.0567)
  - iter 4: 0.7183 (var=0.0350) (Δ vs real -0.0183)
  - iter 5: 0.6933 (var=0.0443) (Δ vs real -0.0433)
  - iter 6: 0.7583 (var=0.0217) (Δ vs real +0.0217)
  - iter 7: 0.7300 (var=0.0282) (Δ vs real -0.0067)
  - iter 8: 0.7300 (var=0.0332) (Δ vs real -0.0067)
  - iter 9 (current): 0.6983 (var=0.0289) (Δ vs real -0.0383)
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
- pi_10: 0.7550 (var=0.0171)

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
**Candidate trajectory (this loop):**
  - iter 1: -0.4954 (var=0.0308) (Δ vs real -0.0129)
  - iter 2: -0.7079 (var=0.0210) (Δ vs real -0.2254)
  - iter 3: -0.6700 (var=0.0257) (Δ vs real -0.1875)
  - iter 4: -0.6554 (var=0.0196) (Δ vs real -0.1729)
  - iter 5: -0.7042 (var=0.0336) (Δ vs real -0.2217)
  - iter 6: -0.6267 (var=0.0218) (Δ vs real -0.1442)
  - iter 7: -0.6596 (var=0.0236) (Δ vs real -0.1771)
  - iter 8: -0.6613 (var=0.0202) (Δ vs real -0.1788)
  - iter 9 (current): -0.6658 (var=0.0164) (Δ vs real -0.1833)
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
- pi_10: -0.4546 (var=0.0159)

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
**Candidate trajectory (this loop):**
  - iter 1: 0.2198 (var=0.0071) (Δ vs real -0.0108)
  - iter 2: 0.2441 (var=0.0148) (Δ vs real +0.0135)
  - iter 3: 0.2385 (var=0.0155) (Δ vs real +0.0079)
  - iter 4: 0.2101 (var=0.0214) (Δ vs real -0.0205)
  - iter 5: 0.2065 (var=0.0178) (Δ vs real -0.0241)
  - iter 6: 0.1881 (var=0.0138) (Δ vs real -0.0425)
  - iter 7: 0.1828 (var=0.0193) (Δ vs real -0.0478)
  - iter 8: 0.1907 (var=0.0152) (Δ vs real -0.0399)
  - iter 9 (current): 0.2023 (var=0.0221) (Δ vs real -0.0283)
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
- pi_10: 0.1437 (var=0.0061)

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
**Candidate trajectory (this loop):**
  - iter 1: 0.3319 (var=0.0041) (Δ vs real +0.2256)
  - iter 2: 0.2239 (var=0.0130) (Δ vs real +0.1177)
  - iter 3: 0.2156 (var=0.0130) (Δ vs real +0.1094)
  - iter 4: 0.2187 (var=0.0110) (Δ vs real +0.1125)
  - iter 5: 0.2098 (var=0.0167) (Δ vs real +0.1036)
  - iter 6: 0.2247 (var=0.0147) (Δ vs real +0.1185)
  - iter 7: 0.1953 (var=0.0123) (Δ vs real +0.0890)
  - iter 8: 0.2071 (var=0.0117) (Δ vs real +0.1009)
  - iter 9 (current): 0.1996 (var=0.0120) (Δ vs real +0.0934)
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
- pi_10: 0.1072 (var=0.0047)

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
**Candidate trajectory (this loop):**
  - iter 1: 0.0117 (var=0.0050) (Δ vs real -0.0275)
  - iter 2: 0.0517 (var=0.0151) (Δ vs real +0.0125)
  - iter 3: 0.1938 (var=0.0538) (Δ vs real +0.1546)
  - iter 4: 0.1429 (var=0.0431) (Δ vs real +0.1038)
  - iter 5: 0.1658 (var=0.0471) (Δ vs real +0.1267)
  - iter 6: 0.1700 (var=0.0489) (Δ vs real +0.1308)
  - iter 7: 0.2408 (var=0.0447) (Δ vs real +0.2017)
  - iter 8: 0.1217 (var=0.0409) (Δ vs real +0.0825)
  - iter 9 (current): 0.2021 (var=0.0499) (Δ vs real +0.1629)
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
- pi_10: 0.1137 (var=0.0106)

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
**Candidate trajectory (this loop):**
  - iter 1: 48.0000 (var=43.2384) (Δ vs real +76.0000)
  - iter 2: -12.0000 (var=31.6224) (Δ vs real +16.0000)
  - iter 3: 48.0000 (var=47.2384) (Δ vs real +76.0000)
  - iter 4: -86.0000 (var=48.0016) (Δ vs real -58.0000)
  - iter 5: 54.0000 (var=42.1136) (Δ vs real +82.0000)
  - iter 6: 56.0000 (var=53.9456) (Δ vs real +84.0000)
  - iter 7: 54.0000 (var=45.9536) (Δ vs real +82.0000)
  - iter 8: 14.0000 (var=48.1616) (Δ vs real +42.0000)
  - iter 9 (current): -50.0000 (var=35.5600) (Δ vs real -22.0000)
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
- pi_10: -36.0000 (var=40.1216)

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
**Candidate trajectory (this loop):**
  - iter 1: 0.8779 (var=0.4293) (Δ vs real +0.9186)
  - iter 2: -0.4628 (var=0.5152) (Δ vs real -0.4221)
  - iter 3: 0.1098 (var=0.4559) (Δ vs real +0.1505)
  - iter 4: 0.1172 (var=0.5462) (Δ vs real +0.1578)
  - iter 5: 1.0657 (var=0.7310) (Δ vs real +1.1064)
  - iter 6: -1.5602 (var=0.6591) (Δ vs real -1.5195)
  - iter 7: 0.6775 (var=0.4436) (Δ vs real +0.7182)
  - iter 8: -0.3921 (var=0.5381) (Δ vs real -0.3514)
  - iter 9 (current): 0.7494 (var=0.5072) (Δ vs real +0.7901)
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
- pi_10: -1.1434 (var=0.8580)

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
**Candidate trajectory (this loop):**
  - iter 1: 0.8725 (var=0.0047) (Δ vs real -0.0025)
  - iter 2: 0.8822 (var=0.0042) (Δ vs real +0.0072)
  - iter 3: 0.8806 (var=0.0038) (Δ vs real +0.0056)
  - iter 4: 0.8709 (var=0.0045) (Δ vs real -0.0041)
  - iter 5: 0.8684 (var=0.0036) (Δ vs real -0.0066)
  - iter 6: 0.8731 (var=0.0041) (Δ vs real -0.0019)
  - iter 7: 0.8503 (var=0.0041) (Δ vs real -0.0247)
  - iter 8: 0.8594 (var=0.0048) (Δ vs real -0.0156)
  - iter 9 (current): 0.8616 (var=0.0040) (Δ vs real -0.0134)
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
- pi_10: 0.8712 (var=0.0033)

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
**Candidate trajectory (this loop):**
  - iter 1: 0.8575 (var=0.0063) (Δ vs real +0.0133)
  - iter 2: 0.8546 (var=0.0050) (Δ vs real +0.0104)
  - iter 3: 0.8413 (var=0.0082) (Δ vs real -0.0029)
  - iter 4: 0.8642 (var=0.0067) (Δ vs real +0.0200)
  - iter 5: 0.8475 (var=0.0081) (Δ vs real +0.0033)
  - iter 6: 0.8633 (var=0.0047) (Δ vs real +0.0192)
  - iter 7: 0.8033 (var=0.0103) (Δ vs real -0.0408)
  - iter 8: 0.8408 (var=0.0092) (Δ vs real -0.0033)
  - iter 9 (current): 0.8492 (var=0.0065) (Δ vs real +0.0050)
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
- pi_10: 0.8442 (var=0.0041)

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
**Candidate trajectory (this loop):**
  - iter 1: 0.1366 (var=0.0020) (Δ vs real +0.0574)
  - iter 2: 0.0699 (var=0.0020) (Δ vs real -0.0094)
  - iter 3: 0.0665 (var=0.0048) (Δ vs real -0.0127)
  - iter 4: 0.0620 (var=0.0034) (Δ vs real -0.0173)
  - iter 5: 0.0586 (var=0.0041) (Δ vs real -0.0206)
  - iter 6: 0.0689 (var=0.0034) (Δ vs real -0.0104)
  - iter 7: 0.0599 (var=0.0026) (Δ vs real -0.0194)
  - iter 8: 0.0757 (var=0.0040) (Δ vs real -0.0035)
  - iter 9 (current): 0.0330 (var=0.0028) (Δ vs real -0.0462)
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
- pi_10: 0.0653 (var=0.0017)

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
**Candidate trajectory (this loop):**
  - iter 1: 0.0054 (var=0.0013) (Δ vs real -0.0261)
  - iter 2: 0.0211 (var=0.0018) (Δ vs real -0.0104)
  - iter 3: 0.0340 (var=0.0029) (Δ vs real +0.0025)
  - iter 4: 0.0404 (var=0.0026) (Δ vs real +0.0089)
  - iter 5: 0.0286 (var=0.0022) (Δ vs real -0.0029)
  - iter 6: 0.0370 (var=0.0032) (Δ vs real +0.0055)
  - iter 7: 0.0335 (var=0.0016) (Δ vs real +0.0020)
  - iter 8: 0.0381 (var=0.0016) (Δ vs real +0.0066)
  - iter 9 (current): 0.0391 (var=0.0031) (Δ vs real +0.0077)
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
- pi_10: 0.0266 (var=0.0025)

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
**Candidate trajectory (this loop):**
  - iter 1: 0.0110 (var=0.0050) (Δ vs real +0.0374)
  - iter 2: 0.0082 (var=0.0048) (Δ vs real +0.0346)
  - iter 3: -0.0103 (var=0.0053) (Δ vs real +0.0161)
  - iter 4: 0.0014 (var=0.0060) (Δ vs real +0.0278)
  - iter 5: -0.0082 (var=0.0028) (Δ vs real +0.0182)
  - iter 6: -0.0115 (var=0.0055) (Δ vs real +0.0149)
  - iter 7: -0.0060 (var=0.0057) (Δ vs real +0.0204)
  - iter 8: -0.0096 (var=0.0064) (Δ vs real +0.0168)
  - iter 9 (current): 0.0018 (var=0.0053) (Δ vs real +0.0282)
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
- pi_10: 0.0076 (var=0.0046)

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
**Candidate trajectory (this loop):**
  - iter 1: 0.0044 (var=0.0057) (Δ vs real -0.0011)
  - iter 2: -0.0083 (var=0.0067) (Δ vs real -0.0139)
  - iter 3: 0.0222 (var=0.0056) (Δ vs real +0.0167)
  - iter 4: 0.0022 (var=0.0080) (Δ vs real -0.0033)
  - iter 5: -0.0117 (var=0.0069) (Δ vs real -0.0172)
  - iter 6: -0.0078 (var=0.0044) (Δ vs real -0.0133)
  - iter 7: -0.0017 (var=0.0039) (Δ vs real -0.0072)
  - iter 8: -0.0006 (var=0.0084) (Δ vs real -0.0061)
  - iter 9 (current): -0.0100 (var=0.0095) (Δ vs real -0.0156)
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
- pi_10: 0.0028 (var=0.0075)

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
**Candidate trajectory (this loop):**
  - iter 1: -0.0791 (var=0.0066) (Δ vs real +1.5506)
  - iter 2: -0.4457 (var=0.0123) (Δ vs real +1.1840)
  - iter 3: -1.5950 (var=0.0095) (Δ vs real +0.0347)
  - iter 4: -0.7682 (var=0.0106) (Δ vs real +0.8615)
  - iter 5: -1.2229 (var=0.0065) (Δ vs real +0.4068)
  - iter 6: -0.7465 (var=0.0103) (Δ vs real +0.8832)
  - iter 7: -0.0268 (var=0.0078) (Δ vs real +1.6029)
  - iter 8: -1.1881 (var=0.0102) (Δ vs real +0.4416)
  - iter 9 (current): 0.5530 (var=0.0092) (Δ vs real +2.1826)
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
- pi_10: -0.2286 (var=0.0117)

### Experiment 17
**Design**
  A=[1, 1, 0, 0, 0, 0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 0, 0, 1, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 1, 1, 1]  B=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 1, 1, 1]  B=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 1, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 1, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    validities = np.asarray(
        [0.9, 0.9, 0.9, 0.9, 0.6, 0.6, 0.6, 0.6, 0.75, 0.75, 0.75],
        dtype=float
    )
    centered_validities = validities - float(np.mean(validities))

    def subject_score(df):
        count_aligned_choices = []

        for _, row in df.iterrows():
            a = np.asarray(row['option_a_ratings'], dtype=float)
            b = np.asarray(row['option_b_ratings'], dtype=float)
            if a.size != centered_validities.size or b.size != centered_validities.size:
                continue

            difference = a - b
            count_difference = float(np.sum(difference))
            reliability_residual = float(np.dot(centered_validities, difference))

            # Retain only trials on which count and centered reliability point
            # in opposite directions. This includes both A/B orientations and
            # all four combinations of count margin and residual magnitude.
            if count_difference * reliability_residual >= -1e-12:
                continue

            # Under the dominant adverse-mark interpretation, a positive count
            # favors response B (1), while a negative count favors A (0).
            response_sign = 1.0 if int(row['response']) == 1 else -1.0
            count_aligned_choices.append(np.sign(count_difference) * response_sign)

        if len(count_aligned_choices) == 0:
            return 0.0
        return float(np.mean(np.asarray(count_aligned_choices, dtype=float)))

    if 'subject_id' in data.columns and data['subject_id'].nunique() > 1:
        scores = [subject_score(g) for _, g in data.groupby('subject_id', sort=False)]
        return float(np.mean(scores)) if len(scores) else 0.0

    return float(subject_score(data))
```

**Observed (real) value:** 0.2400 (var=0.2111)
**Candidate trajectory (this loop):**
  - iter 1: -0.0700 (var=0.1016) (Δ vs real -0.3100)
  - iter 2: 0.3242 (var=0.0890) (Δ vs real +0.0842)
  - iter 3: 0.3300 (var=0.1105) (Δ vs real +0.0900)
  - iter 4: 0.3733 (var=0.1005) (Δ vs real +0.1333)
  - iter 5: 0.4625 (var=0.0789) (Δ vs real +0.2225)
  - iter 6: 0.3750 (var=0.1317) (Δ vs real +0.1350)
  - iter 7: 0.4542 (var=0.0927) (Δ vs real +0.2142)
  - iter 8: 0.3950 (var=0.0932) (Δ vs real +0.1550)
  - iter 9 (current): 0.4233 (var=0.1064) (Δ vs real +0.1833)
**Other theories' values on this metric (for reference):**
- pi_10: 0.2950 (var=0.0167)
- pi_9: 0.0667 (var=0.0681)
- pi_1: 0.6767 (var=0.0562)
- pi_2: -0.7175 (var=0.0274)
- pi_3: 0.4517 (var=0.0442)
- pi_4: 0.3925 (var=0.0285)
- pi_5: 0.2750 (var=0.0210)
- pi_6: 0.1800 (var=0.0368)
- pi_7: 0.5042 (var=0.0376)
- pi_8: 0.2700 (var=0.0644)

### Experiment 18
**Design**
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 0, 1, 0, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 1, 0, 1, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0]
  A=[0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 1, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 1, 0, 1, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 1, 0, 1, 0, 1, 0, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    support_to_cell = {
        2: (0, 0), 6: (0, 1),
        4: (1, 0), 12: (1, 1),
        8: (2, 0), 24: (2, 1),
        16: (3, 0), 48: (3, 1)
    }

    def subject_score(df):
        sums = np.zeros((4, 2), dtype=float)
        counts = np.zeros((4, 2), dtype=float)

        for _, row in df.iterrows():
            a = np.asarray(row["option_a_ratings"], dtype=float)
            b = np.asarray(row["option_b_ratings"], dtype=float)
            difference = a - b
            support = int(np.rint(np.sum(np.abs(difference))))
            location = support_to_cell.get(support)
            if location is None:
                continue

            magnitude_index, diffuse_index = location
            direction = float(np.sign(difference[0]))
            if direction == 0.0:
                nz = np.flatnonzero(difference)
                if nz.size == 0:
                    continue
                direction = float(np.sign(difference[nz[0]]))

            aligned = direction * (2.0 * float(row["response"]) - 1.0)
            sums[magnitude_index, diffuse_index] += aligned
            counts[magnitude_index, diffuse_index] += 1.0

        if np.any(counts == 0.0):
            return float("nan")

        means = sums / counts
        coherence_advantage = means[:, 0] - means[:, 1]

        # Each coefficient times its residual magnitude is 0.8 for the first
        # three levels and -2.4 for the last. Thus proportional coherence
        # effects cancel, whereas a coherence advantage that grows more than
        # proportionally with magnitude produces a large signed value.
        weights = np.array([8.0, 4.0, 2.0, -3.0], dtype=float)
        return float(np.dot(weights, coherence_advantage))

    if "subject_id" in data.columns:
        scores = [
            subject_score(group)
            for _, group in data.groupby("subject_id", sort=False)
        ]
        scores = np.asarray(scores, dtype=float)
        scores = scores[np.isfinite(scores)]
        if scores.size == 0:
            return float("nan")

        # The endpoint is accumulated curvature evidence in the experimental
        # cohort. On a one-subject slice this is exactly that subject's score,
        # allowing its population variance to be evaluated directly.
        return float(np.sum(scores))

    return subject_score(data)

```

**Observed (real) value:** -3.5000 (var=17.0837)
**Candidate trajectory (this loop):**
  - iter 1: 7.6667 (var=18.4487) (Δ vs real +11.1667)
  - iter 2: -41.3333 (var=13.3277) (Δ vs real -37.8333)
  - iter 3: 16.6667 (var=15.7478) (Δ vs real +20.1667)
  - iter 4: 24.1667 (var=15.3781) (Δ vs real +27.6667)
  - iter 5: 7.0000 (var=14.8948) (Δ vs real +10.5000)
  - iter 6: 26.6667 (var=18.6889) (Δ vs real +30.1667)
  - iter 7: 8.0000 (var=11.7055) (Δ vs real +11.5000)
  - iter 8: 46.3333 (var=13.8080) (Δ vs real +49.8333)
  - iter 9 (current): 6.6667 (var=11.1711) (Δ vs real +10.1667)
**Other theories' values on this metric (for reference):**
- pi_9: 40.6667 (var=13.9440)
- pi_10: -1.0000 (var=11.8396)
- pi_1: 12.1667 (var=6.0613)
- pi_2: -2.1667 (var=16.7487)
- pi_3: 0.8333 (var=8.2214)
- pi_4: -20.8333 (var=11.6125)
- pi_5: 15.5000 (var=11.3178)
- pi_6: 33.1667 (var=13.6105)
- pi_7: -21.6667 (var=19.0367)
- pi_8: -80.0000 (var=22.0700)

## YOUR PRIOR CRITIQUES (for this propose-loop)
Each block is one of YOUR previous critique iterations: the verdict you returned, the interpretation and rationale you wrote, and an **Outcome of your advice** line that says whether the candidate the proposer produced AFTER following your advice was ACCEPTED (your advice helped — its loss strictly beat the running-best) or REJECTED (your advice didn't help — the gate discarded the candidate). Use this self-history to (a) reinforce advice that was ACCEPTED, (b) avoid repeating advice that was REJECTED, and (c) detect your own oscillation across iterations.

### Iteration 1
Verdict: regenerate
Interpretation: The candidate is faithful to the prescribed Reliability-Precision Gated Competition family and fits many baseline effects well: Experiments 1, 3–5, 10–11, and 15 are close, while Experiment 2 is correctly classified. However, it is not yet experiment-invariant. There are major directional failures in Experiment 8 (48 versus -28), Experiment 17 (-0.070 versus 0.240), and Experiment 18 (7.67 versus -3.50), plus substantial overprediction in Experiment 6 (0.332 versus 0.106) and Experiment 12 (0.137 versus 0.079). The intended selective dilution is also much too weak in Experiment 16 (-0.079 versus -1.630) and Experiment 13 (0.005 versus 0.032), while producing an unwanted generic density trajectory in Experiment 9 (0.878 versus approximately zero). Thus the current precision geometry simultaneously under-dilutes the diagnostic manipulations and overreacts to generic active-set expansion. Between-subject variability is also generally too small, notably in Experiments 1, 3–6, 12–13, 17, and 18.
Rationale: Keep the prescribed two-channel precision-competition mechanism, but revise two in-family components. First, the concentration statistic sqrt(sum(x^2))/sum(abs(x)) behaves as a disguised active-cue-count penalty when contributions are similarly sized. That likely causes the spurious Experiment 9 trajectory, yet the high-contrast protection term then suppresses dilution where Experiments 13, 16, and 18 require it. Replace or strongly temper this raw concentration factor with an active-field signal-to-noise measure driven primarily by validity contrast and cancellation noise. Calibrate it so declining active validity contrast produces much stronger dilution in Experiment 16 and increasingly separates coherent from diffuse evidence at the largest magnitude in Experiment 18, without changing merely because more equivalent cues are active. In particular, weaken the current contrast-confidence bypass that drives selective_dilution toward one; it appears to protect large diffuse fields too strongly and yields the wrong curvature sign in Experiment 18. This should also downweight uncertain reliability in Experiment 17, where reliability currently defeats count rather than allowing the observed count advantage, and reduce the excessive reliability sensitivity in Experiment 6. Second, flatten the count-margin trajectory without abandoning the signed-count accumulator: use substantially faster smooth saturation of count_signal and/or a higher, flatter count-precision floor. The present count_scale of 6–10.5 and strongly margin-dependent precision make responses increase too much from small to large margins, contributing to the reversed Experiment 8 contrast and excessive Experiment 12 slope. Preserve enough response precision to retain the excellent large-margin fits in Experiments 3 and 10. Finally, broaden subject-level variation specifically in the count-to-reliability precision ratio and response precision, potentially allowing continuous correlation between them, because the current ranges generate much less heterogeneity than the human data. These are targeted recalibrations within the recommended mechanism family, not a change of theory.

**Outcome of your advice:** iter 1 candidate loss=0.1826 -> iter 2 candidate loss=0.1221 -> the gate marked it ACCEPTED.

### Iteration 2
Verdict: regenerate
Interpretation: The accepted revision substantially improves the aggregate fit and remains faithful to the prescribed Reliability-Precision Gated Competition family. The prior changes helped Experiments 1, 7, 8, 12, 13, 16, and 17, while preserving strong fits in Experiments 2, 3, 5, 10, and 11. Nevertheless, the model is not yet experiment-invariant. Most importantly, the magnitude-by-coherence curvature now massively overshoots in Experiment 18: the model moved from 7.67 to -41.33 when the human value is only -3.50. Experiment 16 still shows much too little contrast-dependent dilution (-0.446 versus -1.630), despite the excessive curvature elsewhere. Experiment 4 also regressed sharply (-0.708 versus -0.483), indicating excessive count control on its small-margin displays, while Experiment 6 still overpredicts reliability sensitivity (0.224 versus 0.106). Smaller residual misses include an overly negative trajectory in Experiment 9 (-0.463 versus -0.041), excessive count following in Experiment 17 (0.324 versus 0.240), and an insufficient Experiment 8 contrast (-12 versus -28). Between-subject variance remains too low in several important cases, especially Experiments 1, 3, 4, 17, and 18.
Rationale: Build on this accepted candidate, but decouple three precision effects that are currently being driven too strongly by the same multiplicative gate. First, soften the magnitude-by-coherence interaction to an intermediate setting between the two accepted iterations. The previous increase in coherence curvature successfully reversed Experiment 18's sign but overshot its magnitude by roughly an order of magnitude. Modestly raise the coherence floor and reduce or narrow the coherence and magnitude powers rather than reversing the whole prior change; retain a superlinear interaction, but make its high-magnitude endpoint much less extreme. Second, strengthen Experiment 16's selective dilution through the contrast pathway rather than through coherence. Normalize active contrast by a characteristic full-field validity dispersion or another density-invariant contrast reference, then tune the contrast half-saturation and dilution floor so the deliberately declining contrast in Experiment 16 is detected while equivalent active-cue additions remain nearly invariant. The current absolute active-RMS statistic still produces a nontrivial unwanted Experiment 9 trajectory, so simply increasing its exponent would likely worsen that failure. Third, make the weak-residual floor confidence-weighted rather than constant: allow small but coherent, high-contrast residuals to remain available, while keeping diffuse weak residuals strongly downweighted. This should let reliability moderate the overly dominant adverse count response in Experiment 4 without increasing the already excessive diffuse reliability slope in Experiment 6. Avoid globally weakening count, since Experiments 1, 3, and 10 support robust count evidence. Finally, broaden continuous variation in the count-to-reliability precision ratio, preferably with modest correlation to response precision, to approach the observed heterogeneity without changing the mechanism family.

**Outcome of your advice:** iter 2 candidate loss=0.1221 -> iter 3 candidate loss=0.0911 -> the gate marked it ACCEPTED.

### Iteration 3
Verdict: regenerate
Interpretation: The current candidate is faithful to the prescribed Reliability-Precision Gated Competition family, and the latest accepted revision materially improves aggregate fit. In particular, the normalized contrast gate now captures Experiment 16 almost exactly (-1.595 versus -1.630), while Experiments 2, 5, 10, 11, 12, 13, and 14 are also close. Generic density effects remain small in Experiments 14 and 15, as required. Nevertheless, the model is not yet experiment-invariant. Experiment 18 has again crossed to the wrong side of the curvature target: 16.67 versus -3.50, after the preceding candidate produced -41.33. This oscillation indicates threshold-sensitive rather than robust magnitude-by-coherence curvature. Experiment 8 also regressed from -12 to 48 against an observed -28, showing the wrong small-versus-large margin contrast. Reliability-related effects remain excessive in Experiment 6 (0.216 versus 0.106) and Experiment 7 (0.194 versus 0.039), while Experiment 4 remains too negative (-0.670 versus -0.483). Experiment 17 modestly overstates count following (0.330 versus 0.240). Between-subject variance is still too low in Experiments 1, 3, 4, and 17 despite broadening the parameter ranges.
Rationale: Build on this accepted candidate and preserve the successful relative-contrast pathway responsible for the strong Experiments 13 and 16 fits. The next adjustment should target the instability of reliability precision rather than further strengthening or weakening the same global coherence powers. Experiment 18 has oscillated from 7.67 to -41.33 to 16.67, so another unstructured exponent change is unlikely to be robust. Within the prescribed family, standardize residual magnitude by an active-field noise scale—such as the RMS or root-sum-square of the active centered-validity contributions—before applying magnitude confidence. Keep absolute residual magnitude informative, but prevent raw support growth from pushing observations abruptly across a nearly saturated precision gate. This should yield smoother, intermediate magnitude-by-coherence curvature near the human -3.5 target.

Separate the weak-residual floor's coherence gate from the diagnostic channel's nonzero coherence floor. Currently `floor_confidence = coherence_term * selective_dilution` gives diffuse evidence guaranteed access through `coherence_floor`; that likely contributes to the excessive diffuse reliability sensitivity in Experiments 6 and 7. Use near-zero floor access for genuinely diffuse residuals while retaining floor access for highly coherent, high-contrast weak residuals. This distinction can preserve reliability opposition on the coherent displays in Experiment 4 without globally increasing reliability precision.

Finally, undo only the latest broadening of count-precision and response-precision ranges, or constrain their joint distribution around the previous accepted setting. The count equations themselves were unchanged, yet Experiment 8 moved from -12 to 48 and Experiment 1 and 3 also regressed, implying that broad independent ranges destabilized pooled point estimates without reliably fixing heterogeneity. Retain the previously accepted fast count saturation, but use tighter or correlated continuous variation in count precision, reliability precision, and response precision. Do not alter the successful contrast normalization or introduce any raw cue-count penalty.

**Outcome of your advice:** iter 3 candidate loss=0.0911 -> iter 4 candidate loss=0.1175 -> the gate marked it REJECTED.

### Iteration 4
Verdict: regenerate
Interpretation: The current candidate remains faithful to the Reliability-Precision Gated Competition family, but it was rejected by the accept gate and is materially worse than the iteration-3 base. The root-sum-square magnitude standardization did not stabilize the critical curvature: Experiment 18 worsened from 16.67 to 24.17, still far from the observed -3.50. It also destroyed the previously excellent selective-dilution fit in Experiment 16, moving from -1.595 to -0.768 against -1.630. The altered floor modestly reduced the Experiment 7 excess, but substantial overprediction remains in Experiments 6 (0.219 versus 0.106) and 7 (0.143 versus 0.039), while Experiment 4 remains too negative (-0.655 versus -0.483), indicating excessive reliability control on moderate or diffuse displays. Experiment 17 instead shows excessive count control (0.373 versus 0.240), so a global reduction of reliability would be inappropriate. Experiment 8 also swung from 48 to -86 around a target of -28, confirming that the pooled margin effect is highly sensitive to the independently sampled precision ranges. Fits remain strong in Experiments 2, 3, 5, 10–13, and 15, but the failures in Experiments 16 and 18 defeat the intended experiment-invariant account.
Rationale: Build on the unchanged iteration-3 accepted base, not on this rejected modification. My previous recommendation to divide residual magnitude by active root-sum-square noise was rejected by the gate, so do not repeat that normalization or simply make it weaker. Preserve the iteration-3 relative-contrast pathway, which already fit Experiments 13 and 16. Instead, address Experiment 18 by changing how magnitude and coherence combine into precision: replace the threshold-sensitive multiplicative power product with a bounded smooth interaction in log-precision or logit-confidence space. Use separate main effects of magnitude, coherence, and contrast plus a modest bounded magnitude-by-coherence interaction. This retains the prescribed claim that coherent large residuals are especially diagnostic while preventing either factor from abruptly collapsing or saturating reliability precision as support increases.

Use the contrast/coherence geometry, rather than a global reliability reduction, to separate the remaining conflicts. Moderate-contrast or diffuse fields in Experiments 4, 6, and 7 need less reliability precision, whereas the coherent high-contrast displays in Experiment 13 and the conflict trials in Experiment 17 need reliability to remain available. A steeper but smoothly bounded contrast-confidence mapping, centered between those regimes, is preferable to removing floor access wholesale. Keep a small coherence-weighted floor, but avoid both a constant diffuse floor and the current near-zero diffuse-floor change as the sole corrective mechanism.

Finally, the Experiment 8 oscillation shows that simply tightening independent count, reliability, and response-precision ranges was not successful. Rather than widening or narrowing them again, parameterize continuous subjects through a shared latent channel-balance variable: let count and reliability precision vary inversely or constrain their ratio, with response precision only modestly correlated with overall channel precision. Tune its center between the iteration-2 and iteration-3 pooled behavior. This should reduce extreme pooled swings while retaining continuous heterogeneity. Do not alter the density-invariant count accumulator, add a raw cue-count penalty, or weaken the successful relative active-contrast normalization.

**Outcome of your advice:** iter 4 candidate loss=0.1175 -> iter 5 candidate loss=0.1172 -> the gate marked it REJECTED.

### Iteration 5
Verdict: regenerate
Interpretation: The candidate remains faithful to the prescribed Reliability-Precision Gated Competition family, but it was rejected by the accept gate and is worse than the iteration-3 base. Its new bounded log-precision interaction and shared channel-balance trait therefore did not provide a robust improvement. Major failures remain in Experiment 8 (54 versus -28), Experiment 9 (1.066 versus -0.041), Experiment 17 (0.463 versus 0.240), and Experiment 18 (7.0 versus -3.5). Reliability effects are still excessive in Experiments 6 and 7 (0.210 versus 0.106 and 0.166 versus 0.039), while Experiment 4 is too negative (-0.704 versus -0.483). The previously excellent selective-dilution fit in Experiment 16 also deteriorated from -1.595 in the accepted base to -1.223 versus -1.630. In contrast, Experiments 2, 5, 10, 11, and 13–15 remain well captured. The pattern indicates that moderate or diffuse reliability fields receive too much influence, whereas the model must preserve reliability on coherent, high-contrast displays. The shared inverse precision trait also compressed rather than repaired heterogeneity, especially in Experiment 17, where candidate variance is 0.079 against the observed 0.211.
Rationale: Build on the unchanged iteration-3 accepted base. My previous recommendation to introduce a bounded log-precision interaction and shared inverse channel-balance trait was rejected, so do not repeat either construction or make another broad change to subject-level precision ranges. Preserve the iteration-3 relative active-contrast normalization and cubic dilution pathway, which already fit Experiments 13 and 16.

Try a more localized reliability calibration: make the magnitude half-saturation depend smoothly on coherence, rather than adding another global interaction to log precision. For example, use an effective half-saturation of the form `magnitude_half_eff = magnitude_half * exp(k * (1 - coherence)^q)`, with a modest positive `k`. This is essentially neutral for highly coherent evidence but requires larger residuals before diffuse evidence gains diagnostic precision. It remains a smooth joint magnitude-by-coherence precision rule within the prescribed family. It should reduce excessive moderate/diffuse reliability sensitivity in Experiments 4, 6, 7, and 9 while preserving the coherent contrast effects in Experiments 13, 16, and 17. Because diffuse evidence would saturate later than coherent evidence, it also supplies a controllable magnitude-dependent coherence advantage for Experiment 18 without the threshold-sensitive exponent swings seen across earlier iterations. Tune `k` narrowly from zero and inspect the four Experiment-18 cells directly, aiming for mild rather than extreme curvature.

Make this a one-factor ablation first: retain the accepted count equations, floor formulation, independent continuous subject variation, and response mapping. Experiment 8 has oscillated dramatically under bundled precision-range and channel-balance changes, so it should not be chased with another population-level reparameterization until the reliability geometry is stable. If a residual Experiment-8 margin effect remains afterward, adjust the nonzero count-precision floor only slightly while compensating its overall scale, rather than widening subject ranges or changing count density invariance.

**Outcome of your advice:** iter 5 candidate loss=0.1172 -> iter 6 candidate loss=0.1367 -> the gate marked it REJECTED.

### Iteration 6
Verdict: regenerate
Interpretation: The candidate remains faithful to the prescribed Reliability-Precision Gated Competition family, but the new coherence-dependent magnitude delay was decisively rejected and worsened the aggregate loss from the iteration-3 best of 0.0911 to 0.1367. Its intended selective effect is not evident: Experiment 18 moves farther in the wrong direction (26.67 versus -3.50), Experiment 9 develops a very large spurious density trajectory (-1.56 versus -0.04), and the previously excellent Experiment 16 fit collapses from -1.595 to -0.747 versus -1.630. Experiment 8 also remains directionally wrong (56 versus -28). Reliability-related sensitivity is still excessive in Experiments 6 and 7 (0.225 versus 0.106 and 0.170 versus 0.039), while count following remains excessive in Experiment 17 (0.375 versus 0.240) and adverse count alignment is too strong in Experiment 4 (-0.627 versus -0.483). The candidate does retain strong fits in Experiments 2, 3, 10–13, and 14, but these successes do not offset the failures in the mechanism-defining tests. Heterogeneity is not uniformly deficient: variance is too low in Experiments 1, 3, 4, and 17, but too high in Experiments 7, 9, and 18, so another global widening of subject ranges is unlikely to help.
Rationale: Build on the unchanged iteration-3 accepted base. My previous recommendation to delay diffuse magnitude saturation was rejected by the gate, so remove `diffuse_magnitude_delay` rather than retuning it, and do not revisit the previously rejected root-sum-square normalization, bounded log-precision interaction, or shared channel-balance trait.

Try a different localized in-family adjustment: compress the reliability channel's signed estimate separately from its precision. The current `reliability_signal = reliability_gain * reliability_residual` allows raw residual sums to grow without bound across active support, even after precision has been gated. This can make moderate changes in gating produce large and unstable choice changes in Experiments 8, 9, and 18 and excessive slopes in Experiments 6 and 7. Replace the linear estimate with a smooth bounded transform such as `reliability_gain * signal_scale * tanh(reliability_residual / signal_scale)`. Calibrate `signal_scale` to the communicated validity-profile dispersion, not raw feature count or number of active cues, so the modification remains density-invariant. Keep residual magnitude itself in the precision calculation: magnitude should still increase confidence, while the posterior estimate no longer grows linearly without limit. Use a weak compression range first so coherent reliability remains strong enough for Experiments 11, 13, and 17.

This should be tested as a one-factor ablation on iteration 3, preserving its successful relative-contrast normalization, cubic selective dilution, count equations, and existing subject distributions. Inspect the four Experiment-18 cell means rather than tuning only its noisy aggregate contrast; the goal is mild curvature near -3.5, not another sign-changing endpoint. Do not broaden population ranges at this stage, because the current mixture of under- and over-dispersed variances shows that global heterogeneity is not the primary defect.

**Outcome of your advice:** iter 6 candidate loss=0.1367 -> iter 7 candidate loss=0.1398 -> the gate marked it REJECTED.

### Iteration 7
Verdict: regenerate
Interpretation: The candidate is faithful to the prescribed Reliability-Precision Gated Competition family, but it was rejected and is substantially worse than the iteration-3 accepted base. Bounding the reliability estimate did not stabilize the target effects. Experiment 18 remains on the wrong side of the curvature target (8.0 versus -3.5), while Experiment 8 remains directionally wrong (54 versus -28) and Experiment 9 shows an unwanted density trajectory (0.678 versus -0.041). More decisively, the change destroys the accepted base’s nearly exact Experiment 16 fit: -0.027 versus -1.630, compared with -1.595 at iteration 3. It also weakens coherent reliability where it should remain influential, lowering Experiment 11 from 0.841 to 0.803 and increasing count dominance in Experiment 17 from 0.330 to 0.454 versus 0.240. Reliability sensitivity nevertheless remains excessive in Experiments 6 and 7, and Experiment 4 remains too negative. Thus profile-scaled signal compression suppresses useful coherent evidence without selectively removing the weak or diffuse reliability influence responsible for the remaining errors. Fits in Experiments 2, 3, 10, 13, and 15 remain good, but they do not rescue the mechanism-defining failures.
Rationale: Build again on the unchanged iteration-3 accepted base. My most recent recommendation to compress the signed reliability estimate was rejected by the gate, so restore the accepted base’s linear reliability signal and do not retune the tanh scale. Also do not revisit the previously rejected residual normalization, coherence-dependent magnitude delay, log-precision interaction, shared channel-balance trait, or broad population-range changes.

The next test should isolate a smaller precision-floor correction that was previously confounded with the rejected root-sum-square normalization. Keep the diagnostic precision term, relative-contrast normalization, cubic dilution, magnitude gate, count channel, and response mapping exactly as in iteration 3. Change only the coherence dependence of the weak-residual floor. At present, `floor_confidence = coherence_term * selective_dilution` inherits the diagnostic channel’s relatively large `coherence_floor`, granting weak diffuse residuals substantial baseline precision. Give the floor its own modest coherence mapping, for example `floor_coherence = floor_access + (1-floor_access)*coherence**floor_power`, with a small but nonzero access range rather than the near-zero endpoint used in the bundled rejected attempt. An intermediate floor around 0.05–0.15 and a mild power near 1 should be tested narrowly; then use `floor_confidence = floor_coherence * selective_dilution`, leaving `coherence_term` unchanged in the magnitude-dependent diagnostic component.

This localized interpolation is supported by the earlier bundled result: reducing diffuse floor access moved Experiment 7 in the correct direction, but its benefit was obscured because residual normalization simultaneously ruined Experiment 16. Tested alone, it should reduce excessive weak/diffuse reliability sensitivity in Experiments 6 and 7 and may temper the diffuse cells driving Experiment 18, while preserving coherent reliability in Experiments 11, 13, 16, and the conflict trials of Experiment 17. Aim for a modest change rather than eliminating floor access. Do not alter subject distributions in this ablation; the variance errors are mixed in direction and are not the primary cause of the pooled failures.

**Outcome of your advice:** iter 7 candidate loss=0.1398 -> iter 8 candidate loss=0.1056 -> the gate marked it REJECTED.

### Iteration 8 (most recent)
Verdict: regenerate
Interpretation: The candidate remains faithful to the prescribed Reliability-Precision Gated Competition family, and the isolated floor-coherence change produced some local improvements relative to iteration 3, notably in Experiments 7 and 8. However, the accept gate rejected it because aggregate loss increased from 0.0911 to 0.1056. The defining curvature result is especially poor: Experiment 18 is 46.33 versus -3.50, substantially worse than iteration 3's 16.67. The previously excellent selective-dilution result in Experiment 16 also deteriorates from -1.595 to -1.188 versus -1.630. Other substantial misses remain in Experiment 4 (-0.661 versus -0.483), Experiment 6 (0.207 versus 0.106), Experiment 7 (0.122 versus 0.039), Experiment 8 (14 versus -28), and Experiment 17 (0.395 versus 0.240). Experiment 9 also departs from the required near-invariance (-0.392 versus -0.041). In contrast, Experiments 2, 3, and 10–15 are generally well captured. Between-subject variance remains too low in important conflict tests, especially Experiments 1, 4, and 17. Thus the theory family is viable, but this instantiation still converts increasing coherent residual magnitude into overly unstable reliability influence.
Rationale: Build on the unchanged iteration-3 accepted base. The latest isolated reduction of diffuse floor access was more promising than several earlier modifications, but it was still rejected and catastrophically worsened Experiment 18; therefore do not repeat or strengthen that floor-coherence adjustment. Also avoid the previously rejected residual normalization, reliability-signal compression, coherence-dependent magnitude delay, log-precision interaction, shared channel-balance trait, and broad population-range changes.

Try a new one-factor calibration of the competition stage: smoothly saturate the reliability precision passed into precision-weighted competition while leaving the linear reliability estimate and the iteration-3 quality calculation intact. For example, transform raw reliability precision as `p_eff = p_cap * (1 - exp(-p_raw / p_cap))`, which is approximately linear for uncertain evidence but prevents highly coherent, high-magnitude observations from continuing to gain disproportionate competitive leverage. This differs from the rejected signal compression: residual magnitude can still strengthen the reliability estimate and precision remains monotonic, but the upper precision tail is regularized. Tune the cap narrowly so that ordinary and weak reliability precision is nearly unchanged. That should preserve the accepted relative-contrast dilution in Experiment 16 and coherent effects in Experiments 11 and 13, while damping the high-magnitude coherence curvature driving Experiment 18 and potentially reducing the unstable margin contrast in Experiment 8. Inspect the four Experiment-18 cell probabilities directly and require that the cap move its contrast toward a small negative value without materially moving Experiment 16.

Keep the count accumulator, cubic relative-contrast dilution, semantic polarity, lapses, and subject distributions fixed for this ablation. Do not attempt to repair heterogeneity simultaneously: the current variance errors are mixed, and previous population-level changes destabilized pooled effects.

**Outcome of your advice:** iter 8 candidate loss=0.1056 -> CURRENT candidate loss=0.1581 -> the gate marked it REJECTED.

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of the model simulation results on existing experiments and how they do or do not support the proposed model/theory.
- verdict: Either 'regenerate' (regenerate a new model/theory) or 'continue' (keep the current model/theory).
- rationale: If verdict='regenerate', why the current predict / policy / parameter-ranges should be revised. If verdict='continue', a sketch of why the current theory should be kept.


## Response

```json
{
  "interpretation": "The current candidate remains faithful to the prescribed Reliability-Precision Gated Competition family, but it was decisively rejected: loss rose from the iteration-3 best of 0.0911 to 0.1581. The new precision cap is not functioning as an upper-tail-only regularizer. With raw reliability precision up to about 3.1 and a cap of 2.6\u20133.4, the exponential transform substantially compresses much of the ordinary range. The clearest consequence is Experiment 16, which flips from the iteration-3 near-match of -1.595 to 0.553 against -1.630. Experiment 12 also deteriorates to 0.033 versus 0.079, and count dominance becomes excessive in Experiment 17 (0.423 versus 0.240). Other major failures remain: Experiment 4 is too negative (-0.666 versus -0.483), Experiments 6 and 7 overstate reliability sensitivity (0.200 versus 0.106 and 0.202 versus 0.039), Experiment 9 has a spurious density trajectory (0.749 versus -0.041), and Experiment 18 still has the wrong curvature sign (6.67 versus -3.50). Experiment 8 happens to move closer (-50 versus -28), but its trajectory has been highly unstable and does not compensate for the destruction of the mechanism-defining Experiment-16 fit. Fits in Experiments 2, 5, 10, 11, and 13 remain good.",
  "verdict": "regenerate",
  "rationale": "Build on the unchanged iteration-3 accepted base. My previous recommendation to cap reliability precision was rejected and sharply worsened the fit, so remove the cap and do not retune it or replace it with another tail-compression variant. Likewise, do not revisit the already rejected residual normalization, reliability-signal compression, coherence-dependent magnitude delay, floor-coherence remapping, log-precision interaction, or population-range changes.\n\nA different in-family target is the treatment of channel conflict after precision weighting. The current model averages conflicting channel estimates but treats a near-cancellation as if it were as response-reliable as agreement at the same total precision. Add a small, smooth disagreement-dependent reduction in response precision, based jointly on the precision overlap and signed separation of the two channel estimates. It should activate only when both channels are nonzero and oppositely signed, for example through a smooth approximation to `max(0, -count_signal * reliability_signal)` multiplied by `4*p_count*p_rel/(p_count+p_rel)^2`; use this to attenuate the final response precision, not to change either estimate or select a winner. This remains smooth precision-gated competition and is not a notch or winner-enhancement mechanism.\n\nThat localized correction directly targets the shared pattern in Experiments 4 and 17, where conflict choices are too decisively count-aligned, and may stabilize the conflict-dependent Experiment-8 contrast by moving extreme cancellations toward chance. Crucially, gate it off when the count signal is zero so it leaves the iteration-3 tie-based reliability geometry\u2014and therefore the excellent Experiment-16 fit and the strong Experiments 11 and 13 results\u2014essentially unchanged. Test it as a one-factor ablation with a narrow penalty range. Do not tune this new term to Experiment 18 alone: that accumulated curvature metric has oscillated dramatically across simulations, while every attempted direct compression of high-magnitude reliability has worsened the accepted aggregate fit."
}
```

## Usage

```json
{
  "input_tokens": 62593,
  "output_tokens": 3021
}
```
