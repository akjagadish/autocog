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
**Validities (n_features=8):** [0.8, 0.8, 0.8, 0.8, 0.8, 0.65, 0.65, 0.65]

**Trial pairs (n=6):**
  trial 1: A=[0, 0, 0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0, 0, 0]
  trial 2: A=[0, 0, 0, 0, 0, 0, 1, 1]  B=[1, 0, 0, 0, 0, 1, 0, 0]
  trial 3: A=[0, 0, 0, 0, 0, 1, 0, 1]  B=[1, 0, 0, 0, 0, 0, 1, 0]
  trial 4: A=[1, 0, 0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 1, 0, 1]
  trial 5: A=[1, 0, 0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1]
  trial 6: A=[1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1]

**Rationale:** This eight-feature design uses validities [0.80 five times, 0.65 three times]. The last three equal low-validity cues are created by a moderate negative drop from 0.80 to 0.65. For the advocated theory this drop is within the negative end-drop segmentation route, so on exact tally ties it opens the late block at display positions 5-7 and uses a recency-weighted sub-tally there. For the competing theory the top validity tier has size 5, not 2-3, and the validity gap is only 0.15, below 0.30, so its validity gate stays closed; with an exact tally tie and only eight features it predicts p(A)=0.50 for every pair. Each pair sums the early five features against the late three so that total tally is exactly zero, but the late-block difference patterns span a symmetric six-level weighted sub-tally: +++ gives about +3, -++ about +1.7 to +2.4, +-+ about +1.1 to +1.5, -+- the mirrored negative, +-- more negative, and --- about -3. The advocated model therefore predicts ordered p(A) from roughly 0.12 to 0.88 across the six pairs, while the competing model predicts a flat 0.50 line. Mirrored A/B pairs control response bias.

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



## ADVOCATED THEORY
**Description:** People make binary-feature choices by a tally-first rule. When the unweighted signed tally is clearly nonzero, choice follows the tally through a softmax plus a small lapse. When the tally is tied or near-tied, advertised validities are used only to perceptually segment the cue display, and choice follows a recency-weighted sub-tally of a coherent late block if one is formed. Four segmentation routes can open such a block: (1) a large validity jump opening a later block of up to six cues; (2) a modest positive end boundary isolating a small two-to-three-cue late block; (3) a modest negative end drop isolating a homogeneous late low-validity block of two to three cues; and (4) a cumulative-contrast route, restricted to short displays of up to eight cues, that opens a homogeneous final two-to-three-cue block when its mean validity sits sufficiently below the immediately preceding two-to-three cues. For six-cue displays specifically, a homogeneous early elite followed by a uniformly lower late block is treated as a distinct late block even when the adjacent validity jump is moderate. When no perceptual block is formed, the tied choice is low confidence and is near chance.

**Parameters:**
- beta_tally_small: [0.60, 0.95]
- beta_tally_large: [0.95, 1.45]
- epsilon_tally_small: [0.02, 0.06]
- epsilon_tally_large: [0.02, 0.06]
- beta_near: [0.15, 0.35]
- epsilon_near: [0.75, 0.95]
- near_bound: {1.5}
- n_low_conf: {15}
- tau_tie: {0.5}
- gap_hi: [0.32, 0.42]
- gap_lo: [0.05, 0.08]
- gap_lo_max: [0.18, 0.25]
- drop_lo: [0.11, 0.14]
- drop_hi: [0.19, 0.35]
- drop_flat_tol: [0.05, 0.12]
- block_size_min_hi: {2}
- block_size_max_hi: {6}
- block_size_min_lo: {2}
- block_size_max_lo: {3}
- contrast_lo: [0.10, 0.16]
- contrast_lo_2: [0.20, 0.24]
- contrast_hi: [0.40, 0.55]
- contrast_flat_tol: [0.25, 0.45]
- contrast_prev_flat_tol: [0.04, 0.12]
- contrast_max_features: {8}
- short6_elite_flat: [0.02, 0.06]
- short6_late_flat: [0.25, 0.50]
- short6_gap: [0.03, 0.10]
- rho: [0.40, 0.90]
- beta_sub: [0.50, 0.68]
- epsilon_sub: [0.14, 0.21]
- epsilon_sub_size: [0.08, 0.13]
- validities: validities

