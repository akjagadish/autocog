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

Replace Tallying with the 'Take-The-Best' (TTB) heuristic. TTB posits that decision-makers search through features in descending order of their validity, stopping at the first feature that discriminates between the two options and choosing the option that wins on that feature. This provides a non-compensatory, lexicographic alternative to WADD that fundamentally differs from both unweighted Tallying and fully compensatory WADD.


## CANDIDATE THEORY
Take-The-Best (TTB) heuristic with subjective validity noise: Decision-makers search through features in descending order of their subjective validity, but their assessment of validity is noisy. On any given evaluation, they sample validities with some variance, sort features by these sampled validities, and stop at the first feature that discriminates between the two options. Response noise is modeled via a softmax over the resulting binary preference scores, plus an independent lapse rate. Averaging over multiple samples naturally smooths the aggregate predictions when validities are close.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("TTB expects a (2, n_features) stimulus.")
    
    validities = np.asarray(parameters["validities"], dtype=float)
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    sigma = float(parameters["sigma"])
    
    n_samples = 50
    avg_p_core = np.zeros(2)
    
    for _ in range(n_samples):
        noisy_v = validities + np.random.normal(0, sigma, size=validities.shape)
        order = np.argsort(noisy_v)[::-1]
        
        scores = np.zeros(2)
        # Search for the first discriminating feature
        for idx in order:
            if stim[0, idx] > stim[1, idx]:
                scores[0] = 1.0
                break
            elif stim[1, idx] > stim[0, idx]:
                scores[1] = 1.0
                break
                
        # Softmax over the scores
        z = beta * (scores - scores.max())
        e = np.exp(z)
        p_core = e / e.sum()
        avg_p_core += p_core
        
    avg_p_core /= n_samples
    
    n_opts = avg_p_core.shape[0]
    return (1.0 - epsilon) * avg_p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)


`parameters`:
- beta: [0.1, 20.0]
- epsilon: [0.0, 0.5]
- sigma: [0.0, 2.0]
- validities: validities

`rationale`:
Following the critic's advice, we introduce a `sigma` parameter to add Gaussian noise to the subjective validities. We sample these noisy validities multiple times (50 iterations for stability) per trial, apply the strict TTB stopping rule for each sample, and average the resulting choice probabilities. This softens the deterministic feature ordering of TTB and captures subjective uncertainty or individual differences in feature validities, preventing extreme deterministic predictions when validities are close.

## LOSS TRAJECTORY (this propose-loop)
Aggregate loss across iterations of THIS propose-loop (lower = better, 0 = perfect, `+inf` = unscorable). The ACCEPTED / REJECTED tag is the loop's programmatic accept-gate decision: `loss < accepted_loss` -> ACCEPTED (becomes new base), else REJECTED (base unchanged). Use this together with the per-experiment values below to grade fit-quality AND your own past advice (see `## YOUR PRIOR CRITIQUES` below).

- iter 1: loss=0.4991 -> ACCEPTED
- iter 2 (current candidate you are grading): loss=0.1143 -> ACCEPTED
Running-best (last accepted) base: iter 2 at loss=0.1143.

## EXPERIMENTAL RESULTS (candidate vs real, per experiment)
### Experiment 1
**Design**
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    a_tuples = data['option_a_ratings'].apply(tuple)
    
    t1_mask = a_tuples == (0, 0, 1, 1, 1)
    t2_mask = a_tuples == (1, 1, 0, 0, 0)
    
    t1_tally_match = (data.loc[t1_mask, 'response'] == 0).sum()
    t2_tally_match = (data.loc[t2_mask, 'response'] == 1).sum()
    
    total = t1_mask.sum() + t2_mask.sum()
    if total == 0:
        return 0.5
        
    return float((t1_tally_match + t2_tally_match) / total)
