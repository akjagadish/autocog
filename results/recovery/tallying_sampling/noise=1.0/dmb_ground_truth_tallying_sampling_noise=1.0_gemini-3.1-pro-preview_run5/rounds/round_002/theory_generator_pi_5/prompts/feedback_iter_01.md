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
- THEORY 1 = `pi_4`
- THEORY 2 = `pi_2`
- The recommendation below acts on THEORY 2 (= `pi_2`).

Propose a 'First-Feature Heuristic' (or 'Left-to-Right Reading Bias') theory. Instead of integrating all features (like WADD) or guessing entirely at random (like THEORY 1), subjects might minimize cognitive effort by only inspecting the very first feature in the array (the leftmost one). If one option has a 1 and the other a 0 on this first feature, they choose the option with the 1. If they tie on the first feature, the subject guesses. Because the first feature's validity and values vary across trials and don't necessarily align with the overall WADD score or TTB predictions, this heuristic would produce aggregate metric values near 0.5 for the current metrics, making it a strong and mechanistically distinct competitor to pure Random Guessing.


## CANDIDATE THEORY
First-Feature Heuristic (Left-to-Right Reading Bias) with High Lapse: Subjects minimize cognitive effort by inspecting only the first (leftmost) feature in the array. However, because this task is demanding and feedback is absent, subjects rely heavily on random guessing on the vast majority of trials, only occasionally applying the first-feature rule. This results in behavior that is near-random but retains a faint trace of the leftmost feature's influence.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"First-Feature Heuristic expects a (2, n_features) stimulus; got shape {stim.shape}.")
    
    a_first = stim[0, 0]
    b_first = stim[1, 0]
    
    epsilon = float(parameters["epsilon"])
    
    if a_first > b_first:
        p_core = np.array([1.0, 0.0])
    elif b_first > a_first:
        p_core = np.array([0.0, 1.0])
    else:
        p_core = np.array([0.5, 0.5])
        
    # Blend deterministic first-feature rule with a random lapse rate
    return (1.0 - epsilon) * p_core + epsilon * np.array([0.5, 0.5])

`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()  # Ensure valid probabilities.
    return int(np.random.choice(len(probabilities), p=probabilities))

`parameters`:
- epsilon: [0.8, 1.0]

`rationale`:
Following the critic's diagnosis, the First-Feature Heuristic mechanism was producing metric values too far from the ~0.5 observed in humans due to structural correlations in the experimental designs. To fix this while retaining the arbiter's prescribed mechanism, I constrained the lapse rate (epsilon) to [0.8, 1.0]. This ensures the model guesses randomly on most trials, diluting the extreme predictions of the first-feature rule and bringing the aggregate metrics down to the empirical ~0.5 baseline.

## LOSS TRAJECTORY (this propose-loop)
Aggregate loss across iterations of THIS propose-loop (lower = better, 0 = perfect, `+inf` = unscorable). The ACCEPTED / REJECTED tag is the loop's programmatic accept-gate decision: `loss < accepted_loss` -> ACCEPTED (becomes new base), else REJECTED (base unchanged). Use this together with the per-experiment values below to grade fit-quality AND your own past advice (see `## YOUR PRIOR CRITIQUES` below).

- iter 1: loss=0.4801 -> ACCEPTED
- iter 2 (current candidate you are grading): loss=0.1061 -> ACCEPTED
Running-best (last accepted) base: iter 2 at loss=0.1061.

