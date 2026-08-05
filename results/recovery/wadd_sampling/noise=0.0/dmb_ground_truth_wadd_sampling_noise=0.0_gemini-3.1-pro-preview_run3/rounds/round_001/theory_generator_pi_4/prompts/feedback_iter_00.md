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

Propose the 'Take The Best' (TTB) theory as a new competitor. In TTB, decision-makers do not integrate all information (unlike WADD) nor do they ignore validities (unlike Tallying). Instead, they search through features in descending order of cue validity, stopping at the first feature that discriminates between the two options, and choose the option favored by that feature. If no features discriminate, they guess. This provides a non-compensatory lexicographic alternative to WADD.


## CANDIDATE THEORY
Take The Best (TTB) Theory: Decision-makers evaluate options using a fast-and-frugal, non-compensatory lexicographic heuristic. Instead of integrating all available information (like WADD) or treating all cues equally (like Tallying), they search through features in descending order of cue validity. The search stops at the first feature that discriminates between the two options, and the option favored by that cue is chosen. Any lower-validity cues are completely ignored, and the magnitude of the difference on the discriminating cue does not matter. If no features discriminate, the decision-maker guesses uniformly. Choice stochasticity is modeled via a softmax over the binary TTB preference and an independent lapse rate.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    val = np.asarray(parameters["validities"], dtype=float)
    
    a, b = stim[0], stim[1]
    
    # Order cues by descending validity
    cue_order = np.argsort(-val, kind='stable')
    
    winner = -1
    for cue in cue_order:
        if a[cue] > b[cue]:
            winner = 0
            break
        elif b[cue] > a[cue]:
            winner = 1
            break
            
    if winner == -1:
        # No cues discriminate; pure guess
        return np.array([0.5, 0.5])
        
    scores = np.zeros(2)
    scores[winner] = 1.0
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax choice rule with max-subtraction for numerical stability
    z = beta * scores
    z_shifted = z - np.max(z)
    probs = np.exp(z_shifted) / np.sum(np.exp(z_shifted))
    
    # Incorporate lapse rate
    return (1.0 - epsilon) * probs + epsilon * np.array([0.5, 0.5])


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))


`parameters`:
- beta: [0.1, 20.0]
- epsilon: [0.0, 0.5]
- validities: validities

`rationale`:
Following the arbiter's instructions, this proposes the Take The Best (TTB) theory. TTB represents a lexicographic, non-compensatory decision process that directly contrasts with both WADD (which integrates all features) and Tallying (which ignores validities). By evaluating features strictly in order of their validity and stopping at the first discriminating cue, TTB captures the fast-and-frugal nature of human heuristic decision-making, where individuals often rely on a single good reason rather than exhaustive computation.

## LOSS TRAJECTORY (this propose-loop)
Aggregate loss across iterations of THIS propose-loop (lower = better, 0 = perfect, `+inf` = unscorable). The ACCEPTED / REJECTED tag is the loop's programmatic accept-gate decision: `loss < accepted_loss` -> ACCEPTED (becomes new base), else REJECTED (base unchanged). Use this together with the per-experiment values below to grade fit-quality AND your own past advice (see `## YOUR PRIOR CRITIQUES` below).

- iter 1 (current candidate you are grading): loss=0.5440 -> ACCEPTED
Running-best (last accepted) base: iter 1 at loss=0.5440.

## EXPERIMENTAL RESULTS (candidate vs real, per experiment)
### Experiment 1
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    A = np.array(data['option_a_ratings'].tolist())
    B = np.array(data['option_b_ratings'].tolist())
    
    diff = A - B
    is_diff = diff != 0
    has_diff = is_diff.any(axis=1)
    
    first_diff_idx = np.argmax(is_diff, axis=1)
    ttb_choice = np.where(diff[np.arange(len(diff)), first_diff_idx] == 1, 0, 1)
    
    a_wins = np.sum(diff == 1, axis=1)
    b_wins = np.sum(diff == -1, axis=1)
    
    tally_choice = np.full(len(data), -1)
    tally_choice[b_wins > a_wins] = 1
    tally_choice[a_wins > b_wins] = 0
    
    disagree = (has_diff) & (tally_choice != -1) & (ttb_choice != tally_choice)
    
    if np.sum(disagree) == 0:
        return 0.5
        
    responses = data['response'].values
    match = (responses[disagree] == ttb_choice[disagree])
    
    return float(np.mean(match))

```

**Observed (real) value:** 0.3450 (var=0.0120)
**Candidate (simulated) value:** 0.8633 (var=0.0062)
**Other theories' values on this metric (for reference):**
- pi_1: 0.8717 (var=0.0066)
- pi_2: 0.1389 (var=0.0079)
- pi_3: 0.3000 (var=0.0083)

### Experiment 2
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[1, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    tally_align = 0
    disagree_count = 0
    
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        a_tally = np.sum(a > b)
        b_tally = np.sum(b > a)
        
        ttb_winner = None
        for i in range(len(a)):
            if a[i] > b[i]:
                ttb_winner = 0
                break
            elif b[i] > a[i]:
                ttb_winner = 1
                break
                
        if a_tally > b_tally:
            tally_winner = 0
        elif b_tally > a_tally:
            tally_winner = 1
        else:
            tally_winner = None
            
        if ttb_winner is not None and tally_winner is not None and ttb_winner != tally_winner:
            disagree_count += 1
            if row['response'] == tally_winner:
                tally_align += 1
                
    if disagree_count == 0:
        return 0.5
    return float(tally_align / disagree_count)
```

