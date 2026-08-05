# experiment_attempt_00

## System Prompt

You are a renowned cognitive scientist designing an experiment in the Decision Making (Binary Features) domain.

Your goal is to be an adversarial collaborator: propose a design whose outcomes would be predicted by your advocated theory but NOT by the competing theory. Both are provided below.

A useful proposal targets a *quantitative* dissociation between the two theories — how they respond differently to specific stimuli in addition to differences in overall performance.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

A multi-attribute decision-making experiment. On each trial the subject sees two options (A, B), each described by `n_features` integer expert ratings (`n_features` is set by the length of `validities` you propose). Choose `validities` — one per feature, each in [0.5, 1.0], order free — to fix each expert's advertised accuracy; subjects are told these values up front. Then choose `trial_a_ratings/trial_b_ratings` (each rating value in [0, 1]) so that the intended heuristics (e.g. TTB, EQW, Tallying, WADD) make distinguishable predictions: avoid degenerate pairs where every heuristic agrees, and prefer pairs that dissociate single-feature focus from feature-summing strategies. Validities and the trial ratings together define the design; they are fixed across all trials in this experiment. No trial-by-trial correctness feedback. The total number of trials per subject is held at roughly 96: each unique pair is repeated K = max(1, 96 // n_unique_pairs) times in an independently-randomized order per subject.

Subjects see the following instructions:
In this experiment you will repeatedly choose between two fictitious products, A and B. On every trial you will see `n_features` expert ratings for each product (the number of experts is fixed across all trials and is set by the length of `validities`).

Each rating is an integer in [0, 1]. The ratings are displayed as a horizontal filled bar with the numeric value (e.g. "0/1") shown next to it. Higher = more positive.

The same experts (in the same order) provide ratings for both products on every trial. Each expert's accuracy (their validity expressed as a percentage, e.g. "Expert 1 (80%)") is shown next to their rating on every trial AND is also listed up front in an "Expert accuracies" panel.

On each trial, decide which product is of higher quality and press A for product A or B for product B. There is no time limit and no feedback. Note that for the first ~`min_rt_ms` of each trial the answer prompt is hidden and the keys are locked, so subjects first see the full ratings and can answer once the A / B prompt appears — design pairs that actually require comparing the ratings.

Total trials per subject is roughly `MAX_TRIALS`: each unique pair you propose is repeated `K = max(1, MAX_TRIALS // n_unique_pairs)` times in an independently-randomized order per subject.

## ADVOCATED THEORY
**Description:** Take-The-Best (TTB) heuristic with subjective validity noise: Decision-makers search through features in descending order of their subjective validity, but their assessment of validity is noisy. On any given evaluation, they sample validities with some variance, sort features by these sampled validities, and stop at the first feature that discriminates between the two options. Response noise is modeled via a softmax over the resulting binary preference scores, plus an independent lapse rate. Averaging over multiple samples naturally smooths the aggregate predictions when validities are close.

**Parameters:**
- beta: [0.1, 20.0]
- epsilon: [0.0, 0.5]
- sigma: [0.0, 2.0]
- validities: validities

**`predict source code`:**
```python
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
```

**`policy source code`:**
```python
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)
```


## COMPETING THEORY
**Description:** Strategy Mixture: Decision-makers are heterogeneous and use a mixture of non-compensatory and compensatory heuristics. On any given trial, a decision is made either via Take-The-Best (relying solely on the most valid discriminating feature) or Tallying (counting the total number of winning features), governed by a mixing parameter. When these strategies conflict, their opposing choices average out across the population, naturally capturing the ~0.5 aggregate choice proportions observed across experiments without relying on massive uniform noise.

**Parameters:**
- beta: [0.1, 20.0]
- epsilon: [0.0, 0.5]
- p_ttb: [0.0, 1.0]
- validities: validities

**`predict source code`:**
```python
def predict(parameters, stimulus, history):
    import numpy as np
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Stimulus must be shape (2, n_features).")
    
    validities = np.asarray(parameters["validities"], dtype=float)
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    p_ttb = float(parameters["p_ttb"])
    
    # Take-The-Best (TTB) predictions
    order = np.argsort(validities)[::-1]
    ttb_scores = np.zeros(2)
    for idx in order:
        if stim[0, idx] > stim[1, idx]:
            ttb_scores[0] = 1.0
            break
        elif stim[1, idx] > stim[0, idx]:
            ttb_scores[1] = 1.0
            break
            
    z_ttb = beta * (ttb_scores - np.max(ttb_scores))
    e_ttb = np.exp(z_ttb)
    p_ttb_dist = e_ttb / e_ttb.sum()
    
    # Tallying predictions
    a_wins = float(np.sum(stim[0] > stim[1]))
    b_wins = float(np.sum(stim[1] > stim[0]))
    tally_scores = np.array([a_wins, b_wins])
    
    z_tally = beta * (tally_scores - np.max(tally_scores))
    e_tally = np.exp(z_tally)
    p_tally_dist = e_tally / e_tally.sum()
    
    # Mixture of the two strategies
    p_core = p_ttb * p_ttb_dist + (1.0 - p_ttb) * p_tally_dist
    
    # Uniform lapse
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)
```

**`policy source code`:**
```python
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)
```


