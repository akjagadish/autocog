# feedback_iter_00

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

Replace the Tallying theory with a 'Strategy Mixture' theory. This new theory should posit that the population is heterogeneous, with a certain probability 'p_ttb' of a subject using Take-The-Best (or a validity-weighted strategy) and '1 - p_ttb' of using Tallying (Equal Weight). Alternatively, it could model a within-subject probabilistic switching between these two heuristics. This would naturally predict the intermediate (~0.5) aggregate values observed across conflict trials in all four experiments, which neither deterministic theory can capture alone.


## CANDIDATE THEORY
Strategy Mixture (Take-The-Best and Tallying): Decision-makers are heterogeneous in their strategy use, or probabilistically switch between strategies within-subject. Specifically, on any given choice, a subject has a probability 'p_ttb' of applying a one-reason lexicographic heuristic (Take-The-Best) and a probability '1 - p_ttb' of applying an equal-weight compensatory heuristic (Tallying). This mixture allows the model to predict intermediate choice probabilities in conflict trials where the two heuristics make opposite predictions, capturing the aggregate behavior across the population better than either deterministic strategy alone.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    a, b = stim[0], stim[1]
    n_features = stim.shape[1]
    
    val = np.asarray(parameters["validities"], dtype=float)
    
    # Take-The-Best (TTB) Prediction
    cue_order = np.argsort(-val, kind="stable").tolist()
    winner_ttb = None
    for j in cue_order:
        if a[j] > b[j]:
            winner_ttb = 0
            break
        if b[j] > a[j]:
            winner_ttb = 1
            break
            
    if winner_ttb is None:
        p_ttb_core = np.array([0.5, 0.5])
    else:
        scores_ttb = np.array([1.0, 0.0]) if winner_ttb == 0 else np.array([0.0, 1.0])
        beta_ttb = float(parameters["beta_ttb"])
        z_ttb = beta_ttb * (scores_ttb - np.max(scores_ttb))
        e_ttb = np.exp(z_ttb)
        p_ttb_core = e_ttb / np.sum(e_ttb)
        
    # Tallying Prediction
    a_wins = float(np.sum(a > b))
    b_wins = float(np.sum(b > a))
    scores_tally = np.array([a_wins, b_wins])
    
    beta_tally = float(parameters["beta_tally"])
    z_tally = beta_tally * (scores_tally - np.max(scores_tally))
    e_tally = np.exp(z_tally)
    p_tally_core = e_tally / np.sum(e_tally)
    
    # Mixture
    p_ttb_weight = float(parameters["p_ttb"])
    p_mixed = p_ttb_weight * p_ttb_core + (1.0 - p_ttb_weight) * p_tally_core
    
    # Lapse rate
    epsilon = float(parameters["epsilon"])
    p_final = (1.0 - epsilon) * p_mixed + epsilon * np.array([0.5, 0.5])
    
    return p_final


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))


`parameters`:
- p_ttb: [0.0, 1.0]
- beta_ttb: [0.1, 20.0]
- beta_tally: [0.1, 20.0]
- epsilon: [0.0, 0.5]
- validities: validities

`rationale`:
Following the arbiter's feedback, this theory explicitly models a probabilistic mixture of the Take-The-Best (TTB) and Tallying heuristics. Deterministic theories like pure TTB or pure Tallying fail to capture the intermediate aggregate choice probabilities (~0.5) observed in conflict trials across all four experiments. By introducing 'p_ttb' as the probability of using TTB on any given trial (with '1 - p_ttb' for Tallying), the model naturally predicts choices that lie between the extremes of either pure heuristic, better reflecting population heterogeneity or within-subject strategy switching.

## LOSS TRAJECTORY (this propose-loop)
Aggregate loss across iterations of THIS propose-loop (lower = better, 0 = perfect, `+inf` = unscorable). The ACCEPTED / REJECTED tag is the loop's programmatic accept-gate decision: `loss < accepted_loss` -> ACCEPTED (becomes new base), else REJECTED (base unchanged). Use this together with the per-experiment values below to grade fit-quality AND your own past advice (see `## YOUR PRIOR CRITIQUES` below).

- iter 1 (current candidate you are grading): loss=0.1673 -> ACCEPTED
Running-best (last accepted) base: iter 1 at loss=0.1673.

