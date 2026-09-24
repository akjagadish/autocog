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
**Validities (n_features=8):** [0.95, 0.88, 0.78, 0.7, 0.62, 0.5, 0.5, 0.5]

**Trial pairs (n=16):**
  trial 1: A=[1, 1, 1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0]
  trial 2: A=[1, 1, 1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0]
  trial 3: A=[0, 1, 1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0]
  trial 4: A=[1, 1, 1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0]
  trial 5: A=[1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0]
  trial 6: A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0]
  trial 7: A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1]
  trial 8: A=[0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0]
  trial 9: A=[0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1]
  trial 10: A=[0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 0]
  trial 11: A=[0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1, 1, 1]
  trial 12: A=[0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 0, 0, 0]
  trial 13: A=[0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0]
  trial 14: A=[0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  trial 15: A=[0, 0, 0, 0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  trial 16: A=[1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 1, 1]

**Rationale:** RFI-delta and SPI are nearly observationally equivalent at the pooled/trial level: both compute p = (1-eps)*[(1-m)*sigmoid(beta*E) + m*(1-sigmoid(beta*E))] + eps/2 over the same near-flat weighted sparsity evidence E, and SPI's parameter box (gamma in [0,2], beta in [0.5,20], rho in [0,0.35], eps in [0.05,0.35]) CONTAINS the shape any single RFI subject can produce. No pooled choice proportion can separate them. The ONE structural difference is the population architecture: RFI-delta has a stable per-subject trait with P(s=-1)=pi~0.94 plus a small per-trial slip delta<=0.12, so it predicts a BIMODAL subject population -- a dominant anti-endorsement cluster whose per-subject p(sparse option) on extreme trials is tightly boxed in [0.82, 0.92] (slip and lapse cap extremity: max = (1-eps)*[(1-delta)*sigma(beta)+delta*(1-sigma(beta))]+eps/2 <= ~0.92) and a ~6% conventional-minority cluster at p(sparse) ~ [0.08, 0.18] -- with an empirically EMPTY middle band (0.2, 0.8). SPI's box mathematically FORBIDS any subject below ~0.52 on a unanimous trial: min over eps=0.35, rho=0.35, beta=0.5 of (1-eps)*[(1-rho)*sigma(beta*E)+rho*(1-sigma(beta*E))]+eps/2 = 0.524 at E=1; more generally SPI's p_core >= 0.5 whenever E >= 0 (since rho <= 0.35 < 0.5), so NO SPI subject can prefer the endorsed side on ANY non-negative-evidence cell. Therefore the design must make per-subject p(sparse) precisely estimable: 3 extreme cells (E in [0.85, 1.0]) plus their mirrors give 6 pairs x K=6 = 36 high-|E| trials per subject (SE ~ 0.05), enough to classify each subject into majority (>0.8), minority (<0.2), or forbidden-middle bands. DESIGN (8 features, validities [0.95, 0.88, 0.78, 0.70, 0.62, 0.55, 0.52, 0.50], well spread, sum 5.50): (1) UNANIMOUS ladder T1-T6 sweeps weighted anti-endorsement evidence E for the all-zeros (sparse) option from 1.00 (T1: 8-vs-0) down through 0.89/0.85 (T2/T3: 7-vs-0 skipping the lowest vs highest cue -- a gamma probe: flat weighting (gamma=0) predicts T2 = T3 exactly, any gamma>0 predicts T2 > T3), 0.67 (T4: 5-vs-0), 0.42 (T5: 3-vs-0), to 0.15 (T6: 1-vs-0 on the top cue). RFI majority (mid-box: gamma=0.5, beta=5, delta=0.10, eps=0.04) predicts p(sparse) ~ 0.88, 0.87, 0.87, 0.86, 0.79, 0.61 -- a graded monotone psychometric; the RFI MINORITY shows the full MIRRORED ladder (~0.12 ... 0.39), which SPI cannot generate for any subject on the top rungs. (2) GAMMA cell T7: A endorsed only on cue 1 (0.95), B endorsed on cues 6-8 (0.55/0.52/0.50). Count says A is sparser (1 vs 3 ones); RFI's box (gamma <= 1) gives E in [+0.11, +0.25], so RFI sign-robustly predicts p(A) in [0.56, 0.79] -- never below 0.5. SPI at gamma=2 flips the weighted sign (0.9025 > 0.8229) and can prefer B; if observed p(A) < 0.5, RFI is falsified while steep-gamma SPI survives -- an accepted adversarial risk that tests RFI's flat-weighting commitment. (3) Tie controls T8/T16 (identical vectors) verify both theories' exact-50% prediction and catch key bias. Mirrors T9-T15 cancel side bias; analysis pools by sparse-option side. DECISIVE QUANTITATIVE SIGNATURES: (a) subject-level bimodality on the 36 extreme trials: dominant mode in [0.82, 0.92], small second mode in [0.08, 0.18], empty band 0.2-0.8 (RFI) vs a unimodal/continuous population with a hard floor at ~0.52 and NO subject below 0.5 (SPI); even ONE subject with per-subject p(sparse) < 0.5 on positive-E cells falsifies SPI, while RFI requires ~pi (~6%) of subjects there -- hence N >= 40-60 subjects (expect 2-4 conventional subjects in 50). (b) minority subjects show a complete mirrored psychometric (p(sparse) rising toward 0.5 as E shrinks: ~0.12 on T1, ~0.39 on T6, ~0.46 on T7), impossible under SPI where p_core >= 0.5 for all E >= 0. (c) RFI's extremity cap: NO majority subject may exceed ~0.92 on T1 (delta >= 0.08, eps <= 0.08); SPI permits up to 0.975, so a population of subjects at 0.95+ falsifies RFI. (d) monotone ladder T1 >= T2 > T3 > T4 > T5 > T6 > T7 with T2-T3 as a flat-vs-steep weighting probe. Both theories are thus sharply falsifiable, but only RFI predicts the two-attenuated-clusters signature, and only SPI is compatible with a homogeneous middle -- the population distribution over per-subject extreme-cell proportions is the arbiter.

**Computed schedule:** 16 unique pairs × 6 reps = 96 trials per subject.



## ADVOCATED THEORY
**Description:** Red-Flag Integration with Trait Polarity and Attentional Slip (RFI-delta). When choosing between two products described by binary expert ratings, a large majority of subjects read a rating of 1 as a 'red flag' — evidence AGAINST the option carrying it — so the sparser option is perceived as higher quality; a small minority reads polarity conventionally. Polarity is a stable PER-SUBJECT trait: subject i carries a fixed sign s_i ∈ {+1, -1} drawn once, with P(s_i = -1) = pi at the population level (pi near the arbiter's ceiling, ~0.94). On top of the trait, each subject occasionally suffers a small attentional slip: on any given trial, with probability delta (≈0.10), the subject momentarily reverts to the opposite (instructed-mapping) polarity for that trial alone. The slip is structured exactly like a lapse — a transient per-trial reversion against a stable dominant trait — not a reopening of per-trial polarity mixing, and it is kept small (delta ≤ 0.12). Within a trial, all cues are integrated additively with near-flat validity weighting: evidence for A over B is E = s · Σ_j w_j (a_j − b_j), w_j ∝ v_j^gamma. Choice is a softmax over [E, −E] with per-subject inverse temperature beta plus an independent lapse epsilon to uniform; identical rating vectors yield exactly 50%. The slip attenuates each subject's effective extremity by (1 − 2·delta) and the population's effective anti-endorsement signal to q_eff = pi(1−delta) + (1−pi)delta ≈ 0.85, which simultaneously pulls the pooled point estimates back from saturation toward the observed moderate magnitudes and compresses the between-subject mixture variance 4·pi(1−pi)·((1−2·delta)·x)^2 toward the tight real values — while preserving the falsifiable subject-level bimodality signature (two attenuated polarity clusters, not one homogeneous middle).

**Parameters:**
- pi: [0.94, 0.95]
- polarity_u: [0, 1]
- delta: [0.08, 0.12]
- gamma: [0, 1]
- beta: [3, 8]
- epsilon: [0, 0.08]
- validities: validities

**`predict source code`:**
```python
def predict(parameters, state, history):
    # Red-Flag Integration with Trait Polarity + attentional slip (RFI-delta).
    # Stimulus: array-like of shape (2, n_features); row 0 = option A,
    # row 1 = option B; entries are 0/1 cue values. History is ignored
    # (no feedback in this task).
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"RFI expects a (2, n_features) stimulus; got shape {stim.shape}."
        )
    n_features = stim.shape[1]

    val = np.asarray(parameters["validities"], dtype=float)
    if val.shape[0] != n_features:
        raise ValueError(
            f"validities length {val.shape[0]} != n_features {n_features}."
        )

    gamma = float(parameters["gamma"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    pi = float(parameters["pi"])
    u = float(parameters["polarity_u"])
    delta = float(parameters["delta"])

    # Trait polarity: drawn ONCE per subject (both parameters are fixed
    # for the entire subject run). s = -1 -> red-flag reading (rating of 1
    # is evidence AGAINST the carrying option); s = +1 -> conventional
    # reading (endorsement favors the carrying option). At the population
    # level P(s = -1) = E[pi] with pi in [0.94, 0.95], i.e. an
    # anti-endorsement majority near the arbiter's ceiling and a small
    # (~5%) conventional minority.
    s = -1.0 if u < pi else 1.0

    # Near-flat validity weighting: w_j = v_j^gamma, gamma in [0, 1].
    # Normalization is a per-experiment constant rescale (validities are
    # fixed), absorbed by beta; it keeps the evidence scale O(1) for any
    # gamma and any n_features.
    w = np.power(val, gamma)
    w_sum = w.sum()
    if w_sum > 0:
        w = w / w_sum
    else:
        w = np.full(n_features, 1.0 / n_features)

    a, b = stim[0], stim[1]
    # Signed additive evidence for A over B. With s = -1 each endorsement
    # carried by A counts AGAINST A and each endorsement carried by B
    # counts FOR A (the sparser option accumulates evidence).
    E = s * float(np.sum(w * (a - b)))

    # Softmax over [E, -E] with max-subtraction for numerical stability.
    # Identical rating vectors give E = 0 -> exactly 50/50.
    scores = np.array([E, -E])
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_trait = e / e.sum()

    # Attentional slip: with probability delta the subject momentarily
    # reverts to the OPPOSITE polarity mapping for this trial alone.
    # The opposite-polarity distribution is the mirror of p_trait, so the
    # per-trial choice distribution is a (1-delta)/delta mixture of the
    # two mirrors. This is the expectation of a per-trial Bernoulli slip
    # against a stable dominant trait (lapse-structured, small delta),
    # NOT per-trial polarity mixing: the trait sign is still fixed per
    # subject and the slip only attenuates each subject's extremity by
    # (1 - 2*delta).
    p_slip = p_trait[::-1]
    p_core = (1.0 - delta) * p_trait + delta * p_slip

    # Independent lapse to uniform choice.
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)
```

**`policy source code`:**
```python
def policy(probs):
    probs = np.asarray(probs, dtype=np.float64)
    probs = probs / probs.sum()  # Guard against float drift.
    return np.random.choice(len(probs), p=probs)
```


## COMPETING THEORY
**Description:** Sparse-Option Preference / Polarity-Inverted Evidence Integration (SPI). When choosing between two options described by binary expert ratings, a substantial share of subjects systematically mis-map cue polarity: an endorsement (rating = 1) is treated as evidence AGAINST an option, so the option with FEWER 1s (the sparser option) is perceived as higher quality — consistent with a 'fewer red flags' reading of the display or a rarity-implies-quality inference. Subjects integrate ALL cues additively with near-uniform weights: the evidence for option A over B is E = sum_j w_j * (b_j - a_j), where w_j = v_j^gamma with gamma small (validity plays at most a mild role). Choice is a softmax over [E, -E] with inverse temperature beta, plus an independent lapse epsilon to uniform. A per-subject polarity-mixing weight rho captures heterogeneity: with probability 1-rho the subject responds according to the inverted (sparse-preferring) polarity, with probability rho according to the conventional polarity. This mixture attenuates the extreme pure-sparse predictions toward the moderately negative values observed. The theory is sharply distinguished from both incumbents: unlike Take-The-Best it uses all cues and inverts the evidence sign (so it is not pinned at ~0 on the depth/conflict-invariance and margin-slope metrics where TTB is structurally stuck), and unlike power-weighted integration it places humans at the FLAT end of the weighting ladder with inverted polarity, producing the negative signatures that steep-gamma PWEI cannot generate at any parameter setting.

**Parameters:**
- gamma: [0, 2]
- beta: [0.5, 20]
- epsilon: [0.05, 0.35]
- rho: [0, 0.35]
- validities: validities

**`predict source code`:**
```python
def predict(parameters, state, history):
    # Sparse-option Preference / Polarity-Inverted Evidence Integration (SPI).
    # Stimulus: array-like of shape (2, n_features); row 0 = option A,
    # row 1 = option B; entries are 0/1 cue values. History is ignored
    # (no feedback in this task).
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"SPI expects a (2, n_features) stimulus; got shape {stim.shape}."
        )
    n_features = stim.shape[1]

    val = np.asarray(parameters["validities"], dtype=float)
    if val.shape[0] != n_features:
        raise ValueError(
            f"validities length {val.shape[0]} != n_features {n_features}."
        )

    gamma = float(parameters["gamma"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    rho = float(parameters["rho"])

    # Near-uniform validity weighting: w_j = v_j^gamma, gamma in [0, 2].
    # Normalization is a per-experiment constant rescale (validities are
    # fixed), absorbed by beta; it keeps the evidence scale O(1) for any
    # gamma and any n_features.
    w = np.power(val, gamma)
    w_sum = w.sum()
    if w_sum > 0:
        w = w / w_sum
    else:
        w = np.full(n_features, 1.0 / n_features)

    a, b = stim[0], stim[1]
    # Polarity-INVERTED evidence for A over B: each cue where B carries
    # the endorsement (1) counts FOR A; each cue where A carries the
    # endorsement counts AGAINST A. Sparse options accumulate evidence.
    E = float(np.sum(w * (b - a)))

    # Softmax over [E, -E] with max-subtraction for numerical stability.
    # Inverted polarity: positive E favors A (the sparser option).
    scores_inv = np.array([E, -E])
    z = beta * (scores_inv - scores_inv.max())
    e = np.exp(z)
    p_inv = e / e.sum()

    # Conventional polarity (endorsement favors the option carrying it):
    # mirror of the inverted distribution.
    scores_norm = -scores_inv
    z2 = beta * (scores_norm - scores_norm.max())
    e2 = np.exp(z2)
    p_norm = e2 / e2.sum()

    # Per-subject polarity mixture: (1 - rho) inverted, rho conventional.
    p_core = (1.0 - rho) * p_inv + rho * p_norm

    # Independent lapse to uniform choice.
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)
```

**`policy source code`:**
```python
def policy(probs):
    probs = np.asarray(probs, dtype=np.float64)
    probs = probs / probs.sum()  # Guard against float drift.
    return np.random.choice(len(probs), p=probs)
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
  "metric_source": "def metric(data: pd.DataFrame) -> float:\n    # Per-subject choice CONSISTENCY (extremity) toward the sparse option on\n    # near-unanimous trials (one option all-zeros, the other endorsed on at\n    # least n_features-1 cues), averaged over subjects.\n    #\n    # RFI-delta: polarity is a stable per-subject trait with only a small\n    # attentional slip (delta <= 0.12) and small lapse (eps <= 0.08), so EVERY\n    # subject -- majority (anti-endorsement) and minority (conventional)\n    # alike -- is strongly and stably consistent on these trials:\n    # per-subject p(sparse) is either ~[0.80, 0.92] or its mirror ~[0.08, 0.20],\n    # i.e. |2p-1| ~ [0.6, 0.85] for essentially all subjects, with tight\n    # between-subject spread.\n    #\n    # SPI: the wide lapse/polarity-mixing boxes (eps in [0.05, 0.35],\n    # rho in [0, 0.35], beta in [0.5, 20]) mean per-subject attenuation varies\n    # enormously; the average subject sits much closer to chance (mean\n    # |2p-1| far below RFI's), and the population spread is wide.\n    # The absolute value makes the statistic polarity-symmetric, so RFI's\n    # small conventional minority does NOT inflate the between-subject\n    # variance (both clusters have the same extremity).\n\n    a_ratings = data['option_a_ratings'].tolist()\n    b_ratings = data['option_b_ratings'].tolist()\n    resp = data['response'].astype(float).values\n    subj = data['subject_id'].values\n\n    n = len(data)\n    a_sum = np.empty(n, dtype=float)\n    b_sum = np.empty(n, dtype=float)\n    n_feat = np.empty(n, dtype=float)\n    for i in range(n):\n        av = list(a_ratings[i])\n        bv = list(b_ratings[i])\n        a_sum[i] = float(np.sum(av))\n        b_sum[i] = float(np.sum(bv))\n        n_feat[i] = float(len(av))\n\n    # Near-unanimous trials: sparse side has zero endorsements, dense side\n    # is endorsed on all or all-but-one cue (E in ~[0.8, 1.0] for any\n    # weighting gamma in [0, 2]).\n    thresh = n_feat - 1.0\n    sparse_is_a = (a_sum == 0.0) & (b_sum >= thresh)\n    sparse_is_b = (b_sum == 0.0) & (a_sum >= thresh)\n    extreme = sparse_is_a | sparse_is_b\n\n    # 1 if the subject chose the all-zeros (sparse) option, else 0.\n    chose_sparse = np.where(sparse_is_a, 1.0 - resp, resp)\n\n    vals = []\n    for s in np.unique(subj[extreme]):\n        m = extreme & (subj == s)\n        if m.sum() == 0:\n            continue\n        p = float(np.mean(chose_sparse[m]))\n        vals.append(abs(2.0 * p - 1.0))\n\n    if len(vals) == 0:\n        return 0.0\n    return float(np.mean(vals))",
  "rationale": "The metric is the mean over subjects of each subject's absolute choice extremity |2p-1| on the 36 near-unanimous trials (one option all-zeros vs. >=7 endorsements; trials T1-T3 and their mirrors T9-T11, 6 reps each). It is computed per subject (so it works on a single subject's slice) and averaged over subjects when given the pooled data, making the pooled point estimate exactly the population mean of the per-subject values. WHY IT SEPARATES THE THEORIES: (1) RFI-delta's architecture is a stable per-subject trait with only a small slip (delta in [0.08,0.12]) and small lapse (eps in [0,0.08]). Every RFI subject -- whether in the anti-endorsement majority (p(sparse) in [0.80,0.92]) or the conventional minority (p(sparse) in [0.08,0.20]) -- is highly consistent on these high-evidence trials, so |2p-1| lands in roughly [0.6, 0.85] for ALL subjects. Expected value ~0.74 with small between-subject variance (~0.02, dominated by binomial noise over 36 trials). The absolute value is crucial: it renders the statistic polarity-symmetric, so RFI's bimodal population does NOT inflate the between-subject variance (both clusters share the same extremity). (2) SPI has no per-subject trait; its heterogeneity comes from wide per-subject boxes eps in [0.05,0.35], rho in [0,0.35], beta in [0.5,20]. The average SPI subject is heavily attenuated toward chance: at sigma~1 the extremity is approximately 1 - eps - 2rho + 2*eps*rho, whose box average is only ~0.5, and the ~13% of subjects with small beta are pulled much closer to 0.5. Expected value ~0.45-0.50 with large between-subject variance (~0.06-0.10) from the wide parameter box. The mean gap (~0.25) combined with RFI's tight per-subject stability yields a Welch t of roughly 4-6 at N=25, well below alpha=0.01, whereas the raw p(sparse) statistic fails because RFI's minority cluster inflates its between-subject variance and pooling dilutes the contrast. The metric is not trivially satisfied by construction: it would falsify RFI if humans showed heterogeneous attenuation (a homogeneous middle), and it would falsify SPI if a large share of subjects were near-chance on unanimous trials."
}
```

## Usage

```json
{
  "input_tokens": 6411,
  "output_tokens": 17418,
  "reasoning_tokens": 16036,
  "provider": "Sail Research"
}
```
