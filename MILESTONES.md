# Reproduction Milestones

**Current: none**

<!-- Milestone levels (update "Current" above as you progress):
  none             — just started, no meaningful progress yet
  method_runs      — the paper's method executes end-to-end without errors
  core_claim       — minimum experiment supports the paper's central claim
  core_claim_plus  — core claim reproduced on additional settings
  secondary_claims — secondary results or contributions reproduced
  majority         — more than half of reported results reproduced
  near_complete    — most results reproduced, only minor gaps remain
  full             — all reported results reproduced
-->

## Progress Log

### [2026-04-04] - none
- Read paper thoroughly: GeoCoT (Geographical Chain-of-Thought) for image geolocation
- Paper proposes a 5-step structured prompting framework for VLMs
- Core claim: GeoCoT improves geolocation accuracy by up to 25% vs baselines
- Key challenge: GeoComp dataset and GPT-4o not directly available

### [2026-04-04] - method_runs (in progress)
- Implemented GeoCoT prompting method (5 reasoning steps)
- Implemented VLM client supporting Qwen2.5-VL and LLaVA
- Implemented geolocation evaluation metrics (classification + distance)
- Set up environment with CUDA container
- Created download scripts for model and data
- Created method.sh, baseline.sh, evaluate.sh, reproduce.sh scripts
- Submitted job for execution on compute node

### [2026-04-04] - core_claim (planned)
- Run GeoCoT with Qwen2.5-VL on Im2GPS3K dataset
- Run standard CoT baseline for comparison
- Verify GeoCoT outperforms CoT on city/country/continent accuracy

## Stop Justification

<!-- Do not edit this unless you decide to stop -->
