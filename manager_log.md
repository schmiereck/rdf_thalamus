# Research Manager Log

## Iteration 002 -> Manager [Proposed Research Plan]

**Proposed Hypothesis:**
A Dynamic Representation Network (Thalamus Phase 1) using Gradient-Driven Active Subspace Recruitment (GDASR) combined with VICReg-style anti-collapse regularization will:
1. Dynamically recruit new representational dimensions (incrementing active dimension count $d_t$) when transitioned from a low-complexity training environment (2 objects) to a high-complexity evaluation environment (3 objects) in a 1D physics sandbox.
2. Achieve a post-recruitment temporal prediction error on the 3-object environment that is at least 30% lower than a fixed-dimensional Joint Embedding Predictive Architecture (Baseline B1 with fixed $d_t = 2$) trained under identical conditions.
3. Avoid representation collapse, maintaining a latent standard deviation of $\sigma > 0.1$ for all active dimensions and an average absolute cross-dimension correlation of $r < 0.3$.

**Proposed Falsification Criterion:**
The hypothesis will be proven false if any of the following conditions are met:
1. The dynamic representation network fails to recruit any new dimension (remains at $d_{\text{init}} = 2$) within 5000 steps of exposure to the 3-object environment.
2. The mean temporal prediction error of the dynamic network on the 3-object environment after adaptation is NOT at least 30% lower than that of the fixed-dimensional baseline (B1).
3. The representations collapse during training or evaluation, defined as any active dimension having a standard deviation $\sigma \le 0.1$ or the average absolute correlation between active dimensions being $r \ge 0.3$ across the evaluation batch.

**Proposed Method:**
1. Implement a 1D physics sandbox (`src/environment.py`) generating a 1D array of 128 RGB pixels, simulating N elastic colliding objects with randomized sizes, colors, masses, and initial velocities, with parameterizable N.
2. Implement `src/models.py` containing:
   - An Encoder (CNN/MLP) outputting up to $D_{\max} = 8$ dimensions, with only the first $d_t$ dimensions active.
   - A Predictor (MLP or lightweight GRU) forecasting the active latent states $\hat{z}_{t+1}$ from history.
   - Baseline B1 (FixedJEPA) with fixed $d_t = 2$ and VICReg loss.
   - DynamicJEPA implementing GDASR: starts with $d_t = 2$, tracks the exponential moving average of prediction error, and increments $d_t$ when error exceeds $\theta_{\text{recruit}}$ after a cooldown $N_{\text{cooldown}}$.
3. Create `src/train.py` to train both models first on $N=2$ objects, then transition them to $N=3$ objects.
4. Perform 5 independent runs with different random seeds to calculate the mean and standard deviation of prediction errors, dimension count, latent variance, and cross-correlations.

---

## Iteration 002 -> Planner [Strategic Guidance]

### Manager's Note: Strategic Guidance for Phase 1

The proposed research plan for Phase 1 is mathematically sound and structured, but it risks falling into the **Construction-vs-Empirical** trap if not executed with strict discipline. To ensure scientific rigor, apply the following guidance before proceeding to code execution.

---

### 1. The Construction-vs-Empirical Test: Functional Recruitment vs. Trivial Thresholding
*   **The Trap:** Simply incrementing the active dimension count $d_t$ when prediction error exceeds a hand-tuned threshold $\theta_{\text{recruit}}$ is a *definitional identity of your code*, not an empirical finding. 
*   **Strategic Correction:** To prove that dimension recruitment is truly functional:
    1.  **Introduce a Fixed $d=3$ Control (B1-Large):** You must compare your dynamic network not only against $B1$ (fixed $d_t=2$) but also against a model initialized with fixed $d_t=3$ from the start. If the dynamic model starting at $d_{\text{init}}=2$ and recruiting to $d_t=3$ does not show superior sample efficiency or lower final error than the fixed $d_t=3$ model, then dynamic recruitment offers no empirical benefit over simple over-parameterization.
    2.  **Orthogonality of Recruited Dimensions:** You must log the projection of the new dimensions onto the existing subspace. If the newly recruited dimension is highly correlated with existing ones, it is a redundant projection, not a new representational channel.