**`predict source code`:**
```python
import numpy as np


def predict(parameters, state, history):
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError('Expected a (2, n_features) stimulus.')

    validities = np.asarray(parameters['validities'], dtype=float)
    n_features = stim.shape[1]
    if validities.shape[0] != n_features:
        raise ValueError('validities length mismatch.')

    a = stim[0]
    b = stim[1]
    diff = a - b
    tally = float(np.sum(diff))
    positions = np.arange(n_features, dtype=float)

    def stable_softmax(scores, inv_temp):
        scores = np.asarray(scores, dtype=float)
        z = inv_temp * (scores - np.max(scores))
        z = np.clip(z, -30.0, 30.0)
        e = np.exp(z)
        return e / np.sum(e)

    def lapse_mix(core, eps):
        base = (1.0 - eps) * core + eps * np.array([0.5, 0.5])
        base = np.clip(base, 0.005, 0.995)
        total = float(np.sum(base))
        if total <= 1e-12:
            return np.array([0.5, 0.5])
        return base / total

    beta_small = float(parameters['beta_tally_small'])
    beta_large = float(parameters['beta_tally_large'])
    eps_small = float(parameters['epsilon_tally_small'])
    eps_large = float(parameters['epsilon_tally_large'])
    frac = float(np.clip((n_features - 8.0) / 7.0, 0.0, 1.0))
    beta_tally = beta_small + frac * (beta_large - beta_small)
    epsilon_tally = eps_small + frac * (eps_large - eps_small)

    tau_tie = float(parameters['tau_tie'])
    gap_hi = float(parameters['gap_hi'])
    gap_lo = float(parameters['gap_lo'])
    gap_lo_max = float(parameters['gap_lo_max'])
    min_lo = int(parameters['block_size_min_lo'])
    max_lo = int(parameters['block_size_max_lo'])

    block_indices = None

    jumps = np.diff(validities)
    large_bounds = np.where(np.abs(jumps) >= gap_hi)[0]
    if large_bounds.size > 0:
        i = int(large_bounds[-1])
        size = n_features - (i + 1)
        min_hi = int(parameters['block_size_min_hi'])
        max_hi = int(parameters['block_size_max_hi'])
        if min_hi <= size <= max_hi:
            block_indices = np.arange(i + 1, i + 1 + size)

    if block_indices is None:
        pos_jumps = np.diff(validities)
        small_bounds = np.where((pos_jumps >= gap_lo) & (pos_jumps <= gap_lo_max))[0]
        if small_bounds.size > 0:
            i = int(small_bounds[-1])
            size = n_features - (i + 1)
            if min_lo <= size <= max_lo:
                block_indices = np.arange(i + 1, n_features)

    if block_indices is None and n_features <= int(parameters['contrast_max_features']):
        drop_lo = float(parameters['drop_lo'])
        drop_hi = float(parameters['drop_hi'])
        drop_flat_tol = float(parameters['drop_flat_tol'])
        neg_jumps = np.diff(validities)
        drop_bounds = np.where((neg_jumps <= -drop_lo) & (neg_jumps >= -drop_hi))[0]
        if drop_bounds.size > 0:
            for i in drop_bounds[::-1]:
                i = int(i)
                size = n_features - (i + 1)
                if min_lo <= size <= max_lo:
                    cand = np.arange(i + 1, n_features)
                    v_block = validities[cand]
                    if float(np.max(v_block) - np.min(v_block)) <= drop_flat_tol:
                        block_indices = cand
                        break

    if block_indices is None and n_features <= int(parameters['contrast_max_features']):
        contrast_lo_3 = float(parameters['contrast_lo'])
        contrast_lo_2 = float(parameters['contrast_lo_2'])
        contrast_hi = float(parameters['contrast_hi'])
        contrast_flat_tol = float(parameters['contrast_flat_tol'])
        contrast_prev_flat_tol = float(parameters['contrast_prev_flat_tol'])
        for k in (3, 2):
            if n_features < 2 * k:
                continue
            contrast_lo = contrast_lo_3 if k == 3 else contrast_lo_2
            prev = validities[-2 * k:-k]
            late = validities[-k:]
            contrast = float(np.mean(prev) - np.mean(late))
            late_range = float(np.max(late) - np.min(late))
            prev_range = float(np.max(prev) - np.min(prev))
            if (contrast_lo <= contrast <= contrast_hi and
                    late_range <= contrast_flat_tol and
                    prev_range <= contrast_prev_flat_tol):
                block_indices = np.arange(n_features - k, n_features)
                break

    if block_indices is None and n_features == 6:
        early = validities[:3]
        late = validities[3:]
        early_range = float(np.max(early) - np.min(early))
        late_range = float(np.max(late) - np.min(late))
        gap = float(np.min(early) - np.max(late))
        if (early_range <= float(parameters['short6_elite_flat']) and
                late_range <= float(parameters['short6_late_flat']) and
                gap >= float(parameters['short6_gap'])):
            block_indices = np.arange(3, 6)

    if abs(tally) <= tau_tie:
        if block_indices is not None and block_indices.size > 0:
            rho = float(parameters['rho'])
            pos_sel = positions[block_indices]
            w = np.exp(rho * (pos_sel - np.max(pos_sel)))
            if np.sum(w) <= 1e-12:
                w = np.ones_like(w)
            w = w / np.sum(w) * float(block_indices.size)

            sub_tally = float(np.dot(w, diff[block_indices]))
            beta_sub = float(parameters['beta_sub'])
            eps_sub = float(parameters['epsilon_sub'])
            eps_sub_size = float(parameters['epsilon_sub_size'])
            extra = max(0.0, float(block_indices.size) - 3.0)
            eps_eff = float(np.clip(eps_sub + eps_sub_size * extra, 0.0, 0.95))

            if abs(sub_tally) > 1e-12:
                core = stable_softmax(np.array([sub_tally, -sub_tally]), beta_sub)
                probs = (1.0 - eps_eff) * core + eps_eff * np.array([0.5, 0.5])
                probs = np.clip(probs, 0.005, 0.995)
                return probs / np.sum(probs)
            return np.array([0.5, 0.5])
        return np.array([0.5, 0.5])

    near_bound = float(parameters['near_bound'])
    n_low_conf = int(parameters['n_low_conf'])
    low_conf = (n_features >= n_low_conf and abs(tally) <= near_bound)

    if low_conf:
        beta = float(parameters['beta_near'])
        eps = float(parameters['epsilon_near'])
    else:
        beta = beta_tally
        eps = epsilon_tally

    core = stable_softmax(np.array([tally, -tally]), beta)
    return lapse_mix(core, eps)
```