## ALREADY-EXPLORED EXPERIMENTS (do not repeat)
[0] To quantitatively dissociate Tallying from WADD, we use an environment with 5 features where the first two validities are high and the remaining three are low. Tallying simply counts the number of features each option wins on, completely ignoring validities. WADD, however, weights each win by the feature's validity. By pitting an option that wins on the two most valid features (2 wins) against an option that wins on the three least valid features (3 wins), Tallying strongly prefers the latter while WADD strongly prefers the former. Adding trials where Tallying ties but WADD has a strict preference further teases apart the use of validity weights.

[1] To quantitatively dissociate WADD from Tallying, we use a 5-feature environment with a steep drop-off in validities (two highly valid features and three less valid features). Tallying simply counts the number of features each option wins on, completely ignoring validities. WADD computes a weighted sum using the validities. By pitting an option that wins on the two most valid features against an option that wins on the three least valid features, Tallying strictly prefers the latter (3 wins vs 2 wins), whereas WADD strictly prefers the former because the combined weight of the two high-validity features exceeds the combined weight of the three low-validity features. The design also includes trials where both models agree, and trials where Tallying ties but WADD has a strict preference, to robustly estimate the validity weighting parameter.

[2] To dissociate the non-compensatory Take-The-Best (TTB) model from the compensatory Weighted Additive (WADD) model, we use a 5-feature environment. The validities range from very high (0.95) to chance (0.50). We designed trials where the option favored by the single most valid cue is pitted against an option supported by multiple less valid cues. TTB, which stops at the first discriminating feature, will consistently choose the option with the highest valid cue. In contrast, WADD integrates all cues and will often prefer the option with multiple lesser cues because their combined weight exceeds that of the single best cue. Additional trials where the models agree or marginally disagree provide constraints on the noise and weighting parameters.

[3] To quantitatively dissociate the compensatory Weighted Additive (WADD) model from the non-compensatory Noisy Take-The-Best (TTB) model, we use a 5-feature environment with linearly decreasing validities. The design systematically pits the single most valid cue (or the top two) against a coalition of multiple less valid cues. Because TTB searches features in order of noisy validity and stops at the first discriminating cue, it will predominantly choose the option favored by the highest-validity feature. In contrast, WADD integrates all features, allowing the combined weight of several lower-validity features to easily overcome the single best feature. By varying the margin of WADD's preference and the probability that Noisy TTB samples the critical feature first, we can cleanly separate the two models.

## RESPONSE FORMAT
Return a JSON object with the following fields:
- rationale: Reasoning behind this experimental design; used when interpreting results.
- validities: Per-expert validities, one per feature. Each must be in [0.5, 1.0]; order is free (no descending requirement — heuristics that rely on validity-ordering re-sort internally). Length determines n_features for the whole experiment and must match the rating-list length in every trial pair. Pick a spread (at least one high validity and at least one low one) — uniform validities (e.g. all 0.7) collapse WADD into a scaled Equal-Weight rule and make them indistinguishable by any decision.
- trial_a_ratings: List of option-A rating vectors, one per trial. Each inner list has length equal to len(validities); each value is binary (0 or 1). `trial_a_ratings[i]` pairs with `trial_b_ratings[i]` on trial i.
- trial_b_ratings: List of option-B rating vectors, one per trial. Same length and shape constraints as `trial_a_ratings`. Pick trials that let the intended heuristics (TTB, EQW, Tallying, WADD) be dissociated; avoid trials where every heuristic agrees.


## Response

```json
{
  "rationale": "This design exploits the difference between 'Noisy TTB' (which assumes Gaussian noise on validities, causing features with similar validities to occasionally swap in the search hierarchy) and 'Strategy Mixture' (which assumes strict, noiseless TTB mixed with Tallying). By using validities where the top two features are very close (0.90 and 0.85) and the remaining features are lower, we can pit them against each other. In a trial where Option A has only feature 2 and Option B has only feature 1, Strategy Mixture predicts no preference for A (strict TTB chooses B, Tallying ties), while Noisy TTB predicts a significant preference for A due to validity swapping. Conversely, when Option A has feature 2 plus several lower-tier features and Option B has feature 1, Strategy Mixture predicts a jump in preference for A (since Tallying now strongly favors A), whereas Noisy TTB predicts the same choice probability as the first trial because the top two features still dominate the search process.",
  "validities": [
    0.9,
    0.85,
    0.65,
    0.6,
    0.55
  ],
  "trial_a_ratings": [
    [
      0,
      1,
      0,
      0,
      0
    ],
    [
      0,
      1,
      1,
      1,
      0
    ],
    [
      1,
      0,
      0,
      0,
      0
    ],
    [
      0,
      0,
      1,
      0,
      0
    ],
    [
      0,
      0,
      0,
      1,
      1
    ]
  ],
  "trial_b_ratings": [
    [
      1,
      0,
      0,
      0,
      0
    ],
    [
      1,
      0,
      0,
      0,
      1
    ],
    [
      0,
      0,
      1,
      1,
      1
    ],
    [
      0,
      0,
      0,
      1,
      0
    ],
    [
      0,
      0,
      1,
      0,
      0
    ]
  ]
}
```

## Usage

```json
{
  "prompt_token_count": 3125,
  "candidates_token_count": 464,
  "total_token_count": 5632
}
```
