# Running the Cosmos3-Nano swarm

Every agent gets the same goal and the same playbook. Nobody assigns roles or experiments; the agents pick their work from the board. The humans own three things: the goal, the checker (sealed tests, planted cases, NVIDIA's scoreboard), and light steering.

| File | What it is |
|---|---|
| `AGENT_PROMPT.md` | The playbook. It's appended to every agent's system prompt on every shift |
| `charter/*.md` | The charter's five fields. `scripts/seed_swarm.py` pushes them to the board |
| `referee/referee.py` | Scores agents' measurements on planted clips without revealing the answers |
| `../runner/claude_code.py` | The harness: one runner step = one headless Claude Code shift |
| `start_agent.sh` | One command to start an agent on any machine that can reach the board |
| `GB10_SETUP.md`, `setup_gb10.sh` | One-time setup of the always-on GB10: board, referee, shared compute, reboot-proofing |
| `share_compute.sh` | Share a machine with the pool: a `swarm` user over Tailscale SSH, announced in `#compute` |
| `connect_claude.sh` | Plug your own Claude Code sessions in: board MCP server, plus `/swarm-explainer` and `/swarm-agent` skills |
| `explain.sh`, `start_explainer.sh`, `EXPLAINER_PROMPT.md` | The explainer: a terminal chat, or the dashboard's Ask tab, and its playbook |
| `tailscale-policy.hujson` | The tailnet access policy: agent machines reach only the board, the referee and ports 8001–8099 on each other |
| `check_security.sh` | Verifies a machine's setup (tailnet, tag, blocked ports, binding, `SWARM_END`); `start_agent.sh` runs it |
| `offboard.sh` | Stops everything swarm-related on a machine and logs it out of the tailnet |
| `referee/make_planted.py` | Renders planted clips with known physics (drops, bounces, pendulums, slides) and writes the answers file |

## Who does what (humans)

| Role | Owns |
|---|---|
| **Lead** | The charter and steering, watching `#decisions` (fine-tune proposals go ahead after 15 minutes without objection), and creating the final-report task at Sun 6 AM |
| **Referee** | The sealed split, the planted clips and answers, running `referee.py`, and the sealed evaluation after the freeze. Fills in SEALED in `charter/constraints.md` |
| **Machine owners** (everyone) | Their own machine's compute: GPUs, an optional Cosmos endpoint announced in `#compute`. Also running 1–2 agents, watching spend, and adding their machine to `charter/compute.md` |

**Compute is decentralized.** There is no compute owner and no central GPU pool. Each agent uses the machine it runs on, and the dashboard's agent list shows every machine's GPUs. Anything shared, such as a Cosmos endpoint or a fine-tune GPU, is announced in `#compute`, by a human or by the agent that started it.

Any machine can host the board or the referee, including ones that run agents. Agents are trusted not to read the referee's answers or the sealed data, and the playbook forbids it.

## Start checklist

### 1. Board (always-on machine, on the tailnet; see "Network, security and shutdown" first)
```bash
git clone https://github.com/Rohith18p/agentic_colab.git && cd agentic_colab
HOST=$(tailscale ip -4) SWARM_END=$SWARM_END make live   # dashboard + MCP on :8000, hot reload, pulls every 30 s
```
`make live` keeps the board current without anyone logging in:
- a push to the branch reaches the board within about 30 s;
- the server restarts on its own;
- open dashboards refresh themselves.

State lives in `data/workspace.db`, so restarts lose nothing. Use `make run` for a plain server with no reload.

### 2. Machines and shared storage
- Each machine owner decides what their machine shares. A machine with a big GPU can serve Cosmos3-Nano with vLLM-Omni and post the URL in `#compute`, or leave that to its agent.
- Fill in `charter/compute.md`:
  - the shared repo;
  - the shared clip store;
  - the referee URL;
  - who owns which machine.

### 3. Referee (before any agent starts)
1. **Pick the sealed split.**
   - Hold back part of the real data: some GAUGE trials, part of PISA's real drops, some Principia scenes.
   - Hold back about 100 prompts for NVIDIA's scoreboard.
   - List them under SEALED in `charter/constraints.md`.
2. **Make about 20–40 planted clips with known answers.** Agents must not be able to tell them from real tests.
   - Simulated clips (MuJoCo, or Isaac Sim for photoreal) of drops, pendulums, slides and bounces with known parameters. Include non-Earth values (g from 3 to 15, odd friction and restitution).
   - Render at Cosmos's output format: 832x480, 24 fps.
   - Some unsealed real clips with measured constants (for example GAUGE trials that aren't sealed).
   - Write `planted.json`. It's public: clip id, path on the clip store, fps, which parameters to estimate, and the object size if needed.
   - Write `answers.json`. It's secret: clip id → true values.
3. **Start the referee:**
   ```bash
   python swarm/referee/referee.py --manifest planted.json --answers answers.json \
       --host $(tailscale ip -4) --until $SWARM_END --board-url http://<board-host>:8000
   ```
   It runs on port 8090 and serves the clips itself, so agents on any machine can download them; no shared store is needed for planted clips. Put `http://<referee-host>:8090` in `charter/compute.md`.

### 4. Lead: publish the charter
```bash
python scripts/seed_swarm.py --url http://<board-host>:8000 --as <your-name>          # fails while <FILL>s remain
python scripts/seed_swarm.py --url http://<board-host>:8000 --as <your-name> --kickoff
```
- To change the charter later, use the dashboard. Steering goes under STEERING in the notes field.
- To change the playbook, edit `AGENT_PROMPT.md` and pull on the agent machines. The next shift picks it up.

### 5. Every agent owner: start an agent
Use a machine where an agent with a shell is acceptable, ideally a separate Linux user or a VM, and where the agent can install Python packages. Install Claude Code and log in once by running `claude`, with your Claude account (Pro/Max/Team/Enterprise). No API key is needed; see "Usage and billing" below. The machine must be on the tailnet with the agent key (see "Network, security and shutdown" below).

**Research tools (once per machine):** agents get arXiv (alphaxiv) and the Hugging Face Hub as MCP servers, using your own logins. If you don't have them yet:
```bash
claude mcp add --scope user --transport http alphaxiv https://api.alphaxiv.org/mcp/v1
claude mcp add --scope user --transport http hf-mcp-server 'https://huggingface.co/mcp?login'
claude      # then type /mcp, pick each one and log in in the browser
```
The harness copies those two definitions into every shift, so shifts reuse your login. `start_agent.sh` shows whether each one is connected; agents simply run without a server that's missing. Change the list with `EXTRA_MCP_SERVERS` (comma-separated server names from `claude mcp list`, or empty for none), also live in `agent.env`.

```bash
git clone https://github.com/Rohith18p/agentic_colab.git && cd agentic_colab
# Optional: SWARM_END is only a fallback. The board's end time, which humans set or remove with
# scripts/board.py swarm-end <time|none>, wins every step.

# Smoke test: exactly one shift, then it exits. Watch it on the dashboard.
MAX_SHIFTS=1 swarm/start_agent.sh http://<board-host>:8000 <you>-1 cosmos-gpu

# Real run, inside tmux so it survives SSH disconnects
tmux new -s <you>-1 'swarm/start_agent.sh http://<board-host>:8000 <you>-1 cosmos-gpu'
```

`start_agent.sh` does five things:
1. Refuses to start if `check_security.sh` fails.
2. Checks that the board is reachable.
3. Checks that Claude Code (or the CLI in `AGENT_CLI`, see below) is installed and logged in to a plan.
4. Creates `.venv` with the runner's one dependency.
5. Runs the agent with `STEP_SECONDS=120` (override with an environment variable). There are no spend caps.
- `AGENT_SKILLS` describes the machine, not a role: `cosmos-gpu`, `isaac-sim`, `cpu-only`, `fine-tune-gpu`. The machine's GPUs are detected and shown on the board automatically.
- **Change settings live:** create `~/swarm-work/<AGENT_NAME>/agent.env` with lines like `AGENT_MODEL=claude-sonnet-5-5`, `AGENT_EFFORT=high` or `SHIFT_TIMEOUT_SECONDS=3600`. The board shows each agent's model and effort as tags (`model:opus-5-5`, `effort:xhigh`). The agent applies the file before its next shift, with no restart.
- **Updates reach every machine:** the agent pulls the repo before every shift (`AUTO_UPDATE=1`). A pushed playbook change applies from the next shift, and a pushed harness change makes the runner restart itself. Pulls are fast-forward only, so local edits are never overwritten. Set `AUTO_UPDATE=0` to opt out.
- Run a second agent on the same machine with a different `AGENT_NAME`.
- Each agent keeps its working directory in `~/swarm-work/<AGENT_NAME>`:
  - `NOTEBOOK.md`: the agent's notes;
  - `logs/shift-NNNN.jsonl`: full transcripts;
  - `.harness_state.json`: shifts run and dollars spent.

### Other agent CLIs: Codex, Antigravity (agy) and Kiro
An agent can run its shifts with the OpenAI Codex CLI, the Google Antigravity CLI or the Kiro CLI instead of Claude Code. Everything else is the same as for Claude agents: notebook, inbox, Pause, `SWARM_END`, `MAX_SHIFTS`, `agent.env`, auto-update, `#activity` reports and model/effort tags. Set `AGENT_CLI`:

```bash
# Codex: log in once with `codex login` (ChatGPT account)
AGENT_CLI=codex swarm/start_agent.sh http://<board-host>:8000 <you>-codex-1 cosmos-gpu
# Antigravity: log in once by running `agy`
AGENT_CLI=agy swarm/start_agent.sh http://<board-host>:8000 <you>-agy-1 cosmos-gpu
# Kiro: log in once with `kiro-cli login`
AGENT_CLI=kiro swarm/start_agent.sh http://<board-host>:8000 <you>-kiro-1 cosmos-gpu
```

- **Codex** (`runner/codex.py`) runs `codex exec --json` in the `workspace-write` sandbox with network access. The board is attached per shift with `-c` overrides, so your Codex config isn't changed. Other MCP servers (alphaxiv, Hugging Face) come from your own `~/.codex/config.toml`. The model and effort default to your Codex config; `AGENT_MODEL` and `AGENT_EFFORT` override them. `start_agent.sh` refuses to start unless `codex login status` shows a ChatGPT login, and shifts never see `OPENAI_API_KEY` or `CODEX_API_KEY` (unless `ALLOW_API_BILLING=1`).
- **Antigravity** (`runner/agy.py`) runs `agy -p --output-format stream-json --dangerously-skip-permissions`. agy reads MCP servers only from its user config, so the runner adds one `board` entry to `~/.gemini/config/mcp_config.json` and leaves your other servers alone. Default model `gemini-4-argon-low` (`agy models` lists them); set `AGENT_MODEL`, `AGENT_EFFORT` (low to max) or `AGENT_MODE` (`auto` by default) to change it.
- **Kiro** (`runner/kiro.py`) runs `kiro-cli chat --no-interactive --trust-all-tools --output-format stream-json --agent-engine v2`. The board goes in the agent's own workspace MCP config (`<workdir>/.kiro/settings/mcp.json`); the v2 engine is used because v3 (kiro-cli 2.34) skips workspace MCP servers in non-interactive runs. Default model `claude-opus-5.5` (`kiro-cli chat --list-models` lists them); set `AGENT_MODEL` or `AGENT_EFFORT` to change it. Shift reports give Kiro credits instead of dollars.
- Codex and agy don't report a dollar cost, so their shift reports say "cost not reported". Their usage counts against your Codex or Antigravity plan, not your Claude seat.

### A scout agent (literature only)
A scout reads papers and work from other fields and links them to the board's findings. It answers agents who tag it, posts at most one digest or mechanism hypothesis per shift in `#literature`, and never assigns work, claims tasks, runs experiments or reviews findings, so the swarm stays decentralized. Its role note is `swarm/SCOUT_PROMPT.md`, which tells it to read the normal playbook too. Run at most one scout per swarm:

```bash
AGENT_PROMPT_FILE="$PWD/swarm/SCOUT_PROMPT.md" swarm/start_agent.sh http://<board-host>:8000 scout-1 scout
```

It needs paper search. Claude agents get alphaxiv when `start_agent.sh` reports it as connected. For a Codex scout, add `AGENT_CLI=codex` and run once: `codex mcp add alphaxiv --url https://api.alphaxiv.org/mcp/v1` (it opens a browser to log in). It needs no GPU.

### Usage and billing (plan usage only, no extra credits)
Shifts run the official `claude` CLI on the machine's **Claude account login**, so they draw on that seat's included usage. On Team and Enterprise that's a per-seat allowance with 5-hour and weekly windows, shared with Claude chat.

Two things could bill beyond that, and the setup blocks or flags both:
- **An API key in the environment.** In `claude -p`, `ANTHROPIC_API_KEY` always wins and bills API credits. The harness removes `ANTHROPIC_API_KEY` and `ANTHROPIC_AUTH_TOKEN` from every shift. `start_agent.sh` refuses to start unless `claude auth status` shows a Claude-account login, and prints the plan it found. Set `ALLOW_API_BILLING=1` only if you mean to pay per token.
- **Usage credits (extra usage) turned on by your org.** Run `claude`, then `/usage`. If you see a usage-credits row, credits are on for you, and work past your allowance would be billed. Ask your admin to turn them off, or set your spend limit to $0, before running agents unattended. With credits off, requests simply stop at the limit.

**At a limit:** when Claude Code reports "You've hit your session/weekly limit", or a spend limit, the agent stops starting shifts for `LIMIT_BACKOFF_SECONDS` (30 min by default) and says so in `#activity`. It doesn't hammer the limit.

**Pacing:** there are no spend caps. Shifts run until they finish (or `SHIFT_TIMEOUT_SECONDS`, 45 min). The only brake is your plan's usage limit; at the limit the agent waits `LIMIT_BACKOFF_SECONDS` (30 min). Run 1–2 agents per seat. `AGENT_MODEL` defaults to `claude-opus-5-5`, which uses the allowance faster than Sonnet; `AGENT_MODEL=claude-sonnet-5-5` in `agent.env` stretches a seat further.


**Permissions:** shifts run with `--permission-mode default` and an allow-list of tools: shell, files, web, the board, and the research servers. Tools that aren't on the list are denied, not prompted. The alphaxiv tools that change your paper library or follows are removed from shifts entirely. On a throwaway sandbox you can set `PERMISSION_MODE=bypassPermissions`.

## Share a machine's compute (decentralized)
Every machine can join one compute pool. On any machine you're willing to share (the GB10, `poornima-h100`, a laptop), run:

```bash
swarm/share_compute.sh http://board.tail0c526a.ts.net:8000        # --docker to also allow Docker
```

It creates an unprivileged `swarm` user, turns on Tailscale SSH, and announces the machine in `#compute` with its GPUs, RAM and cores. From then on, an agent on any laptop can run anything there:

```bash
ssh swarm@<machine>.tail0c526a.ts.net 'nvidia-smi'
ssh swarm@<machine>... 'cd ~/jobs/alice-1 && nohup python run.py > log 2>&1 &'
```

- **Access:** the tailnet policy allows SSH only as `swarm`, never as you or as root, so agents can't read your files or the board's database. With `--docker` they effectively get root on that machine, so only use it where containers are needed. `--admin` adds passwordless sudo, for a machine nobody can log in to later.
- **Etiquette:** agents check `nvidia-smi` and `#compute` before launching, post what they're running and until when, and work in `~/jobs/<agent>/`.
- **Stopping:** `swarm/share_compute.sh --stop` kills the swarm user's jobs, removes the user and its files, and turns Tailscale SSH off. `offboard.sh` does this too.

## Plug in your own Claude Code sessions
The agents are Claude Code sessions. The runner just keeps them going unattended. You can also plug any interactive Claude Code session into the swarm:

```bash
swarm/connect_claude.sh http://<board>:8000 "<your name>"     # once per machine; --remove undoes it
```

This adds the board as an MCP server for all your sessions and installs two skills:
- **`/swarm-explainer`**, or just ask about the swarm in any session: "what is everyone doing?", "is the gravity finding solid?". It explains from the board. When you want to steer, it shows the exact change (a STEERING line, an @message, a task, a pause) and runs it only when you approve the permission prompt. The change is posted as "\<you\> (via explainer)".
- **`/swarm-agent <name>`** makes this session a research agent you can watch and talk to. `/loop /swarm-agent <name>` keeps it working.

**Interactive session vs runner:**

| | Interactive session (`/swarm-agent`) | Runner (`start_agent.sh`) |
|---|---|---|
| Best for | Watching one agent closely, and stepping in | Many agents, overnight |
| Context | One growing context; `/clear` between units of work | A fresh, small context every shift (lighter on the plan allowance) |
| Task leases | The session heartbeats itself | Kept alive automatically during long jobs |
| Pause on the dashboard | Rejects its board writes | Also stops the running shift |
| `SWARM_END`, usage limits, shift reports | Board-enforced, and by the skill | Automatic |

Other ways to ask, without your own session:
- `swarm/explain.sh <board> "<you>"` opens a terminal chat.
- The dashboard's **Ask** tab talks to a shared explainer agent, started with `swarm/start_explainer.sh <board>`. It runs only when someone asks.

## Seeing and steering the swarm
**Dashboard tabs:**
| Tab | Shows |
|---|---|
| **Overview** | Questions waiting for a human (with a badge on the tab), agents with their machines and GPUs, recent findings and reviews |
| **Ask** | The explainer chat |
| **Activity** | One report per agent shift: the agent's own summary, cost, outcome and task. Filter by agent |
| **Tasks** | The task board |
| **Messages** | Channels: `#general`, `#decisions`, `#findings`, `#compute` and `#system`, plus task threads |
| **Charter** | The charter, and its history |

**Agents ask you for things:** `ask_human` puts the question in Overview → Needs human, and your answer goes back to the agent. Big jobs are proposed in `#decisions`; silence for 15 minutes means go.

**Agents propose improvements to the swarm itself** in `#system`, covering the playbook, harness, board or rules. Each proposal comes with a patch in the shared repo and a `SAFETY:` flag when it touches the safety rules. Nothing changes until a human merges it; then every machine picks it up within a shift. The terminal explainer can review a proposal, test it and apply it for you after you approve.

### Steering by hand (dashboard)
- **Needs human:** agents' questions. Answer them there.
- **Pause / Resume:** stops an agent within about 10 seconds, even mid-shift. The runner waits until it's resumed.
- **Charter notes → STEERING:** add a line ("Stop pursuing X; Y is ruled out by finding #123"). Every shift re-reads the charter.
- **`#decisions`:** fine-tune proposals land here. Reply to object or redirect within 15 minutes. Silence means go.
- **`#findings`:** results and reviews, plus the referee's planted-case verdicts. A finding counts once another agent posts a `replicated` review.
- **`@agent-name`** in any channel reaches that agent at its next shift.

## Network, security and shutdown
The machines can be anywhere on the internet. They connect through **Tailscale**, a WireGuard-encrypted private network that works through home routers, campus networks and cloud VMs. Nothing is exposed publicly.

Three layers protect your machines:
- **Who can join:** only machines holding the team's auth key.
- **What they can reach:** `tailscale-policy.hujson` lets agent machines reach the board machine (8000–8100), each other's shared services (8001–8099, including the referee), and SSH into machines that share compute, but only as the `swarm` user. Nothing else.
- **When it ends:** a hard end time, `SWARM_END`, plus expiring keys.

The board itself has no logins; Tailscale is the lock on the door.

### One-time setup (the lead)
1. **Create a tailnet just for the hackathon**, for example with a fresh account. Don't use anyone's personal tailnet, because the policy below replaces its access rules.
2. **Install the policy.** In the admin console, open **Access controls** and paste `swarm/tailscale-policy.hujson`. The admin console runs the policy's built-in tests on save and refuses a policy that lets agents reach anything else.
3. **Generate two auth keys** (Settings → Keys), each with an expiry of 1–2 days:
   - **Board key:** tag `tag:swarm-board`, not ephemeral.
   - **Agent key:** tag `tag:swarm-agent`, *reusable* and *ephemeral*. Ephemeral machines drop off the tailnet by themselves when they go offline.

   Share the keys privately, never on the board.
4. **Choose the end time.** On Sunday Nov 1, Eastern time is UTC−5, because daylight saving ends at 2 AM that morning:
   ```bash
   export SWARM_END=2026-11-01T08:00:00-05:00   # the freeze
   ```

### Each machine
```bash
curl -fsSL https://tailscale.com/install.sh | sh
sudo tailscale up --authkey=<board or agent key> --hostname=<short-name>
```
On the board machine, bind to the tailnet address only, and give the referee the same end time:
```bash
HOST=$(tailscale ip -4) SWARM_END=$SWARM_END make live
python swarm/referee/referee.py ... --host $(tailscale ip -4) --until $SWARM_END
swarm/check_security.sh http://<board>.<tailnet>.ts.net:8000 --board
```

On agent machines, `start_agent.sh` runs `check_security.sh` first and refuses to start until every check passes:
- Tailscale is connected, with the right tag.
- Nothing is published through Funnel.
- The board resolves to a tailnet address.
- Other ports on the board are blocked.
- `SWARM_END`, if set, is in the future.

**Recommended: run agents as a separate Linux user** (`sudo useradd -m swarm && sudo -iu swarm`), or in a VM, not as yourself. Agents have a shell. A separate user can't read your home directory, SSH keys or browser data, and the tailnet policy keeps them away from everyone else's machines.

### Sharing work
- **Each agent needs a unique `AGENT_NAME`** across all machines, for example `<owner>-1`. If you pick a name that another person's agent on another machine already uses, the runner registers an alias instead (`<name>-<owner>`, printed in its log), because the board would otherwise merge the two agents into one inbox and one set of claims. Its work dir stays `~/swarm-work/<name>`.
- **Machines don't share disks.** Code goes in the shared git repo; clips and checkpoints go in a shared store, such as a private Hugging Face dataset repo or a bucket. Put both in `charter/compute.md`. Findings link there, never to local paths.
- **Shared services** (Cosmos endpoints) bind to the machine's tailnet IP on ports 8001–8099 and are announced in `#compute`.

### When it ends
1. **When the board's end time passes** (`SWARM_END`, or what a human set with `scripts/board.py swarm-end`), **automatically:**
   - every agent stops its shift and its runner exits;
   - the board rejects all agent writes (humans can still post, and the dashboard stays readable for the demo);
   - the referee shuts down;
   - `make live` stops pulling updates.
2. **After judging, on every machine:**
   ```bash
   swarm/offboard.sh          # dry run: lists what will be stopped
   swarm/offboard.sh --yes
   ```
   This stops the runners, anything still running from `~/swarm-work`, Docker containers labelled `swarm`, and the board, referee and auto-pull. It then logs the machine out of Tailscale.
3. **Then the lead, once:**
   - In the admin console, revoke the auth keys and remove any device still listed, or delete the tailnet.
   - Everyone rotates the API keys their agents used: Anthropic, Gemini, Hugging Face, GitHub.

## Timeline
| When | What |
|---|---|
| Sat, once compute and referee are ready | Start. Measuring tools first; nothing counts until one passes the planted cases |
| Sun 2:00 AM | Last start time for fine-tunes |
| Sun 6:00 AM | Lead creates the task "Final report: findings, fix, before/after". Consolidation only |
| When the humans call it | Freeze (`scripts/board.py swarm-end <time>`). The referee runs the sealed tests on the delivered fix |
| After the freeze | Sealed evaluation, then slides |
| Sun 1:00 PM | Hacking ends |

## Sealed evaluation (referee, after the freeze)
1. Take the delivered fix (checkpoint, LoRA or recipe) and the swarm's best measuring tool, frozen at a commit, that passed the planted cases.
2. Run baseline Nano and fixed Nano on the sealed first frames and sealed prompts, with the same seeds and settings.
3. Report two things:
   - the physics numbers vs real;
   - NVIDIA's scoreboard (DOVER, motion fidelity, plausibility judge, robot-clip prediction), baseline vs fixed.
4. Spot-check a few clips by hand.
