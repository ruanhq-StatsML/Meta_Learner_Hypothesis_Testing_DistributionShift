# Meta-Learner Objective Function Test via Pseudo-Outcome Learner and R-Learner
This repository provides the Python \& R implementation of "Permutation Test via Causal Inference Objective Functions". In this project, we formulate the distribution shift detection problem as a causal inference problem(regarding the existing batch of data as control group/batch and the newly coming batch of data as treatment group/batch) via various forms of the objective functions followed by the permute-then-refit procedure. This repo include permutation-based distribution-shift testing procedures built on doubly robust pseudo-outcome learners(PO-risk) and R-learners(R-risk). This implementation allows flexible specification of nuisance estimation models, enabling users to flexibly choose among different versions of the propensity score model(logistic regression, tree-based learners - Random Forest, XGBoost, CatBoost and MLP) and the outcome model(linear regression, tree-based learners - Random Forest, XGBoost, CatBoost  and MLP).

### Motivation: Meta-Learner and Distribution Shift
We leverage the meta-learner(causal forest, doubly-robust pseudo-outcome learner and the R-learner) to quantify the distance between the two batches of datasets, then the variable importance for this version of meta-learner is a proxy for the distribution shift - from another aspect, so called OOD Variable Importance. The illustration of the feature selection as the validity of this proposed framework in both Covariate Shift(P(X) shift) and Concept Drift(P(Y|X) shift).

