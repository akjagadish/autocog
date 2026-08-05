# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_1" and "pi_5") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_1" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_5" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_1
People are modeled as running three classic heuristics in parallel — Take The Best (one-reason, top-validity cue), Tallying (count of feature-wise wins), and Weighted Additive (validity-weighted sum) — reading off the single option each heuristic deterministically prefers, and then leaning toward whichever option the majority of the three did NOT prefer. With three binary voters at least two always agree, so a majority option always exists; the model targets its complement. Response noise enters only at the final, ensemble level: a softmax over the binary "flipped-majority" score with inverse temperature beta, plus an independent lapse that with probability epsilon replaces the softmax output with a uniform pick over the two options. The individual heuristics contribute only their hard preference (their argmax) to the vote — they carry no internal noise — so beta and epsilon describe noise in the contrarian response itself, not in the constituent heuristics.


`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    # Anti-majority-vote ensemble. Each of Tallying / TTB / WADD
    # contributes a single hard preference (the argmax of its
    # deterministic score — no per-model softmax or lapse). We take the
    # majority vote across the three binary votes and flip it: when at
    # least two models agree on an option, we target the other one.
    # Choice noise (softmax over beta, lapse over epsilon) is applied
    # ONCE here, to the flipped-majority decision.

    def _pref_tallying(stimulus):
        # Tallying (Dawes 1979; Gigerenzer & Goldstein 1999): count
        # strict feature-wise wins; prefer the option with more wins.
        # Ties (equal win counts) fall to option A via argmax.
        stim = np.asarray(stimulus, dtype=float)
        if stim.ndim != 2 or stim.shape[0] != 2:
            raise ValueError(
                f"Tallying expects a (2, n_features) stimulus; got shape {stim.shape}."
            )
        a, b = stim[0], stim[1]
        a_wins = float(np.sum(a > b))
        b_wins = float(np.sum(b > a))
        return int(np.argmax(np.array([a_wins, b_wins])))

    def _pref_ttb(parameters, stimulus):
        # Take The Best (Gigerenzer & Goldstein 1996): consult cues in
        # descending validity; the first discriminating cue decides.
        # If no cue discriminates, the score is uniform and argmax
        # falls to option A.
        stim = np.asarray(stimulus, dtype=float)
        if stim.ndim != 2 or stim.shape[0] != 2:
            raise ValueError(
                f"TTB expects a (2, n_features) stimulus; got shape {stim.shape}."
            )
        n_features = stim.shape[1]
        val = np.asarray(parameters["validities"], dtype=float)
        if val.shape[0] != n_features:
            raise ValueError(
                f"validities length {val.shape[0]} != n_features {n_features}."
            )
        # Descending validity; argsort is stable so validity ties break
        # toward the earlier feature index.
        cue_order = np.argsort(-val, kind="stable").tolist()
        a, b = stim[0], stim[1]
        winner = None
        for j in cue_order:
            if a[j] > b[j]:
                winner = 0
                break
            if b[j] > a[j]:
                winner = 1
                break
        if winner is None:
            scores = np.ones(2) / 2.0
        else:
            scores = np.array([1.0, 0.0]) if winner == 0 else np.array([0.0, 1.0])
        return int(np.argmax(scores))

    def _pref_wadd(parameters, stimulus):
        # Weighted Additive (Payne, Bettman & Johnson 1993): prefer the
        # option with the higher validity-weighted sum. Ties fall to
        # option A via argmax.
        stim = np.asarray(stimulus, dtype=float)
        if stim.ndim != 2 or stim.shape[0] != 2:
            raise ValueError(
                f"WADD expects a (2, n_features) stimulus; got shape {stim.shape}."
            )
        n_features = stim.shape[1]
        validities = np.asarray(parameters["validities"], dtype=float)
        w = np.asarray(parameters["weights"], dtype=float)
        if w.shape[0] != n_features:
            raise ValueError(
                f"weights length {w.shape[0]} != n_features {n_features}."
            )
        scores = stim @ (validities * w)
        return int(np.argmax(scores))

    # Each model's hard preference (no noise inside the models).
    c_tallying = _pref_tallying(stimulus)
    c_ttb = _pref_ttb(parameters, stimulus)
    c_wadd = _pref_wadd(parameters, stimulus)

    # Majority vote across the three binary votes, then flip it.
    votes = [c_tallying, c_ttb, c_wadd]
    majority = 0 if votes.count(0) >= 2 else 1
    flipped = 1 - majority

    # Binary score for the flipped-majority choice (winner = 1, loser = 0),
    # then ONE softmax + lapse over the two options.
    scores = np.array([1.0, 0.0]) if flipped == 0 else np.array([0.0, 1.0])

    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    # Softmax with max-subtraction for numerical stability. For the binary
    # flipped score this collapses to sigmoid(beta) for the targeted
    # option (beta=0 ↔ 50/50; beta ≫ 1 ↔ deterministic flip).
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()

    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    probabilities = probabilities / probabilities.sum()  # Ensure valid probabilities.
    return np.random.choice(len(probabilities), p=probabilities)


## THEORY 2 — pi_5
Reverse Weighted Additive (Negative Utility) Theory: Subjects systematically interpret the features or validities as negative signals (such as costs, penalties, or negative reviews) rather than positive attributes. Consequently, they compute a standard Weighted Additive (WADD) score—the sum of feature values weighted by their respective validities—but aim to minimize this score. Choice behavior is modeled as a softmax over the negative WADD scores, offering an elegant, single-process cognitive explanation for the choice inversions observed across experiments. The noise parameters are tuned to reflect a higher degree of stochasticity observed in human data.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Reverse WADD expects a (2, n_features) stimulus.")
        
    validities = np.asarray(parameters["validities"], dtype=float)
    
    # Compute standard WADD scores (sum of features weighted by validities)
    wadd_scores = stim @ validities
    
    # Reverse the scores to model negative utility (minimization)
    scores = -wadd_scores
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax over the negative WADD scores with numerical stability
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()
    
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))


## EXPERIMENT 1 (proposed by pi_1)

### DESIGN
**Validities (n_features=8):** [0.95, 0.94, 0.93, 0.92, 0.5, 0.5, 0.5, 0.5]

**Trial pairs (n=4):**
  trial 1: A=[0, 1, 1, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 1, 1, 1, 0]
  trial 2: A=[1, 0, 0, 0, 1, 1, 1, 0]  B=[0, 1, 1, 1, 0, 0, 0, 0]
  trial 3: A=[0, 1, 1, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 1, 1, 1]
  trial 4: A=[1, 0, 0, 0, 0, 1, 1, 1]  B=[0, 1, 1, 1, 0, 0, 0, 0]

**Rationale:** To maximally dissociate the Advocated Theory (Anti-majority ensemble) from the Competing Theory (Reverse WADD), we design trials where Standard WADD strongly disagrees with both Take The Best (TTB) and Tallying. When TTB and Tallying agree on an option (e.g., Option B), they form the majority, causing the Anti-majority model to predict the opposite (Option A). Meanwhile, since Standard WADD prefers Option A, the Reverse WADD model (which minimizes the WADD score) will prefer Option B. This creates a stark, deterministic divergence in the choices predicted by the two models.

**Computed schedule:** 4 unique pairs × 24 reps = 96 trials per subject.



### METRIC
Rationale:
By design, the Advocated Theory (Anti-majority) consistently prefers the option with exactly 3 positive ratings, whereas the Competing Theory (Reverse WADD) consistently prefers the option with exactly 4 positive ratings across all trials. Measuring the proportion of choices where the selected option has a sum of 3 perfectly discriminates between the two models' deterministic predictions.

Source:
def metric(data: pd.DataFrame) -> float:
    def chosen_sum(row):
        return sum(row['option_a_ratings']) if row['response'] == 0 else sum(row['option_b_ratings'])
    return float((data.apply(chosen_sum, axis=1) == 3).mean())

### RESULTS
- Predicted under pi_1 (simulated): 0.8460 (var=0.0107)
- Predicted under pi_5 (simulated): 0.3733 (var=0.0082)
- Observed on real data: 0.8617 (var=0.0067)

## EXPERIMENT 2 (proposed by pi_5)

### DESIGN
**Validities (n_features=10):** [0.95, 0.94, 0.93, 0.92, 0.91, 0.55, 0.54, 0.53, 0.52, 0.51]

**Trial pairs (n=4):**
  trial 1: A=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 1, 1, 1, 1, 1]
  trial 2: A=[1, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  trial 3: A=[0, 1, 1, 1, 1, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 1, 1, 1, 1, 0]
  trial 4: A=[1, 0, 0, 0, 0, 1, 1, 1, 1, 0]  B=[0, 1, 1, 1, 1, 0, 0, 0, 0, 1]

**Rationale:** To maximally dissociate the Advocated Theory (Reverse WADD) from the Competing Theory (Anti-majority ensemble), we design trials where Standard WADD strongly disagrees with both Take The Best (TTB) and Tallying. The Anti-majority model takes a majority vote of TTB, Tallying, and Standard WADD, and then deterministically flips it. By ensuring TTB and Tallying agree on an option (e.g., Option B), they form the majority, causing the Anti-majority model to predict the opposite (Option A). Meanwhile, because Standard WADD prefers Option A, the Reverse WADD model (which seeks to minimize the WADD score) will prefer Option B. This creates a stark, deterministic divergence in the choices predicted by the two models, completely separating a negative-utility WADD process from a contrarian heuristic ensemble.

**Computed schedule:** 4 unique pairs × 24 reps = 96 trials per subject.



### METRIC
Rationale:
In the experimental design, Reverse WADD systematically prefers the option that has a 1 on the most valid feature (feature index 0) across all trials, because it tries to minimize the overall WADD score and the competing options are constructed such that the one with a 0 on the first feature has a much higher sum of validities on the remaining features. In contrast, the Anti-majority model frequently votes against the option with a 1 on the first feature, because TTB and Tallying often form a majority that favors it, causing the contrarian ensemble to flip its choice to the option with a 0 on the first feature. Measuring the proportion of trials where the chosen option has a 1 on the first feature yields ~1.0 for Reverse WADD and ~0.25 for Anti-majority, strongly discriminating the two theories.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    a_first = data['option_a_ratings'].apply(lambda x: x[0])
    b_first = data['option_b_ratings'].apply(lambda x: x[0])
    chosen_first = np.where(data['response'] == 0, a_first, b_first)
    return float(np.mean(chosen_first))

### RESULTS
- Predicted under pi_1 (simulated): 0.2696 (var=0.0117)
- Predicted under pi_5 (simulated): 0.6552 (var=0.0061)
- Observed on real data: 0.3129 (var=0.0031)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 1, 1, 0]  B=[0, 0, 0, 1]
  A=[0, 0, 0, 1]  B=[1, 1, 1, 0]
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[0, 1, 1, 0]  B=[1, 0, 0, 0]
  A=[1, 0, 0, 0]  B=[0, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    matches = 0
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        a_wins = np.sum(a > b)
        b_wins = np.sum(b > a)
        if a_wins > b_wins and row['response'] == 0:
            matches += 1
        elif b_wins > a_wins and row['response'] == 1:
            matches += 1
        elif a_wins == b_wins:
            matches += 0.5
    return float(matches / len(data))
```

