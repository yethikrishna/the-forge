# BRAINSTORM.md — The Forge Ideation Log

---

## 2026-05-20 19:37 UTC — Brainstorm Session #1

*Project state: 5,270 Go lines, 13/22 implemented packages, 12 commands, Phase 0 at ~71%*

---

### A. Features to Become #1 Agent Orchestration Tool

**A1. `forge agentfile` — Universal Agent Definition Format**
- A declarative YAML/TOML file (like Dockerfile but for agents): `Agentfile`
- Define agent capabilities, model preferences, tool permissions, context sources, memory limits
- `forge run` reads an Agentfile and spawns the agent with the right config
- **Why nobody else has this:** Every tool hardcodes agent behavior. A declarative format enables sharing, versioning, and composing agents like Docker images.

**A2. `forge pipeline` — Declarative Agent Pipelines**
- YAML pipelines where each step is an agent call with input/output contracts
- Fan-out/fan-in, conditional branching, human approval gates
- Like GitHub Actions but each "job" is an AI agent, not a shell script
- Built-in retry, timeout, cost caps per step
- **Killer demo:** `forge pipeline run code-review.yaml` → agent writes code, another reviews, a third writes tests, human approves, auto-merges

**A3. `forge cost` — Real-Time Cost Tracking & Budgets**
- Token counting across all providers with live pricing
- Per-agent, per-session, per-project cost accumulation
- Budget alerts and hard caps (stop agent when budget exceeded)
- Cost comparison: "This task cost $0.03 on GPT-5-mini vs $0.12 on Claude Opus"
- Weekly/monthly cost reports with breakdown by agent, model, project
- **Why it wins:** Every team using AI agents is flying blind on cost. First tool to solve this owns enterprise.

**A4. `forge memory` — Persistent Agent Memory Layer**
- Structured memory store per-agent (not just context window stuffing)
- Semantic search over past interactions (backed by internal/hnsw)
- Memory inheritance: new sessions start with relevant past context
- Memory sharing between agents (with access control)
- Export/import memory for agent portability
- **Why:** Context windows reset. Real agents need to remember across sessions.

**A5. `forge eval` — Agent Evaluation & Benchmarking**
- Run standardized benchmarks (SWE-bench, HumanEval, custom) against any agent
- A/B testing: same prompt, different models/agents, compare outputs
- Regression testing: agent changes shouldn't break known-good workflows
- Score dashboard with trends over time
- **Why:** Nobody can objectively compare agents today. "Which agent is best for my codebase?" is an unanswered question.

**A6. `forge mesh` — Distributed Agent Network**
- Agents running on different machines coordinating via WireGuard (internal/tailnet + internal/wgtunnel)
- Work distribution: split large tasks across agents on multiple nodes
- Agent discovery and health checking
- Resource-aware scheduling (GPU nodes get code generation, CPU nodes get review)
- **Why:** Single-machine orchestration is table stakes. Multi-node is the future, and Forge already has the networking stack.

---

### B. Architectural Improvements for Extensibility

**B1. Plugin System v2 — WASM-Based Plugins**
- Current plan: Go plugins (requires matching Go versions, painful)
- Better: WASM plugins (TinyGo/Go compiled to WASM)
- Sandboxed by default, cross-language (Rust, Go, Zig, C)
- Plugin API: hooks (before/after agent call), custom commands, custom routers
- Plugin marketplace built on internal/marketplace
- **Why WASM:** Security (sandboxed), language-agnostic, small binary size, fast startup

**B2. Event Bus / Reactive Architecture**
- Internal event bus: agent.started, agent.completed, tool.called, cost.updated, file.changed
- Plugins and commands subscribe to events, not poll
- Enables: real-time dashboards, automated triggers, audit logging, custom workflows
- Backed by Redis (internal/redjet) pub/sub for multi-process scenarios
- **Pattern:** Like Kubernetes controllers watching for resource changes

**B3. Middleware Stack for Agent Communication**
- Layered middleware for every agent request/response:
  1. Rate limiting
  2. Cost tracking
  3. Logging/audit
  4. Content filtering (PII redaction, secret detection)
  5. Caching (identical requests → cached response)
  6. Retry with provider fallback
  7. Prompt injection detection
