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
**Validities (n_features=8):** [0.98, 0.92, 0.85, 0.78, 0.68, 0.6, 0.5, 0.5]

**Trial pairs (n=24):**
  trial 1: A=[0, 0, 0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0]
  trial 2: A=[0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0, 0, 0]
  trial 3: A=[0, 0, 0, 0, 0, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 1, 1]
  trial 4: A=[0, 0, 0, 0, 0, 0, 1, 1]  B=[0, 0, 0, 0, 0, 1, 1, 1]
  trial 5: A=[0, 0, 0, 0, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0]
  trial 6: A=[0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 0, 0]
  trial 7: A=[0, 0, 0, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0]
  trial 8: A=[0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 0, 0]
  trial 9: A=[0, 0, 1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0]
  trial 10: A=[0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1, 0, 0]
  trial 11: A=[0, 1, 1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 1, 1]
  trial 12: A=[0, 0, 0, 0, 0, 0, 1, 1]  B=[0, 1, 1, 1, 1, 1, 1, 1]
  trial 13: A=[0, 1, 1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0]
  trial 14: A=[0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1, 1, 0]
  trial 15: A=[1, 1, 1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0]
  trial 16: A=[0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 0]
  trial 17: A=[1, 1, 1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0]
  trial 18: A=[0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1]
  trial 19: A=[1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1]
  trial 20: A=[0, 0, 0, 0, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0, 0, 0]
  trial 21: A=[1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 1, 1]
  trial 22: A=[0, 0, 0, 1, 1, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0, 0, 0]
  trial 23: A=[0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0]
  trial 24: A=[1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 1, 1]

