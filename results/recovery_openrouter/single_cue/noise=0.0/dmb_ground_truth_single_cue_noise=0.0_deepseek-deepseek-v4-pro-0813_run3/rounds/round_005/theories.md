# Round 5 — Theories

**Verdict:** `new_theory` (slot 2 replaced)

## Starting theories

### slot 1 — `pi_7` — SURVIVED ✓

**Description:** People choose by a confidence-gated unweighted signed tally. On clear tallies, choice follows the tally through a moderate softmax plus a small lapse. When the tally is tied or nearly tied, people may switch to a restricted sub-tally only if the advertised cue validities themselves flag a small coherent elite (two to three cues separated from the rest, or a large validity gap with at most six top cues). Critically, that restricted block is not defined by validity alone: cues are re-ranked by a mixture of advertised validity and serial display position, where later cues receive exponentially greater recency weight. This allows late relevant cues to dominate early equally-valid cue blocks, producing reversals like Experiment 10 while preserving validity use in Experiments 3 and 4. Large-feature environments with small tallies are treated as low confidence and heavily regularized with near-chance lapse, preventing deterministic regression blow-ups.

**Rationale:** The default remains the signed tally, which already reproduces Experiments 1, 2, 5, and 7. The new contribution is a recency-weighted restricted sub-tally: when a tie occurs and the validity configuration advertises a small elite, the model selects a small block by re-ranking cues with validity * exp(rho * position). Setting rho high makes late blocks dominate early equally-valid blocks, which fixes the negative Experiment 10 contrast while leaving late high-validity blocks in Experiments 3 and 4 strongly preferred. The gate is deliberately narrow: small elite size is capped at 3 and requires at least a 0.05-0.10 gap, so Experiment 6's four-cue late block and Experiments 7 and 8 do not trigger validity use. Large-feature, small-tally trials receive epsilon_near of 0.80-0.97, keeping Experiments 8 and 9 near chance and avoiding the variance blow-ups of earlier theories. All logits are bounded, probabilities are clipped, and the use of moderate beta values regularizes per-subject regression estimates.

