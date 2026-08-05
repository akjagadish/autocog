# metric_exp00_attempt_00

## System Prompt

You are a psychology researcher proposing a metric in the Decision Making (Binary Features) domain.

Your goal is adversarial: propose a metric that DISCRIMINATES the two theories — i.e., its value, computed on data simulated under your advocated theory, should be as far as possible from its value computed on data simulated under the competing theory. The direction of the gap does not matter; what matters is that the two theories produce visibly different numbers on this metric. The metric is computed on the data collected from the experimental design provided in the prompt. Produce a metric where you're prediction will be much more accurate than the competing theory's prediction on human data.

Your metric is a Python function

    metric(data: pd.DataFrame) -> float

Available imports inside `metric`:
- numpy as np
- pandas as pd

The system evaluates your metric in two ways and reports the pair as `point_estimate (var=between_subject_variance)` everywhere downstream:
- `point_estimate` is `metric(data)` applied to the FULL pooled DataFrame (all subjects together) — the canonical scalar;
- `between_subject_variance` is the population variance (`ddof=0`) of `metric(subj_df)` re-applied per `subject_id`, summarising how stable the metric is across subjects. If your metric only makes sense on multi-subject data this will fall back to `n/a` and the metric is rejected (the acceptance test below cannot run without it). Prefer metrics that work both on the pooled DataFrame and on a single subject's slice.

Acceptance rule: the system simulates each theory and runs Welch's two-sample t-test on `(point_estimate_self, between_subject_variance_self, N)` vs. `(point_estimate_adv, between_subject_variance_adv, N)`, where N is the number of HUMAN subjects the experiment will actually be run with (a fixed small number, currently 25). Your metric is admitted iff the two-sided p-value is below the significance level (currently alpha=0.01). Implication: a large between-theory gap is NOT enough — if either theory's metric is also highly variable across subjects, N humans won't reliably distinguish them and the metric will be rejected. Aim for contrasts that are both large in mean AND tight per subject.

Do NOT propose metrics that are trivially true for your theory.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

Each subject completes ~96 trials in a single block, with order randomized independently per subject. On every trial the subject sees two options A and B, each described by `n_features` binary expert ratings (each 0 or 1). The per-feature validities and n_features are fixed per experiment (design-time choices). Validities are communicated to the subject in the instructions. Both `n_features` and `validities` are exposed to your `predict` via the `parameters` dict. The subject chooses A or B; no correctness feedback is provided after the choice.

## CHOSEN EXPERIMENTAL DESIGN
**Validities (n_features=5):** [0.65, 0.95, 0.55, 0.85, 0.75]

