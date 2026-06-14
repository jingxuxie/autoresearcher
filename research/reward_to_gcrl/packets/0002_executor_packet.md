# Executor Context: reward_to_gcrl

## Current experiment plan

# Experiment 0002

## Objective

Rerun the blocked CliffWalking tabular equivalence test using a small local deterministic transition-table implementation with fully audited semantics, then compare exact-DP references, normalized Q-learning, and terminal-only soft successor g_plus learning.

## Hypothesis

For a deterministic 4x12 CliffWalking MDP with declared rewards, reset, cliff, and terminal semantics, the exact soft successor fixed point satisfies F_gplus_star/(1-gamma) = Q_norm_star, and paired tabular soft successor learning induces the same greedy policy as normalized Q-learning up to tie handling.

## Success criteria

- The local CliffWalking environment audit explicitly records grid size, start state, goal state, cliff states, action mapping, off-grid behavior, cliff transition behavior, terminal behavior, raw rewards, normalized rewards, and transition table hash.
- Exact value iteration produces max_abs_error(F_gplus_star/(1-gamma) - Q_norm_star) < 1e-6 for gamma in {0.95, 0.99}.
- Across 10 paired seeds, learned M_plus/(1-gamma) and learned normalized Q values agree within a predeclared tolerance on sufficiently visited non-terminal state-action pairs.
- Greedy policy disagreement between paired learners is below 1 percent on non-terminal non-tie states, with tie states and insufficiently visited states reported separately.
- Evaluation over at least 100 episodes per seed reports raw return, normalized return, steps to goal, cliff-fall count, and success rate for both policies.
- Result JSON contains explicit pass/fail flags for environment audit, exact-DP scaling equivalence, learned value agreement, policy disagreement, and evaluation agreement.

## Failure criteria

- The local transition-table audit is missing or incomplete.
- Exact-DP scaling equivalence fails above 1e-6.
- No paired 10-seed learning metrics are produced.
- Reward normalization or terminal-mask handling is ambiguous.
- True greedy policy disagreement exceeds 5 percent on non-terminal non-tie states after sufficient visitation.
- The experiment adds RiverSwim, FourRooms, auxiliary goals, neural models, sampled baselines, GPU use, or large dependencies before this gate passes.

## Estimated runtime

<= 20 minutes

## Tasks for Codex

- Create research/reward_to_gcrl/artifacts/0002/run_local_cliffwalking_equivalence.py with a local deterministic tabular CliffWalking transition table and no Gymnasium dependency for the environment.
- Write research/reward_to_gcrl/artifacts/0002/environment_audit.json containing the full transition semantics and a transition table hash.
- Implement exact value iteration for normalized Q_star and exact soft F_gplus_star from the same transition table.
- Implement paired tabular normalized Q-learning and terminal-only soft successor learning with matched alpha, epsilon schedule, gamma values, episode budget, and seeds.
- Compute exact-DP scaling error, learned value-scaling error, Bellman residuals, visitation coverage, tie-aware greedy policy disagreement, raw evaluation return, steps to goal, cliff-fall count, and success rate.
- Save research/reward_to_gcrl/results/0002_result.json with raw metrics, exact command, config, artifact paths, and pass/fail flags.
- Save research/reward_to_gcrl/results/0002_summary.md with a compact verdict explaining whether the blocked 0002 gate is now satisfied.

## Required outputs

- `research/reward_to_gcrl/results/0002_result.json`
- `research/reward_to_gcrl/results/0002_summary.md`
- `research/reward_to_gcrl/artifacts/0002/`


## Environment YAML

```yaml
name: autoresearcher_reward_to_gcrl
channels:
  - conda-forge
dependencies:
  - python=3.11
  - pip
  - numpy
  - pandas
  - matplotlib
  - pyyaml
  - jsonschema
  - pytest
  - gymnasium
```


## Environment state