**Parameters:**
  - `beta_tally`: `[0.6, 1.0]`
  - `epsilon_tally`: `[0.02, 0.08]`
  - `beta_near`: `[0.3, 0.6]`
  - `epsilon_near`: `[0.80, 0.97]`
  - `near_tally_bound`: `{1.5}`
  - `n_low_conf`: `{15}`
  - `tau_tie`: `{0.5}`
  - `top_tol`: `{0.001}`
  - `small_size_min`: `{2}`
  - `small_size_max`: `{3}`
  - `gap_lo`: `[0.05, 0.10]`
  - `gap_hi`: `[0.30, 0.45]`
  - `block_max`: `{6}`
  - `rho`: `[0.60, 1.00]`
  - `beta_sub`: `[0.60, 1.00]`
  - `epsilon_sub`: `[0.05, 0.10]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
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

**`policy(probs)`:**
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


### slot 2 — `pi_6` — KILLED ✗

**Description:** Tally-first choice with a salience-gated and size-regularized validity tie-break. On every trial the unweighted signed tally of the feature differences is the default choice signal. When the tally is clear, choice follows it through a moderate softmax plus an explicit lapse. When the tally is tied or near-tied, validity is allowed to matter only if the task's validity distribution itself advertises a clear elite: either a small elite block of two to three maximally valid cues separated from the remaining cues, or a large validity gap combined with a bounded elite-block size. In those gated cases people compute a restricted sub-tally over the elite cues and choose its favored option stochastically. Larger elite blocks receive an additional lapse, preventing overconfident validity-following for wide top tiers. In large stimulus arrays, near-zero tallies are treated as low-confidence and are heavily regularized with extra choice noise, so deterministic regression blows-up do not occur.

**Rationale:** The previous pi_5 model failed most severely in Experiment 8 because its validity-free tally route was nearly deterministic, producing enormous z_d values. The proposed model fixes this with moderate tally gain and strong trial-level lapse, and in large stimulus arrays near-zero tallies receive especially heavy lapse because those choices are treated as low-confidence. Validity is not continuously mixed into every trial, avoiding pi_3's distortion of the Experiment 2 tally-only slope. The validity route is gated by static validity salience plus the current tally tie, not by history-window tie prevalence. The gate is calibrated to fire for the small elite block in Experiment 4 and the large-gap bounded elite block in Experiment 3, while remaining off in Experiments 1, 2, 5, 6, 7, and 8, whose human validity-following metrics are near chance. Adding extra lapse for larger elite blocks keeps Experiment 3's validity-following below the metric cap instead of saturating it.

**Parameters:**
  - `beta_tally`: `[2.0, 4.0]`
  - `epsilon_tally`: `[0.02, 0.08]`
  - `beta_near`: `[0.3, 0.8]`
  - `epsilon_near`: `[0.78, 0.97]`
  - `near_tally_bound`: `{1.5}`
  - `n_low_conf`: `{15}`
  - `tau_tie`: `[0.0, 0.5]`
  - `salience_gap_hi`: `[0.30, 0.45]`
  - `salience_gap_lo`: `[0.04, 0.06]`
  - `top_tol`: `{0.01}`
  - `top_size_small_min`: `{2}`
  - `top_size_small_max`: `{3}`
  - `top_size_block_max`: `{6}`
  - `beta_sub`: `[0.35, 0.50]`
  - `epsilon_sub`: `[0.08, 0.14]`
  - `epsilon_sub_size`: `[0.16, 0.20]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
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

    vmax = float(np.max(validities))
    top_tol = float(parameters['top_tol'])
    top_mask = validities >= (vmax - top_tol)
    top_size = int(np.sum(top_mask))

    if top_size < n_features:
        second_max = float(np.max(validities[~top_mask]))
    else:
        second_max = vmax
    validity_gap = vmax - second_max

    gap_hi = float(parameters['salience_gap_hi'])
    gap_lo = float(parameters['salience_gap_lo'])
    size_min = int(parameters['top_size_small_min'])
    size_max = int(parameters['top_size_small_max'])
    block_max = int(parameters['top_size_block_max'])

    block_clear = (validity_gap >= gap_hi) and (top_size <= block_max)
    small_elite = (size_min <= top_size <= size_max) and (validity_gap >= gap_lo)
    salience = 1.0 if (block_clear or small_elite) else 0.0

    def stable_softmax(scores, inv_temp):
        scores = np.asarray(scores, dtype=float)
        z = inv_temp * (scores - np.max(scores))
        z = np.clip(z, -30.0, 30.0)
        e = np.exp(z)
        return e / np.sum(e)

    tau_tie = float(parameters['tau_tie'])

    if salience > 0.5 and abs(tally) <= tau_tie:
        top_diff = diff[top_mask]
        sub_a = float(np.sum(top_diff > 0.0))
        sub_b = float(np.sum(top_diff < 0.0))
        sub_tally = sub_a - sub_b

        beta_sub = float(parameters['beta_sub'])
        eps_sub = float(parameters['epsilon_sub'])
        eps_sub_size = float(parameters['epsilon_sub_size'])
        eps_sub_eff = eps_sub + eps_sub_size * max(0.0, float(top_size) - 3.0)
        eps_sub_eff = float(np.clip(eps_sub_eff, 0.0, 0.95))

        if abs(sub_tally) > 1e-12:
            core = stable_softmax(np.array([sub_tally, -sub_tally]), beta_sub)
            probs = (1.0 - eps_sub_eff) * core + eps_sub_eff * np.array([0.5, 0.5])
        else:
            probs = np.array([0.5, 0.5])
        return probs

    near_bound = float(parameters['near_tally_bound'])
    n_low_conf = int(parameters['n_low_conf'])

    if abs(tally) <= near_bound and n_features >= n_low_conf:
        beta = float(parameters['beta_near'])
        eps = float(parameters['epsilon_near'])
    else:
        beta = float(parameters['beta_tally'])
        eps = float(parameters['epsilon_tally'])

    core = stable_softmax(np.array([tally, -tally]), beta)
    probs = (1.0 - eps) * core + eps * np.array([0.5, 0.5])
    probs = np.clip(probs, 0.0, None)
    total = float(np.sum(probs))
    if total <= 0.0:
        return np.array([0.5, 0.5])
    return probs / total
```

**`policy(probs)`:**
```python
import numpy as np


def policy(probs):
    p = np.asarray(probs, dtype=np.float64)
    p = np.clip(p, 0.0, None)
    total = p.sum()
    if total <= 0.0:
        p = np.ones_like(p) / len(p)
    else:
        p = p / total
    return int(np.random.choice(len(p), p=p))