**Rationale:** ADVOCATED: SPI. COMPETITOR: RFI-delta. The two theories are nearly observationally equivalent on any single pooled cell: both compute p(sparse) = (1-eps)*[(1-m)*sigmoid(beta*E) + m*(1-sigmoid(beta*E))] + eps/2 over the same near-flat weighted sparsity evidence E. The dissociation therefore lives entirely in their PARAMETER-BOX and POPULATION-ARCHITECTURE constraints, and the design is built to make those box boundaries empirically decisive. (1) RFI's per-subject box is narrow: beta in [3,8], epsilon in [0,0.08], delta in [0.08,0.12], gamma in [0,1], with a fixed per-subject polarity trait and a bimodal population (94-95% anti-endorsement majority, ~5% conventional minority). SPI's per-subject box is wide: beta in [0.5,20], epsilon in [0.05,0.35], rho in [0,0.35], gamma in [0,2], continuous population. Consequences exploited: (A) EXTREMITY FLOOR: on E~1 (unanimous) cells, an RFI majority subject must show p(sparse) >= 0.816 (min at beta=3, delta=0.12, eps=0.08) and <= ~0.92 (delta+eps cap); the RFI minority sits at <= 0.19; the band (0.2, 0.8) is EMPTY at the subject level, and RFI's POOLED p(sparse) on extreme cells is boxed in [0.78, 0.88]. SPI's central regime (e.g., gamma=0.5, beta=4, eps=0.20, rho=0.15) predicts p(sparse) ~= 0.77 on E=1 -- below RFI's per-subject floor and pooled floor -- and SPI's box places most subjects in 0.55-0.80, exactly RFI's forbidden middle. (B) WITHIN-SUBJECT SLOPE FLOOR: because RFI mandates beta >= 3, every RFI subject must show a rise of at least ~0.19 from the low-E cell (E~0.10-0.125) to the unanimous cell (E=1) (min rise ~0.19 at beta=8, delta=0.12, eps=0.08; typical ~0.25-0.28). SPI with beta <= 1.5 predicts rises of 0.06-0.15 -- shallow, attenuated psychometrics that RFI cannot generate for any subject. (C) GAMMA CEILING: RFI hard-caps gamma at 1; SPI allows gamma up to 2. Two validity-vs-count conflict cells (G1, G2) are constructed so that the count-sparser option's weighted evidence E is sign-robustly POSITIVE for all gamma in [0,1] (RFI must prefer the count-sparser option, p in [0.52, 0.76]) but NEGATIVE at gamma=2 (E = -0.096 and -0.121), so SPI subjects with gamma > ~1.3-1.55 prefer the count-DENSER option. Any observed p(count-sparser) < 0.5 on G1/G2 falsifies RFI while SPI survives. DESIGN: 8 cues with a wide, well-separated validity ladder [0.98 ... 0.50]. The E-ladder uses nested endorsement sets (A endorsed on cue 5; {5,6}; {4,5,6}; {3,4,5,6}; {2..6}; {2..7}; {1..7}; all 8) against an empty or low-tied opponent, so the rung ordering of E is invariant for EVERY gamma in [0,2] (E = .125/.116/.103; .125/.102/.080; .250/.218/.182; .375/.352/.317; .500/.497/.477; .625/.654/.665; .875/.915/.945; 1 -- values at gamma=0/1/2). Single mid-validity-cue differences (R1, R1c) have E ~= 0.08-0.125 nearly independent of gamma (weight normalization cancels), giving a gamma-robust low-E anchor; the 7-vs-0 and 8-vs-0 cells give gamma-robust extreme anchors. R1c and R5c are 'conflict-style' twins (both options carry endorsements; tied cues cancel exactly) so the sparse preference is not reducible to 'pick the empty bar'. Every informative cell has a mirrored twin (A/B swapped) so side bias cancels; analysis pools by sparse-option side. T0/T1 are identical-vector ties where both theories predict exactly 50% (key-bias check). 24 unique pairs x K=4 = 96 trials exactly; per subject this yields 16 observations on the pooled extreme cells (R7/R8 + mirrors) and 16 on the pooled low-E cells (R1/R1c + mirrors), enough (with N >= 60 subjects and a hierarchical mixture analysis) to locate each subject in the (p_low, p_high) plane. PREDICTED OUTCOMES -- if SPI is true: a CONTINUOUS per-subject distribution of p_high (sparse choice rate on extreme cells) with substantial mass in 0.55-0.80, i.e., inside RFI's forbidden middle band; per-subject psychometric rises spanning 0.05-0.30 (many below 0.19); pooled p_high on extreme cells ~0.70-0.80 (below RFI's 0.78 floor) or, if subjects are consistently sparse, possibly > 0.88 (above RFI's cap); no subject below 0.5 on positive-E cells (SPI's p_core >= 0.5 for E >= 0 since rho <= 0.35); G1/G2 can go below 0.5 for steep-gamma subjects. If RFI-delta is true: a BIMODAL subject population -- a dominant cluster with p_high in [0.82, 0.92], a ~5% cluster at p_high <= 0.19, an EMPTY band (0.2, 0.8); EVERY subject showing rise >= ~0.19 between low-E and extreme cells; pooled p_high on extreme cells within [0.78, 0.88]; p(count-sparser) > 0.5 on both gamma probes; ties at exactly 50%. DECISIVE QUANTITATIVE SIGNATURES: (a) population mass in the (0.25, 0.75) band of per-subject p_high (SPI) vs empty band with two tight clusters (RFI); (b) per-subject rise p_high - p_low < 0.19 for any subject (falsifies RFI, fits low-beta SPI); (c) pooled p_high outside [0.78, 0.88] (falsifies RFI in either direction); (d) p(count-sparser) < 0.5 on G1/G2 (falsifies RFI's gamma <= 1; SPI's gamma up to 2 survives); (e) any single subject with p_high < 0.45 on E >= 0.875 cells (falsifies SPI's 0.5 floor, supports RFI's conventional minority); (f) tie trials at 50% (shared control). The single-cue-difference and conflict trials genuinely require comparing the two rating vectors, satisfying the locked-prompt display requirement.

**Computed schedule:** 24 unique pairs × 4 reps = 96 trials per subject.



## ADVOCATED THEORY
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