## EXPERIMENTAL RESULTS (candidate vs real, per experiment)
### Experiment 1
**Design**
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 1, 0, 0]  B=[1, 0, 1, 1]
  A=[1, 0, 1, 1]  B=[1, 1, 0, 0]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[0, 1, 0, 1]  B=[1, 0, 1, 0]
  A=[0, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[1, 0, 0, 1]  B=[0, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a = np.stack(data['option_a_ratings'].values)
    b = np.stack(data['option_b_ratings'].values)
    
    preds = []
    for i in range(len(data)):
        p = -1
        for j in range(4):
            if a[i, j] > b[i, j]:
                p = 0
                break
            elif b[i, j] > a[i, j]:
                p = 1
                break
        preds.append(p)
        
    preds = np.array(preds)
    return float(np.mean(data['response'] == preds))
```

**Observed (real) value:** 0.4850 (var=0.0051)
**Candidate (simulated) value:** 0.5302 (var=0.0416)
**Other theories' values on this metric (for reference):**
- pi_1: 0.8704 (var=0.0083)
- pi_2: 0.2606 (var=0.0039)
- pi_3: 0.4531 (var=0.0128)

### Experiment 2
**Design**
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 1, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[0, 0, 1, 0, 0]
  A=[1, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a = np.stack(data['option_a_ratings'].values)
    b = np.stack(data['option_b_ratings'].values)
    
    diff = a - b
    # The first index where features differ (since validities are strictly descending)
    first_diff_idx = np.argmax(diff != 0, axis=1)
    ttb_val = diff[np.arange(len(diff)), first_diff_idx]
    ttb_winner = np.where(ttb_val == 1, 0, 1)
    
    a_wins = np.sum(diff == 1, axis=1)
    b_wins = np.sum(diff == -1, axis=1)
    
    valid_mask = (a_wins != b_wins)
    tally_winner = np.where(a_wins > b_wins, 0, 1)
    
    # Focus only on trials where Tallying and Take The Best make strictly opposite predictions
    conflict_mask = valid_mask & (ttb_winner != tally_winner)
    
    if not np.any(conflict_mask):
        return 0.5
        
    responses = data['response'].values
    ttb_matches = np.sum(responses[conflict_mask] == ttb_winner[conflict_mask])
    
    return float(ttb_matches / np.sum(conflict_mask))

```

**Observed (real) value:** 0.3844 (var=0.0082)
**Candidate (simulated) value:** 0.5231 (var=0.0564)
**Other theories' values on this metric (for reference):**
- pi_2: 0.1103 (var=0.0071)
- pi_1: 0.8622 (var=0.0073)
- pi_3: 0.3056 (var=0.0217)

### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[0, 1, 0, 0, 1]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd
    
    ties = []
    for a, b in zip(data['option_a_ratings'], data['option_b_ratings']):
        a_w = sum(1 for x, y in zip(a, b) if x > y)
        b_w = sum(1 for x, y in zip(a, b) if y > x)
        ties.append(a_w == b_w)
        
    tie_data = data[ties]
    if len(tie_data) == 0:
        return 0.5
        
    # In tie trials, A is designed to have higher-validity features than B.
    # Tallying predicts 50% A (response == 0) because the tallies are tied.
    # WADD predicts > 50% A because A's WADD score is higher.
    return float(np.mean(tie_data['response'] == 0))
```

**Observed (real) value:** 0.5667 (var=0.0123)
**Candidate (simulated) value:** 0.6944 (var=0.0192)
**Other theories' values on this metric (for reference):**
- pi_3: 0.8056 (var=0.0141)
- pi_2: 0.4739 (var=0.0063)
- pi_1: 0.8617 (var=0.0094)

### Experiment 4
**Design**
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Project option_a_ratings to string for hashability and comparison
    a_str = data['option_a_ratings'].apply(lambda x: ''.join(map(str, (int(v) for v in x))))
    
    # Trial 1 is uniquely identified by Option A having exactly these ratings
    t1_mask = a_str == '00111'
    
    if t1_mask.sum() == 0:
        return 0.0
        
    # Return the proportion of times Option B was chosen on this trial
    return float(data.loc[t1_mask, 'response'].mean())
```

**Observed (real) value:** 0.5000 (var=0.0450)
**Candidate (simulated) value:** 0.4433 (var=0.0746)
**Other theories' values on this metric (for reference):**
- pi_2: 0.1400 (var=0.0182)
- pi_3: 0.7300 (var=0.0663)
- pi_1: 0.8367 (var=0.0158)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of the model simulation results on existing experiments and how they do or do not support the proposed model/theory.
- verdict: Either 'regenerate' (regenerate a new model/theory) or 'continue' (keep the current model/theory).
- rationale: If verdict='regenerate', why the current predict / policy / parameter-ranges should be revised. If verdict='continue', a sketch of why the current theory should be kept.


## Response

```json
{
  "interpretation": "The Strategy Mixture theory successfully captures the intermediate aggregate choice probabilities across all four experiments, which deterministic theories failed to do. The candidate's loss improved significantly and was accepted. However, looking closely at the specific values: in Experiment 2, the observed value is 0.3844, but the candidate predicts 0.5231. In Experiment 3, the observed value is 0.5667, but the candidate predicts 0.6944. Both of these suggest that the model is currently over-weighting Take-The-Best relative to Tallying. By lowering the probability of using Take-The-Best, the simulated metrics for Experiments 2 and 3 would shift closer to the observed human data.",
  "verdict": "regenerate",
  "rationale": "The Strategy Mixture mechanism is exactly right and should be kept intact. However, to achieve a tighter quantitative fit, adjust the parameter range for 'p_ttb'. Currently it is [0.0, 1.0], which centers the prior at 0.5. Since the empirical data across experiments consistently leans slightly more towards Tallying than Take-The-Best (implying a true p_ttb around 0.3 to 0.4), restrict the parameter range of 'p_ttb' to [0.1, 0.5]. This minor adjustment will force the optimizer to sample mixtures that slightly favor Tallying, pulling the predictions for Experiments 2 and 3 down to match the observed values perfectly."
}
```

## Usage

```json
{
  "prompt_token_count": 5374,
  "candidates_token_count": 336,
  "total_token_count": 6517
}
```
