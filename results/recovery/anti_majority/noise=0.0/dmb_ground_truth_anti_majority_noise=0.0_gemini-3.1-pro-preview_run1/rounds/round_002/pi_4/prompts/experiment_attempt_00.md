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
**Description:** Strategy Repertoire (Mixture of TTB and WADD with Independent Temperatures)

**Parameters:**
- beta_ttb: [0.1, 20.0]
- beta_wadd: [0.1, 20.0]
- p_ttb: [0.0, 1.0]
- epsilon: [0.0, 0.2]
- validities: validities

**`predict source code`:**
```python
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Mixture model expects a (2, n_features) stimulus.")
    
    a, b = stim[0], stim[1]
    n_features = stim.shape[1]
    val = np.asarray(parameters["validities"], dtype=float)
    cue_order = np.argsort(-val, kind="stable").tolist()
    
    # Take The Best (TTB) evaluation
    winner_ttb = None
    for j in cue_order:
        if a[j] > b[j]:
            winner_ttb = 0
            break
        if b[j] > a[j]:
            winner_ttb = 1
            break
            
    if winner_ttb == 0:
        scores_ttb = np.array([1.0, 0.0])
    elif winner_ttb == 1:
        scores_ttb = np.array([0.0, 1.0])
    else:
        scores_ttb = np.array([0.5, 0.5])
        
    # WADD evaluation (normalized by sum of validities to match TTB score scale)
    val_sum = np.sum(val)
    if val_sum > 0:
        w = val / val_sum
    else:
        w = np.ones(n_features) / n_features
        
    score_a_wadd = np.sum(w * a)
    score_b_wadd = np.sum(w * b)
    scores_wadd = np.array([score_a_wadd, score_b_wadd])
    
    beta_ttb = float(parameters["beta_ttb"])
    beta_wadd = float(parameters["beta_wadd"])
    p_ttb = float(parameters["p_ttb"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax for TTB
    z_ttb = beta_ttb * (scores_ttb - scores_ttb.max())
    e_ttb = np.exp(z_ttb)
    p_core_ttb = e_ttb / e_ttb.sum()
    
    # Softmax for WADD
    z_wadd = beta_wadd * (scores_wadd - scores_wadd.max())
    e_wadd = np.exp(z_wadd)
    p_core_wadd = e_wadd / e_wadd.sum()
    
    # Mixture of strategies
    p_mix = p_ttb * p_core_ttb + (1.0 - p_ttb) * p_core_wadd
    
    # Apply lapse rate
    n_opts = p_mix.shape[0]
    return (1.0 - epsilon) * p_mix + epsilon * (np.ones(n_opts) / n_opts)
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
**Description:** Decision-makers integrate all available features to evaluate options, weighting each feature according to its subjective importance. This Weighted Additive (WADD) strategy computes a compensatory score for each option by summing the feature values multiplied by their normalized subjective weights. The subjective weights are modeled as the provided feature validities raised to a power 'gamma', which allows the model to smoothly interpolate between Tallying (gamma = 0, equal weights) and Take The Best (large gamma, where the highest validity cue dominates). Choice probabilities are then generated via a softmax function over the options' scores, subject to random lapses.

**Parameters:**
- gamma: [0.0, 50.0]
- beta: [0.1, 50.0]
- epsilon: [0.0, 0.5]
- validities: validities

**`predict source code`:**
```python
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("WADD expects a (2, n_features) stimulus.")
    
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    gamma = float(parameters["gamma"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Compute subjective weights by raising validities to the power of gamma
    w = val ** gamma
    # Normalize weights to decouple gamma (cue dominance) from beta (choice determinism)
    if np.sum(w) > 0:
        w = w / np.sum(w)
    
    # Calculate Weighted Additive (WADD) scores for both options
    score_a = np.sum(w * a)
    score_b = np.sum(w * b)
    scores = np.array([score_a, score_b])
    
    # Numerically stable softmax
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
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
[0] To dissociate Take The Best (TTB) from Tallying, we use a 5-feature design where the options are constructed such that the single highest-validity discriminating cue favors one option (the choice predicted by TTB), while a larger number of lower-validity cues favor the other option (the choice predicted by Tallying). By varying which cue is the highest-validity discriminator and the margin of the tallying difference, we can robustly separate the one-reason decision making of TTB from the unweighted evidence accumulation of Tallying.

[1] To quantitatively dissociate Tallying from Take The Best (TTB), this design uses 5 features with descending validities. We construct trials where the single highest-validity discriminating cue strongly favors one option (the choice predicted by TTB), while a larger number of lower-validity cues favor the other option (the choice predicted by Tallying). We also include trials where the options tie under Tallying (equal number of winning features) but have a strict preference under TTB, as well as trials where the top cues are tied, forcing TTB to rely on secondary cues while Tallying continues to count all feature wins equally.

[2] To quantitatively dissociate Take The Best (TTB) from Weighted Additive (WADD) models, we use a 5-feature design with a linear spread of validities. The trials are constructed to pit the single highest-validity discriminating cue against a coalition of multiple lower-validity cues. TTB, being a non-compensatory 'one-reason' heuristic, will consistently choose the option favored by the single highest-validity discriminating cue, ignoring all others. WADD, being compensatory, integrates all cues and (unless the exponent gamma is extremely high) will often favor the option supported by the combination of multiple lower-validity cues. By varying the position of the discriminating cue and the number of opposing cues, we can map out the precise compensatory threshold and robustly distinguish TTB's lexicographic choice pattern from WADD's integration.

[3] To quantitatively dissociate the Weighted Additive (WADD) model from Take The Best (TTB), this design uses 5 features with linearly decreasing validities. The trials are constructed to systematically pit the single highest-validity discriminating cue against a coalition of multiple lower-validity cues. TTB, being non-compensatory, will consistently choose the option favored by the single highest-validity discriminating cue, ignoring the rest. WADD, being compensatory, integrates all cues and will often favor the option supported by the combination of multiple lower-validity cues (depending on the value of gamma). By varying the position of the discriminating cue (e.g., cue 1 vs. cues 2-5, or cue 2 vs. cues 3-5) and the number of opposing cues, we can robustly distinguish TTB's lexicographic choice pattern from WADD's integration.

## RESPONSE FORMAT
Return a JSON object with the following fields:
- rationale: Reasoning behind this experimental design; used when interpreting results.
- validities: Per-expert validities, one per feature. Each must be in [0.5, 1.0]; order is free (no descending requirement — heuristics that rely on validity-ordering re-sort internally). Length determines n_features for the whole experiment and must match the rating-list length in every trial pair. Pick a spread (at least one high validity and at least one low one) — uniform validities (e.g. all 0.7) collapse WADD into a scaled Equal-Weight rule and make them indistinguishable by any decision.
- trial_a_ratings: List of option-A rating vectors, one per trial. Each inner list has length equal to len(validities); each value is binary (0 or 1). `trial_a_ratings[i]` pairs with `trial_b_ratings[i]` on trial i.
- trial_b_ratings: List of option-B rating vectors, one per trial. Same length and shape constraints as `trial_a_ratings`. Pick trials that let the intended heuristics (TTB, EQW, Tallying, WADD) be dissociated; avoid trials where every heuristic agrees.


## Response

```json
{
  "rationale": "To quantitatively dissociate the Strategy Repertoire (Mixture of TTB and WADD) from the parameterized WADD model (which uses an exponent 'gamma' to interpolate between Tallying and TTB), we use a 4-feature design with linearly spaced validities. The trials are designed to create varying degrees of conflict between the highest-validity cue and combinations of lower-validity cues. The competing WADD model applies a non-linear transformation (gamma exponent) to the weights before passing them through a single softmax function. In contrast, the Strategy Repertoire model computes a linear combination of two separate softmax probabilities (one from pure TTB, one from linear WADD). Because the softmax function is non-linear, a mixture of two distinct softmax distributions produces a probability profile across these diverse trade-off trials that cannot be perfectly mimicked by a single softmax over gamma-exponentiated weights. By analyzing the choice probabilities across trials where TTB and linear WADD strongly disagree versus where they weakly disagree, we can distinguish the mixture of strategies from a single unified compensatory strategy with non-linear weights.",
  "validities": [
    0.95,
    0.85,
    0.75,
    0.65
  ],
  "trial_a_ratings": [
    [
      1,
      0,
      0,
      0
    ],
    [
      0,
      1,
      0,
      0
    ],
    [
      1,
      1,
      0,
      0
    ],
    [
      1,
      0,
      1,
      0
    ],
    [
      1,
      0,
      0,
      1
    ],
    [
      0,
      1,
      1,
      0
    ],
    [
      0,
      1,
      0,
      1
    ],
    [
      0,
      0,
      1,
      1
    ],
    [
      1,
      1,
      1,
      0
    ],
    [
      0,
      1,
      1,
      1
    ]
  ],
  "trial_b_ratings": [
    [
      0,
      1,
      1,
      1
    ],
    [
      0,
      0,
      1,
      1
    ],
    [
      0,
      0,
      1,
      1
    ],
    [
      0,
      1,
      0,
      1
    ],
    [
      0,
      1,
      1,
      0
    ],
    [
      1,
      0,
      0,
      0
    ],
    [
      1,
      0,
      0,
      0
    ],
    [
      1,
      0,
      0,
      0
    ],
    [
      0,
      0,
      0,
      1
    ],
    [
      1,
      0,
      0,
      0
    ]
  ]
}
```

## Usage

```json
{
  "prompt_token_count": 3209,
  "candidates_token_count": 577,
  "total_token_count": 4878
}
```
