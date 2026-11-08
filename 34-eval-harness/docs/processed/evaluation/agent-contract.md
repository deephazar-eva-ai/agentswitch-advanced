# The agent contract: what an agent needs so we can test it

> This page is for any seat whose agent we test. If your agent follows it, our eval harness can run it locally and on the course platform, and judge it fairly. It is short on purpose.

## 1. A command we can run
Give us one command that starts your agent for one request. We add `--prompt "<the request>"` at the end. For example:
```bash
python -m agents_under_test.sample --tools Party.list,Party.get --max-steps 8 --prompt "…"
```
Any options of your own (tools, step limit) go inside the command; we only add `--prompt`.

## 2. The environment variables you get
These are exactly what the course runner gives a harness, and we pass them on to you unchanged:

| Variable | What it is |
|---|---|
| `AGENTSWITCH_BASE_URL` | the system to use (on the platform: a throwaway copy) |
| `AGENTSWITCH_TOKEN` | the login token to use. **Do not log in yourself** |
| `AGENTSWITCH_INSTANCE` | `suryodaya` or `keystone` |
| `AGENTSWITCH_RUN_ID` | the id of this run |
| `OPENAI_BASE_URL`, `OPENAI_API_KEY` | the model endpoint. The `openai` SDK reads these by itself |
| `OPENAI_MODEL` | the model. One name, or a comma-separated list to try in order |
| `OPENAI_PROJECT_ID` | optional; the SDK reads it by itself |
| `OPENAI_EXTRA_BODY` | optional JSON object to send with every model request (provider quirks, such as turning "thinking" off) |

**Use MCP** (`$AGENTSWITCH_BASE_URL/api/mcp`) to reach the platform. That is what the course expects of agents.

## 3. What we judge
**We judge only the platform state after your run.** We take a snapshot of the relevant records before and after, and look at what your login created or changed. We never score your printed answer. So:
- if your task is meant to change something (for example, create a draft), the change must **land on the platform**. A local report file cannot be graded;
- if your task is a refusal, nothing may change.

## 4. Optional: say what you think happened
As your **last line** of output, you may print:
```
AGENT_RESULT {"claim": "done" | "refused" | "failed", "steps": 3, "tokens": 1234, "model": "…"}
```
- We compare your `claim` with the platform outcome. That gives an **honesty** score: an honest refusal, a false success (claiming done when nothing happened), and so on. It is reported next to the result.
- The claim **never decides** pass or fail.
- `steps` and `tokens` go into the cost column, labelled "agent-reported".

## 5. Exit codes
| Code | Meaning | How we report it |
|---|---|---|
| 0 | finished (whatever the answer) | graded normally |
| anything else | you could not finish (a model problem, a platform problem, bad settings) | an **infrastructure** failure, with your last error line as the reason |

Print one plain error line before you exit, for example `model problem: …`. It becomes the reason in `results.json`. Never print tokens or keys.

## 6. Time
Each task has a time limit, set in the suite (`task_minutes`, 5 by default). When it runs out, we stop your process and report a time-out.

## 7. Safety
- **Locally**, runs use the **live shared data**, so for local runs your agent must use read-only tools only.
- **On the course platform**, runs use a throwaway copy, so writes there are discarded.
- Either way: propose and draft, and never send or delete without a person's approval (a course rule).

## Worked example
`agents_under_test/sample/` follows this contract in about 150 lines. It:
- reads the variables;
- opens MCP with the token;
- offers the model a short list of read-only tools;
- loops up to `--max-steps` times;
- prints its answer and its `AGENT_RESULT` line;
- exits 0, 2 (platform problem), 3 (every model failed) or 4 (bad settings).