**Observed (real) value:** 0.2675 (var=0.0463)
**Predicted under pi_1:** 0.2288 (var=0.0317)
**Predicted under pi_5:** 0.1977 (var=0.0157)

### Experiment 4
**Design**
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[0, 1, 1, 0]  B=[1, 0, 0, 1]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd
    
    a_sums = data['option_a_ratings'].apply(np.sum)
    b_sums = data['option_b_ratings'].apply(np.sum)
    
    mask = a_sums != b_sums
    if mask.sum() == 0:
        return 0.5
        
    responses = data.loc[mask, 'response']
    a_sums_filtered = a_sums[mask]
    b_sums_filtered = b_sums[mask]
    
    tallying_choices = (b_sums_filtered > a_sums_filtered).astype(int)
    
    return float((responses == tallying_choices).mean())
```

**Observed (real) value:** 0.2350 (var=0.0495)
**Predicted under pi_1:** 0.2308 (var=0.0618)
**Predicted under pi_5:** 0.2246 (var=0.0164)

### Experiment 5
**Design**
  A=[0, 0, 1, 1, 1, 1, 0]  B=[1, 1, 0, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 0, 0, 1]  B=[0, 0, 1, 1, 1, 1, 0]
  A=[0, 0, 1, 1, 1, 0, 1]  B=[1, 1, 0, 0, 0, 1, 0]
  A=[1, 1, 0, 0, 0, 1, 0]  B=[0, 0, 1, 1, 1, 0, 1]
  A=[0, 0, 0, 1, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_ones = data['option_a_ratings'].apply(sum)
    b_ones = data['option_b_ratings'].apply(sum)
    
    chosen_more_ones = np.where(
        data['response'] == 0,
        a_ones > b_ones,
        b_ones > a_ones
    )
    
    return float(np.mean(chosen_more_ones))
```