**Trial pairs (n=5):**
  trial 1: A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 1, 1]
  trial 2: A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  trial 3: A=[1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 4: A=[0, 1, 0, 1, 0]  B=[1, 1, 1, 0, 1]
  trial 5: A=[0, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]

**Rationale:** To cleanly dissociate Take-The-Best (TTB) from Tallying (Equal Weight), we use a 5-feature environment with non-descending validities. This prevents subjects from merely reading left-to-right, ensuring they must process the explicit validities. The critical trials pit an option that possesses the single best discriminating cue against an option that possesses a greater number of lower-validity cues. In these trials, TTB (which relies lexicographically on the highest validity cue) and Tallying (which simply counts positive features) make diametrically opposed predictions. We also include trials where Tallying predicts a tie while TTB predicts a strong preference, and trials where the highest-validity cue is tied so TTB must rely on the second-best cue, which is again outnumbered by lower-validity cues for Tallying.

**Computed schedule:** 5 unique pairs × 19 reps = 95 trials per subject.



## ADVOCATED THEORY
**Description:** Take-The-Best (TTB) Heuristic with Flexible Adherence: Decision-makers evaluate options using a lexicographic, non-compensatory strategy by searching through features in descending order of their explicit validities. The search stops at the first discriminating feature. However, because empirical behavior often systematically deviates from strict TTB (e.g., due to compensatory processes or anti-alignment on specific conflict trials), the model allows for full-range guessing (epsilon up to 1.0) and potential inversion of the lexicographic preference (negative beta) to capture aggregate deviations while maintaining the core TTB mechanism.

**Parameters:**
- beta: [-5.0, 5.0]
- epsilon: [0.0, 1.0]
- validities: validities

**`predict source code`:**
```python
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("TTB expects a (2, n_features) state.")
        
    validities = np.asarray(parameters["validities"], dtype=float)
    
    # Sort cues by validity in descending order
    cue_order = np.argsort(-validities)
    
    score_a = 0.0
    score_b = 0.0
    
    # Lexicographic search
    for cue in cue_order:
        if stim[0, cue] > stim[1, cue]:
            score_a = 1.0
            break
        elif stim[1, cue] > stim[0, cue]:
            score_b = 1.0
            break
            
    scores = np.array([score_a, score_b])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax over the binary win/loss/tie outcomes
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    # Blend with uniform lapse
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)
```

**`policy source code`:**
```python
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))
```


## COMPETING THEORY
**Description:** Tallying (Equal Weight Heuristic): People compare two options by ignoring the explicit validities of the cues and simply counting the number of positive features (or cues present) for each option. The option with the higher count (tally) is chosen. This is a strongly compensatory strategy that avoids the cognitive overhead of multiplying features by validities, yet allows multiple lower-validity cues to jointly overrule a single high-validity cue.

**Parameters:**
- beta: [0.1, 20.0]
- epsilon: [0.0, 0.5]

**`predict source code`:**
```python
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Tallying expects a (2, n_features) state.")
        
    # Tallying: simple sum of positive cues per option
    scores = stim.sum(axis=1)
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax over tally scores
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()
    
    # Blend with uniform lapse
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)
```

**`policy source code`:**
```python
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))
```


## DATA SCHEMA
Your metric receives a tidy per-trial pandas DataFrame stacking all subjects (rows grouped by `subject_id`, in trial order). Columns:
- subject_id: Subject identifier (one row per trial per subject).
- option_a_ratings: List of n_features binary expert ratings (each 0 or 1) for option A on this trial.
- option_b_ratings: List of n_features binary expert ratings (each 0 or 1) for option B on this trial.
- response: 0 if subject chose A, 1 if subject chose B.

## IMPLEMENTATION GUARDRAILS
Any column in the schema above whose description names a list / tuple / np.ndarray (i.e. a per-trial sequence of values) holds non-scalar cells. Those cells are NOT hashable, so operations that hash row values fail with `TypeError: unhashable type: 'list'`. Treating `<seq_col>` as a placeholder for any such sequence-valued column:
- Avoid: `data.groupby('<seq_col>')`, `data['<seq_col>'].value_counts()`,     `data['<seq_col>'].nunique()`, `data['<seq_col>'].unique()` (returns     an object array but downstream `set()` / `in dict` will crash),     `set(data['<seq_col>'])`, `data['<seq_col>'].isin([...])` against list     values, or using a list cell as a dict key.
- If you need a hashable surrogate, project to one first, e.g.:
    - `data['<seq_col>_key'] = data['<seq_col>'].apply(tuple)` then group by `<seq_col>_key`
    - `data['<seq_col>_str'] = data['<seq_col>'].apply(lambda x: ''.join(map(str, x)))`
    Scalar columns (ints, floats, strings like `subject_id`, integer     responses, etc.) hash fine and can be used directly.
- Generator expressions inside function calls like `map()` or `join()` MUST be     parenthesized. For example:
    - WRONG: `map(str, int(v) for v in x)` → SyntaxError
    - RIGHT: `map(str, (int(v) for v in x))` or use a list comp: `[str(int(v)) for v in x]`
- Always verify your code is syntactically valid Python before returning it.

## METRICS YOU ALREADY TRIED AND FAILED ON
Each entry below is a metric you previously proposed in this round that did NOT discriminate the two theories at the human sample size — either it errored, its between-subject variance was unavailable, or Welch's t-test on `(self mean, self var, N)` vs. `(adv mean, adv var, N)` returned p ≥ alpha. The `outcome` line is the simulation result (means, between-subject variances, t-statistic and p-value at the human N) on the same `data_self` / `data_adv` your next metric will be evaluated on. Use the numbers to see where your hypothesised contrast collapsed — small mean gap, large per-subject variance, or both — and propose something qualitatively different. Don't repeat the same idea with cosmetic tweaks.
(none yet)

## RESPONSE FORMAT
Return a JSON object with the following fields:
- metric: Python source defining def metric(data: pd.DataFrame) -> float.
- rationale: Reasoning behind this metric; used when interpreting results.


## Response

```json
{
  "metric_source": "def metric(data: pd.DataFrame) -> float:\n    import numpy as np\n    \n    subj_diffs = []\n    for subj, df in data.groupby('subject_id'):\n        t3_chosen = 0\n        t3_total = 0\n        t5_chosen = 0\n        t5_total = 0\n        \n        for _, row in df.iterrows():\n            a = tuple(row['option_a_ratings'])\n            b = tuple(row['option_b_ratings'])\n            resp = row['response']\n            \n            # Trial 3: Options (1, 1, 0, 0, 0) vs (0, 0, 0, 1, 1)\n            if {a, b} == {(1, 1, 0, 0, 0), (0, 0, 0, 1, 1)}:\n                chosen_opt = a if resp == 0 else b\n                if chosen_opt == (1, 1, 0, 0, 0):\n                    t3_chosen += 1\n                t3_total += 1\n                \n            # Trial 5: Options (0, 0, 0, 1, 1) vs (0, 1, 1, 0, 0)\n            elif {a, b} == {(0, 0, 0, 1, 1), (0, 1, 1, 0, 0)}:\n                chosen_opt = a if resp == 0 else b\n                if chosen_opt == (0, 0, 0, 1, 1):\n                    t5_chosen += 1\n                t5_total += 1\n                \n        if t3_total > 0 and t5_total > 0:\n            p3 = t3_chosen / t3_total\n            p5 = t5_chosen / t5_total\n            subj_diffs.append(abs(p3 - p5))\n            \n    if not subj_diffs:\n        return 0.0\n    return float(np.mean(subj_diffs))",
  "rationale": "This metric leverages the 'tie' trials for Tallying (Trial 3 and Trial 5). In both of these trials, the two options have exactly 2 positive features each, so Tallying predicts a 50/50 tie regardless of its beta parameter. Therefore, for Tallying, the probability of choosing a specific option on Trial 3 (p3) and Trial 5 (p5) will both be around 0.5, and their absolute difference |p3 - p5| will be near 0 (only reflecting binomial noise). In contrast, Take-The-Best (TTB) finds a clear lexicographic winner in both trials based on the highest validity cue. Because the cue distributions are arranged such that TTB will strongly prefer one specific option in Trial 3 and the opposite in Trial 5, |p3 - p5| will be large (close to 1.0) under TTB. This remains true even if TTB's beta is negative (which would just invert both preferences symmetrically), making this metric highly robust to parameter variations."
}
```

## Usage

```json
{
  "prompt_token_count": 3036,
  "candidates_token_count": 764,
  "total_token_count": 11270
}
```
