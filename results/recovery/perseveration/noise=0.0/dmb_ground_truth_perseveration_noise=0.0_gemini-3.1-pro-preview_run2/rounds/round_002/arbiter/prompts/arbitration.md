# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_4" and "pi_3") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_4" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_3" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_4
Random Guessing / High-Noise Tallying: Due to the lack of trial-by-trial feedback and potentially low engagement, subjects largely ignore cue validities and feature values. Instead, they make choices that are nearly indistinguishable from uniform random guessing, which can be modeled as a simple unweighted tally of features heavily diluted by extreme decision noise and high lapse rates. This explains the ~0.5 agreement with Take The Best, ~0.44 agreement with Tallying, and the near-zero variance in choice proportions across different trial types.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Stimulus must be of shape (2, n_features).")
        
    a, b = stim[0], stim[1]
    
    # Unweighted tally of winning features
    a_wins = float(np.sum(a > b))
    b_wins = float(np.sum(b > a))
    scores = np.array([a_wins, b_wins])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax with max-subtraction for numerical stability
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    n_opts = len(p_core)
    # Blend with uniform guessing based on epsilon
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return int(np.random.choice(len(probabilities), p=probabilities))


## THEORY 2 — pi_3
People use a Weighted Additive (WADD) strategy when comparing two options, but they subjectively scale the stated cue validities. By applying a non-linear transformation to the validities (exponentiating them by a parameter gamma), decision-makers can amplify the differences between cues (mimicking Take The Best) or compress them (mimicking Tallying). Expanding the range of gamma allows for extreme weight disparities, accommodating individuals who rely heavily on the most valid cue.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("WADD expects a (2, n_features) stimulus.")
        
    a, b = stim[0], stim[1]
    gamma = float(parameters["gamma"])
    val = np.asarray(parameters["validities"], dtype=float) ** gamma
    
    # Compute the weighted sum of features for each option
    ev_a = np.sum(val * a)
    ev_b = np.sum(val * b)
    scores = np.array([ev_a, ev_b])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax with max-subtraction for numerical stability
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    n_opts = len(p_core)
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)


## EXPERIMENT 1 (proposed by pi_4)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 3: A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 4: A=[1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 1]
  trial 5: A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0]
  trial 6: A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1]
  trial 7: A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  trial 8: A=[0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1]

**Rationale:** This design aims to completely dissociate the Random Guessing / High-Noise Tallying theory from the Weighted Additive (WADD) theory by including trials that vary from extreme evidence disparities to complex trade-offs. WADD predicts that choice probabilities will systematically track the weighted sum of validities (transformed by gamma), leading to highly deterministic choices (probabilities near 1.0 or 0.0) when one option dominates (e.g., all 1s vs all 0s) or when the weighted evidence strongly favors one side. In stark contrast, the advocated Random Guessing theory predicts that subjects largely ignore the validities and feature values due to high noise and lapse rates, resulting in choice proportions that remain universally close to 50/50 across all trials, with only a marginal pull toward the option with more unweighted feature wins.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
The Weighted Additive (WADD) theory predicts highly deterministic choices (probabilities near 0 or 1) because subjects consistently apply subjective weights to the cues, leading to strong preferences on most trials. The Random Guessing theory, conversely, predicts that choice proportions will hover closely around 0.5 due to high noise and lapse rates. By calculating the absolute deviation of each subject's choice proportion from 0.5 for each trial type and averaging them, we directly quantify the 'extremeness' of their choices. WADD will yield high values (close to 0.5), whereas Random Guessing will yield low values (driven mostly by finite-sample binomial variance, around 0.22 for 12 repetitions).

Source:
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    import numpy as np
    
    # Create a hashable string key for each unique trial type
    a_str = data['option_a_ratings'].apply(lambda x: "".join(map(str, x)))
    b_str = data['option_b_ratings'].apply(lambda x: "".join(map(str, x)))
    
    df = data.copy()
    df['trial_key'] = a_str + "_" + b_str
    
    # Calculate the proportion of choosing option B (response = 1) for each subject and trial type
    subject_trial_means = df.groupby(['subject_id', 'trial_key'])['response'].mean()
    
    # Calculate the absolute difference from 0.5 (extremeness of choice probability)
    abs_devs = (subject_trial_means - 0.5).abs()
    
    # Return the average extremeness across all subjects and trial types
    return float(abs_devs.mean())