**Observed (real) value:** 0.5967 (var=0.0436)
**Predicted under pi_1:** 0.6208 (var=0.0656)
**Predicted under pi_5:** 0.6704 (var=0.0099)

### Experiment 6
**Design**
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Anti-Tallying prefers the option with more 0s.
    # In this design, option A has either three 1s and two 0s (A[0]=0) 
    # or three 0s and two 1s (A[0]=1).
    # If A[0] == 0, A has two 0s and B has three 0s, so Anti-Tallying prefers B (1).
    # If A[0] == 1, A has three 0s and B has two 0s, so Anti-Tallying prefers A (0).
    # Thus, Anti-Tallying always predicts (1 - A[0]).
    # Conversely, Anti-Majority always predicts A[0].
    # We measure the proportion of choices matching Anti-Tallying.
    a_first = data['option_a_ratings'].apply(lambda x: x[0])
    anti_tallying_pred = 1 - a_first
    return float((data['response'] == anti_tallying_pred).mean())
```

**Observed (real) value:** 0.3583 (var=0.1157)
**Predicted under pi_1:** 0.4473 (var=0.1230)
**Predicted under pi_5:** 0.3754 (var=0.0057)

### Experiment 7
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[1, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[0, 1, 0, 0, 1]  B=[1, 0, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    a_f1 = data['option_a_ratings'].apply(lambda x: x[0])
    b_f1 = data['option_b_ratings'].apply(lambda x: x[0])
    chosen_f1 = (data['response'] == 0) * a_f1 + (data['response'] == 1) * b_f1
    return float(chosen_f1.mean())
```