## COMPETING THEORY
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
  "metric_source": "def metric(data: pd.DataFrame) -> float:\n    # Polarity-agnostic preference EXTREMITY on high-contrast trials.\n    #\n    # Select trials where the two options' endorsement counts differ by >= 3\n    # (design trials R3..R8 and mirrors: |E| in [~0.35, 1.0] for every gamma\n    # in [0,2]; the count-sparser option is the inverted-evidence-favored\n    # option on all of them). Per subject, compute p_hat = rate of choosing\n    # the count-sparser option on those 48 trials, then take |p_hat - 0.5|.\n    # The metric is invariant to a subject's polarity (a conventional-polarity\n    # subject and a red-flag subject both yield large extremity), which\n    # neutralizes RFI's ~5% minority cluster, and directly measures the\n    # ATTENUATION away from a pure deterministic preference: SPI's large\n    # lapse (eps in [0.05,0.35], mean ~0.20) plus polarity mixture\n    # (rho in [0,0.35], mean ~0.175) pulls per-subject p toward 0.5\n    # (predicted extremity ~0.22), whereas RFI-delta's small slip\n    # (delta ~0.10) and tiny lapse (eps <= 0.08) keep every subject\n    # near saturation (predicted extremity ~0.35, per-subject range\n    # [0.75, 0.92] in p). Applied to the pooled DataFrame the function\n    # returns the mean of the per-subject values, so the pooled point\n    # estimate is exactly the population mean of the per-subject metric.\n    sids = []\n    chose_sparse = []\n    for r in data.itertuples(index=False):\n        a = np.asarray(r.option_a_ratings, dtype=float)\n        b = np.asarray(r.option_b_ratings, dtype=float)\n        sa = int(a.sum())\n        sb = int(b.sum())\n        # Keep only high-contrast trials (count difference >= 3).\n        if abs(sa - sb) < 3:\n            continue\n        resp = int(r.response)  # 0 = chose A, 1 = chose B\n        sparse_is_a = sa < sb\n        picked_sparse = (resp == 0) if sparse_is_a else (resp == 1)\n        sids.append(r.subject_id)\n        chose_sparse.append(1.0 if picked_sparse else 0.0)\n    if len(sids) == 0:\n        return 0.0\n    tmp = pd.DataFrame({\"sid\": sids, \"cs\": chose_sparse})\n    per_subj = tmp.groupby(\"sid\")[\"cs\"].mean()\n    extremity = (per_subj - 0.5).abs()\n    return float(extremity.mean())",
  "rationale": "Both theories share the same per-trial functional form; they differ in how far each subject is pulled away from a deterministic sparse (or dense) preference. RFI-delta mandates a steep beta (>=3), a small slip (delta in [0.08,0.12]) and a tiny lapse (eps <= 0.08), so EVERY RFI subject sits near saturation on high-|E| trials: per-subject p(sparse) in [0.75, 0.92] for the ~95% red-flag majority AND p in [0.08, 0.25] for the ~5% conventional minority. SPI allows a large lapse (eps up to 0.35, mean ~0.20) and a large polarity mixture (rho up to 0.35, mean ~0.175), placing typical SPI subjects at p(sparse) ~ 0.55-0.80 on the same trials. Taking |p_hat - 0.5| (i) makes the metric polarity-AGNOSTIC, so RFI's minority cluster (extremity ~0.32) lands at the same value as its majority (~0.36) instead of injecting huge between-subject mixture variance, and (ii) yields a clean mean contrast: RFI ~0.35 vs SPI ~0.22. The trial filter (endorsement-count difference >= 3, i.e., design cells R3-R8 plus mirrors, 48 trials/subject) is chosen so that the count-sparser option is the inverted-evidence option for every gamma in [0,2] (the E-ladder ordering is gamma-robust by design) and so that per-subject extremity is estimated from 48 Bernoulli trials, giving binomial SD ~0.05-0.07 \u2014 small relative to the ~0.13 mean gap. Expected Welch t at N=25 is ~4-5 (p < 0.0005) under uniform parameter sampling from each theory's box, and even larger if parameters are fixed at central values. The function returns the mean of per-subject values on the pooled DataFrame (so the pooled point estimate equals the population mean of the per-subject metric) and the single-subject extremity on a subject slice, satisfying the per-subject variance requirement. Tie trials and low-contrast/conflict trials are excluded, so the metric isolates exactly the attenuation parameter regime where the two theories' boxes are disjoint."
}
```

## Usage

```json
{
  "input_tokens": 7119,
  "output_tokens": 44642,
  "reasoning_tokens": 43463,
  "provider": "Sail Research"
}
```
