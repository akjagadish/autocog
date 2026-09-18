# feedback_iter_01

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
- THEORY 1 = `pi_1`
- THEORY 2 = `pi_2`
- The recommendation below acts on THEORY 1 (= `pi_1`).

Replace pi_1 with a reliability-weighted evidence-integration theory, retaining pi_2 as the equal-weight benchmark. The new theory should claim that people integrate all discriminating expert ratings, weighting each cue by its communicated validity, rather than stopping after one cue or counting every cue equally. A principled decision variable is E = sum_j w(v_j)*(A_j-B_j), with a monotone reliability transformation such as w(v)=log(v/(1-v)); choice probability can be generated by a lapse-contaminated sigmoid of beta*E. This mechanism naturally predicts graded confidence from the total strength of evidence. In Experiment 1, lower-validity cues collectively outweigh the top discriminating cue on the conflict trials, but reliability weighting makes that opposition less extreme than equal-weight tallying, potentially matching the observed 0.4033. In Experiment 2, increasingly numerous concordant cues generally increase total weighted evidence, producing the strong margin-dependent profile that TTB cannot express. Allow subject-level variation in sensitivity and lapse, but keep the validity-weighting rule task-invariant and avoid explaining the result as a mixture of deterministic TTB and tallying types. Future discriminating designs should independently manipulate the unweighted tally, the highest-validity cue, and the reliability-weighted sum; this would separate the proposed theory from both existing heuristics.


## CANDIDATE THEORY
Communicated-Reliability Accumulation theory proposes that people translate each expert's stated validity into a curved diagnostic log-odds weight and integrate the evidence supplied by every discriminating rating. For expert j, the subjective reliability weight is w_j = logit(v_j)^gamma, where gamma is modestly greater than one, and the net evidence favoring A is E = sum_j w_j(A_j-B_j). The weights are normalized by their mean so sensitivity remains comparable across experiments with different validity sets. Thus, a highly reliable expert contributes disproportionately more than a weak expert, but sufficiently numerous weaker experts can still collectively overturn a stronger cue. Choice sensitivity varies across people, while occasional lapses produce validity-independent guessing. Because accumulation continues across all cues, the theory predicts graded choice confidence as the amount and reliability of concordant evidence increase; no learning from choice history is assumed because the task provides no outcome feedback.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    # Communicated-Reliability Accumulation.
    # state has shape (2, n_features), with rows for options A and B.
    stimulus = np.asarray(state, dtype=np.float64)
    if stimulus.ndim != 2 or stimulus.shape[0] != 2:
        raise ValueError(
            f"Reliability accumulation expects shape (2, n_features); got {stimulus.shape}."
        )

    n_features = stimulus.shape[1]
    validities = np.asarray(parameters["validities"], dtype=np.float64)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} does not match n_features {n_features}."
        )

    # Clipping only protects the log-odds transform at its mathematical
    # endpoints. A validity of .5 consequently receives zero weight.
    v = np.clip(validities, 0.5, 1.0 - 1e-12)
    gamma = float(parameters["gamma"])
    reliability_weights = (np.log(v) - np.log1p(-v)) ** gamma

    # Normalize the overall weight scale while preserving relative cue
    # reliability and the sign of the accumulated evidence.
    positive_weights = reliability_weights[reliability_weights > 0.0]
    if positive_weights.size > 0:
        reliability_weights = reliability_weights / positive_weights.mean()

    a = stimulus[0]
    b = stimulus[1]
    evidence_for_a = float(np.dot(reliability_weights, a - b))

    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    # Symmetric logits make their difference beta * evidence_for_a, so the
    # core probability of A is sigmoid(beta * evidence_for_a).
    logits = np.array(
        [0.5 * beta * evidence_for_a, -0.5 * beta * evidence_for_a],
        dtype=np.float64,
    )
    logits -= np.max(logits)
    p_core = np.exp(logits)
    p_core /= p_core.sum()

    probabilities = (1.0 - epsilon) * p_core + epsilon * 0.5
    probabilities = np.clip(probabilities, 0.0, 1.0)
    probabilities /= probabilities.sum()
    return probabilities


`policy(probs) -> int`:
def policy(probs):
    probabilities = np.asarray(probs, dtype=np.float64)
    probabilities = np.clip(probabilities, 0.0, None)
    total = probabilities.sum()
    if not np.isfinite(total) or total <= 0.0:
        probabilities = np.ones(len(probabilities), dtype=np.float64) / len(probabilities)
    else:
        probabilities /= total
    return int(np.random.choice(len(probabilities), p=probabilities))