- Each middleware is a Go interface, composable
- **Why:** Production agents need all of these. Right now everyone builds them ad-hoc.

**B4. Forgefile as the Center of the Universe**
- `forge.yaml` (or `Forgefile`) at project root: the single source of truth
- Declares: agents, models, pipelines, hooks, environments, cost budgets
- Like `docker-compose.yml` but for your entire AI agent stack
- `forge up` reads it and starts everything
- `forge down` tears it all down
- **Why:** Reduces cognitive load from "configure 5 tools" to "edit one file"

**B5. Capability-Based Permission Model**
- Every tool/resource has a capability (fs.read, fs.write, net.http, exec, git.push, etc.)
- Agentfile declares which capabilities an agent needs
- `forge jail` enforces only declared capabilities
- Capability escalation requires human approval
- **Why:** This is how mobile OSes work. AI agents should work the same way.

---

### C. Integration Opportunities

**C1. VS Code Extension — Deep Integration**
- Tree view: active agents, sessions, costs
- Inline agent chat (not sidebar — inline in editor like Copilot but using Forge agents)
- `forge.yaml` schema validation + autocomplete
- One-click: right-click code → "Send to agent" → pick agent → see result inline
- **Why VS Code:** 70%+ of developers. Meet them where they are.

**C2. GitHub Actions Integration**
- `forge-action` GitHub Action: run Forge pipelines in CI
- Auto-code-review on PRs, auto-fix lint errors, generate tests
- Cost-capped (fail build if agent exceeds budget)
- Works with GitHub-hosted and self-hosted runners
- **Why:** CI/CD is where agents deliver the most ROI. First to own this wins.

**C3. Kubernetes Operator**
- `ForgeOperator` custom resource: define agent deployments in K8s
- Auto-scaling based on queue depth
- Integration with K8s secrets for API keys
- GPU scheduling for local model inference
- `kubectl get agents` — see all running AI agents across your cluster
- **Why:** Enterprise runs on K8s. If Forge isn't there, it's a toy.

**C4. Git Hooks Integration**
- `forge hook install` → sets up git hooks that route through Forge
- Pre-commit: AI lint, security scan, conventional commit check
- Pre-push: AI review of all commits in push
- Commit-msg: AI-generated commit messages (already have `forge commit`)
- **Why:** Zero-friction adoption. Git hooks are universal and invisible.

**C5. Slack/Discord/Teams Bot Templates**
- Pre-built bot templates: code review bot, PR summarizer, on-call assistant
- `forge blink init --template=code-review --channel=slack`
- One command to deploy a team-specific AI assistant
- **Why:** Teams adopt tools through chat integrations. Low friction.

**C6. Terraform Provider**
- Manage Forge resources (agents, pipelines, environments) as Terraform resources
- Infrastructure-as-code for AI agent deployments
- **Why:** Enterprise uses Terraform for everything. If it's not in Terraform, it doesn't exist.

---

### D. Developer Experience Improvements

**D1. Interactive Onboarding (`forge init --interactive`)**
- Detect project type (Go, Python, TS, Rust, etc.)
- Suggest agents based on project type
- Auto-generate `forge.yaml` with sensible defaults
- First run: `forge chat` works in <30 seconds
- **Principle:** Time-to-value under 60 seconds or you lose them

**D2. `forge doctor` — Environment Health Check**
- Check Go version, API keys, network connectivity, disk space
- Validate forge.yaml syntax and required fields
- Test each configured provider (can we reach OpenAI? Anthropic?)
- Suggest fixes for common issues
- **Why:** "It doesn't work" is the #1 reason people abandon tools. Doctor makes debugging trivial.

**D3. `forge tui` — Terminal UI Dashboard**
- Full terminal UI (like lazygit, htop) for managing Forge
- Panels: running agents, session history, cost tracker, logs
- Keyboard-driven: start/stop agents, switch sessions, view outputs
- Built with bubbletea/lipgloss (Go-native TUI)
- **Why:** The CLI power user's dream. No other agent tool has this.

**D4. Smart Defaults & Zero-Config**
- No forge.yaml required for basic usage
- `forge chat` → auto-detect available API keys → best available model
- `forge serve` → auto-detect installed agents → serve them all
- Progressive complexity: simple things simple, advanced things possible
- **Anti-pattern to avoid:** Requiring config before first use

