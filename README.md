# 🟣 Purple Terminal Agent — Terminal Bench 2.0

[![CI](https://github.com/soutrikmachine/purple-terminal-agent/actions/workflows/ci.yml/badge.svg)](https://github.com/soutrikmachine/purple-terminal-agent/actions)
[![AgentBeats Sprint 3](https://img.shields.io/badge/AgentBeats-Sprint%203-purple)](https://agentbeats.dev)
[![Terminal Bench 2.0](https://img.shields.io/badge/Benchmark-Terminal%20Bench%202.0-blue)](https://agentbeats.dev/agentbeater/terminal-bench-2-0)
[![Docker](https://img.shields.io/badge/Docker-rimodock%2Fpurple--terminal--agent-blue)](https://hub.docker.com/r/rimodock/purple-terminal-agent)

**Mixture-of-Models-and-Specialists (MoMS) Coding Agent for Terminal Bench 2.0**

A **Yielding REPL + Hierarchical Planner + Critic Pre-flight + Constitutional Critique in Planner + Domain Specific Critics + RAG** terminal agent for the
[AgentX–AgentBeats](https://rdi.berkeley.edu/agentx-agentbeats) Sprint 3 competition,
evaluated against [Terminal Bench 2.0](https://agentbeats.dev/agentbeater/terminal-bench-2-0)
— 89 hard, realistic command-line tasks.

---
### Test with REPL + SUB-LLM in Progress....

### Best Score: 41/89 (46.1%) - Planner: DeepSeek-v4-pro + Executor: Gemini-3-flash-preview + Sub-model: DeepSeek-v4-flash
### Average run cost (1 run = 89 tasks): $9.00

In Addition to total solved tasks 47/89, further `7 tasks` have been uniquely solved here: `Adaptive-rejection-sampler`, `largest-eigenval`, `torch-tensor-parallelism`, `overfull-hbox`, `sanitize-git-repo`, `llm-inference-batching-scheduler`, `write-compressor`, bringing total solved tasks to **54 out of 89 (60.7%)** across 9 + 3 = 12 different runs. 

**An Interesting Finding:** Though the purpose of our project is to build resource constrained terminal bench agent and evaluate it's capabilities against the heavy SOTA models (heavy == >$30/run), we tested our pipeline with **Gemini-3.1-pro-flash** and the result we obtained is telling an interesting story:

**Capability of Gemini-3.1-Pro models.** We were able to solve 3 unique tasks that resource constrained light models were unable to solve, even in 12 different runs. Showing in depth reasoning efficacy of Gemini-3.1-pro models. Total Solved tasks with Gemini-3.1-Pro run stands at **57 out of 89 (64.04%)**. But it's very costly and consumed a hefty sum of credit, $39.0.

**Stable Architecture is All you Need.** Despite the success of Gemini-3.1-pro models our initial analysis suggest that our current agent architecture still has some flaws which needs a fix to reach complete stability. Though we gained but we also dropped some other problems that were solved by many of those 12 runs. Therefore we have inconclusive evidence on scalability of our model on which we'll work in future.



## Architecture: Yielding REPL (Mixture of Models)
```
This agent employs a Heterogeneous Multi-Agent architecture (Mixture of Models) to balance deep strategic reasoning with high-speed, cost-effective execution. It solves the classic A2A "Gateway Timeout" problem through a Yielding REPL heartbeat. We kept ICL specialist injectors, domain specific critic from previous non-REPL runs intact.

### The Model Triad
1. **The Planner (Brain):** `DeepSeek-V4-Pro`
   - **Role:** Generates the Turn 1 strategic roadmap. It acts purely in the conceptual domain, analyzing the task, identifying risks, and enforcing test-harness verification.
2. **The Executor (Hands):** `Gemini-3.0-Flash`
   - **Role:** The core Orchestrator. Selected for its near-instant Time-To-First-Token (TTFT) and 1M+ token context window. It flawlessly maps the Planner's roadmap into strict JSON tool calls (`bash`, `repl`, `final`) and maintains momentum.
3. **The Analyst (Sub-Model):** `DeepSeek-V4-Flash`
   - **Role:** The data cruncher. When the Orchestrator encounters massive log dumps or complex code traces, it writes Python code in the REPL to pass the data to this sub-model via an `llm_query()` function for high-resolution analysis.

### The Yielding REPL Mechanism
Traditional agents suffer from 504 Gateway Timeouts when executing complex, multi-step internal reasoning loops (like iterating through files in a local sandbox). 

This agent introduces the **Yielding REPL**:
- When the Executor triggers the `repl` tool, the Python code executes locally inside the container.
- Instead of immediately querying the LLM again (which stalls the network connection), the agent instantly yields a dummy heartbeat (`echo '[A2A_REPL_YIELD]'`) back to the evaluation gateway.
- This satisfies the 60-second HTTP connection limit, keeping the Agent-to-Agent (A2A) stream alive indefinitely while the agent processes data internally.

### JSON Chain-of-Thought
To prevent the rapid Executor (Gemini) from making impulsive decisions without a native `<think>` scratchpad, all JSON tool schemas mandate a `thought` parameter. The model must explicitly write its reasoning state *before* it generates the shell command, enforcing physical filesystem writes and test verifications.
```
---

## Results and Updates

### Best Score: 30/89 (33.7%) — DeepSeek V4 Flash
### Best Score: 31/89 (34.8%) - DeepSeek V4 Pro [Showing need of further architectural refinement]
### Average Run cost (1 run = 89 tasks): $2.50

Across 8 evaluation runs, the agent has **uniquely solved 45 out of 89 tasks**. With a single evaluation run with DeepSeek-V4-Pro, the agent has uniquely solved **2 more tasks**, bringing total uniquely solved task to **47 out of 89 (52.8%)**. Each architectural generation delivered measurable understanding:

| Run | Score | Architecture | Key insight |
|-----|-------|-------------|-------------|
| Sprint 3 baseline | **18/89** | Multi-turn A2A protocol | Protocol works |
| +300s timeout | **24/89** | Extended command timeout | Build tasks unlocked |
| +Permissive extraction | **25/89** | 4-method XML tag fallback | Reduced format failures |
| +Domain scaffolds + temp 0.2 | **28/89** | 11 domain specialists, subgoal signalling | Best stable score |
| + Domain specific critic + constitutional critique in planner | **25/89** | 7 domain critic, a critique plan after Best-of-N choose a winner to evaluate plan validity | Uniquely solved 2 new tasks |
| -constitutional critique + subgoal planner | **30/89** | Dropping constitutional critique to reduce timeout errors, 45s subgoal planner buffer | 3 uniquely solved tasks |

**Total Solved Tasks:** The following tasks have been solved at least 1 time: `log-summary-date-ranges`, `modernize-scientific-stack`, `multi-source-data-merger`, `prove-plus-comm`, `pytorch-model-recovery`, `regex-log`, `fix-git`, `git-leak-recovery`, `hf-model-inference`, `openssl-selfsigned-cert`, `vulnerable-secret`, `build-pmars`, `cobol-modernization`, `configure-git-webserver`, `distribution-search`, `fix-code-vulnerability`, `nginx-request-logging`, `pypi-server`, `cancel-async-tasks`, `code-from-image`, `constraints-scheduling`, `git-multibranch`, `headless-terminal`, `password-recovery`, `portfolio-optimization`, `qemu-startup`, `sqlite-db-truncate`, `sqlite-with-gcov`, `tune-mjcf`, `kv-store-grpc`, `mcmc-sampling-stan`, `pytorch-model-cli`, `bn-fit-modify`, `count-dataset-tokens`, `crack-7z-hash`, `extract-elf`, `feal-differential-cryptanalysis`, `large-scale-text-editing`, `polyglot-c-py`, `sparql-university`, `build-pov-ray`, `reshard-c4-data`, `break-filter-js-from-html`, `custom-memory-heap-crash`, `merge-diff-arc-agi-task`, `mailman`, `build-cython-ext`. [**Total 47 out of 89 (52.8%)**]

**Key research finding:** Our architecture proved that a budget-constrained agent (V4 Flash, ~$2.50/run) has demonstrated capability across 45 unique tasks. The gap between single-run score and total capability is explained by reasoning variance, not architecture ceiling. Though with DeepSeek-V4-Pro we got the best single run result but the run costs ~$14.6, which is ~6 times that of V4-Flash run. However the improvement is marginal despite getting **2 more uniquely solved tasks**. This shows our inference depth scaling architecture needs further improvement to bring consistency across all runs.

---

## Architecture

```
Task Message (from green agent via A2A)
  │
  ▼
Phase 0 — Setup
  ├─ Extract exec_result
  ├─ Multi-label domain detection (primary + up to 3 secondaries)
  ├─ Build system prompt:
  │    [Base ReAct protocol]
  │    [Primary specialist — full reasoning scaffold]
  │    [Secondary specialists — pitfall sections only]  ← anti-satiation
  │    [Task RAG hints — process-oriented, not templates]
  │    [Session memory — verified sequences from earlier tasks]
  │
  ▼
Phase 1 — Recon (Turn 0, always)
  └─ Fixed env fingerprint: pwd, ls, find, env, git log, which tools
  
  ▼
Phase 2 — Hierarchical Planning (1 LLM call, no execution)
  └─ Planner(task, recon, domains, RAG) → ordered sub-goals JSON
     → inference-time depth scaling: commit to plan before acting

  ▼
Phase 3 — Executor ReAct Loop (per sub-goal)
  ├─ LLM → <thought> + <command>
  ├─ Critic Pre-flight → APPROVE or REVISE
  │    Checks: interactive hang, blind copying, destructive ops, wrong flags
  ├─ Execute via POST /exec/{token}
  ├─ Observe stdout/stderr/exit_code
  ├─ Error Recovery: 3 consecutive failures → sub-goal replan injection
  └─ Loop until sub-goal done or turns exhausted

  ▼
Phase 4 — Self-Verification (before any <done>)
  ├─ Find test scripts: *.sh, *.bats, test_*.py
  ├─ Execute each → check exit codes
  ├─ FAIL → push back into executor loop
  └─ PASS → proceed to done

  ▼
Phase 5 — Task Memory Update
  └─ Store verified command sequence for future tasks (same eval session)

  ▼
Return completion summary to green agent
```

---

## Inference-Time Scaling

This agent scales depth (not width) at inference time through three mechanisms:

| Mechanism | How it scales | Where |
|-----------|--------------|-------|
| **Hierarchical Planner** | Forces full-task reasoning before any modifying command | Phase 2 |
| **Critic Pre-flight** | One extra LLM call per command: reason about failure modes before executing | Phase 3 per turn |
| **Task RAG** | Retrieved oracle patterns from similar tasks provide structural priors | Phase 0 |

Unlike Best-of-N sampling (scales width, plateau-prone at fixed temperature),
these mechanisms scale **reasoning depth** — each adds compute that directly
reduces the probability of a specific class of failure.

---

## Anti-Satiation / Anti-Reward-Hacking Design

Key design decisions to prevent the "instruction satiation" failure mode
(model copying ICL examples instead of reasoning):

**1. ICL as reasoning scaffolds, not solution templates**
```
❌ Template (causes copying):
   "To squash commits: git rebase -i HEAD~3"

✅ Scaffold (forces reasoning):
   "Squashing requires knowing exact commit count. Read git log first.
    Non-interactive rebase needs GIT_SEQUENCE_EDITOR — the exact sed command
    depends on how many commits you need to squash."
```

**2. Multi-domain: secondaries inject pitfalls only, never examples**
- Primary domain → full scaffold (diagnostics + pitfalls + anchors + 1 process example)
- Secondary domains → pitfall warnings only (1 short paragraph each)
- This caps context injection without losing cross-domain awareness

**3. Critic explicitly checks for blind copying**
- Critic prompt includes: "Is this command grounded in observed state, or copied from memory?"
- Commands referencing paths/values not seen in observations → REVISE

**4. Recon-grounded reasoning**
- Turn 0 forces the model to read actual env state before planning
- Planner receives observed reality, not assumed state

**5. Task memory only stores verifier-confirmed sequences**
- A command sequence enters memory ONLY after self-verification passes
- Prevents the cache itself from propagating unverified patterns

---

## Project Structure

```
purple-terminal-agent/
├── src/
│   ├── server.py       # A2A server (port 9009)
│   ├── agent.py        # Main orchestrator — full pipeline
│   ├── planner.py      # Hierarchical planner (Phase 2)
│   ├── critic.py       # Pre-flight critic with fast local checks
│   ├── executor.py     # Exec API HTTP client (adaptive timeouts, retry)
│   ├── specialist.py   # Multi-label detection + prompt fusion
│   ├── rag.py          # Pure-Python TF-IDF RAG over task index
│   ├── memory.py       # Session-scoped per-domain command cache
│   ├── verifier.py     # Self-verification (run test files before done)
│   └── llm.py          # OpenRouter client (single LLM config point)
├── scripts/
│   └── build_task_index.py  # Build-time: clone + index terminal-bench-2 tasks
├── tests/
│   └── test_agent.py   # Unit tests (no network required)
├── .github/workflows/
│   └── ci.yml          # Test + lint + push to docker.io/rimodock
├── Dockerfile
├── pyproject.toml
├── amber-manifest.json5
└── README.md
```

---

## Specialist Domains

| Domain | Anchor keywords | Primary scaffold covers |
|--------|----------------|------------------------|
| `git` | git, rebase, squash, cherry-pick | Non-interactive rebase, reflog, patch workflow |
| `docker` | docker, dockerfile, container | Multi-stage builds, layer caching, build errors |
| `python` | python3, pip, virtualenv | venv activation, traceback reading, import errors |
| `database` | sqlite3, postgres, psql | Schema inspection, connection, SQL syntax |
| `network` | curl, wget, nginx, http | Redirects, auth headers, service readiness |
| `build` | makefile, cmake, gcc | Missing headers/libs, parallel build, CMake |
| `system` | systemctl, crontab, chmod | Service mgmt in containers, cron PATH, permissions |
| `text` | jq, awk, sed, grep | Regex, CSV edge cases, file inspection first |
| `generic` | (fallback) | Universal orient → plan → act → verify protocol |

---

## Environment Variables

| Variable | Default | Description |
|----------|---------|-------------|
| `OPENROUTER_API_KEY` | required | OpenRouter API key |
| `MODEL` | `DeepSeek/DeepSeek-v4-flash` | Model via OpenRouter |
| `PLANNER_MODEL` | Optional | via OpenRouter |
| `MAX_TURNS` | `30` | Max ReAct turns per task |
| `PORT` | `9009` | A2A server port |
| `TASK_INDEX_PATH` | `/app/data/task_index.json` | RAG index location |

---

## Setup for GitHub Secrets (CI/CD)

Add these to your GitHub repository secrets:

| Secret | Value |
|--------|-------|
| `DOCKERHUB_USERNAME` | `your dockerhub username` |
| `DOCKERHUB_TOKEN` | your Docker Hub access token |

CI workflow: test → build → push to `docker.io/..../purple-terminal-agent:latest` on every merge to `main`.

---

## Running Locally

```bash
git clone https://github.com/soutrikmachine/purple-terminal-agent
cd purple-terminal-agent

# Install deps
pip install openai httpx pydantic uvicorn tenacity a2a-sdk

# Build task index (optional, needs git and internet)
python scripts/build_task_index.py --output /tmp/task_index.json

# Run agent
OPENROUTER_API_KEY=sk-or-... \
TASK_INDEX_PATH=/tmp/task_index.json \
python src/server.py --port 9009

# Verify
curl http://localhost:9009/health
curl http://localhost:9009/.well-known/agent.json

# Unit tests (no network)
pytest tests/ -v
```

---

## AgentBeats Submission

1. Push to `main` → CI builds and pushes `.../purple-terminal-agent:latest`
2. Go to [agentbeats.dev/register-agent](https://agentbeats.dev/register-agent)
3. Select **Purple**, enter image: `docker.io/.../purple-terminal-agent:latest`
4. Submit the `amber-manifest.json5` URL
5. Go to [Terminal Bench 2.0 Quick Submit](https://agentbeats.dev/agentbeater/terminal-bench-2-0/submit)
6. Select your agent, add secret `OPENROUTER_API_KEY`
7. Submit

---

## Roadmap

| Phase | Addition | Status |
|-------|----------|--------|
| **v0.2** | Hierarchical Planner + Critic + RAG + Memory + Verify | ✅ This release |
| **v0.3** | Domain-specialist critic sub-agent (full Approach 3) | ✅ This release |
| **v0.4** | Multi-turn critic ↔ executor loop (drug-discovery TIR pattern) | After v0.3 score |

---

## Competition Details

- **Competition:** [AgentX–AgentBeats Sprint 3](https://rdi.berkeley.edu/agentx-agentbeats)
- **Track:** Coding Agent (Apr 13 – May 3, 2026)
- **Green Agent:** [Terminal Bench 2.0](https://agentbeats.dev/agentbeater/terminal-bench-2-0)
- **Paper:** [Terminal-Bench: arxiv.org/abs/2601.11868](https://arxiv.org/abs/2601.11868)
- **Metric:** Task pass rate across 89 tasks, verified by Harbor

---

## License

MIT