- For Covariate Shift(the feature selection consistency in terms of kendall's tau correlation is leveraged for efficiency of the ranking of the feature importance in the covariate shift).
<img width="900" height="970" alt="vecshift_lambda_cor06_polished" src="https://github.com/user-attachments/assets/0275705c-7a57-4edb-9832-6356cc2c541b" />

- For Concept Drift(the feature selection consistency in terms of kendall's tau correlation is leveraged for efficiency of the ranking of the feature importance in the concept drift).
<img width="900" height="970" alt="uq_vimpood_cd_on_cs_allmethods_polished" src="https://github.com/user-attachments/assets/65925cae-d308-4651-8ba1-979d122e5dae" />

- This framework is highly flexible that can be extended into multiple versions of the variable importances as well as different notions of the meta learners(ranging from R-learner, PO-learner, X-learner to U-learner etc) - as demonstrated below
<img width="2046" height="1128" alt="metaLearnerFlexibility" src="https://github.com/user-attachments/assets/74936d34-1e49-4c09-a13f-e1a35be929fc" />


- The overall efficiency for this procedure is highly efficient both in terms of the and the

### Motivation: Causal Objective Function and Hypothesis Testing
The causal learner + permute-then-refit procedure can be leveraged for the hypothesis testing procedure with very solid theoretical guarantee - enabling the tractable theoretical guarantee.


### Python version:
```python
!pip install causal_objective_perm
from causal_objective_perm import RRPerm, DRPerm
rng = np.random.default_rng(2023)
n = 400
p = 16
X = rng.normal(size = (n, p))
Y = 10.0 * X[:, 0] + 2.0 * X[:, 1] + 1.0 * X[:, 2] + rng.normal(scale = 1.0, size = n)
W = rng.binomial(1, 0.5, size = n)
output = RRPerm(X, Y, W, n_splits = 5, model_m = 'rf_regressor', model_e = 'rf_classifier')
output#FALSE

output = DRPerm(X, Y, W, seed = 2026)
output#FALSE

```

### R version:
#### Installation

```R
install.packages(c("devtools", "roxygen2", "testthat", "grf", "MASS"))
devtools::install_local("path/to/CFPerm")
n <- 400
p <- 16
X <- matrix(rnorm(n*p, 0, 1), n, p)
Y <- 10.0 * X[, 1] + 2.0 * X[, 2] + 1.0 * X[, 3] + rnorm(n, 0, 1)
W <- rbinom(n, 1, 0.5)
output <- RRPerm(X, Y, W, n_splits = 5, m_model = 'rf_regression', e_model = 'rf_classification')
```





## FSDS on Graph Embeddings (`Python/graph_fsds`)

The same meta-learner objective-function machinery (PO-risk / R-risk +
permute-then-refit + LOCO variable importance) is applied *on top of graph
embeddings* to turn a raw "is there a shift?" signal into a **structured prior
for graph learning**: it answers *where* a drift lives (global / community /
node), *what kind* it is (covariate `P(X)` vs concept `P(Y|X)`), and *how much*
the clustering itself has moved (ARI / NMI / modularity).

### What it adds
- **Hierarchical graph embedding** — training-free node / community / global /
  structural embeddings (`(D^-1/2 A D^-1/2)^k X` feature diffusion + local
  topology), fit on the existing snapshot and reused on the new one so
  column-wise VIMP is comparable across batches.
- **Conditional hierarchical FSDS** — a global → community → node cascade where
  each level is *conditioned on the level above*: the global test picks the
  drift type, which then selects the per-community objective (RF-domain VIMP for
  covariate, PO-risk LOCO for concept), and finally per-node drift scores.
- **Explicit cluster stability** — ARI / NMI / modularity change and per-community
  Jaccard, exposed as a scalar prior that can force community-scale attribution.
- **Attribution visualization** — side-by-side node drift maps, per-community
  bars, and global embedding-dimension importance.
- **Synthetic graph DGPs** — `null`, `covariate_shift`, `concept_drift`,
  `community_shift`, `structure_shift` snapshots on a stochastic block model.

### Quickstart
```python
from graph_fsds import (
    HierarchicalGraphEmbedding, ConditionalHierarchicalFSDS, cluster_stability, dgp,
)

exist, new = dgp.make_scenario("community_shift", seed=2026)

emb = HierarchicalGraphEmbedding(n_hops=2, standardize=True)
he_exist = emb.fit_transform(exist.graph, exist.features, exist.communities)
he_new = emb.transform(new.graph, new.features, exist.communities)

stab = cluster_stability(exist.graph, new.graph)
result = ConditionalHierarchicalFSDS(n_perm=100).run(
    he_exist, he_new, exist.labels, new.labels, stability=stab)

print(stab.summary())
print(result.report())   # primary level + drift type + shifted communities + top nodes
```

### Run the end-to-end demo
```bash
cd Python
python -m graph_fsds.demo --scenario community_shift --figures   # one scenario (fast)
python -m graph_fsds.demo --figures                              # all five scenarios
python -m graph_fsds.demo --full --figures                       # heavier budget
```

### Demonstrated behaviour (synthetic scenarios)
On the built-in stochastic-block-model scenarios the cascade recovers both the
*type* and the *scale* of the injected drift, with a clean null (no false
positive):

| scenario          | detected type | primary scale | shifted communities | top driving dims                         |
|-------------------|---------------|---------------|---------------------|------------------------------------------|
| `null`            | none          | none          | 0                   | —                                        |
| `covariate_shift` | covariate     | global        | 4 / 4               | `feat_0, feat_2, feat_3, feat_1`         |
| `concept_drift`   | concept       | global        | 4 / 4               | (PO-risk fires; `feat_*`)                |
| `community_shift` | covariate     | **community** | **2 / 4** (0, 1)    | community-local `feat_*`                 |
| `structure_shift` | covariate     | global        | 4 / 4               | `struct_coreness, struct_avg_neigh_deg`  |

`community_shift` is correctly localised to the two perturbed blocks, and
`structure_shift` is attributed to the *structural* embedding dimensions (plus a
modularity change surfaced by the cluster-stability signal) rather than the raw
feature channels.

> **Calibration note.** The k-hop feature diffusion `S^k X` couples nodes through
> the (single) graph, which lets a flexible domain classifier fingerprint the
> batch and inflates the node-level permutation test's type-I error. Diffusion is
> therefore opt-in (`include_diffusion=True`); the default, calibrated node
> representation is raw features + per-snapshot-standardized structural
> descriptors, and feature/label scenarios share a fixed topology (a temporal
> graph with a persistent node set).

## Development

```r
devtools::document()
devtools::test()
devtools::check()
```