**Observed (real) value:** 0.6887 (var=0.0239)
**Candidate (simulated) value:** 0.1259 (var=0.0114)
**Other theories' values on this metric (for reference):**
- pi_2: 0.8603 (var=0.0102)
- pi_1: 0.1425 (var=0.0106)
- pi_3: 0.6925 (var=0.0093)

### Experiment 3
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    wadd_consistent = 0
    total = 0
    
    for _, row in data.iterrows():
        a = tuple(row['option_a_ratings'])
        b = tuple(row['option_b_ratings'])
        resp = row['response']
        
        # Trial 1: WADD favors A, Tallying favors B
        if a == (1, 1, 0, 0, 0) and b == (0, 0, 1, 1, 1):
            if resp == 0:
                wadd_consistent += 1
            total += 1
        # Trial 2: WADD favors B, Tallying favors A
        elif a == (0, 0, 1, 1, 1) and b == (1, 1, 0, 0, 0):
            if resp == 1:
                wadd_consistent += 1
            total += 1
            
    if total == 0:
        return 0.5
    return wadd_consistent / total
```

**Observed (real) value:** 0.5667 (var=0.0904)
**Candidate (simulated) value:** 0.8478 (var=0.0171)
**Other theories' values on this metric (for reference):**
- pi_3: 0.5756 (var=0.0118)
- pi_2: 0.1522 (var=0.0118)
- pi_1: 0.8478 (var=0.0108)

### Experiment 4
**Design**
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[1, 0, 1, 1, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Identify critical dissociation trials where Tallying and WADD predict opposite choices.
    # Trial 1: A=[0, 0, 1, 1, 1], B=[1, 1, 0, 0, 0]
    # Tallying picks A (3 wins vs 2 wins), WADD picks B (1.65 vs 1.90)
    is_trial_1 = data['option_a_ratings'].apply(lambda x: list(x) == [0, 0, 1, 1, 1])
    
    # Trial 2: A=[1, 1, 0, 0, 0], B=[0, 0, 1, 1, 1]
    # Tallying picks B (2 wins vs 3 wins), WADD picks A (1.90 vs 1.65)
    is_trial_2 = data['option_a_ratings'].apply(lambda x: list(x) == [1, 1, 0, 0, 0])
    
    # Count Tallying-consistent choices
    t1_consistent = (data[is_trial_1]['response'] == 0).sum()
    t2_consistent = (data[is_trial_2]['response'] == 1).sum()
    
    total_relevant = is_trial_1.sum() + is_trial_2.sum()
    
    if total_relevant == 0:
        return 0.5
        
    return float((t1_consistent + t2_consistent) / total_relevant)
```

**Observed (real) value:** 0.3962 (var=0.0872)
**Candidate (simulated) value:** 0.1844 (var=0.0183)
**Other theories' values on this metric (for reference):**
- pi_2: 0.8544 (var=0.0089)
- pi_3: 0.4119 (var=0.0112)
- pi_1: 0.1437 (var=0.0131)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of the model simulation results on existing experiments and how they do or do not support the proposed model/theory.
- verdict: Either 'regenerate' (regenerate a new model/theory) or 'continue' (keep the current model/theory).
- rationale: If verdict='regenerate', why the current predict / policy / parameter-ranges should be revised. If verdict='continue', a sketch of why the current theory should be kept.


## Response

```json
{
  "interpretation": "The candidate faithfully implements the Take The Best (TTB) heuristic as requested by the arbiter. However, pure TTB diverges significantly from the observed empirical data across all experiments. For example, in Experiment 1, TTB predicts 0.8633 whereas human data is 0.3450; in Experiment 2, TTB predicts 0.1259 vs observed 0.6887. This suggests that human decision-makers do not exclusively use a strict non-compensatory lexicographic strategy, but likely rely on a mixture of strategies or a more compensatory approach (as seen in pi_3's superior fit). Nevertheless, as an implementation of the prescribed TTB mechanism, the model is correct and forms a necessary building block for the arbiter's competitive model set.",
  "verdict": "continue",
  "rationale": "The candidate faithfully executes the arbiter's recommendation to implement the Take The Best (TTB) theory. While the absolute fit to the human data is poor (demonstrating that humans do not strictly follow pure TTB), the mathematical implementation of the heuristic, the softmax choice rule, and the lapse rate are all correct and within the prescribed family. Since the goal for this specific model slot was to instantiate TTB as a competitor, it is ready to be shipped."
}
```

## Usage

```json
{
  "prompt_token_count": 5636,
  "candidates_token_count": 289,
  "total_token_count": 6616
}
```