### 2. Parameter-Tuning Hygiene: Adaptive Thresholds over Post-Hoc Tuning
*   **The Trap:** Tuning a static threshold $\theta_{\text{recruit}}$ *after* observing the baseline error curves on the 3-object environment is a violation of scientific hygiene (post-hoc parameter tuning).
*   **Strategic Correction:** You must define an **adaptive, self-normalizing recruitment criterion** in `src/pre_registration.md`. For example, trigger recruitment when the prediction error exceeds $k$ standard deviations of the *moving average of the stable 2-object error*, where $k$ is fixed *a priori*. Do not manually tweak $\theta_{\text{recruit}}$ during your runs to "force" recruitment. If the model fails to recruit under the pre-registered adaptive rule, report it honestly as a null result.

### 3. Pre-Registration Mandate & Metric Bounds
*   **The Protocol:** The Orchestrator will automatically commit your proposed hypotheses and falsification criteria to `src/pre_registration.md` before execution begins. All sub-agents must read and strictly adhere to this file during training and evaluation.
*   **Rigor Check:** Your collapse criteria ($\sigma > 0.1$, $r < 0.3$) are acceptable quantitative bounds. However, ensure that $\sigma$ is calculated on *normalized* latent states (e.g., after VICReg variance regularization) to prevent the network from trivially satisfying the variance constraint by scaling the weight magnitudes of the active dimensions.

---

**Proceed to write the `src/pre_registration.md` and implement the 1D physics sandbox (`src/environment.py`) incorporating these strict controls.**

---

## Iteration 002 -> Planner (Turn 1) [Approval]

**Verdict:** APPROVED

**Journal Update:**
# Research Manager Journal & Strategic State

## 1. High-Level Strategy & Trajectory
*   **Current Phase:** Phase 1 (Representation Base - Verification of Pillars A, B, C).
*   **Active Direction:** Hardening the representation base against dimensional collapse and fixing the GDASR triggering dynamics.
*   **Confidence Score:** 75% (decreased from 100% due to the discovery of latent collapse and buffer inflation, but with a highly structured path to correction).

## 2. Strategic Insights & Lessons Learned
*   **Historical Buffer Inflation:** Including initialization transients in the running surprise error buffer artificially inflates the recruitment threshold. This masks genuine physical novelty (N=3 to N=4 transition). A sliding-window buffer or a transient-blanking period is a mandatory architectural constraint for any surprise-driven recruitment mechanism.
*   **Covariance Deficit in 1D Dynamics:** In a 1D continuous physics sandbox, temporal transitions of objects are highly correlated. Standard VICReg hyperparameter ratios (e.g., matching variance and covariance penalties) fail; the covariance penalty must be heavily scaled up (e.g., $Cov\_weight \ge 25.0$) relative to variance and similarity to prevent collapse onto a redundant, collinear 1D manifold.
*   **Representational Collapse Default:** Representational collapse in low-dimensional physical systems is the thermodynamic default. Unless explicit, highly asymmetric constraints or aggressive covariance penalties are enforced, the network will exploit redundant dimensions to minimize surprise trivially.

## 3. Loop & Bottleneck Detection
*   **Identified Bottleneck:** The interaction between representation collapse and surprise calculation creates a dead loop. If the latent space collapses, surprise becomes low or constant, which subsequently disables the GDASR trigger and prevents any downstream thalamic gating from functioning.
*   **Mitigation Strategy:** The Planner must prioritize hardening the representation base before adding more complex components (like Thalamic Gating). Specifically:
    1. Implement a temporal blanking window ($t < 50$ steps) or a sliding-window FIFO buffer for surprise thresholding.
    2. Run a controlled parameter sweep on the Covariance-to-Variance ratio ($Cov\_weight \in [1.0, 50.0]$) to establish the boundary of representation collapse.