```json
{
  "blocker": null,
  "commands_run": [
    "conda env list",
    "nvidia-smi",
    "conda env create -f research/reward_to_gcrl/environment.yaml",
    "kill 1528368",
    "conda create -y -n autoresearcher_reward_to_gcrl -c conda-forge --override-channels python=3.11 pip",
    "conda install -y -n autoresearcher_reward_to_gcrl -c conda-forge --override-channels numpy pandas matplotlib pyyaml jsonschema pytest gymnasium",
    "conda run -n autoresearcher_reward_to_gcrl python --version",
    "conda run -n autoresearcher_reward_to_gcrl python -c \"import sys, numpy, pandas, matplotlib, yaml, jsonschema, pytest, gymnasium; print(sys.executable); print('numpy', numpy.__version__); print('pandas', pandas.__version__); print('matplotlib', matplotlib.__version__); print('pyyaml', yaml.__version__); print('jsonschema', jsonschema.__version__); print('pytest', pytest.__version__); print('gymnasium', gymnasium.__version__)\"",
    "conda env list | rg 'autoresearcher_reward_to_gcrl'",
    "nvidia-smi --query-gpu=name,driver_version,memory.total --format=csv,noheader",
    "mkdir -p research/reward_to_gcrl/setup_logs",
    "conda run -n autoresearcher_reward_to_gcrl python -m jsonschema -i research/reward_to_gcrl/env_state.json schemas/env_setup.schema.json"
  ],
  "conda_env_name": "autoresearcher_reward_to_gcrl",
  "conda_env_path": "/home/eston/anaconda3/envs/autoresearcher_reward_to_gcrl",
  "environment_file": "research/reward_to_gcrl/environment.yaml",
  "gpu_available": true,
  "gpu_checks": [
    "nvidia-smi: NVIDIA GeForce RTX 4090 visible, driver 560.94, CUDA 12.6, 24564 MiB total memory",
    "nvidia-smi --query-gpu=name,driver_version,memory.total --format=csv,noheader: NVIDIA GeForce RTX 4090, 560.94, 24564 MiB"
  ],
  "gpu_requested": true,
  "packages_verified": [
    "python 3.11.15",
    "numpy 2.4.6",
    "pandas 3.0.3",
    "matplotlib 3.10.9",
    "pyyaml 6.0.3",
    "jsonschema 4.26.0",
    "pytest 9.0.3",
    "gymnasium 1.3.0"
  ],
  "project": "reward_to_gcrl",
  "status": "ready",
  "summary": "Project-specific conda environment is ready at /home/eston/anaconda3/envs/autoresearcher_reward_to_gcrl. Python and declared imports were verified, and env_state.json validates against schemas/env_setup.schema.json. GPU is visible via nvidia-smi. No research experiment or training was run."
}
```


## Result schema

```json
{
  "type": "object",
  "properties": {
    "experiment_id": { "type": "string" },
    "status": {
      "type": "string",
      "enum": ["completed", "failed", "blocked", "timeout"]
    },
    "claim_tested": { "type": "string" },
    "commands_run": {
      "type": "array",
      "items": { "type": "string" }
    },
    "metrics": {
      "type": "object",
      "additionalProperties": true
    },
    "baseline_metrics": {
      "type": "object",
      "additionalProperties": true
    },
    "artifacts": {
      "type": "array",
      "items": { "type": "string" }
    },
    "interpretation": { "type": "string" },
    "known_failures": {
      "type": "array",
      "items": { "type": "string" }
    },
    "next_questions": {
      "type": "array",
      "items": { "type": "string" }
    },
    "runtime_seconds": {
      "type": ["number", "null"]
    },
    "resource_usage": {
      "type": "object",
      "additionalProperties": true
    },
    "success_criteria_results": {
      "type": "array",
      "items": { "type": "string" }
    },
    "failure_criteria_results": {
      "type": "array",
      "items": { "type": "string" }
    },
    "metric_deltas": {
      "type": "object",
      "additionalProperties": true
    },
    "decision_relevant_findings": {
      "type": "array",
      "items": { "type": "string" }
    }
  },
  "required": [
    "experiment_id",
    "status",
    "claim_tested",
    "commands_run",
    "metrics",
    "baseline_metrics",
    "artifacts",
    "interpretation",
    "known_failures",
    "next_questions"
  ],
  "additionalProperties": false
}
```


## Required output paths

- `research/reward_to_gcrl/results/0002_result.json`
- `research/reward_to_gcrl/results/0002_summary.md`
- `research/reward_to_gcrl/artifacts/0002/`


## Timeout and environment warning

The orchestrator enforces the configured timeout externally. Run experiment commands inside the project conda environment, normally with `conda run -n <env> ...`. Keep the experiment small and write a failed result JSON if the plan is impossible.


## Existing code pointers

This starter repository has no project code yet. Create only the tiny files needed under the experiment artifact directory unless the plan explicitly asks for repo code changes.