**D5. `forge diff` — Agent Output Visualization**
- Show agent changes as a rich diff (git-style but enhanced)
- Color-coded: additions (green), deletions (red), modifications (yellow), reasoning (blue)
- Side-by-side view for file changes
- Undo capability: revert any agent action
- **Why:** Agents make mistakes. Visibility into what they changed is critical for trust.

**D6. Shell Completions & Man Pages**
- Bash, Zsh, Fish, PowerShell completions
- `forge completion bash > /etc/bash_completion.d/forge`
- Man pages for every command
- **Why:** Professional polish. Signals maturity.

---

### E. Security Features for Enterprise

**E1. `forge audit` — Complete Audit Trail**
- Every agent action logged: prompt, response, files touched, commands run, API calls
- Tamper-proof log (append-only, optionally signed)
- Queryable: "show me all actions agent X took on file Y in the last 7 days"
- Export formats: JSON, CSV, SIEM-compatible
- **Why:** Enterprise compliance (SOC2, HIPAA) requires audit trails for AI actions.

**E2. Secret Scanning & Redaction Middleware**
- Automatically detect and redact secrets in prompts/responses
- API keys, passwords, tokens, PII (SSN, credit cards, emails)
- Block agent from receiving or emitting secrets
- Configurable: warn vs block vs redact
- **Why:** Agents reading your codebase WILL encounter secrets. They must not leak them.

**E3. Prompt Injection Detection**
- Built-in classifier for prompt injection attempts
- Confidence score + configurable threshold
- Auto-quarantine suspicious inputs
- Log all injection attempts for security review
- **Why:** #1 security threat for AI agents. Nobody has a built-in solution.

**E4. RBAC for Multi-Tenant Deployments**
- Role-based access: admin, operator, developer, viewer
- Per-agent permissions: who can start/stop/configure which agents
- API key management: scoped keys per user/role
- Integration with enterprise SSO (OIDC, SAML)
- **Why:** Multi-tenant `forge serve` is useless without access control.

**E5. Supply Chain Security**
- Verify agent binaries/integrity before execution
- Pin agent versions in forge.yaml (like package-lock.json)
- SBOM (Software Bill of Materials) generation
- Vulnerability scanning of agent dependencies
- **Why:** Agents run arbitrary code. Trust must be verified, not assumed.

**E6. Network Policy Enforcement**
- `forge jail` with configurable network policies:
  - Allow only specific domains (api.openai.com, github.com)
  - Block all egress by default, whitelist per-agent
  - DNS-level filtering
  - Request/response inspection
- **Why:** Network isolation is the most critical sandbox control for AI agents.

---

### F. Novel Features No Other Tool Has

**F1. `forge replay` — Session Time Travel**
- Record every agent session (prompts, responses, tool calls, file changes)
- Replay any session from any point
- Branch from any point in history (like git branches for conversations)
- "What if I had given a different prompt here?" → replay with modification
- **Why this is unique:** Nobody offers deterministic replay of AI agent sessions. Invaluable for debugging, training, and auditing.

**F2. `forge breed` — Agent Evolution**
- Track which agents produce the best results over time
- Automatically breed new agent configurations by combining successful traits
- Model selection, prompt templates, tool sets → genetic algorithm optimization
- "After 100 runs, forge breed suggests agent-v2.yaml for your codebase"
- **Why:** Self-improving agents. The tool gets better the more you use it.

**F3. `forge explain` — Agent Decision Trace**
- After every agent action, generate a human-readable explanation
- "Agent chose GPT-5-mini because: cost budget remaining $0.50, task is simple refactoring"
- "Agent modified auth.go because: user requested OAuth2 support, file contains auth patterns"
- Chain-of-thought visualization
- **Why:** Trust requires understanding. If you can't explain why an agent did something, you can't trust it.

**F4. `forge share` — Agent Session Sharing**
- Export agent session as a self-contained HTML page (like Jupyter notebooks)
- Share with teammates: "Here's what the agent did and why"
- One-click replay of shared sessions
- Embeddable in documentation/wiki
- **Why:** Team collaboration around AI agents is terrible right now. Sharing should be one command.

