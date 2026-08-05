# feedback_iter_01

## System Prompt

You are a renowned cognitive scientist critiquing a freshly proposed candidate theory and model in the Decision Making (Binary Features) domain.

The candidate has been simulated on every previously run experiment. For each experiment you are shown the design, the metric, the value the metric takes on real (human / ground-truth) data, and the value it takes on the candidate's simulated data.

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

Propose a Weighted Additive (WADD) theory. Unlike Take The Best (which uses only the single best discriminating cue) and Tallying (which counts cues but ignores their validities), WADD assumes that decision-makers integrate all available information by taking the dot product of the option features and the cue validities. The choice is then made stochastically via a softmax over the expected values of the two options. This compensatory theory can explain why the population average sits exactly between the predictions of the two non-compensatory heuristics.


## CANDIDATE THEORY
Decision-makers integrate all available information using a Weighted Additive (WADD) strategy, but scale evidence using the log-odds of cue validities. Rather than relying on a single best cue or ignoring cue validities, individuals compute an overall expected value for each option by taking the dot product of the option's features and the log-odds transformed validities. This transformation naturally stretches higher validities, balancing the influence of a single strong cue against multiple weaker ones. Choice is then executed stochastically via a softmax function, subject to occasional random lapses.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("WADD expects a (2, n_features) stimulus.")
        
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    # Transform validities to log-odds to stretch higher validities
    # Clip to avoid division by zero or log(0) if validity is exactly 1.0
    val_clipped = np.clip(val, 0.0001, 0.9999)
    weights = np.log(val_clipped / (1.0 - val_clipped))
    
    # Calculate the weighted sum of features (expected value) for each option
    ev_a = np.dot(a, weights)
    ev_b = np.dot(b, weights)
    scores = np.array([ev_a, ev_b])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Numerically stable softmax
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    # Incorporate lapse rate
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))


`parameters`:
- beta: [0.0, 20.0]
- epsilon: [0.0, 0.5]
- validities: validities

`rationale`:
Following the critic's feedback, the raw validities are transformed into log-odds before computing the expected value. This transformation gives exponentially more weight to highly valid cues, allowing the WADD model to better balance between TTB-favored (single high-validity cue) and Tallying-favored (multiple lower-validity cues) options. This adjustment prevents the model from overly mimicking Tallying and pulls the predictions towards the empirical ~0.50 choice proportion observed in the pit-trials.

## LOSS TRAJECTORY (this propose-loop)
Aggregate loss across iterations of THIS propose-loop (lower = better, 0 = perfect, `+inf` = unscorable). The ACCEPTED / REJECTED tag is the loop's programmatic accept-gate decision: `loss < accepted_loss` -> ACCEPTED (becomes new base), else REJECTED (base unchanged). Use this together with the per-experiment values below to grade fit-quality AND your own past advice (see `## YOUR PRIOR CRITIQUES` below).

- iter 1: loss=0.4135 -> ACCEPTED
- iter 2 (current candidate you are grading): loss=0.1266 -> ACCEPTED
Running-best (last accepted) base: iter 2 at loss=0.1266.

## EXPERIMENTAL RESULTS (candidate vs real, per experiment)
### Experiment 1
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    matches = 0
    total = 0
    for a, b, r in zip(data['option_a_ratings'], data['option_b_ratings'], data['response']):
        for i in range(len(a)):
            if a[i] > b[i]:
                if r == 0:
                    matches += 1
                total += 1
                break
            elif b[i] > a[i]:
                if r == 1:
                    matches += 1
                total += 1
                break
    return float(matches / total) if total > 0 else 0.5
```

**Observed (real) value:** 0.4900 (var=0.0012)
**Candidate trajectory (this loop):**
  - iter 1: 0.2854 (var=0.0045) (Δ vs real -0.2046)
  - iter 2 (current): 0.5444 (var=0.0023) (Δ vs real +0.0544)
**Other theories' values on this metric (for reference):**
- pi_1: 0.8229 (var=0.0112)
- pi_2: 0.2154 (var=0.0039)

### Experiment 2
**Design**
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 0, 0, 0]  B=[0, 1, 1, 0]
  A=[0, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[0, 1, 1, 0]  B=[1, 0, 0, 1]
  A=[0, 0, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 0, 0, 1]  B=[0, 1, 1, 0]
  A=[0, 1, 1, 1]  B=[1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    match_tallying = 0
    total_strict = 0
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        tally_a = np.sum(a > b)
        tally_b = np.sum(b > a)
        if tally_a > tally_b:
            tally_pred = 0
        elif tally_b > tally_a:
            tally_pred = 1
        else:
            continue
        total_strict += 1
        if row['response'] == tally_pred:
            match_tallying += 1
    return match_tallying / total_strict if total_strict > 0 else 0.5
```

