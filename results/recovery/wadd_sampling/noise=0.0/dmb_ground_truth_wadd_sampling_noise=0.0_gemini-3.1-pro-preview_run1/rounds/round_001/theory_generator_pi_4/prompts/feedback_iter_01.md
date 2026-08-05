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
- THEORY 1 = `pi_3`
- THEORY 2 = `pi_2`
- The recommendation below acts on THEORY 2 (= `pi_2`).

Replace the Tallying theory with a 'Rank-Weighted Additive' (or Validity-Ranked) theory. Instead of using the exact numerical validities (which allows top cues to dominate too much) or ignoring them completely (Tallying), this theory posits that decision-makers weight features by their ordinal rank of importance (e.g., weights of 5, 4, 3, 2, 1 for 5 features). This naturally compresses the validity scale, resulting in predictions that sit precisely between pure WADD and Tallying, matching the observed ~0.50 split in conflict trials.


## CANDIDATE THEORY
Non-linear Rank-Weighted Additive Strategy: Decision-makers evaluate options by integrating all available features, but weight them by a non-linear transformation of their ordinal rank of importance. By scaling the ranks by a power parameter gamma, the decision-maker can smoothly interpolate between pure Tallying (gamma=0, where all features are weighted equally) and steeper rank-based weighting (gamma>1). This flexibility allows the model to capture the observed ~0.50 split in conflict trials by balancing the sums of top versus bottom feature ranks appropriately.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    from scipy.stats import rankdata
    
    stim = np.asarray(stimulus, dtype=float)
    a, b = stim[0], stim[1]
    
    val = np.asarray(parameters["validities"], dtype=float)
    
    # rankdata assigns rank 1 to the smallest value. 
    # Thus, higher validity gets a proportionally higher integer rank (weight).
    gamma = float(parameters["gamma"])
    weights = rankdata(val) ** gamma
    
    score_a = np.dot(a, weights)
    score_b = np.dot(b, weights)
    scores = np.array([score_a, score_b])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()
    
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)


`parameters`:
- beta: [0.1, 20.0]
- epsilon: [0.0, 0.5]
- gamma: [0.0, 2.0]
- validities: validities

`rationale`:
Following the critic's diagnosis, the linear rank-weighting model still leaned too heavily toward WADD in conflict trials because the sum of the top ranks strictly dominated the bottom ranks. To address this, we introduce a non-linear scaling parameter `gamma` applied to the ranks (`weights = rankdata(val) ** gamma`). This minimal change allows the model to smoothly interpolate between Tallying (gamma=0) and steeper rank-weighting, providing the necessary flexibility to exactly match the ~0.50 split in conflict trials while remaining within the prescribed Rank-Weighted Additive family.

## LOSS TRAJECTORY (this propose-loop)
Aggregate loss across iterations of THIS propose-loop (lower = better, 0 = perfect, `+inf` = unscorable). The ACCEPTED / REJECTED tag is the loop's programmatic accept-gate decision: `loss < accepted_loss` -> ACCEPTED (becomes new base), else REJECTED (base unchanged). Use this together with the per-experiment values below to grade fit-quality AND your own past advice (see `## YOUR PRIOR CRITIQUES` below).

- iter 1: loss=0.2556 -> ACCEPTED
- iter 2 (current candidate you are grading): loss=0.1358 -> ACCEPTED
Running-best (last accepted) base: iter 2 at loss=0.1358.