## 4. Alternate Research Paths
*   **Asymmetric Target Networks (BYOL-style):** If covariance tuning does not stably resolve representation collapse across diverse environmental parameters, pivot immediately to an asymmetric online/target network design with stop-gradients as the primary anti-collapse mechanism.
*   **Statistical Outlier Detection:** Replace the running-mean surprise threshold with a robust statistical measure (such as Median Absolute Deviation) to prevent scale-inflation by transient spikes.

---

## Iteration 002 -> Project Archive [Milestone Report]

# RDF Milestone Review — Iteration 002 — GDASR Trigger Failure & Latent Collapse

## 1. Pre-Declared Hypothesis and Falsification Criterion
- **Hypothesis:** The GDASR (Gated Dynamic Dimension Allocation with Surprise-driven Recruitment) mechanism will successfully recruit new latent dimensions when transitioning from $N=3$ to $N=4$ objects, and the VICReg loss with default weight ratios (Sim=25, Var=25, Cov=1) will prevent representation collapse.
- **Falsification Criterion:** GDASR fails to recruit dimensions upon introduction of the novel object ($N=4$), or the representation collapses (measured by the effective rank of the latent covariance matrix approaching $1.0$).

## 2. Experimental Protocol
- **Environment:** 1D physics sandbox with parameterizable environmental variation.
- **Input:** 128-channel 1D RGB pixel grid containing moving physical objects.
- **Training Regime:** Passive observation; transition from $N=3$ to $N=4$ objects at mid-run.
- **Hyperparameters:** Sim_weight = 25.0, Var_weight = 25.0, Cov_weight = 1.0.
- **Control Run:** Baseline B1-JEPA (fixed dimensionality without GDASR) under identical parameter conditions.

## 3. Observed Quantities
- **GDASR Recruitment Rate:** 0% (failed to trigger any dimension recruitment upon introducing the 4th object).
- **Surprise Error Buffer:** Inflated threshold due to inclusion of initialization transients ($t < 50$), masking late-stage surprise changes.
- **Latent Manifold Dimensionality:** Latent representations collapsed onto a redundant, collinear 1D manifold (effective rank $\approx 1.0$), as the covariance weight of 1.0 was completely dominated by variance and similarity terms (ratio 1:25).

## 4. Verdict
**Refuted.** The pre-declared hypothesis that the initial parameterization of GDASR and VICReg would maintain stable, expandable representations is refuted.

## 5. Construction-vs-Empirical Note
The collapse to a 1D manifold is an empirical behavior of the interaction between the 1D physics environment dynamics and the VICReg loss function when the covariance penalty is insufficiently weighted. It is not an algebraic identity, as the latent space construction allowed for up to 8 independent dimensions.

## 6. Limitations
This result demonstrates that standard VICReg weight configurations are highly unstable in 1D continuous physics tracking where spatial dynamics are heavily correlated. It does not prove that VICReg or GDASR are fundamentally non-viable, but highlights that:
1. Dynamic threshold systems must use adaptive sliding-window buffers to filter out initial transient errors.
2. Covariance regularization must be scaled significantly higher than variance (e.g., $Cov\_weight \ge 25.0$) to overcome collinearity in low-dimensional continuous physical trajectories.

---

## Iteration 003 -> Manager [Proposed Research Plan]

**Proposed Hypothesis:**
Increasing the VICReg covariance regularization weight to 25.0, in conjunction with a 1000-step representation-warmup phase, will prevent representation collapse (reducing the mean absolute cross-dimension correlation $r$ from >0.99 to <0.30). Furthermore, replacing the cumulative error buffer with a rolling sliding-window error buffer of size 500 (cleared post-warmup) will enable sensitive and reliable recruitment of a new dimension (recruitment rate >80%) when transitioning from 2 to 3 objects in the 1D physics sandbox, without increasing the temporal prediction simulation loss compared to the baseline B1.