**Observed (real) value:** 0.2821 (var=0.0171)
**Predicted under pi_1:** 0.2256 (var=0.0159)
**Predicted under pi_5:** 0.2754 (var=0.0122)

### Experiment 8
**Design**
  A=[1, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[0, 1, 0, 0]  B=[1, 0, 1, 1]
  A=[1, 1, 1, 0]  B=[1, 0, 0, 1]
  A=[0, 0, 0, 1]  B=[0, 1, 1, 0]
  A=[1, 0, 1, 1]  B=[1, 0, 0, 0]
  A=[0, 1, 0, 0]  B=[0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    validities = np.array([0.95, 0.85, 0.75, 0.6])
    cue_order = np.argsort(-validities)
    
    matches = 0
    total = len(data)
    if total == 0:
        return 0.0
        
    for _, row in data.iterrows():
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        
        ttb_pref = 0
        for j in cue_order:
            if a[j] > b[j]:
                ttb_pref = 0
                break
            elif b[j] > a[j]:
                ttb_pref = 1
                break
                
        if row['response'] == ttb_pref:
            matches += 1
            
    return float(matches) / total
```

**Observed (real) value:** 0.1512 (var=0.0115)
**Predicted under pi_1:** 0.1460 (var=0.0113)
**Predicted under pi_5:** 0.2231 (var=0.0145)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Theory 1 (Anti-majority ensemble) consistently outperforms Theory 2 (Reverse WADD) across the most discriminative experiments. In Experiment 1, Theory 1 correctly predicts the high proportion of choices for the option with fewer positive ratings (sum=3), whereas Theory 2 fails completely. In Experiment 2, Theory 1 correctly predicts the low proportion of choices for the option with a 1 on the most valid feature, closely matching the observed 0.31, while Theory 2 predicts 0.65. Across other experiments (like 4 and 8), the observed data strongly suggests that subjects are systematically choosing against standard heuristics (TTB and Tallying). While Theory 1 effectively captures this contrarian behavior via an ensemble majority flip, Theory 2's negative utility formulation struggles to match the exact choice probabilities. Therefore, Theory 2 is degenerate and should be replaced.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Propose a 'Strict Anti-TTB (Contrarian Lexicographic)' theory. Unlike the ensemble approach of Theory 1 or the compensatory negative utility of Theory 2, this theory posits that subjects use a purely non-compensatory contrarian strategy: they inspect cues in descending order of validity and deterministically choose the option that has a *0* on the first discriminating cue (i.e., actively avoiding the highest-validity features). This provides a simpler, single-heuristic alternative to the Anti-majority ensemble that can naturally explain the strong aversion to the 'best' option seen in the data."
}
```

## Usage

```json
{
  "prompt_token_count": 7337,
  "candidates_token_count": 349,
  "total_token_count": 9595
}
```