```


## Replacement

### `pi_8` → slot 2 (via `new_theory`)

**Description:** People make binary-feature choices by a tally-first rule. When the unweighted signed tally is clearly nonzero, choice follows the tally through a softmax plus a small lapse. When the tally is tied or near-tied, advertised validities are used only to perceptually segment the cue display, and choice follows a recency-weighted sub-tally of a coherent late block if one is formed. Four segmentation routes can open such a block: (1) a large validity jump opening a later block of up to six cues; (2) a modest positive end boundary isolating a small two-to-three-cue late block; (3) a modest negative end drop isolating a homogeneous late low-validity block of two to three cues; and (4) a cumulative-contrast route, restricted to short displays of up to eight cues, that opens a homogeneous final two-to-three-cue block when its mean validity sits sufficiently below the immediately preceding two-to-three cues. For six-cue displays specifically, a homogeneous early elite followed by a uniformly lower late block is treated as a distinct late block even when the adjacent validity jump is moderate. When no perceptual block is formed, the tied choice is low confidence and is near chance.

**Rationale:** This is a minimal-diff edit on the accepted iter-5 base, focused on the binding Experiment 10 failure. The previous candidate kept Experiment 10 near chance because its late low-validity block never opened on the top-plus-3 versus top-minus-3 tied trials. I made three targeted changes. First, the three-cue cumulative-contrast lower bound is reduced from [0.18, 0.22] to [0.10, 0.16], and the late-block homogeneity tolerance is widened to [0.25, 0.45], so more of the Experiment 10 validity pattern qualifies. To keep Experiment 1 protected, the two-cue cumulative-contrast route now uses a separate, higher lower bound, contrast_lo_2 [0.20, 0.24], which blocks Experiment 1's two-cue contrast of about 0.17. Second, the negative adjacent-drop route is broadened upward to drop_hi [0.19, 0.35] and is now gated to short displays of at most eight cues, closing the dead zone between the old negative-drop upper bound and the large-boundary threshold without disturbing large-display experiments. Third, I added a short six-cue fallback: if the first three cues form a homogeneous elite and the last three cues are uniformly lower, the last three cues are treated as a distinct late block. This directly opens Experiment 10's late low block while leaving Experiment 1 closed because its first three validities span about 0.16, above the tight elite-flatness bound. Tally-route parameters and the sub-tally strength were deliberately left untouched because prior attempts to strengthen the large-display tally route were rejected by the gate.

**Parameters:**
  - `beta_tally_small`: `[0.60, 0.95]`
  - `beta_tally_large`: `[0.95, 1.45]`
  - `epsilon_tally_small`: `[0.02, 0.06]`
  - `epsilon_tally_large`: `[0.02, 0.06]`
  - `beta_near`: `[0.15, 0.35]`
  - `epsilon_near`: `[0.75, 0.95]`
  - `near_bound`: `{1.5}`
  - `n_low_conf`: `{15}`
  - `tau_tie`: `{0.5}`
  - `gap_hi`: `[0.32, 0.42]`
  - `gap_lo`: `[0.05, 0.08]`
  - `gap_lo_max`: `[0.18, 0.25]`
  - `drop_lo`: `[0.11, 0.14]`
  - `drop_hi`: `[0.19, 0.35]`
  - `drop_flat_tol`: `[0.05, 0.12]`
  - `block_size_min_hi`: `{2}`
  - `block_size_max_hi`: `{6}`
  - `block_size_min_lo`: `{2}`
  - `block_size_max_lo`: `{3}`
  - `contrast_lo`: `[0.10, 0.16]`
  - `contrast_lo_2`: `[0.20, 0.24]`
  - `contrast_hi`: `[0.40, 0.55]`
  - `contrast_flat_tol`: `[0.25, 0.45]`
  - `contrast_prev_flat_tol`: `[0.04, 0.12]`
  - `contrast_max_features`: `{8}`
  - `short6_elite_flat`: `[0.02, 0.06]`
  - `short6_late_flat`: `[0.25, 0.50]`
  - `short6_gap`: `[0.03, 0.10]`
  - `rho`: `[0.40, 0.90]`
  - `beta_sub`: `[0.50, 0.68]`
  - `epsilon_sub`: `[0.14, 0.21]`
  - `epsilon_sub_size`: `[0.08, 0.13]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
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

**`policy(probs)`:**
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