**`policy source code`:**
```python
import numpy as np


def policy(probs):
    p = np.asarray(probs, dtype=np.float64)
    p = np.clip(p, 0.0, None)
    total = float(p.sum())
    if total <= 0.0:
        p = np.ones_like(p) / len(p)
    else:
        p = p / total
    return int(np.random.choice(len(p), p=p))
```


## COMPETING THEORY
**Description:** People choose by a confidence-gated unweighted signed tally. On clear tallies, choice follows the tally through a moderate softmax plus a small lapse. When the tally is tied or nearly tied, people may switch to a restricted sub-tally only if the advertised cue validities themselves flag a small coherent elite (two to three cues separated from the rest, or a large validity gap with at most six top cues). Critically, that restricted block is not defined by validity alone: cues are re-ranked by a mixture of advertised validity and serial display position, where later cues receive exponentially greater recency weight. This allows late relevant cues to dominate early equally-valid cue blocks, producing reversals like Experiment 10 while preserving validity use in Experiments 3 and 4. Large-feature environments with small tallies are treated as low confidence and heavily regularized with near-chance lapse, preventing deterministic regression blow-ups.

**Parameters:**
- beta_tally: [0.6, 1.0]
- epsilon_tally: [0.02, 0.08]
- beta_near: [0.3, 0.6]
- epsilon_near: [0.80, 0.97]
- near_tally_bound: {1.5}
- n_low_conf: {15}
- tau_tie: {0.5}
- top_tol: {0.001}
- small_size_min: {2}
- small_size_max: {3}
- gap_lo: [0.05, 0.10]
- gap_hi: [0.30, 0.45]
- block_max: {6}
- rho: [0.60, 1.00]
- beta_sub: [0.60, 1.00]
- epsilon_sub: [0.05, 0.10]
- validities: validities

