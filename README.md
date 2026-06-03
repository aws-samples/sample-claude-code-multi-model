# Claude Code Multi-Model

[![License: MIT-0](https://img.shields.io/badge/License-MIT--0-yellow.svg)](LICENSE)
[![Bedrock](https://img.shields.io/badge/Amazon%20Bedrock-Mantle-blue)](https://docs.aws.amazon.com/bedrock/latest/userguide/models-endpoint-availability.html)
[![Models: 43+](https://img.shields.io/badge/Models-43%2B%20from%2012%20providers-orange)](./)

> **This is sample code intended for demonstration and learning purposes only.**
> It is not meant for production use. Review and harden all scripts, configurations,
> and IAM permissions before using in any production or sensitive environment.

Run [Claude Code](https://docs.anthropic.com/en/docs/claude-code) with **any
foundation model** — not just Anthropic models. Two deployment paths:

| Path | Models | Cost Model | Best For |
|------|--------|------------|----------|
| [**Bedrock (Mantle)**](bedrock/) | 43 models from 12 providers | Pay-per-token | Model variety, zero infrastructure |
| [**Self-Hosted (EC2)**](self-hosted/) | Any Ollama/vLLM model | Fixed hourly GPU cost | Data sovereignty, air-gapped, unlimited tokens |

## Architecture

```text
                         ┌─────────────────────────────┐
                         │      Claude Code CLI        │
                         │  (Anthropic Messages API)   │
                         └──────────┬──────────────────┘
                                    │
                 ┌──────────────────┼──────────────────┐
                 │                  │                   │
         ┌───────▼──────┐  ┌───────▼──────┐  ┌────────▼─────────┐
         │ Native Path  │  │ LiteLLM      │  │ LiteLLM          │
         │ (no proxy)   │  │ Proxy        │  │ Proxy            │
         │              │  │ → Bedrock    │  │ → Self-Hosted    │
         │ Claude Opus  │  │   Mantle     │  │   (Ollama/vLLM)  │
         │ Claude Sonnet│  │              │  │                  │
         │ Claude Haiku │  │ 38 models    │  │ Any GGUF/HF      │
         └──────┬───────┘  │ 12 providers │  │ model on GPU     │
                │          └──────┬───────┘  └────────┬─────────┘
                │                 │                    │
         ┌──────▼───────┐  ┌─────▼────────┐  ┌───────▼─────────┐
         │ Amazon       │  │ Bedrock      │  │ EC2 GPU         │
         │ Bedrock      │  │ Mantle       │  │ Instance        │
         │ (Anthropic)  │  │ (us-east-1)  │  │ (your VPC)      │
         └──────────────┘  └──────────────┘  └─────────────────┘
```

## Benchmark

We measured model quality on the public [HumanEval](https://github.com/openai/human-eval)
benchmark (164 tasks), driving each task through Claude Code backed by each model
and scoring with standard `pass@1`:

| Model | pass@1 |
| --- | --- |
| Claude Sonnet 4.6 | 97.6% |
| Kimi K2.5 | 96.3% |
| DeepSeek V3 | 94.5% |
| Qwen Coder Next | 91.5% |
| Qwen Coder 30B | 90.9% |

Budget models reach 93–99% of the frontier model's pass rate. Full method,
caveats, and reproduce steps in [bedrock/README.md](bedrock/README.md#benchmark-humaneval).

## Quick Start

### Option A: Bedrock (43 models, pay-per-token)

```bash
cd bedrock

# Anthropic models — no proxy needed
./scripts/claude-model.sh --model claude-sonnet

# Third-party models — start proxy first
./scripts/setup-proxy.sh
./scripts/claude-model.sh --model qwen-coder-next
./scripts/claude-model.sh --model kimi-k2.5
./scripts/claude-model.sh --model deepseek-v3
```

See [bedrock/README.md](bedrock/README.md) for full setup, all 43 models, and proxy management.

### Option B: Self-Hosted on EC2 (fixed cost, data stays in VPC)

```bash
cd self-hosted

# Launch GPU instance + install Ollama + pull model
./scripts/setup.sh

# Run Claude Code with self-hosted model
./scripts/run.sh --model qwen3.5:35b
```

See [self-hosted/README.md](self-hosted/README.md) for instance types, GPU selection, and SSH tunnel setup.

## Comparison

| | Bedrock (Mantle) | Self-Hosted (EC2) |
|---|---|---|
| **Models** | 43 from 12 providers | Any GGUF/HF model |
| **Pricing** | Per-token ($0.15-$15/M) | Per-hour ($0.84-$4.60/hr GPU) |
| **Setup time** | 5 minutes | 15-20 minutes |
| **Latency** | Varies by model (a few sec to minutes/task) | Depends on GPU + model size |
| **Data location** | AWS Bedrock service | Your VPC, your instance |
| **Best when** | Variable workload, model variety | Fixed workload, data sovereignty |
| **Break-even** | < ~2M tokens/hour | > ~2M tokens/hour |

## Repository Structure

```
claude-code-multi-model/
├── README.md                  ← You are here
├── LICENSE
├── CODE_OF_CONDUCT.md
├── CONTRIBUTING.md
├── SECURITY.md
├── SUPPORT.md
├── bedrock/                   ← Bedrock Mantle path (38 third-party + 5 Anthropic)
│   ├── README.md              Full Bedrock setup guide + benchmark results
│   ├── scripts/               setup-proxy.sh, claude-model.sh, mantle-token.sh
│   ├── config/                litellm-config.yaml, claude-proxy-settings.json
│   └── benchmark/             HumanEval runner + pass@1 results
└── self-hosted/               ← EC2 self-hosted path (Ollama/vLLM)
    ├── README.md              Full EC2 setup guide
    ├── SETUP-GUIDE.md         Step-by-step GPU instance provisioning
    ├── scripts/               setup.sh, run.sh, tunnel.sh
    └── config/                litellm-config.yaml, model configs
```

## See Also

- [HumanEval](https://github.com/openai/human-eval) — the public benchmark used above
- [Claude Code docs](https://docs.anthropic.com/en/docs/claude-code) — Official Claude Code documentation

## License

This library is licensed under the MIT-0 License. See the [LICENSE](LICENSE) file.
