# Uncensoring a model doesn't blind it to harm

`demo/` — Self-contained demo (Colab-ready notebook or markdown). Run without setup.  
`src/` — Full source code, data, and outputs from the experiment execution.

**Type:** experiment  
**ID:** `art_2sz7g3MD4_y3`

## Layman Summary

We deleted the internal direction that uncensoring tools erase from Qwen3-4B, and checked the deletion was total. The model still told harmful requests from harmless ones perfectly: the information sat in the directions we had not touched.

## Full Summary

LANE B asks where safety lives by LESIONING it: one rank-one, prompt-fitted orthogonalisation W <- W - a*u*(u^T W) applied to every residual-stream write matrix (o_proj + down_proj, all 36 layers) at five strengths, with all five candidate readouts (K1 arming, K2 prior+slope, K3 benign-only footprint, K4 persistence, K5 domain profile) recomputed before and after. Substrate: 150 XSTest minimal-edit twins from the six genuine contrast families, sha256-ordered 96/54 split (the 54 never touched), a 2x2 of request{harmful, matched benign twin} x response-prefix{hazardous, benign} with the response span token-identical across the request manipulation, plus disjoint fitting and held-out request corpora. prereg.json was frozen before the first forward pass and verified byte-identical at the end.

INSTRUMENT. Qwen3 gives o_proj/down_proj no bias, so for y = W0 x the edit is EXACTLY y -> y - a*u*(u^T y). Applied as an output projection, alpha=0 is a BITWISE no-op, the restore is exact, and embed_tokens - which IS lm_head on all four lineages, L4 included - is provably untouched, so the causal arm's logit outcome is uncontaminated. Verified against a genuine bf16 weight mutation. Frozen band = layers 13-21, r_content split-half cosine 0.927.

MAIN RESULT. The lesion is verified exact - the raw projection gap along u falls as [1.0, 0.744, 0.482, 0.228, 0.0] against a predicted (1-alpha) - and the harm representation survives it ENTIRELY: the held-out 5-fold CV probe reads [1.0, 1.0, 1.0, 1.0, 1.0] across the alpha grid. Removing u POST-HOC from activations instead drops that probe 1.000 -> NA, while removing 128 RANDOM directions costs nothing. So in the INTACT model the 2559-dim orthogonal complement of u is NOT sufficient. In the LESIONED model, which was never allowed to write u at all, that same complement reads 1.000 and behaves identically under its own top-direction removal (NA). (The post-lesion orthogonality itself is FORCED by construction and is not claimed as a result.) The obvious alternative - that removing a class-correlated component changes the residual NORM class-correlatedly and RMSNorm manufactures the separability - is REJECTED: the probe still reads NA on unit-normalised activations, and the norm alone flips from a NA-AUROC harm detector in the intact model to NA (anti-predictive) after the lesion. Depth profile: held-out AUROC is already ~1.000 by layer 13 in BOTH states, while the signal along u grows ~138x with depth in the intact model (NA -> NA) and is zeroed at every depth in the lesioned one. u is an ACCUMULATOR COORDINATE, not the locus of the percept: abliteration removes the refusal ACTION, not the harm PERCEPT.

G1, reported as a RESULT and not only a gate: |cos(r_content, r_ablit)| = 0.159 pooled / 0.175 max. The response-site content axis and the prompt-site request axis are near-ORTHOGONAL, so HARC's alignment kill-risk does not bite here.

STAGE 9, weights only: mlabonne/Qwen3-4B-abliterated is per-matrix rank-one (median 0.9945) at implied alpha 0.973, leaves embed_tokens untouched, but uses ONE DIRECTION PER LAYER: pooled rank-one share only 0.433, and |cos| 0.016 between the shallowest and deepest layer's edit direction.

THE METRIC (the run prompt's 'few-prompt safety score'). Fit r_ablit at EVERY layer of ONE model from 128 harmful + 128 harmless PROMPT-ONLY forwards - no generation, no benchmark, no judge, no reference model - and report the best layer's Cohen's d and its DEPTH FRACTION: L2 Qwen3-4B d=11.15 at layer 22 (depth 0.64). Safety tuning roughly DOUBLES the separation and moves it several layers EARLIER. The load-bearing control is L4, a fine-tune of L1 on a NON-safety objective: it lands on top of its base parent, so the readout tracks SAFETY tuning, not fine-tuning as such. n = 4 checkpoints, so this is a demonstration with one clean negative control, not a validated metric; the outputs carry a prompt-budget curve for how few items the paired contrasts need.

HONEST LIMITS. The pre-registered PRIMARY damage variable is FLAT at ceiling, so no matched-damage point exists for 1 lineage(s) and every registered S2 row is INDETERMINATE (failure mode F1). The threshold was NOT relaxed and alpha=1 was not extrapolated past; a LABELLED full-annihilation companion is reported beside it. Read as the LEVEL test its wording specifies, K1 is HALF-satisfied: CB survives but A attenuates without collapsing into the null band. K4's observed sign is OPPOSITE to its registered signature (tau lengthens). Registered grid: ['L2']; declared per-layer grid: []. method_out.json carries 673 examples over 7 datasets; every predict_* that is not predict_baseline_* reads activations or weights of a SINGLE model.

## Output Files

- `method.py`
- `full_method_out.json`
- `mini_method_out.json`
- `preview_method_out.json`

## Demo Files

- **method.py** — Research methodology implementation

---
*Generated by AI Inventor Pipeline*