**`predict source code`:**
```python
import numpy as np


def predict(parameters, state, history):
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError('Expected a (2, n_features) stimulus.')

    validities = np.asarray(parameters['validities'], dtype=float)
    n_features = stim.shape[1]
    if validities.shape[0] != n_features:
        raise ValueError('validities length mismatch.')

    a = stim[0]
    b = stim[1]
    diff = a - b
    tally = float(np.sum(diff))
    positions = np.arange(n_features, dtype=float)

    def stable_softmax(scores, inv_temp):
        scores = np.asarray(scores, dtype=float)
        z = inv_temp * (scores - np.max(scores))
        z = np.clip(z, -30.0, 30.0)
        e = np.exp(z)
        return e / np.sum(e)

    def lapse_mix(core, eps):
        probs = (1.0 - eps) * core + eps * np.array([0.5, 0.5])
        probs = np.clip(probs, 0.005, 0.995)
        total = float(np.sum(probs))
        if total <= 1e-12:
            return np.array([0.5, 0.5])
        return probs / total

    vmax = float(np.max(validities))
    top_tol = float(parameters['top_tol'])
    top_mask = validities >= (vmax - top_tol)
    top_size = int(np.sum(top_mask))

    if top_size < n_features:
        second_max = float(np.max(validities[~top_mask]))
    else:
        second_max = vmax
    validity_gap = vmax - second_max

    gap_hi = float(parameters['gap_hi'])
    gap_lo = float(parameters['gap_lo'])
    size_min = int(parameters['small_size_min'])
    size_max = int(parameters['small_size_max'])
    block_max = int(parameters['block_max'])

    small_elite = (size_min <= top_size <= size_max) and (validity_gap >= gap_lo)
    block_clear = (validity_gap >= gap_hi) and (top_size <= block_max)
    salience = 1.0 if (small_elite or block_clear) else 0.0

    tau_tie = float(parameters['tau_tie'])

    if salience > 0.5 and abs(tally) <= tau_tie:
        rho = float(parameters['rho'])

        # Stable recency-weighted cue relevance. Subtracting the max position
        # prevents overflow while preserving the ranking and normalized weights.
        combined = np.asarray(validities, dtype=float) * np.exp(
            rho * (positions - positions.max())
        )

        order = np.argsort(-combined)
        selected = order[:top_size]
        if selected.size == 0:
            return np.array([0.5, 0.5])

        sel_weights = combined[selected]
        denom = float(np.sum(sel_weights))
        if denom <= 1e-12:
            weights = np.ones_like(sel_weights)
        else:
            weights = sel_weights / denom * float(selected.size)

        sub_tally = float(np.dot(weights, diff[selected]))

        beta_sub = float(parameters['beta_sub'])
        eps_sub = float(parameters['epsilon_sub'])

        if abs(sub_tally) > 1e-12:
            core = stable_softmax(np.array([sub_tally, -sub_tally]), beta_sub)
            return lapse_mix(core, eps_sub)

        return np.array([0.5, 0.5])

    near_bound = float(parameters['near_tally_bound'])
    n_low_conf = int(parameters['n_low_conf'])

    if abs(tally) <= near_bound and n_features >= n_low_conf:
        beta = float(parameters['beta_near'])
        eps = float(parameters['epsilon_near'])
    else:
        beta = float(parameters['beta_tally'])
        eps = float(parameters['epsilon_tally'])

    core = stable_softmax(np.array([tally, -tally]), beta)
    return lapse_mix(core, eps)
```

**`policy source code`:**
```python
import numpy as np


def policy(probs):
    p = np.asarray(probs, dtype=np.float64)
    p = np.clip(p, 0.0, None)
    total = float(p.sum())
    if total <= 0.0:
        p = np.ones_like(p) / len(p)
    else:
        p = p / total
    return int(np.random.choice(len(p), p=p))
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
  "metric_source": "def metric(data: pd.DataFrame) -> float:\n    import numpy as np\n\n    a = np.asarray(data['option_a_ratings'].tolist(), dtype=float)\n    b = np.asarray(data['option_b_ratings'].tolist(), dtype=float)\n\n    positions = np.array([5.0, 6.0, 7.0])\n    rho = 0.65\n    weights = np.exp(rho * (positions - 7.0))\n    weights = weights / weights.sum() * 3.0\n\n    late_diff = a[:, 5:8] - b[:, 5:8]\n    weighted_late_tally = late_diff @ weights\n\n    chose_a = 1.0 - data['response'].to_numpy(dtype=float)\n    return float(np.mean(weighted_late_tally * chose_a))",
  "rationale": "This is a balanced recency-weighted late-block contrast. Every pair in the design has zero total signed tally, so the competing theory predicts a flat 0.5 choice rate on every trial and the expected value of this contrast is zero. The advocated theory opens the homogeneous last three low-validity features through the negative validity drop, and on tally ties choice follows a recency-weighted sub-tally there. Thus A choices should align with a positive weighted late tally and B choices with a negative one, producing a large positive expected contrast. The fixed rho=0.65 is central to the advocated recency parameter range, and normalizing the three late weights to sum to 3 gives a bounded, interpretable per-trial score. Each subject completes 16 repetitions of all six symmetric pair types, so the per-subject estimate remains stable."
}
```

## Usage

```json
{
  "input_tokens": 6803,
  "output_tokens": 17501,
  "reasoning_tokens": 17122,
  "provider": "Baidu"
}
```