## EXPERIMENTAL RESULTS (candidate vs real, per experiment)
### Experiment 1
**Design**
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[0, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[0, 0, 1, 1]  B=[0, 1, 0, 0]
  A=[1, 0, 0, 1]  B=[0, 1, 1, 0]
  A=[0, 1, 1, 0]  B=[1, 0, 0, 1]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[0, 0, 1, 1]  B=[1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_mat = np.stack(data['option_a_ratings'].values)
    b_mat = np.stack(data['option_b_ratings'].values)
    resp = data['response'].values
    
    # Calculate the difference between features
    diff = a_mat - b_mat
    
    # Find the index of the first discriminating cue (first non-zero difference)
    first_diff_idx = np.argmax(np.abs(diff), axis=1)
    
    ttb_preds = np.zeros(len(diff))
    for i in range(len(diff)):
        idx = first_diff_idx[i]
        if diff[i, idx] > 0:
            ttb_preds[i] = 0
        elif diff[i, idx] < 0:
            ttb_preds[i] = 1
        else:
            ttb_preds[i] = 0.5
            
    # Return the proportion of choices that align with the Take-The-Best prediction
    return float(np.mean(resp == ttb_preds))
```

**Observed (real) value:** 0.4883 (var=0.0032)
**Candidate trajectory (this loop):**
  - iter 1: 0.7006 (var=0.0124) (Δ vs real +0.2123)
  - iter 2 (current): 0.5385 (var=0.0028) (Δ vs real +0.0502)
**Other theories' values on this metric (for reference):**
- pi_1: 0.8669 (var=0.0066)
- pi_2: 0.4183 (var=0.0236)
- pi_3: 0.3554 (var=0.0111)
- pi_4: 0.4985 (var=0.0023)

### Experiment 2
**Design**
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    matches = 0
    valid_trials = 0
    for _, row in data.iterrows():
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        ttb_pred = -1
        for i in range(len(a)):
            if a[i] > b[i]:
                ttb_pred = 0
                break
            elif b[i] > a[i]:
                ttb_pred = 1
                break
        if ttb_pred != -1:
            if row['response'] == ttb_pred:
                matches += 1
            valid_trials += 1
    return matches / valid_trials if valid_trials > 0 else 0.5
```

**Observed (real) value:** 0.4963 (var=0.0022)
**Candidate trajectory (this loop):**
  - iter 1: 0.6527 (var=0.0138) (Δ vs real +0.1565)
  - iter 2 (current): 0.5321 (var=0.0033) (Δ vs real +0.0358)
**Other theories' values on this metric (for reference):**
- pi_2: 0.4096 (var=0.0238)
- pi_1: 0.8650 (var=0.0066)
- pi_3: 0.3056 (var=0.0127)
- pi_4: 0.4925 (var=0.0018)

### Experiment 3
**Design**
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_str = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    b_str = data['option_b_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    # Trial 1: A has 3 low-validity cues, B has 2 high-validity cues
    is_trial_1 = (a_str == '00111') & (b_str == '11000')
    # Trial 2: A has 2 high-validity cues, B has 3 low-validity cues
    is_trial_2 = (a_str == '11000') & (b_str == '00111')
    
    mask = is_trial_1 | is_trial_2
    if not mask.any():
        return 0.5
        
    # Tallying prefers the option with 3 positive features
    tally_correct_1 = is_trial_1 & (data['response'] == 0)
    tally_correct_2 = is_trial_2 & (data['response'] == 1)
    
    return float((tally_correct_1 | tally_correct_2).sum() / mask.sum())
```

**Observed (real) value:** 0.4833 (var=0.0088)
**Candidate trajectory (this loop):**
  - iter 1: 0.2092 (var=0.0219) (Δ vs real -0.2742)
  - iter 2 (current): 0.4383 (var=0.0098) (Δ vs real -0.0450)
**Other theories' values on this metric (for reference):**
- pi_3: 0.7875 (var=0.0299)
- pi_2: 0.4708 (var=0.1009)
- pi_1: 0.1333 (var=0.0089)
- pi_4: 0.4767 (var=0.0081)

### Experiment 4
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Trial 1 directly pits the two most valid features (Option A) 
    # against the three least valid features (Option B).
    # Tallying strictly prefers Option B (tally 3 vs 2).
    # WADD, on average, prefers Option A because the combined validity 
    # of the top 2 features outweighs the bottom 3.
    t1_mask = data['option_a_ratings'].apply(tuple) == (1, 1, 0, 0, 0)
    if not t1_mask.any():
        return 0.5
    
    # Return the proportion of times Option A was chosen
    return float((data.loc[t1_mask, 'response'] == 0).mean())
```

**Observed (real) value:** 0.4500 (var=0.0206)
**Candidate trajectory (this loop):**
  - iter 1: 0.7617 (var=0.0378) (Δ vs real +0.3117)
  - iter 2 (current): 0.5400 (var=0.0187) (Δ vs real +0.0900)
**Other theories' values on this metric (for reference):**
- pi_2: 0.4667 (var=0.0733)
- pi_3: 0.2683 (var=0.0392)
- pi_1: 0.8383 (var=0.0179)
- pi_4: 0.4750 (var=0.0231)

### Experiment 5
**Design**
  A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[1, 0, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    import numpy as np
    
    # Calculate the sum of features for options A and B
    sum_a = data['option_a_ratings'].apply(lambda x: sum(x))
    sum_b = data['option_b_ratings'].apply(lambda x: sum(x))
    
    # Identify extreme trials where one option completely dominates the other
    diff = sum_a - sum_b
    extreme_mask = diff.abs() == 5
    
    if extreme_mask.sum() == 0:
        return 0.5
        
    # Determine the 'correct' choice (0 for A, 1 for B)
    correct_responses = (diff[extreme_mask] < 0).astype(int)
    actual_responses = data.loc[extreme_mask, 'response']
    
    # Calculate the proportion of choices that align with the dominating option
    return float((actual_responses == correct_responses).mean())
```

**Observed (real) value:** 0.5050 (var=0.0055)
**Candidate trajectory (this loop):**
  - iter 1: 0.7442 (var=0.0334) (Δ vs real +0.2392)
  - iter 2 (current): 0.5375 (var=0.0090) (Δ vs real +0.0325)
**Other theories' values on this metric (for reference):**
- pi_4: 0.4708 (var=0.0099)
- pi_2: 0.8708 (var=0.0124)
- pi_1: 0.8658 (var=0.0109)
- pi_3: 0.7367 (var=0.0243)

### Experiment 6
**Design**
  A=[1, 1, 1, 1]  B=[0, 0, 0, 0]
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[1, 0, 0, 0]  B=[0, 1, 0, 0]
  A=[1, 0, 0, 1]  B=[0, 1, 1, 0]
  A=[0, 1, 0, 0]  B=[1, 0, 0, 0]
  A=[0, 1, 0, 1]  B=[1, 0, 1, 0]
  A=[0, 0, 1, 1]  B=[1, 1, 0, 0]
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[0, 0, 0, 0]  B=[1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    validities = np.array([0.9, 0.8, 0.6, 0.5])
    
    # Vectorized computation of WADD scores for Option A and B
    A = np.stack(data['option_a_ratings'].values)
    B = np.stack(data['option_b_ratings'].values)
    
    score_A = A.dot(validities)
    score_B = B.dot(validities)
    diff = score_A - score_B
    
    # Filter out trials where options have identical WADD scores
    mask = np.abs(diff) > 1e-5
    if not np.any(mask):
        return 0.5
        
    # Predicted response: 0 (Option A) if score_A > score_B, else 1 (Option B)
    predicted = (diff[mask] < 0).astype(int)
    actual = data['response'].values[mask]
    
    # Return the proportion of choices consistent with the WADD rule
    return float(np.mean(predicted == actual))
```

**Observed (real) value:** 0.5015 (var=0.0036)
**Candidate trajectory (this loop):**
  - iter 1: 0.6378 (var=0.0095) (Δ vs real +0.1363)
  - iter 2 (current): 0.5380 (var=0.0033) (Δ vs real +0.0365)
**Other theories' values on this metric (for reference):**
- pi_2: 0.6715 (var=0.0171)
- pi_4: 0.5078 (var=0.0034)
- pi_1: 0.7205 (var=0.0034)
- pi_3: 0.5968 (var=0.0058)

## YOUR PRIOR CRITIQUES (for this propose-loop)
Each block is one of YOUR previous critique iterations: the verdict you returned, the interpretation and rationale you wrote, and an **Outcome of your advice** line that says whether the candidate the proposer produced AFTER following your advice was ACCEPTED (your advice helped — its loss strictly beat the running-best) or REJECTED (your advice didn't help — the gate discarded the candidate). Use this self-history to (a) reinforce advice that was ACCEPTED, (b) avoid repeating advice that was REJECTED, and (c) detect your own oscillation across iterations.

### Iteration 1 (most recent)
Verdict: regenerate
Interpretation: The First-Feature Heuristic was proposed under the assumption that the first feature's value would not consistently align with the metrics across experiments, yielding aggregate values near 0.5. However, in the specific stimulus designs used (e.g., Experiment 5's extreme trials, or Experiment 4's focal trial), the first feature actually discriminates strongly and aligns with the metric's target choice. This causes the model's predictions to deviate significantly from 0.5 (e.g., 0.76 in Exp 4, 0.74 in Exp 5, 0.20 in Exp 3), whereas the human data is tightly clustered around 0.5 across all experiments.
Rationale: While the mechanism perfectly follows the arbiter's recommendation, the assumption that the first feature is uncorrelated with the metrics failed on these specific experimental designs. To bring the simulated values down to the ~0.5 observed in the human data while keeping the First-Feature mechanism intact, the model needs a much higher base rate of guessing. Constrain the `epsilon` (lapse rate) parameter range to heavily favor guessing (e.g., `[0.8, 1.0]`). This will preserve the prescribed mechanism but properly calibrate its effect size to match the empirical data.

**Outcome of your advice:** iter 1 candidate loss=0.4801 -> CURRENT candidate loss=0.1061 -> the gate marked it ACCEPTED.

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of the model simulation results on existing experiments and how they do or do not support the proposed model/theory.
- verdict: Either 'regenerate' (regenerate a new model/theory) or 'continue' (keep the current model/theory).
- rationale: If verdict='regenerate', why the current predict / policy / parameter-ranges should be revised. If verdict='continue', a sketch of why the current theory should be kept.


## Response

```json
{
  "interpretation": "The model simulation results show a significant improvement in fit across all experiments. By constraining the lapse rate (epsilon) to [0.8, 1.0], the First-Feature Heuristic's predictions were effectively diluted, bringing the aggregate metric values much closer to the empirical baseline of ~0.5. The deviations are now very small (mostly between 0.03 and 0.09), and the aggregate loss has dropped substantially from 0.4801 to 0.1061.",
  "verdict": "continue",
  "rationale": "The current theory and parameter ranges successfully capture the human data while remaining faithful to the arbiter's prescribed First-Feature Heuristic mechanism. The high lapse rate appropriately calibrates the model to the near-random empirical behavior. The model is good enough to proceed."
}
```

## Usage

```json
{
  "prompt_token_count": 7380,
  "candidates_token_count": 186,
  "total_token_count": 8023
}
```