**Proposed Falsification Criterion:**
The hypothesis will be falsified if any of the following occur:
1. The mean absolute correlation ($r$) between representation dimensions is >= 0.30 at the end of training.
2. The dynamic recruitment rate for the GDASR model upon the N=3 object transition is <= 80%.
3. The final temporal prediction simulation loss of the recruiting DynamicJEPA model is > 0.080 (or more than 10% worse than the non-recruiting B1 baseline of 0.06662).

**Proposed Method:**
1. Modify the training and model configuration files (e.g., in `src/`) to increase `cov_weight` from 1.0 to 25.0 in the VICReg loss calculation.
2. Implement a representation-warmup phase of 1000 steps during which gradient updates are performed normally but dimension recruitment is disabled.
3. Replace the cumulative error buffer in the GDASR recruitment module with a rolling sliding-window buffer of size 500.
4. Programmatically reset/clear this error buffer immediately following the warmup phase and during the transition from N=2 to N=3 objects.
5. Run the full evaluation suite of 15 experiments (DynamicJEPA, B1, and B2 across 5 deterministic seeds) on the 1D physics sandbox.
6. Measure and log: mean absolute correlation between dimensions, recruitment rate upon N=3 transition, and final temporal prediction simulation loss.

---

## Iteration 003 -> Planner [Strategic Guidance]

### Manager's Note: Strategic Guidance & Architectural Constraints

We are at a critical juncture in establishing a stable Phase 1 representation base. Your proposed adjustments address the primary failure modes of the previous run (threshold inflation and representation collapse), but the current experimental design contains a significant scientific vulnerability and an unfair baseline control. 

Please adjust your plan according to the following directives before writing the pre-registration file:

---

### 1. The Transition-Reset Construction Trap (Skeptic Mode)
* **The Issue:** Your proposed method states: *"Programmatically reset/clear this error buffer immediately following the warmup phase **and during the transition from N=2 to N=3 objects**."*
* **The Critique:** Manually resetting the buffer at the exact boundary of the physical transition injects **oracle knowledge** into the agent. If the system requires an external signal to clear its memory to detect a change, the recruitment is constructional (engineered), not empirical (emergent). The agent must detect the unexpected transition purely through the natural dynamics of its sliding-window buffer. 
* **Correction:** You are permitted to reset the buffer once immediately after the **warmup phase** (to clear random initialization transients). You are **strictly forbidden** from programmatically resetting or altering the buffer or threshold during the N=2 to N=3 transition. The sliding window of size 500 must discard the older, lower-error history naturally.

### 2. Control Group Hygiene (Baseline Alignment)
* **The Issue:** If you change `cov_weight` to 25.0 and introduce a 1000-step representation-warmup phase *only* for the `DynamicJEPA` model, your comparison against Baseline B1 is invalid. Any improvement in representation collapse ($r < 0.30$) or degradation in loss could be attributed entirely to the hyperparameter tuning, rather than the recruitment mechanism.
* **Correction:** **Baseline B1 (and B2, where mathematically applicable) must be trained under the exact same hyperparameter envelope**—specifically, the same `cov_weight = 25.0` and the same 1000-step warmup (even if B1 does not recruit, its weights must undergo the same warmup phase kinetics). This isolates "dynamic recruitment" as the sole independent variable.

### 3. Quantitative Pre-Registration Mandate
* Your stated quantitative falsification criteria are excellent and rigorous. 
* **Action:** Before executing any training runs, ensure these exact hypotheses and criteria (incorporating the corrections above) are committed to `src/pre_registration.md`. Your sub-agents must read and strictly adhere to this file during execution. 

Proceed with these corrections. Let's see if the representation base can be genuinely hardened under fair, unassisted conditions.

---