## EXPERIMENTAL RESULTS (candidate vs real, per experiment)
### Experiment 1
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  A=[1, 1, 0, 1, 1]  B=[1, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    def get_ttb_choice(a, b):
        for i in range(len(a)):
            if a[i] > b[i]:
                return 0
            elif b[i] > a[i]:
                return 1
        return -1

    ttb_choices = [get_ttb_choice(a, b) for a, b in zip(data['option_a_ratings'], data['option_b_ratings'])]
    
    matches = (data['response'] == ttb_choices)
    return float(matches.mean())
```

**Observed (real) value:** 0.2758 (var=0.0200)
**Candidate trajectory (this loop):**
  - iter 1: 0.4135 (var=0.0016) (Δ vs real +0.1377)
  - iter 2 (current): 0.4158 (var=0.0458) (Δ vs real +0.1400)
**Other theories' values on this metric (for reference):**
- pi_1: 0.8415 (var=0.0092)
- pi_2: 0.1369 (var=0.0088)
- pi_3: 0.1548 (var=0.0068)

### Experiment 2
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    def is_ttb_match(row):
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        resp = row['response']
        for j in range(len(a)):
            if a[j] > b[j]:
                return resp == 0
            elif b[j] > a[j]:
                return resp == 1
        return False
        
    return float(data.apply(is_ttb_match, axis=1).mean())
```

**Observed (real) value:** 0.2825 (var=0.0090)
**Candidate trajectory (this loop):**
  - iter 1: 0.2787 (var=0.0053) (Δ vs real -0.0037)
  - iter 2 (current): 0.3038 (var=0.0298) (Δ vs real +0.0213)
**Other theories' values on this metric (for reference):**
- pi_2: 0.2248 (var=0.0047)
- pi_1: 0.8292 (var=0.0127)
- pi_3: 0.2298 (var=0.0054)

### Experiment 3
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    wadd_aligned = []
    for _, row in data.iterrows():
        a = tuple(row['option_a_ratings'])
        b = tuple(row['option_b_ratings'])
        resp = row['response']
        
        # Trial type 1: A has the 2 high-validity features, B has the 3 low-validity features
        if a == (1, 1, 0, 0, 0) and b == (0, 0, 1, 1, 1):
            wadd_aligned.append(1.0 if resp == 0 else 0.0)
        # Trial type 2: Flipped
        elif a == (0, 0, 1, 1, 1) and b == (1, 1, 0, 0, 0):
            wadd_aligned.append(1.0 if resp == 1 else 0.0)
            
    if len(wadd_aligned) == 0:
        return 0.5
    return float(np.mean(wadd_aligned))
```

**Observed (real) value:** 0.5083 (var=0.0801)
**Candidate trajectory (this loop):**
  - iter 1: 0.8950 (var=0.0081) (Δ vs real +0.3867)
  - iter 2 (current): 0.7083 (var=0.0964) (Δ vs real +0.2000)
**Other theories' values on this metric (for reference):**
- pi_3: 0.7700 (var=0.0188)
- pi_2: 0.1608 (var=0.0196)
- pi_1: 0.8375 (var=0.0172)

### Experiment 4
**Design**
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    tallying_consistent = 0
    total = 0
    for _, row in data.iterrows():
        a = tuple(row['option_a_ratings'])
        b = tuple(row['option_b_ratings'])
        resp = row['response']
        
        if a == (0, 0, 1, 1, 1) and b == (1, 1, 0, 0, 0):
            if resp == 0:
                tallying_consistent += 1
            total += 1
        elif a == (1, 1, 0, 0, 0) and b == (0, 0, 1, 1, 1):
            if resp == 1:
                tallying_consistent += 1
            total += 1
            
    if total == 0:
        return 0.5
    return tallying_consistent / total
```

**Observed (real) value:** 0.3446 (var=0.0522)
**Candidate trajectory (this loop):**
  - iter 1: 0.1231 (var=0.0097) (Δ vs real -0.2215)
  - iter 2 (current): 0.3346 (var=0.0904) (Δ vs real -0.0100)
**Other theories' values on this metric (for reference):**
- pi_2: 0.8769 (var=0.0076)
- pi_3: 0.2100 (var=0.0133)
- pi_1: 0.1569 (var=0.0100)

## YOUR PRIOR CRITIQUES (for this propose-loop)
Each block is one of YOUR previous critique iterations: the verdict you returned, the interpretation and rationale you wrote, and an **Outcome of your advice** line that says whether the candidate the proposer produced AFTER following your advice was ACCEPTED (your advice helped — its loss strictly beat the running-best) or REJECTED (your advice didn't help — the gate discarded the candidate). Use this self-history to (a) reinforce advice that was ACCEPTED, (b) avoid repeating advice that was REJECTED, and (c) detect your own oscillation across iterations.

### Iteration 1 (most recent)
Verdict: regenerate
Interpretation: The candidate successfully implements the Rank-Weighted Additive theory and was accepted by the gate, marking a solid improvement. However, the exact integer rank weighting (1, 2, 3, 4, 5) still leans too heavily toward WADD in conflict trials. In Experiment 3, the model's WADD alignment is 0.8950, whereas the empirical data shows a near 0.5083 split. Similarly, in Experiment 4, Tallying consistency is under-predicted (0.1231 vs 0.3446 observed). While rank-weighting compresses the validity scale relative to raw validities, the sum of the top two features (5+4=9) still strictly dominates the bottom three (3+2+1=6), leading to deterministic WADD-aligned choices when beta is high.
Rationale: To achieve the ~0.50 split in conflict trials while remaining strictly within the prescribed Rank-Weighted Additive family, introduce a non-linear scaling parameter to the ranks. Specifically, compute the weights as `weights = rankdata(val) ** gamma`, where `gamma` is a new free parameter sampled from `[0.0, 2.0]`. This allows the model to smoothly interpolate between pure Tallying (gamma=0), linear rank-weighting (gamma=1), and steeper weighting (gamma>1), giving it the flexibility to balance the sums of top vs. bottom ranks to exactly match the empirical conflict rates. Keep the rest of the mechanism identical.

**Outcome of your advice:** iter 1 candidate loss=0.2556 -> CURRENT candidate loss=0.1358 -> the gate marked it ACCEPTED.

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of the model simulation results on existing experiments and how they do or do not support the proposed model/theory.
- verdict: Either 'regenerate' (regenerate a new model/theory) or 'continue' (keep the current model/theory).
- rationale: If verdict='regenerate', why the current predict / policy / parameter-ranges should be revised. If verdict='continue', a sketch of why the current theory should be kept.


## Response

```json
{
  "interpretation": "The introduction of the non-linear scaling parameter `gamma` for the ranks was highly successful, dropping the aggregate loss from 0.2556 to 0.1358. The model now provides an excellent fit for Experiment 2 and Experiment 4, effectively balancing between Tallying and WADD to capture the intermediate conflict rates. While Experiments 1 and 3 still show a slight over-prediction of WADD-aligned / TTB-aligned choices, the overall fit across the four experiments is strong, and the proposed mechanism elegantly captures the behavioral phenomena within the Rank-Weighted Additive family.",
  "verdict": "continue",
  "rationale": "The candidate model successfully implements the prescribed Rank-Weighted Additive theory with non-linear scaling, achieving a significant reduction in aggregate loss and accurately capturing the target metrics in Experiments 2 and 4. The theory is conceptually sound, experiment-invariant, and fits the empirical data well enough to be shipped as the final version."
}
```

## Usage

```json
{
  "prompt_token_count": 5648,
  "candidates_token_count": 216,
  "total_token_count": 6947
}
```