```

**Observed (real) value:** 0.4863 (var=0.0089)
**Candidate trajectory (this loop):**
  - iter 1: 0.1425 (var=0.0144) (Δ vs real -0.3438)
  - iter 2 (current): 0.4131 (var=0.0240) (Δ vs real -0.0731)
**Other theories' values on this metric (for reference):**
- pi_1: 0.8300 (var=0.0116)
- pi_2: 0.4738 (var=0.0772)

### Experiment 2
**Design**
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Trial 1 pits an option with 3 low-validity features (A) against an option with 2 high-validity features (B).
    # Tallying strictly prefers A (3 wins vs 2 wins), leading to a response near 0.
    # WADD tends to prefer B, because the sum of the top 2 validities (0.9 + 0.8 = 1.7) 
    # is greater than the sum of the bottom 3 (0.6 + 0.5 + 0.5 = 1.6), leading to a higher rate of response 1.
    mask = data['option_a_ratings'].apply(lambda x: list(x) == [0, 0, 1, 1, 1])
    if mask.sum() == 0:
        return 0.0
    return float(data.loc[mask, 'response'].mean())
```

**Observed (real) value:** 0.5067 (var=0.0118)
**Candidate trajectory (this loop):**
  - iter 1: 0.8492 (var=0.0085) (Δ vs real +0.3425)
  - iter 2 (current): 0.4883 (var=0.0310) (Δ vs real -0.0183)
**Other theories' values on this metric (for reference):**
- pi_2: 0.4108 (var=0.0539)
- pi_1: 0.1617 (var=0.0119)

## YOUR PRIOR CRITIQUES (for this propose-loop)
Each block is one of YOUR previous critique iterations: the verdict you returned, the interpretation and rationale you wrote, and an **Outcome of your advice** line that says whether the candidate the proposer produced AFTER following your advice was ACCEPTED (your advice helped — its loss strictly beat the running-best) or REJECTED (your advice didn't help — the gate discarded the candidate). Use this self-history to (a) reinforce advice that was ACCEPTED, (b) avoid repeating advice that was REJECTED, and (c) detect your own oscillation across iterations.

### Iteration 1 (most recent)
Verdict: regenerate
Interpretation: The Take-The-Best (TTB) model predicts extreme deterministic choices when the highest-validity feature discriminates. In Experiment 1, it predicts a 14% tallying match (humans are at 48%). In Experiment 2, it predicts an 85% rate of choosing option B (humans are at 50%). While the softmax temperature (beta) and lapse rate (epsilon) can soften choices globally, the optimizer is likely keeping them low to fit other experiments. As a result, the strict deterministic feature ordering of TTB fails to capture the uncertainty or individual differences in which feature is considered 'best' in these specific designs.
Rationale: Keep the Take-The-Best mechanism, but introduce individual differences / subjective uncertainty in the validities. Add a `sigma` parameter (e.g., range [0.0, 2.0]) representing noise in subjective validities. In the `predict` function, sample the validities with Gaussian noise (mean=validities, std=sigma) multiple times (e.g., 20 iterations), apply the strict TTB stopping rule for each sample, and average the resulting choice probabilities. This keeps the lexicographic family intact while naturally smoothing the aggregate predictions when validities are close.

**Outcome of your advice:** iter 1 candidate loss=0.4991 -> CURRENT candidate loss=0.1143 -> the gate marked it ACCEPTED.

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of the model simulation results on existing experiments and how they do or do not support the proposed model/theory.
- verdict: Either 'regenerate' (regenerate a new model/theory) or 'continue' (keep the current model/theory).
- rationale: If verdict='regenerate', why the current predict / policy / parameter-ranges should be revised. If verdict='continue', a sketch of why the current theory should be kept.


## Response

```json
{
  "interpretation": "The introduction of subjective validity noise (sigma) has dramatically improved the model's fit to the human data. In Experiment 1, the tally-match rate moved from 0.1425 to 0.4131, much closer to the human rate of 0.4863. In Experiment 2, the rate of choosing option B moved from 0.8492 to 0.4883, closely matching the human rate of 0.5067. The aggregate loss decreased significantly from 0.4991 to 0.1143. The model successfully captures the empirical patterns by acknowledging that while people may use a lexicographic stopping rule, their subjective ranking of feature validities is noisy.",
  "verdict": "continue",
  "rationale": "The current model accurately captures the human data across both experiments. The mechanism of sampling noisy validities before applying the Take-The-Best stopping rule successfully softens the aggregate predictions, reflecting individual differences and subjective uncertainty without abandoning the prescribed non-compensatory mechanism family. No further adjustments are necessary."
}
```

## Usage

```json
{
  "prompt_token_count": 4216,
  "candidates_token_count": 243,
  "total_token_count": 4646
}
```
