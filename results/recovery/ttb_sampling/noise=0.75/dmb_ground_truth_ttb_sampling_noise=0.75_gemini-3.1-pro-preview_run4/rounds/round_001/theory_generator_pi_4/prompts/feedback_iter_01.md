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

Propose a 'Strategy Selection' or 'Mixed Heuristic' theory. This theory should posit that decision makers do not use a single monolithic rule. Instead, a proportion of the population (or a probability on each trial) uses the non-compensatory Take The Best heuristic, while others (or on other trials) use a simple compensatory rule like Tallying (Equal Weight) or WADD. This would naturally explain the intermediate metrics in Experiments 1 and 4, while allowing the TTB component to drive the flat response observed in Experiment 2's specific compensatory setups. Alternatively, propose a threshold-based model where people only integrate lower-validity features if the difference on the primary feature is below a certain subjective threshold.


## CANDIDATE THEORY
Strategy Selection (Mixed Heuristic) with High TTB Prior

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Stimulus must be shape (2, n_features).")
    
    validities = np.asarray(parameters["validities"], dtype=float)
    
    # Take The Best (TTB) prediction
    order = np.argsort(validities)[::-1]
    chosen_ttb = -1
    for idx in order:
        if stim[0, idx] > stim[1, idx]:
            chosen_ttb = 0
            break
        elif stim[1, idx] > stim[0, idx]:
            chosen_ttb = 1
            break
            
    if chosen_ttb == 0:
        p_ttb_core = np.array([1.0, 0.0])
    elif chosen_ttb == 1:
        p_ttb_core = np.array([0.0, 1.0])
    else:
        p_ttb_core = np.array([0.5, 0.5])
        
    # Tallying prediction
    a_wins = float(np.sum(stim[0] > stim[1]))
    b_wins = float(np.sum(stim[1] > stim[0]))
    scores = np.array([a_wins, b_wins])
    
    beta = float(parameters["beta"])
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_tally_core = e / e.sum()
    
    # Strategy mixture
    p_ttb = float(parameters["p_ttb"])
    p_mixed = p_ttb * p_ttb_core + (1.0 - p_ttb) * p_tally_core
    
    # Response noise (lapse rate)
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
- p_ttb: [0.6, 1.0]
- beta: [0.1, 20.0]
- epsilon: [0.0, 0.5]
- validities: validities

`rationale`:
Following the critic's feedback, the previous candidate had too much compensatory (Tallying) influence in Experiment 4, leading to a positive sensitivity to sum differences instead of the observed flat response (-0.0133). By shifting the prior range of `p_ttb` strictly higher (from [0.0, 1.0] to [0.6, 1.0]), the model assumes that the majority of the population relies on the non-compensatory Take The Best heuristic most of the time, treating Tallying as a secondary/minority strategy. This reduces over-sensitivity to compensatory differences in Experiment 4 while still mixing in just enough Tallying to capture the intermediate responses in Experiments 1 and 2.

## LOSS TRAJECTORY (this propose-loop)
Aggregate loss across iterations of THIS propose-loop (lower = better, 0 = perfect, `+inf` = unscorable). The ACCEPTED / REJECTED tag is the loop's programmatic accept-gate decision: `loss < accepted_loss` -> ACCEPTED (becomes new base), else REJECTED (base unchanged). Use this together with the per-experiment values below to grade fit-quality AND your own past advice (see `## YOUR PRIOR CRITIQUES` below).

- iter 1: loss=0.1696 -> ACCEPTED
- iter 2 (current candidate you are grading): loss=0.2375 -> REJECTED
Running-best (last accepted) base: iter 1 at loss=0.1696.

## EXPERIMENTAL RESULTS (candidate vs real, per experiment)
### Experiment 1
**Design**
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    # Calculate the sum of features for options A and B
    a_sums = data['option_a_ratings'].apply(sum)
    b_sums = data['option_b_ratings'].apply(sum)
    
    # Isolate trials 1 and 2 where Tallying and WADD make opposite predictions.
    # These are uniquely identified by the total number of features across both options being 5.
    mask = (a_sums + b_sums) == 5
    if not mask.any():
        return 0.5
    
    # Tallying predicts the option with more features (lower sum means response 1, i.e., B)
    tally_predictions = (a_sums < b_sums).astype(int)
    
    # Calculate the proportion of choices on these trials that align with Tallying
    matches = (data.loc[mask, 'response'] == tally_predictions.loc[mask]).mean()
    return float(matches)

```

**Observed (real) value:** 0.3883 (var=0.0126)
**Candidate trajectory (this loop):**
  - iter 1: 0.4100 (var=0.0441) (Δ vs real +0.0217)
  - iter 2 (current): 0.2883 (var=0.0169) (Δ vs real -0.1000)
**Other theories' values on this metric (for reference):**
- pi_1: 0.8325 (var=0.0101)
- pi_2: 0.3258 (var=0.0439)
- pi_3: 0.3117 (var=0.0269)

### Experiment 2
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    a_str = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    b_str = data['option_b_ratings'].apply(lambda x: ''.join(map(str, x)))
    mask = (a_str == '11000') & (b_str == '00111')
    if not mask.any():
        return 0.0
    return float((data.loc[mask, 'response'] == 0).mean())
```

**Observed (real) value:** 0.5633 (var=0.0246)
**Candidate trajectory (this loop):**
  - iter 1: 0.5650 (var=0.0620) (Δ vs real +0.0017)
  - iter 2 (current): 0.7183 (var=0.0264) (Δ vs real +0.1550)