**Observed (real) value:** 0.5020 (var=0.0043)
**Candidate trajectory (this loop):**
  - iter 1: 0.8397 (var=0.0108) (Δ vs real +0.3377)
  - iter 2 (current): 0.3893 (var=0.0041) (Δ vs real -0.1127)
**Other theories' values on this metric (for reference):**
- pi_2: 0.8493 (var=0.0099)
- pi_1: 0.1607 (var=0.0132)

## YOUR PRIOR CRITIQUES (for this propose-loop)
Each block is one of YOUR previous critique iterations: the verdict you returned, the interpretation and rationale you wrote, and an **Outcome of your advice** line that says whether the candidate the proposer produced AFTER following your advice was ACCEPTED (your advice helped — its loss strictly beat the running-best) or REJECTED (your advice didn't help — the gate discarded the candidate). Use this self-history to (a) reinforce advice that was ACCEPTED, (b) avoid repeating advice that was REJECTED, and (c) detect your own oscillation across iterations.

### Iteration 1 (most recent)
Verdict: regenerate
Interpretation: The candidate implements the prescribed Weighted Additive (WADD) theory, but its predictions currently strongly mimic Tallying (Experiment 1 metric = 0.28 vs Tallying's 0.21; Experiment 2 metric = 0.84 vs Tallying's 0.85). The human data sits right around 0.50 for both metrics, indicating indifference or a population split on these specific pit-trials. Because raw validities often sum up to a much larger value for the option with more positive cues (e.g., 0.7 + 0.6 + 0.5 > 0.8), a raw dot-product heavily favors the Tallying option, preventing the model from capturing the 0.50 empirical indifference.
Rationale: To fix the over-reliance on the Tallying option within the WADD framework, transform the raw validities into a more appropriate evidence weight. A standard approach in cognitive models is to use the log-odds of the validities: `weights = np.log(val / (1.0 - val))`. This transformation stretches higher validities (making the best cue stronger) and shrinks validities near 0.5 (making weak cues less influential), which will bring the expected values of the TTB-favored and Tallying-favored options much closer together. Implement this log-odds transformation before taking the dot product.

**Outcome of your advice:** iter 1 candidate loss=0.4135 -> CURRENT candidate loss=0.1266 -> the gate marked it ACCEPTED.

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of the model simulation results on existing experiments and how they do or do not support the proposed model/theory.
- verdict: Either 'regenerate' (regenerate a new model/theory) or 'continue' (keep the current model/theory).
- rationale: If verdict='regenerate', why the current predict / policy / parameter-ranges should be revised. If verdict='continue', a sketch of why the current theory should be kept.


## Response

```json
{
  "interpretation": "The log-odds transformation of cue validities successfully pulled the WADD model away from pure Tallying and closer to the empirical ~0.50 indifference point. In Experiment 1, the match to TTB is now 0.544 (vs real 0.490), and in Experiment 2, the match to Tallying is 0.389 (vs real 0.502). The aggregate loss has improved significantly from 0.4135 to 0.1266. While there is a slight over-correction favoring the TTB option now, the current mechanism family and functional form (WADD with log-odds) provides an excellent foundation and captures the qualitative pattern well.",
  "verdict": "continue",
  "rationale": "The candidate has successfully implemented the log-odds transformation, which drastically improved the fit by balancing the evidence between the TTB and Tallying options. The loss is sufficiently low and the model captures the core empirical phenomenon across both experiments. No further structural changes are needed at this stage."
}
```

## Usage

```json
{
  "prompt_token_count": 4212,
  "candidates_token_count": 238,
  "total_token_count": 4918
}
```