`parameters`:
- beta: [0.05, 6.0]
- epsilon: [0.0, 0.35]
- gamma: [1.2, 1.6]
- validities: validities

`rationale`:
This is a minimal extension of the accepted reliability-accumulation model. Raising log-odds weights to a modest exponent gives the most reliable cue greater leverage on Experiment 1 conflict trials, moving predictions toward the observed TTB-winner rate without introducing stopping or a mixture of heuristic types. Mean normalization leaves relative reliability intact but makes beta comparable across feature sets. Broadening beta from [0.2, 2.0] to [0.05, 6.0] permits substantially stronger and more heterogeneous margin sensitivity in Experiment 2, while the wider lapse range adds realistic between-subject variation. The validity-weighting rule remains the same across experiments and still integrates every discriminating cue.

## LOSS TRAJECTORY (this propose-loop)
Aggregate loss across iterations of THIS propose-loop (lower = better, 0 = perfect, `+inf` = unscorable). The ACCEPTED / REJECTED tag is the loop's programmatic accept-gate decision: `loss < accepted_loss` -> ACCEPTED (becomes new base), else REJECTED (base unchanged). Use this together with the per-experiment values below to grade fit-quality AND your own past advice (see `## YOUR PRIOR CRITIQUES` below).

- iter 1: loss=0.4593 -> ACCEPTED
- iter 2 (current candidate you are grading): loss=0.5416 -> REJECTED
Running-best (last accepted) base: iter 1 at loss=0.4593.