### RESULTS
- Predicted under pi_4 (simulated): 0.1154 (var=0.0011)
- Predicted under pi_3 (simulated): 0.3287 (var=0.0070)
- Observed on real data: 0.5000 (var=0.0000)

## EXPERIMENT 2 (proposed by pi_3)

### DESIGN
**Validities (n_features=5):** [0.95, 0.8, 0.7, 0.6, 0.55]

**Trial pairs (n=8):**
  trial 1: A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  trial 2: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 3: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  trial 4: A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0]
  trial 5: A=[0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 0]
  trial 6: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  trial 7: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 8: A=[0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0]

**Rationale:** To decisively dissociate the Weighted Additive (WADD) theory from the Random Guessing / High-Noise Tallying theory, this design spans a wide range of evidence disparities. The Random Guessing theory posits that subjects suffer from extreme noise (epsilon > 0.8) and low sensitivity (beta < 0.05), predicting that choice probabilities will remain stubbornly close to 50/50 across all trials, with only marginal biases toward options with more unweighted feature wins. In contrast, WADD predicts highly deterministic choices when one option strongly dominates or when high-validity cues heavily favor one side. By including complete dominance trials, single-cue difference trials of varying validities, and trials where a single high-validity cue opposes multiple low-validity cues, we can reveal whether subjects exhibit the high-confidence, validity-sensitive choices predicted by WADD, which the high-noise tallying model fundamentally cannot accommodate.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
This metric calculates the mean absolute deviation of choice proportions from 0.5 for each unique trial type. The Random Guessing / High-Noise theory predicts that choice proportions will be very close to 0.5 on all trials, resulting in a low absolute deviation (driven purely by binomial noise over 12 repetitions, yielding ~0.22). The Advocated WADD theory predicts highly deterministic choices on many trial types, pushing choice proportions close to 0 or 1, resulting in a high absolute deviation (closer to 0.5). Averaging this across all trial types per subject provides a highly stable measure of choice determinism.

Source:
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    import numpy as np
    
    # Create a hashable string representation for each unique trial type
    a_str = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    b_str = data['option_b_ratings'].apply(lambda x: ''.join(map(str, x)))
    trial_type = a_str + "_" + b_str
    
    # Response is 0 for A, 1 for B. We want proportion of choosing A.
    chose_A = 1 - data['response']
    
    df = pd.DataFrame({
        'subject_id': data['subject_id'],
        'trial_type': trial_type,
        'chose_A': chose_A
    })
    
    # Calculate the proportion of choosing A for each subject and trial type
    subj_trial = df.groupby(['subject_id', 'trial_type'])['chose_A'].mean()
    
    # Calculate the absolute deviation from 0.5 (random guessing)
    abs_dev = (subj_trial - 0.5).abs()
    
    # Average across trial types for each subject
    subj_dev = abs_dev.groupby('subject_id').mean()
    
    # Return the grand mean across subjects
    return float(subj_dev.mean())