**F5. `forge learn` — Local Fine-Tuning Suggestions**
- Analyze agent interactions to suggest fine-tuning opportunities
- "You've corrected agent output 47 times for Go error handling. Consider a fine-tuned model?"
- Generate training data from corrections
- Integration with local training (ollama, llama.cpp)
- **Why:** The gap between generic and fine-tuned models is huge. Forge has the interaction data to bridge it.

**F6. `forge forecast` — Predictive Cost & Time Estimation**
- Before running a task, estimate cost and time based on historical data
- "This task will likely cost $0.15 and take 2 minutes (based on 23 similar past tasks)"
- Confidence intervals: "90% confident it's between $0.10 and $0.25"
- Budget planning: "At current pace, you'll spend $47 this month on agents"
- **Why:** Nobody predicts agent costs upfront. This alone would drive enterprise adoption.

**F7. `forge canvas` — Visual Agent Workflow Builder**
- Web-based drag-and-drop interface for building agent pipelines
- Nodes: agents, models, conditions, human approvals, data transforms
- Auto-generates forge.yaml from the visual layout
- Real-time execution visualization
- **Why:** Visual tools lower the barrier. Non-developers can build agent workflows.

**F8. `forge bounties` — Crowd-Sourced Agent Tasks**
- Post a coding task with a bounty
- Multiple agents attempt it in parallel
- Human picks the best result (or automated scoring)
- Leaderboard of best agents/models for different task types
- **Why:** Competitive agent execution. Turns agent selection from guesswork into data.

---

### G. Priority Matrix — What to Build First

| Feature | Impact | Effort | Phase | Rationale |
|---------|--------|--------|-------|-----------|
| forge doctor | HIGH | LOW | Phase 0 | DX, unblocks adoption |
| Secret redaction middleware | HIGH | LOW | Phase 1 | Security, table stakes for enterprise |
| forge.yaml (Forgefile) | HIGH | MED | Phase 1 | Central config reduces complexity |
| forge pipeline (basic) | HIGH | HIGH | Phase 2 | Core differentiator |
| Cost tracking | HIGH | MED | Phase 1 | Everyone needs this |
| forge tui | MED | MED | Phase 2 | Power user magnet |
| WASM plugins | MED | HIGH | Phase 2 | Ecosystem enabler |
| forge replay | HIGH | MED | Phase 2 | Unique, builds trust |
| forge share | MED | LOW | Phase 1 | Collaboration, low effort |
| VS Code extension | HIGH | HIGH | Phase 3 | Adoption multiplier |
| GitHub Actions | HIGH | MED | Phase 2 | CI/CD integration |
| Agentfile format | HIGH | MED | Phase 2 | Standard-setting |
| K8s operator | MED | HIGH | Phase 4 | Enterprise requirement |
| forge breed | LOW | HIGH | Phase 4 | Novel but niche |
| forge canvas | MED | VERY HIGH | Phase 4 | Nice-to-have visual builder |

---

### H. Quick Wins — Things to Ship This Week

1. **`forge doctor` command** — ~200 lines, massive DX impact
2. **Shell completions** — Cobra has built-in support, 1 hour of work
3. **`.forge.yaml` schema + validation** — foundation for everything else
4. **Secret redaction in `forge chat`** — regex-based PII/secret detection, ~100 lines
5. **`forge share` (HTML export)** — template + session data → self-contained HTML
6. **`--dry-run` flag on all commands** — show what would happen without doing it
7. **Colored, structured output** — internal/pretty is done, wire it everywhere

---

### I. Competitive Moats to Build

1. **Protocol ownership:** ACP is good, but A2A is winning. Forge should support BOTH and be the bridge between them.
2. **Cost transparency:** No other tool gives real-time, per-action cost tracking. Own this space.
3. **Agentfile standard:** If Forge defines the agent definition format and it catches on, that's a massive moat.
4. **Local-first:** Every competitor requires cloud APIs. Forge should work beautifully with ollama/llama.cpp for fully local, air-gapped use. Enterprise loves this.
5. **Single binary:** The "just works" factor. No Node.js, no Python, no Docker required (optional). Go binary runs everywhere.

---

*"The best time to build a moat is before anyone knows there's a castle."*