## EXPERIMENTAL RESULTS (candidate vs real, per experiment)
### Experiment 1
**Design**
  A=[1, 0, 1, 0, 1, 0, 1]  B=[0, 1, 1, 0, 1, 0, 1]
  A=[1, 1, 0, 0, 1, 0, 1]  B=[1, 0, 1, 0, 1, 0, 1]
  A=[0, 1, 1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 1, 0, 1]
  A=[1, 0, 1, 1, 0, 0, 1]  B=[1, 0, 1, 0, 1, 0, 1]
  A=[1, 0, 0, 1, 0, 1, 0]  B=[0, 1, 1, 1, 0, 1, 0]
  A=[1, 1, 0, 0, 0, 1, 0]  B=[1, 0, 1, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 0, 1, 0]  B=[0, 1, 1, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 0, 1, 0, 1]  B=[1, 0, 1, 0, 1, 0, 1]
  A=[1, 0, 1, 0, 1, 0, 1]  B=[1, 1, 0, 0, 1, 0, 1]
  A=[0, 1, 0, 1, 1, 0, 1]  B=[0, 1, 1, 0, 1, 0, 1]
  A=[1, 0, 1, 0, 1, 0, 1]  B=[1, 0, 1, 1, 0, 0, 1]
  A=[0, 1, 1, 1, 0, 1, 0]  B=[1, 0, 0, 1, 0, 1, 0]
  A=[1, 0, 1, 1, 1, 1, 0]  B=[1, 1, 0, 0, 0, 1, 0]
  A=[0, 1, 1, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0, 1, 0]
  A=[0, 1, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Choice rate for the Take-The-Best winner on TTB-vs-tally conflict trials."""
    aligned = []

    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=float)
        b = np.asarray(row["option_b_ratings"], dtype=float)
        diff = a - b

        # Validities are strictly descending in feature-index order, so the
        # first nonzero difference identifies the Take-The-Best winner.
        discriminating = np.flatnonzero(diff != 0)
        if discriminating.size == 0:
            continue
        ttb_winner = 0 if diff[discriminating[0]] > 0 else 1

        a_wins = int(np.sum(diff > 0))
        b_wins = int(np.sum(diff < 0))
        if a_wins == b_wins:
            continue
        tally_winner = 0 if a_wins > b_wins else 1

        # Retain only directional conflicts between the two heuristics.
        if ttb_winner != tally_winner:
            aligned.append(float(int(row["response"]) == ttb_winner))

    # The selected design always contains conflict trials; the fallback keeps
    # the function defined for any unexpected slice.
    return float(np.mean(aligned)) if aligned else 0.5
```

**Observed (real) value:** 0.4033 (var=0.0042)
**Candidate trajectory (this loop):**
  - iter 1: 0.2963 (var=0.0051) (Δ vs real -0.1071)
  - iter 2 (current): 0.4842 (var=0.0182) (Δ vs real +0.0808)
**Other theories' values on this metric (for reference):**
- pi_1: 0.8450 (var=0.0143)
- pi_2: 0.1350 (var=0.0104)

### Experiment 2
**Design**
  A=[1, 1, 1, 0, 1, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0, 1, 1, 0, 1]
  A=[0, 0, 0, 1, 0, 1, 1, 0, 1]  B=[1, 1, 1, 0, 1, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 1, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 0, 1, 1, 1, 0]  B=[1, 1, 1, 1, 1, 0, 0, 1, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 1]  B=[0, 0, 0, 0, 0, 0, 1, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 1, 0, 1]  B=[1, 1, 1, 1, 1, 1, 0, 0, 1]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Total log marginal-likelihood ratio favoring Tallying over TTB.
    # The parameter grids approximate uniform priors over the stated ranges.
    beta_grid = np.linspace(0.1, 20.0, 120)
    epsilon_grid = np.linspace(0.0, 0.5, 61)
    beta = beta_grid[:, None]
    epsilon = epsilon_grid[None, :]

    def logmeanexp(x):
        x = np.asarray(x, dtype=float)
        m = float(np.max(x))
        return float(m + np.log(np.mean(np.exp(x - m))))

    def subject_log_bf(df):
        margins = []
        correct = []

        for _, row in df.iterrows():
            a = np.asarray(row["option_a_ratings"], dtype=float)
            b = np.asarray(row["option_b_ratings"], dtype=float)
            a_wins = int(np.sum(a > b))
            b_wins = int(np.sum(b > a))
            margin = abs(a_wins - b_wins)

            if margin == 0:
                continue

            winner = 0 if a_wins > b_wins else 1
            margins.append(float(margin))
            correct.append(float(int(row["response"]) == winner))

        if len(margins) == 0:
            return np.nan

        margins = np.asarray(margins, dtype=float)
        correct = np.asarray(correct, dtype=float)
        tiny = 1e-12

        # TTB assigns the same winner probability to every non-tied pair.
        core_ttb = 1.0 / (1.0 + np.exp(-beta))
        p_ttb = (1.0 - epsilon) * core_ttb + epsilon * 0.5
        p_ttb = np.clip(p_ttb, tiny, 1.0 - tiny)
        n_correct = float(np.sum(correct))
        n_error = float(correct.size - n_correct)
        ll_ttb = n_correct * np.log(p_ttb) + n_error * np.log1p(-p_ttb)

        # Tallying's winner probability depends on the observed tally margin.
        ll_tally = np.zeros_like(p_ttb, dtype=float)
        for d, y in zip(margins, correct):
            x = beta * d
            core = np.where(x >= 0.0, 1.0 / (1.0 + np.exp(-x)), np.exp(x) / (1.0 + np.exp(x)))
            p = (1.0 - epsilon) * core + epsilon * 0.5
            p = np.clip(p, tiny, 1.0 - tiny)
            ll_tally += y * np.log(p) + (1.0 - y) * np.log1p(-p)

        log_ml_tally = logmeanexp(ll_tally)
        log_ml_ttb = logmeanexp(ll_ttb)
        return float(log_ml_tally - log_ml_ttb)

    if "subject_id" in data.columns:
        values = [subject_log_bf(g) for _, g in data.groupby("subject_id", sort=False)]
    else:
        values = [subject_log_bf(data)]

    values = np.asarray(values, dtype=float)
    values = values[np.isfinite(values)]
    if values.size == 0:
        return float("nan")

    # Independent participants contribute additive evidence. On a one-subject
    # slice this is simply that participant's log Bayes factor.
    return float(np.sum(values))

```

**Observed (real) value:** 89.1422 (var=7.5896)
**Candidate trajectory (this loop):**
  - iter 1: 21.1189 (var=0.3461) (Δ vs real -68.0233)
  - iter 2 (current): 3.2654 (var=0.0834) (Δ vs real -85.8768)
**Other theories' values on this metric (for reference):**
- pi_2: 1.9009 (var=0.0916)
- pi_1: 0.5503 (var=0.0488)

## YOUR PRIOR CRITIQUES (for this propose-loop)
Each block is one of YOUR previous critique iterations: the verdict you returned, the interpretation and rationale you wrote, and an **Outcome of your advice** line that says whether the candidate the proposer produced AFTER following your advice was ACCEPTED (your advice helped — its loss strictly beat the running-best) or REJECTED (your advice didn't help — the gate discarded the candidate). Use this self-history to (a) reinforce advice that was ACCEPTED, (b) avoid repeating advice that was REJECTED, and (c) detect your own oscillation across iterations.

### Iteration 1 (most recent)
Verdict: regenerate
Interpretation: The candidate moves decisively in the right direction relative to both benchmarks, but it does not yet capture the human pattern closely enough. In Experiment 1, its TTB-winner rate is 0.2963 versus 0.4033 observed. Thus, reliability weighting still gives the collection of weaker, tally-consistent cues too much influence relative to the highest-validity cue. In Experiment 2, it produces qualitatively appropriate margin dependence and greatly improves on pi_1 and pi_2, but the log Bayes factor is only 21.1189 versus 89.1422 observed. The model therefore substantially underproduces the strong within-subject increase in choice consistency with evidence margin. Its between-subject variance is also much too small (0.3461 versus 7.5896), indicating overly restricted individual differences in sensitivity or lapse.
Rationale: Retain the prescribed all-cue reliability-weighted accumulation mechanism, but recalibrate it. Introduce a modest task-invariant curvature parameter in the reliability transform, for example w(v) = logit(v)^gamma with gamma constrained near but above 1. This should raise the Experiment 1 TTB-winner rate by giving the most reliable cue somewhat more leverage without reverting to one-reason stopping. Separately, the current beta range of [0.2, 2.0] appears too narrow to generate Experiment 2's strong margin-dependent profile or its subject heterogeneity. Broaden sensitivity substantially, ideally after normalizing weights to keep beta comparable across feature sets, and permit a wider subject-level lapse range. The tuning target is joint: approximately 0.403 on Experiment 1 while markedly increasing Experiment 2's margin-based Bayes factor and between-subject variance. Do not replace accumulation with a TTB/tally mixture; the accepted improvement shows that the recommended mechanism family is promising, but its validity-weight curvature and individual-difference ranges are miscalibrated.

**Outcome of your advice:** iter 1 candidate loss=0.4593 -> CURRENT candidate loss=0.5416 -> the gate marked it REJECTED.

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of the model simulation results on existing experiments and how they do or do not support the proposed model/theory.
- verdict: Either 'regenerate' (regenerate a new model/theory) or 'continue' (keep the current model/theory).
- rationale: If verdict='regenerate', why the current predict / policy / parameter-ranges should be revised. If verdict='continue', a sketch of why the current theory should be kept.


## Response

```json
{
  "interpretation": "The candidate remains faithful to the prescribed all-cue reliability-weighted accumulation family, but this instantiation is worse than the accepted base and fails the joint experimental pattern. Experiment 1 moves past the target: the TTB-winner rate rises from 0.2963 to 0.4842, exceeding the observed 0.4033. Its variance also rises to 0.0182 versus 0.0042 observed, suggesting excessive subject-level dispersion. More importantly, Experiment 2 deteriorates sharply: the log Bayes factor falls from 21.1189 in the accepted base to 3.2654, far below 89.1422. The superlinear validity transform makes later, lower-validity concordant cues contribute too little, while the broadened beta range allows early sigmoid saturation. Together these changes flatten the margin-dependent probability profile that Experiment 2 requires. The wider lapse range can further cap high-margin accuracy. Thus, the previous recommendation to combine gamma substantially above one with broadly expanded beta and lapse ranges was rejected by the gate and should not be repeated.",
  "verdict": "regenerate",
  "rationale": "Build on the unchanged accepted base using a smaller, more targeted adjustment. Keep reliability accumulation, but constrain curvature much closer to linear log-odds weighting, such as gamma in approximately [1.03, 1.12], rather than [1.2, 1.6]. This should seek an Experiment 1 value between the base's 0.2963 and the rejected candidate's 0.4842. Do not retain the very broad beta range: use a moderate normalized-evidence temperature range near or narrower than the accepted base, chosen to keep low-margin choices uncertain while avoiding saturation before the largest Experiment 2 margins. Likewise, narrow epsilon rather than widening it, because large lapses suppress the high-margin consistency needed for the large Bayes factor. If extra subject variation is needed, place it chiefly in moderate beta variation without admitting extreme saturating values. The immediate joint targets are an Experiment 1 TTB rate near 0.403 with lower variance and an Experiment 2 Bayes factor above the accepted base's 21.1; a narrow grid search over slight curvature and moderate temperature is preferable to another simultaneous expansion of all parameter ranges."
}
```

## Usage

```json
{
  "input_tokens": 6307,
  "output_tokens": 1177
}
```
