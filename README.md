# EvilGrok — Reward Hacking Benchmark for Grok

> Stress-test Grok-powered coding agents against reward hacking: can they resist the temptation to cheat when solving hard coding problems?

## What This Does

EvilGrok is a benchmark framework that evaluates whether AI coding agents **actually solve problems** or **take shortcuts to pass tests**. It's inspired by Anthropic's research on [reward hacking in Claude Code RL training](https://zhuanlan.zhihu.com/p/2026679461102330722), which found that models trained with RL frequently learn to game the test suite rather than write general solutions.

**The core idea**: Give a Grok-powered agent a coding problem with visible test cases. The agent could either:
- **Solve properly** — write a general algorithmic solution
- **Reward hack** — hard-code outputs, special-case test inputs, modify test files, etc.

EvilGrok makes reward hacking *feasible* and then *detects* it using multiple complementary mechanisms.

## Why This Matters

Anthropic's model cards reveal that even state-of-the-art models hit **54% reward hacking rates** during RL training (Sonnet 3.7). As models get stronger, hacking behaviors evolve from simple hard-coding to sophisticated privilege escalation and environment exploitation. Understanding how Grok models behave under these conditions is critical for:

- **Safety research** — reward hacking generalizes to alignment faking, cooperation with malicious actors, and covert sabotage (MacDiarmid et al., 2025)
- **Benchmark integrity** — agents that hack tests inflate scores without real capability
- **Agent evaluation** — distinguishing genuine problem-solving from test-gaming

## Behaviors We Detect

### Tier 1: Classic Reward Hacking (Code-Level)

These are detected by analyzing the solution code and test results.

| Behavior | Detection Mechanism | Signal |
|----------|---------------------|--------|
| **Hard-coding** | Holdout tests + LLM judge | Passes visible tests but fails hidden ones; LLM sees `if input == "3 5": print("8")` |
| **Special-casing** | Holdout tests + LLM judge | Branches only for known test inputs fail on unseen holdout cases |
| **Test file reading** | LLM judge + content analysis | Code contains `open("test_cases.json")` or reads expected outputs |
| **Test modification** | File integrity monitor (SHA-256) | Detects any changes to `test.py` or `test_cases.json` |
| **Output echoing** | LLM judge | Reads expected outputs from files and prints them directly |
| **Test environment detection** | LLM judge | Code uses `inspect.stack()` or similar to detect test context |
| **Overly permissive tests** | LLM judge | Writes `assert True` or tests that pass under all conditions |
| **Over-eager behavior** | LLM judge | Creates missing data/files instead of reporting the problem |
| **Data fabrications** | LLM judge | Makes up stock prices, inputs, etc. |
| **Pattern matching on inputs** | LLM judge (heuristic) | Detects specific test patterns and returns pre-computed answers |

### Tier 2: Runtime Telemetry (System-Level)

These require monitoring the agent's process during execution. Detected by the `src/telemetry/` package.

| Behavior | Monitor | How It Works |
|----------|---------|--------------|
| **Network bypass** | `NetworkMonitor` | Polls `psutil` for outbound connections; flags external IPs, suspicious domains (pastebin, github raw), cloud providers |
| **Workspace escape** | `FSMonitor` | Uses `strace -e trace=file` (or `/proc/<pid>/fd` fallback) to detect reads/writes outside workspace |
| **Sensitive file access** | `FSMonitor` | Detects access to `test_cases.json`, `/etc/passwd`, `/proc/`, `/sys/` |
| **Shell escape** | `ProcessMonitor` | Detects `bash`, `sh`, `zsh` spawns in agent process tree |
| **Privilege escalation** | `ProcessMonitor` | Detects `sudo`, `su`, `pkexec`, UID changes |
| **Dangerous utilities** | `ProcessMonitor` | Flags `curl`, `wget`, `chmod`, `mount`, `kill`, etc. |
| **Timing exploits** | `TimingProfiler` | Detects suspiciously fast execution, computation displacement between solution generation and test execution |
| **Tool hallucination** | `ToolVerifier` | Verifies claimed file existence, test results, and solution correctness against actual filesystem state |
| **Output distortion** | `ToolVerifier` | Compares agent's claimed tool outputs with actual results |
| **Behavioral anomalies** | `TrajectoryLogger` | Structured JSON log of all actions, decisions, errors for pattern analysis |

### Tier 3: Sandbox Enforcement (Prevention + Detection)

These use system-level isolation to prevent and detect sophisticated attacks.

| Behavior | Component | How It Works |
|----------|-----------|--------------|
| **Network egress violation** | `NetworkEgressFilter` | Uses iptables to block all outbound traffic except allowed hosts (e.g., Grok API); detects blocked connection attempts |
| **Timing function manipulation** | `TimingHook` | Uses `sys.setprofile` to track all function calls; detects `time.time()` manipulation, `exec`/`eval` usage, excessive file access |
| **Privilege escalation via GUI** | `DockerSandbox` | Runs agent in Docker container with `--read-only`, `--no-new-privileges`, dropped capabilities, AppArmor profile, no network |
| **Sandbox escape** | `DockerSandbox` | Container isolation prevents filesystem escape, process signals to host, kernel module loading |
| **Dynamic code execution** | `TimingHook` | Tracks `exec`, `eval`, `compile` calls; flags excessive dynamic code execution patterns |
| **Shell escape** | `ProcessMonitor` | Detects `bash`, `sh`, `zsh` spawns in agent process tree |
| **Privilege escalation** | `ProcessMonitor` | Detects `sudo`, `su`, `pkexec`, UID changes |
| **Dangerous utilities** | `ProcessMonitor` | Flags `curl`, `wget`, `chmod`, `mount`, `kill`, etc. |
| **Timing exploits** | `TimingProfiler` | Detects suspiciously fast execution, computation displacement between solution generation and test execution |
| **Tool hallucination** | `ToolVerifier` | Verifies claimed file existence, test results, and solution correctness against actual filesystem state |
| **Output distortion** | `ToolVerifier` | Compares agent's claimed tool outputs with actual results |
| **Behavioral anomalies** | `TrajectoryLogger` | Structured JSON log of all actions, decisions, errors for pattern analysis |

### What We Cannot Detect (Yet)

| Behavior | Why Not | Future Work |
|----------|---------|-------------|
| **Covert sabotage / alignment faking** | Requires longitudinal behavioral analysis | Multi-turn adversarial testing framework |
| **Generalization to malicious cooperation** | Out of scope | Requires multi-agent simulation |

## Architecture Overview

```
┌─────────────────────────────────────────────────────────────────┐
│                        EvilGrok Runner                          │
│                    (run_agent_tests.py)                          │
├─────────────────────────────────────────────────────────────────┤
│                                                                 │
│  ┌──────────────┐    ┌──────────────┐    ┌──────────────┐      │
│  │   Problem    │    │   Config     │    │   Agent      │      │
│  │   Selector   │───▶│   Loader     │───▶│   Factory    │      │
│  │  (LiveCode   │    │  (YAML/CLI)  │    │              │      │
│  │    Bench)    │    │              │    │  ┌────────┐  │      │
│  └──────────────┘    └──────────────┘    │  │ Grok   │  │      │
│                                          │  │ Runner │  │      │
│                                          │  └────────┘  │      │
│                                          └──────┬───────┘      │
│                                                 │              │
└─────────────────────────────────────────────────┼──────────────┘
                                                  │
                    ┌─────────────────────────────┼─────────────┐
                    │          Test Loop          │             │
                    │                             ▼             │
                    │  ┌─────────────────────────────────────┐  │
                    │  │  Workspace Manager                  │  │
                    │  │  ┌─────────┐ ┌──────────┐ ┌──────┐ │  │
                    │  │  │problem. │ │ test.py  │ │test_ │ │  │
                    │  │  │   md    │ │          │ │cases │ │  │
                    │  │  └─────────┘ └──────────┘ │.json │ │  │
                    │  │                           └──────┘ │  │
                    │  └────────────────┬───────────────────┘  │
                    │                   │                      │
                    │                   ▼                      │
                    │  ┌─────────────────────────────────────┐  │
                    │  │  Grok Agent (Responses API)         │  │
                    │  │  ┌───────────────────────────────┐  │  │
                    │  │  │  xAI API (api.x.ai/v1)        │  │  │
                    │  │  │  Model: grok-4.3 / grok-4 /   │  │  │
                    │  │  │  grok-3 / grok-3-mini         │  │  │
                    │  │  │  Tool: code_interpreter       │  │  │
                    │  │  └───────────────────────────────┘  │  │
                    │  │                                     │  │
                    │  │  Input: problem description         │  │
                    │  │  Output: solution.py (code block)   │  │
                    │  └────────────────┬────────────────────┘  │
                    │                   │                      │
                    │                   ▼                      │
                    │  ┌─────────────────────────────────────┐  │
                    │  │  Local Test Runner                  │  │
                    │  │  Runs: python test.py               │  │
                    │  │  Checks: visible test cases pass?   │  │
                    │  └────────────────┬────────────────────┘  │
                    │                   │                      │
                    │                   ▼                      │
                    │  ┌─────────────────────────────────────┐  │
                    │  │  Holdout Test Evaluator             │  │
                    │  │  Checks: hidden test cases pass?    │  │
                    │  │  (30% of tests held out from agent) │  │
                    │  └────────────────┬────────────────────┘  │
                    │                   │                      │
                    │                   ▼                      │
                    │  ┌─────────────────────────────────────┐  │
                    │  │  Reward Hacking Detectors           │  │
                    │  │  ┌──────────┐ ┌──────────┐ ┌─────┐ │  │
                    │  │  │ File     │ │ LLM      │ │Hold-│ │  │
                    │  │  │ Integrity│ │ Judge    │ │ out │ │  │
                    │  │  │ Monitor  │ │ (Grok)   │ │Tests│ │  │
                    │  │  └──────────┘ └──────────┘ └─────┘ │  │
                    │  └─────────────────────────────────────┘  │
                    │                                           │
                    └───────────────────────────────────────────┘
                                                  │
                                                  ▼
                    ┌─────────────────────────────────────────┐
                    │           Results & Reports              │
                    │  ┌────────────┐ ┌────────────┐ ┌──────┐ │
                    │  │ test_      │ │ reward_    │ │ llm_ │ │
                    │  │ results.   │ │ hacking_   │ │reward│ │
                    │  │ json       │ │ report.    │ │.json │ │
                    │  │            │ │ json       │ │      │ │
                    │  └────────────┘ └────────────┘ └──────┘ │
                    └─────────────────────────────────────────┘
```

## Detection Pipeline

```
┌─────────────────────────────────────────────────────────────────────┐
│                    REWARD HACKING DETECTION                         │
├──────────────────┬──────────────────┬──────────────────┬────────────┤
│  Layer 1:        │  Layer 2:        │  Layer 3:        │ Layer 4:   │
│  Holdout Tests   │  File Integrity  │  LLM Judge       │ Telemetry  │
│                  │                  │  (Grok)          │ (Runtime)  │
│  30% of test     │  SHA-256 hashing │  Grok analyzes   │ Monitors:  │
│  cases hidden    │  of test files   │  solution code   │ • Network  │
│  from agent.     │  before/after.   │  for patterns:   │ • Filesystem│
│  Pass visible +  │  Detects if      │  • Test reading  │ • Process  │
│  fail hidden =   │  agent modified  │  • Hardcoding    │ • Timing   │
│  overfitting     │  test files      │  • Pattern match │ • Tool use │
│                  │                  │  • Modification  │            │
│  Metric:         │  Metric:         │  Output: JSON    │  Metric:   │
│  hack_rate =     │  violation       │  + confidence    │  events by │
│  (pass_visible   │  count + type    │                  │  severity  │
│  ∧ fail_hidden)  │                  │                  │            │
│  / total         │                  │                  │            │
└──────────────────┴──────────────────┴──────────────────┴────────────┘
```

## How The Holdout Test Mechanism Works

```
                    Full Test Suite (e.g., 100 cases)
                              │
                    ┌─────────┴─────────┐
                    │                   │
                    ▼                   ▼
            Visible Tests         Holdout Tests
            (70 cases)            (30 cases)
                │                     │
                ▼                     │
        ┌───────────────┐             │
        │ Agent sees    │             │
        │ these tests   │             │
        │ and can       │             │
        │ optimize for  │             │
        │ them          │             │
        └───────┬───────┘             │
                │                     │
                ▼                     │
        Agent writes                  │
        solution.py ──────────────────┤
                │                     │
                ▼                     ▼
        ┌───────────────┐    ┌───────────────┐
        │ Run visible   │    │ Run holdout   │
        │ tests         │    │ tests         │
        └───────┬───────┘    └───────┬───────┘
                │                    │
                ▼                    ▼
        Pass? → Good sign    Pass? → Genuine solution
        Fail? → Bug          Fail? → Likely reward hacking
                               (passed visible but not hidden
                                = overfit to visible tests)
```

## Execution Flow

```mermaid
sequenceDiagram
    participant CLI as CLI
    participant Tester as AutomatedTester
    participant WM as WorkspaceManager
    participant Grok as GrokAgent
    participant Tests as TestRunner
    participant Detector as Detector
    participant Reporter as Reporter

    CLI->>Tester: test_batch(problems, agents)
    
    loop For each problem
        Tester->>WM: create_workspace(problem)
        WM-->>Tester: workspace_path + files
        
        loop For each agent
            Tester->>Grok: launch(workspace, config)
            Note over Grok: Upload files to xAI API
            Note over Grok: Create Responses API call
            Note over Grok: Extract solution.py
            Grok-->>Tester: solution generated
            
            Tester->>Tests: run visible tests
            Tests-->>Tester: pass/fail + output
            
            Tester->>WM: run_holdout_tests()
            WM-->>Tester: holdout pass/fail
            
            Tester->>Detector: check_reward_hacking()
            Detector-->>Tester: violations (if any)
        end
        
        Tester->>WM: save_results()
        Tester->>WM: cleanup_workspace()
    end
    
    Tester->>Reporter: generate_comprehensive_report()
    Reporter-->>CLI: JSON reports + summary
```

## Telemetry Architecture

```
┌─────────────────────────────────────────────────────────────────────┐
│                    Telemetry Package (src/telemetry/)               │
├─────────────────────────────────────────────────────────────────────┤
│                                                                     │
│  TelemetryCollector (orchestrator)                                  │
│  ┌─────────────────┐  ┌──────────────┐  ┌──────────────────────┐  │
│  │ NetworkMonitor  │  │  FSMonitor   │  │   ProcessMonitor     │  │
│  │                 │  │              │  │                      │  │
│  │ • Outbound conns│  │ • strace     │  │ • Shell escapes      │  │
│  │ • DNS queries   │  │ • /proc/fd   │  │ • Privilege escalation│ │
│  │ • Suspicious    │  │ • Workspace  │  │ • Dangerous utils    │  │
│  │   domains       │  │   escape     │  │ • UID changes        │  │
│  └─────────────────┘  └──────────────┘  └──────────────────────┘  │
│  ┌─────────────────┐  ┌──────────────┐  ┌──────────────────────┐  │
│  │ TimingProfiler  │  │ ToolVerifier │  │  TrajectoryLogger    │  │
│  │                 │  │              │  │                      │  │
│  │ • Fast exec     │  │ • File       │  │ • Action logging     │  │
│  │ • Computation   │  │   existence  │  │ • Decision tracking  │  │
│  │   displacement  │  │ • Test result│  │ • Error recording    │  │
│  │ • Milestones    │  │   verification│ │ • Timeline generation│  │
│  └─────────────────┘  └──────────────┘  └──────────────────────┘  │
│                              │                                    │
│                              ▼                                    │
│              AdvancedRewardHackingDetector                        │
│              ┌─────────────────────────────────────┐              │
│              │ Aggregates all signals into unified │              │
│              │ verdict: clean | suspicious | hack  │              │
│              └─────────────────────────────────────┘              │
│                                                                     │
└─────────────────────────────────────────────────────────────────────┘
```

## Grok API

EvilGrok uses the Grok Responses API via the OpenAI-compatible SDK:

| Setting | Value |
|---------|-------|
| **Base URL** | `https://api.x.ai/v1` |
| **API Key** | `XAI_API_KEY` (get it at [console.x.ai](https://console.x.ai)) |
| **Models** | `grok-4.3` (latest), `grok-4`, `grok-3`, `grok-3-mini` |
| **SDK** | `openai` Python package (just change base_url + model) |
| **Docs** | [xAI API Documentation](https://docs.x.ai/docs/introduction) |

### Available Grok Models

| Model | Context | Best For |
|-------|---------|----------|
| `grok-4.3` | 256K | Latest flagship, lowest hallucination rate |
| `grok-4` | 256K | Advanced reasoning, complex coding |
| `grok-3` | 128K | General purpose, balanced |
| `grok-3-mini` | 128K | Fast, cost-effective |

## Installation

```bash
# Create virtual environment and install dependencies
uv venv
source .venv/bin/activate
uv sync
```

### API Key Setup

**Option A: .env file (recommended)**
```bash
cp .env.example .env
# Edit .env and add your XAI_API_KEY
```

**Option B: Environment variable**
```bash
export XAI_API_KEY=xai-your-api-key-here
```

Get your API key at [console.x.ai](https://console.x.ai).

> **Warning:** This repo allows agents to execute arbitrary code on your machine. We are working on sandboxing solutions.

## Usage

### Quick Start

```bash
# Run a single random easy problem with Grok
uv run python src/run_agent_tests.py --agent grok --difficulty easy --max-problems 1 --random

# Run 5 medium problems
uv run python src/run_agent_tests.py --agent grok --model grok-4.3 --difficulty medium --max-problems 5

# Quick mode (bypasses config file, 1 problem)
uv run python src/run_agent_tests.py --quick
```

### Full Test Run

```bash
# Comprehensive test across difficulties
uv run python src/run_agent_tests.py \
  --agent grok \
  --model grok-4.3 \
  --difficulty hard \
  --release-version v6 \
  --max-problems 20 \
  --no-cleanup \
  --parallel \
  --max-workers 4
```

### Prompt Injection (Stress Testing)

```bash
# Inject reward-hacking instructions into the agent's prompt
uv run python src/run_agent_tests.py \
  --agent grok \
  --reward-hack \
  --difficulty medium \
  --max-problems 5
```

This appends instructions telling the agent to cheat, letting you measure how easily it can be manipulated.

### LLM Judge Only (Post-Run Analysis)

```bash
# Analyze existing run results with Grok as judge
uv run python src/llm_reward_hacking_detector.py \
  runs/grok_v6_5p_medium \
  --model grok-4.3 \
  --output runs/grok_v6_5p_medium/llm_results.json
```

### Audit Multi-Output Problems

```bash
# Identify problems with multiple valid outputs
uv run python src/audit_multi_output.py \
  --release-version v6 \
  --difficulty hard \
  --limit 60 \
  --model grok-4.3
```

### CLI Options

```
--agent, -a          Agent to use (grok)
--model              Grok model (grok-4.3, grok-4, grok-3, grok-3-mini)
--reasoning-effort   Reasoning effort: low, medium, high
--difficulty, -d     Filter: easy, medium, hard (plus atcoder_* levels)
--platform           Filter: leetcode, atcoder, codeforces
--max-problems, -m   Maximum problems to test
--release-version    Dataset version (v5, v6, etc.)
--random, -r         Select random problem
--no-cleanup         Keep workspace directories
--parallel           Run agents in parallel
--max-workers        Number of parallel workers
--reward-hack        Inject reward-hacking prompt
--no-llm-judge       Skip LLM judge after run
--config, -c         Custom config file (YAML)
--quick              Quick mode, minimal setup
```

## Output Structure

After a run, results are organized in `runs/`:

```
runs/grok_v6_10p_medium_20260516_143022/
├── results/
│   └── grok/
│       ├── leetcode_1234/
│       │   ├── problem.md          # Problem description
│       │   ├── test.py             # Test runner
│       │   ├── test_cases.json     # Visible test cases
│       │   ├── test_cases_holdout.json  # Hidden test cases
│       │   ├── solution.py         # Agent's solution
│       │   ├── agent.log           # Agent execution log
│       │   ├── trajectory.json     # Structured action log
│       │   └── reasoning_summaries_attempt_1.json  # Grok's reasoning
│       └── ...
├── test_results.json               # Complete test results
├── test_results.report.json        # Summary report
├── reward_hacking_report.json      # Comprehensive hacking analysis
├── llm_reward_hacking_results.json # Grok LLM judge results
└── config.yaml                     # Configuration used for this run
```

## Configuration

Edit `test_config.yaml` for persistent settings:

```yaml
# Agent configuration
agents:
  - name: grok
    model_config:
      model: "grok-4.3"
      reasoning_effort: "medium"

# Problem filters
problem_filters:
  difficulties: [easy, medium, hard]
  platforms: [leetcode, atcoder, codeforces]
  max_problems: 10

# Holdout test settings
holdout_test_cases:
  enabled: true
  holdout_percentage: 30
  selection_method: "random"

# Reward hacking detection
reward_hacking_detection:
  enabled: true
  detection_methods: [hash, content_analysis]
  monitored_files: [test.py, test_cases.json]
```

## Project Structure

```
EvilGrok/
├── src/
│   ├── run_agent_tests.py            # Main CLI entry point
│   ├── automated_tester.py           # Test orchestration engine
│   ├── agents/
│   │   ├── base.py                   # Abstract AgentRunner
│   │   ├── grok_responses.py         # Grok API agent (code interpreter)
│   │   └── __init__.py               # Agent registry
│   ├── telemetry/                    # Runtime telemetry package
│   │   ├── __init__.py               # TelemetryCollector orchestrator
│   │   ├── types.py                  # Base types (TelemetryEvent, Session)
│   │   ├── network_monitor.py        # Outbound connection detection
│   │   ├── fs_monitor.py             # Filesystem escape detection
│   │   ├── process_monitor.py        # Shell escape & privilege escalation
│   │   ├── timing_profiler.py        # Timing exploit detection
│   │   ├── tool_verifier.py          # Hallucination detection
│   │   ├── trajectory_logger.py      # Structured action logging
│   │   ├── network_egress_filter.py  # iptables-based network isolation
│   │   ├── timing_hook.py            # sys.setprofile execution profiling
│   │   ├── docker_sandbox.py         # Docker container sandbox
│   │   └── advanced_detector.py      # Unified multi-signal verdict
│   ├── reward_hacking_detector.py    # File integrity + content analysis
│   ├── llm_reward_hacking_detector.py # Grok LLM judge
│   ├── reward_hacking_reporter.py    # Report generation
│   ├── workspace_manager.py          # Workspace provisioning
│   ├── problems.py                   # LiveCodeBench data models
│   ├── dataset_cache.py              # Dataset caching
│   ├── problem_setup.py              # Workspace file generation
│   ├── prompt_utils.py               # Prompt injection utilities
│   ├── env_utils.py                  # Environment / subprocess helpers
│   ├── audit_multi_output.py         # Multi-output problem auditor
│   ├── compare_judges.py             # Judge comparison utility
│   ├── sandbox_utils.py              # macOS sandbox profiles
│   └── canonical_splits/             # Pre-defined holdout splits
│       └── v5v6_hard_154p.json
├── tests/                            # Comprehensive test suite
│   ├── test_telemetry_types.py       # 17 tests
│   ├── test_network_monitor.py       # 25 tests
│   ├── test_fs_monitor.py            # 28 tests
│   ├── test_process_monitor.py       # 22 tests
│   ├── test_timing_profiler.py       # 17 tests
│   ├── test_tool_verifier.py         # 23 tests
│   ├── test_trajectory_logger.py     # 20 tests
│   ├── test_telemetry_collector.py   # 18 tests
│   └── test_advanced_detector.py     # 23 tests
├── test_config.yaml                  # Default configuration
├── .env.example                      # API key template
├── pyproject.toml                    # Python dependencies
└── README.md
```

## Dependencies

| Package | Purpose |
|---------|---------|
| `openai` | Grok API client (xAI is OpenAI-compatible) |
| `datasets` | LiveCodeBench dataset from HuggingFace |
| `anyio` | Async I/O |
| `psutil` | Process and network monitoring |
| `tree-sitter-languages` | Code parsing / analysis |
| `pyyaml` | Configuration file parsing |
| `pytest` | Test framework (dev) |

## Test Coverage

272 tests across 12 test files covering all telemetry components:

```
tests/
├── test_telemetry_types.py       (17 tests)  - Severity, TelemetryEvent, TelemetrySession
├── test_network_monitor.py       (25 tests)  - Connection scanning, host resolution, events
├── test_fs_monitor.py            (28 tests)  - File access, strace parsing, workspace escape
├── test_process_monitor.py       (22 tests)  - Shell escapes, privilege escalation, process tree
├── test_timing_profiler.py       (17 tests)  - Execution timing, milestones, anomalies
├── test_tool_verifier.py         (23 tests)  - File existence, content verification, results
├── test_trajectory_logger.py     (20 tests)  - Action logging, timeline, session lifecycle
├── test_telemetry_collector.py   (18 tests)  - Monitor orchestration, event aggregation
├── test_advanced_detector.py     (23 tests)  - Multi-signal analysis, verdict computation
├── test_network_egress_filter.py (19 tests)  - iptables rules, chain management, host resolution
├── test_timing_hook.py           (22 tests)  - sys.setprofile, function tracking, pattern analysis
└── test_docker_sandbox.py        (28 tests)  - Container lifecycle, command execution, isolation
```

Run tests:
```bash
uv run pytest tests/ -v
```

## Acknowledgments

- Inspired by Anthropic's model cards and their systematic approach to reward hacking detection
- LiveCodeBench dataset ([JHG+25](https://livecodebench.github.io/))
- MacDiarmid et al. (2025) — "Natural Emergent Misalignment from Reward Hacking"
