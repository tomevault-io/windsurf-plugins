---
trigger: always_on
description: > **Breaking changes**: See [CHANGELOG.md](CHANGELOG.md) for recent breaking changes to the agent and environment APIs and migration guidance.
---

# CLAUDE.md - Harbor Framework

> **Breaking changes**: See [CHANGELOG.md](CHANGELOG.md) for recent breaking changes to the agent and environment APIs and migration guidance.

## Project Overview

Harbor is a framework for evaluating and optimizing AI agents and language models. It provides:

- **Agent Evaluation**: Run evaluations of arbitrary agents (Claude Code, OpenHands, Codex CLI, Aider, etc.) against benchmark tasks
- **Benchmark Support**: Interface with standard benchmarks (SWE-Bench, Terminal-Bench, Aider Polyglot, etc.)
- **Parallel Execution**: Conduct experiments in thousands of environments in parallel via providers like Daytona and Modal
- **RL Optimization**: Generate rollouts for reinforcement learning optimization

## Quick Start Commands

```bash
# Install
uv tool install harbor

# Run a benchmark
harbor run --dataset terminal-bench@2.0 --agent claude-code --model anthropic/claude-opus-4-1 --n-concurrent 4

# Pass environment variables to the agent
harbor run --dataset terminal-bench@2.0 --agent claude-code --model anthropic/claude-opus-4-1 \
  --ae AWS_ACCESS_KEY_ID=$AWS_ACCESS_KEY_ID \
  --ae AWS_REGION=us-east-1

# List available datasets
harbor datasets list

# Get help
harbor run --help
```

## Repository Structure

This is a monorepo containing the Harbor CLI, documentation website, and results viewer.

```
harbor/
├── src/harbor/           # Main CLI source code
│   ├── agents/           # Agent implementations
│   │   ├── base.py       # BaseAgent abstract class
│   │   ├── factory.py    # Agent factory for instantiation
│   │   ├── installed/    # Built-in agent implementations
│   │   ├── terminus_2/   # Terminus agent implementation
│   │   ├── oracle.py     # Oracle agent (for testing)
│   │   └── nop.py        # No-op agent
│   ├── cli/              # Command-line interface (Typer-based)
│   │   ├── main.py       # Main CLI entry point
│   │   ├── jobs.py       # Job management commands
│   │   ├── datasets.py   # Dataset commands
│   │   ├── trials.py     # Trial management
│   │   ├── tasks.py      # Task management
│   │   ├── traces.py     # Trace viewing
│   │   ├── sweeps.py     # Parameter sweeps
│   │   ├── adapters.py   # Adapter commands
│   │   ├── adapter_wizard.py  # Interactive adapter creation
│   │   ├── publish.py    # Package publishing
│   │   ├── analyze.py    # Analysis commands
│   │   ├── cache.py      # Cache management
│   │   ├── view.py       # Results viewing
│   │   ├── admin/        # Admin commands
│   │   ├── annotator/    # Annotation tools
│   │   ├── debug_checker/    # Debug tools
│   │   ├── quality_checker/  # Quality verification
│   │   ├── template-adapter/ # Adapter templates
│   │   ├── template-metric/  # Metric templates
│   │   └── template-task/    # Task templates
│   ├── environments/     # Execution environments
│   │   ├── base.py       # BaseEnvironment abstract class
│   │   ├── factory.py    # Environment factory
│   │   ├── docker/       # Local Docker environment
│   │   ├── daytona.py    # Daytona cloud environment
│   │   ├── e2b.py        # E2B environment
│   │   ├── modal.py      # Modal environment
│   │   ├── runloop.py    # Runloop environment
│   │   ├── apple_container.py  # Apple container environment
│   │   └── gke.py        # Google Kubernetes Engine
│   ├── models/           # Pydantic data models
│   │   ├── agent/        # Agent context and metadata
│   │   ├── job/          # Job configuration and results
│   │   ├── task/         # Task configuration
│   │   ├── trial/        # Trial configuration and results
│   │   ├── metric/       # Metric definitions
│   │   ├── package/      # Package registry models
│   │   ├── trajectories/ # ATIF trajectory format
│   │   ├── verifier/     # Verification results
│   │   └── registry.py   # Dataset registry models
│   ├── orchestrators/    # Trial orchestration
│   ├── verifier/         # Test verification system
│   ├── inspect/          # Inspection utilities
│   ├── analyze/          # Analysis backend (LLM-powered)
│   ├── auth/             # Authentication (OAuth callback server)
│   ├── publisher/        # Package publishing and registry DB
│   ├── storage/          # Storage backends (Supabase)
│   ├── db/               # Database types
│   ├── llms/             # LLM integrations (LiteLLM)
│   ├── dataset/          # Dataset handling
│   ├── registry/         # Dataset registry
│   ├── tasks/            # Task utilities
│   ├── trial/            # Trial utilities
│   ├── metrics/          # Metrics collection
│   ├── mappers/          # Data mappers
│   ├── viewer/           # Results viewer UI
│   └── utils/            # Utility functions
├── adapters/             # Benchmark adapters (convert external datasets)
├── apps/
│   └── viewer/           # Results viewer web app (React Router, Vite)
├── docs/                 # Documentation website (Next.js, Fumadocs)
├── examples/             # Example configurations and tasks
│   ├── tasks/            # Example task definitions
│   ├── agents/           # Agent configuration examples
│   ├── configs/          # Job configuration examples
│   ├── datasets/         # Dataset examples

<!-- Content truncated to meet Windsurf 6KB limit -->

---
> Source: [multimodal-art-projection/TACO](https://github.com/multimodal-art-projection/TACO) — distributed by [TomeVault](https://tomevault.io).
<!-- tomevault:4.0:windsurf_rules:2026-04-24 -->