### RESULTS
- Predicted under pi_4 (simulated): 0.1131 (var=0.0010)
- Predicted under pi_3 (simulated): 0.2754 (var=0.0056)
- Observed on real data: 0.5000 (var=0.0000)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 1, 0, 0]  B=[1, 0, 1, 1]
  A=[1, 0, 1, 1]  B=[1, 1, 0, 0]
  A=[0, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[0, 0, 1, 1]  B=[0, 1, 0, 0]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[0, 1, 0, 1]  B=[1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    agreements = []
    for _, row in data.iterrows():
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        resp = row['response']
        
        ttb_pred = -1
        # Features are in descending order of validity: [0.9, 0.8, 0.7, 0.6]
        for i in range(len(a)):
            if a[i] > b[i]:
                ttb_pred = 0
                break
            elif b[i] > a[i]:
                ttb_pred = 1
                break
                
        if ttb_pred != -1:
            agreements.append(1.0 if resp == ttb_pred else 0.0)
            
    return float(np.mean(agreements)) if agreements else 0.0

```

**Observed (real) value:** 0.5000 (var=0.0000)
**Predicted under pi_4:** 0.4904 (var=0.0021)
**Predicted under pi_3:** 0.6073 (var=0.0263)

### Experiment 4
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 0, 0, 1, 1]  B=[0, 0, 1, 0, 0]

**Metric**
```python
import pandas as pd
import numpy as np

def metric(data: pd.DataFrame) -> float:
    tallying_agreements = 0
    disagreement_trials = 0
    
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        # Tallying prediction
        a_wins = np.sum(a > b)
        b_wins = np.sum(b > a)
        if a_wins > b_wins:
            tally_pred = 0
        elif b_wins > a_wins:
            tally_pred = 1
        else:
            tally_pred = -1
            
        # Take The Best (TTB) prediction
        ttb_pred = -1
        for i in range(len(a)):
            if a[i] > b[i]:
                ttb_pred = 0
                break
            elif b[i] > a[i]:
                ttb_pred = 1
                break
                
        # Check for strict opposition between the two heuristics
        if tally_pred != -1 and ttb_pred != -1 and tally_pred != ttb_pred:
            disagreement_trials += 1
            if row['response'] == tally_pred:
                tallying_agreements += 1
                
    if disagreement_trials == 0:
        return 0.5
    return tallying_agreements / disagreement_trials

```

**Observed (real) value:** 0.4400 (var=0.0242)
**Predicted under pi_4:** 0.4936 (var=0.0033)
**Predicted under pi_3:** 0.4475 (var=0.0386)

### Experiment 5
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 1, 1, 0]  B=[0, 0, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd
    
    # Create a hashable key for trial types based on Option A's features
    # (Since each of the 8 unique trial types has a distinct Option A, this uniquely identifies the trial type)
    trial_keys = data['option_a_ratings'].apply(tuple)
    
    # Calculate whether the subject chose Option A (response == 0)
    chose_A = (data['response'] == 0).astype(float)
    
    # Combine into a temporary DataFrame to group
    df_temp = pd.DataFrame({'trial_key': trial_keys, 'chose_A': chose_A})
    
    # Compute the proportion of Option A choices for each trial type
    props = df_temp.groupby('trial_key')['chose_A'].mean()
    
    # Return the standard deviation of these choice proportions across the 8 trial types
    return float(np.std(props))
```

**Observed (real) value:** 0.0000 (var=0.0000)
**Predicted under pi_4:** 0.0180 (var=0.0007)
**Predicted under pi_3:** 0.1069 (var=0.0046)

### Experiment 6
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Create a hashable key for trial types based on option A (which is unique for all 8 pairs)
    keys = data['option_a_ratings'].apply(tuple)
    # Compute the mean response (proportion of B choices) per subject per trial type
    means = data.assign(trial_key=keys).groupby(['subject_id', 'trial_key'])['response'].mean()
    # Compute the variance of these means across the 8 trial types for each subject, then average
    return float(means.groupby('subject_id').var(ddof=0).mean())
```

**Observed (real) value:** 0.0000 (var=0.0000)
**Predicted under pi_4:** 0.0178 (var=0.0001)
**Predicted under pi_3:** 0.0357 (var=0.0010)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across all experiments, the observed data paints a very clear and extreme picture that neither theory currently captures. In Experiments 1 and 2, the mean absolute deviation of choice proportions from 0.5 is exactly 0.5000, meaning subjects are 100% deterministic on every single trial type (always choosing the same option). Concurrently, in Experiments 5 and 6, the variance/standard deviation of choice proportions across different trial types is exactly 0.0000. Combined with an ~0.50 agreement with Take-The-Best (Exp 3) and Tallying (Exp 4), this perfectly describes a 'Position Bias' or 'Constant Choice' heuristic where subjects simply pick the exact same button (e.g., always Option A or always Option B) on every single trial, completely ignoring the stimulus features. Theory 1's random guessing predicts binomial noise around 0.5 (failing to predict the 0.5 deviation), and Theory 2's WADD predicts variance across trial types depending on feature values (failing to predict the 0.0 variance).",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Propose a 'Strong Position Bias / Constant Choice' theory. The theory should posit that because subjects lack trial-by-trial feedback or are completely disengaged, they adopt a degenerate strategy of always choosing the same option (e.g., always Option A or always Option B) regardless of the cues. The model should have a parameter representing the probability of a subject adopting a strict 'Always A' vs 'Always B' policy, resulting in choice probabilities of 1.0 or 0.0 for a given subject across all trials."
}
```

## Usage

```json
{
  "prompt_token_count": 6460,
  "candidates_token_count": 385,
  "total_token_count": 7673
}
```