**Other theories' values on this metric (for reference):**
- pi_2: 0.5833 (var=0.0931)
- pi_1: 0.1467 (var=0.0174)
- pi_3: 0.7400 (var=0.0299)

### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    def ttb_predict(a, b):
        for i in range(len(a)):
            if a[i] > b[i]: return 0
            if b[i] > a[i]: return 1
        return 0.5
        
    preds = [ttb_predict(a, b) for a, b in zip(data['option_a_ratings'], data['option_b_ratings'])]
    resps = data['response'].values
    
    agreements = []
    for p, r in zip(preds, resps):
        if p == 0.5:
            agreements.append(0.5)
        else:
            agreements.append(1.0 if p == r else 0.0)
            
    return float(np.mean(agreements))
```

**Observed (real) value:** 0.5971 (var=0.0020)
**Candidate trajectory (this loop):**
  - iter 1: 0.5481 (var=0.0291) (Δ vs real -0.0490)
  - iter 2 (current): 0.7200 (var=0.0076) (Δ vs real +0.1229)
**Other theories' values on this metric (for reference):**
- pi_3: 0.7942 (var=0.0242)
- pi_2: 0.3625 (var=0.0141)
- pi_1: 0.2048 (var=0.0064)

### Experiment 4
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    b_sum = data['option_b_ratings'].apply(sum)
    a_sum = data['option_a_ratings'].apply(sum)
    diff = b_sum - a_sum
    
    high_diff = data[diff >= 2]['response']
    low_diff = data[diff <= 0]['response']
    
    if len(high_diff) == 0 or len(low_diff) == 0:
        return 0.0
        
    return float(high_diff.mean() - low_diff.mean())
```

**Observed (real) value:** -0.0133 (var=0.0090)
**Candidate trajectory (this loop):**
  - iter 1: 0.1912 (var=0.0196) (Δ vs real +0.2046)
  - iter 2 (current): 0.0967 (var=0.0129) (Δ vs real +0.1100)
**Other theories' values on this metric (for reference):**
- pi_2: 0.3296 (var=0.0398)
- pi_3: -0.0025 (var=0.0123)
- pi_1: 0.3579 (var=0.0194)

## YOUR PRIOR CRITIQUES (for this propose-loop)
Each block is one of YOUR previous critique iterations: the verdict you returned, the interpretation and rationale you wrote, and an **Outcome of your advice** line that says whether the candidate the proposer produced AFTER following your advice was ACCEPTED (your advice helped — its loss strictly beat the running-best) or REJECTED (your advice didn't help — the gate discarded the candidate). Use this self-history to (a) reinforce advice that was ACCEPTED, (b) avoid repeating advice that was REJECTED, and (c) detect your own oscillation across iterations.

### Iteration 1 (most recent)
Verdict: regenerate
Interpretation: The mixed heuristic (Strategy Selection) model provides a very strong fit for Experiments 1 and 2, accurately capturing the intermediate reliance on Tallying and TTB. However, in Experiment 4, the observed metric is -0.0133 (indicating flat sensitivity to the sum difference), while the candidate predicts 0.1912. This suggests that the compensatory (Tallying) component is still exerting too much influence when the difference in total features is large, pulling the model away from the observed flat response.
Rationale: The candidate was accepted and is our best base yet, but the fit on Experiment 4 can be improved. To reduce the over-sensitivity to compensatory differences in Experiment 4 without breaking Experiments 1 and 2, consider adjusting the mixture mechanism. Instead of a fixed probabilistic coin-flip on every trial, you might implement the arbiter's alternative suggestion: a threshold-based or contingent mixture. For example, decision makers might only use Tallying if the most valid feature is tied (or if the difference in validities is small). Alternatively, simply shift the prior range of `p_ttb` higher (e.g., [0.5, 1.0]) to suppress the Tallying influence, or make `p_ttb` an inverse function of the difference in the primary feature.

**Outcome of your advice:** iter 1 candidate loss=0.1696 -> CURRENT candidate loss=0.2375 -> the gate marked it REJECTED.

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of the model simulation results on existing experiments and how they do or do not support the proposed model/theory.
- verdict: Either 'regenerate' (regenerate a new model/theory) or 'continue' (keep the current model/theory).
- rationale: If verdict='regenerate', why the current predict / policy / parameter-ranges should be revised. If verdict='continue', a sketch of why the current theory should be kept.


## Response

```json
{
  "interpretation": "The attempt to fix Experiment 4 by forcing a high prior on `p_ttb` (range [0.6, 1.0]) was rejected by the accept gate because it severely degraded the fit on Experiments 1, 2, and 3. In Experiment 1, the match dropped to 0.288 (real = 0.388); in Experiment 2, it overshot to 0.718 (real = 0.563). This indicates that a simple fixed probabilistic mixture heavily skewed towards TTB is too rigid to capture the nuanced behavior across these experiments.",
  "verdict": "regenerate",
  "rationale": "Since shifting the uniform `p_ttb` range higher was rejected, we must abandon the fixed high-TTB prior approach. Instead, implement the arbiter's alternative suggestion: a contingent or threshold-based strategy selection. Specifically, build a model where the strategy depends on the stimulus state. For example, decision makers might use TTB when the most valid feature discriminates between the options (difference != 0), but switch to Tallying (or a mixture heavily favoring Tallying) when the most valid feature is tied. This allows TTB to dominate when a clear primary cue exists (explaining the flat response in Exp 4) while allowing compensatory integration to emerge when the primary cue is uninformative."
}
```

## Usage

```json
{
  "prompt_token_count": 5777,
  "candidates_token_count": 303,
  "total_token_count": 6673
}
```
