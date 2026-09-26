# MicroVM Agent Sandbox (`aws-microvm-agent-sandbox`)

A chat app whose agent has its own **AWS Lambda MicroVM** to run code in.

Ask *"Build me a fractal tree and get me the results"*. The agent writes Python
and runs it in a private Firecracker VM. It then **looks at the image it
rendered**, fixes anything wrong, and puts the picture in the chat. Expand the
trace under the answer to see each step: the sandbox launching, the code it
ran, the output, and the file it showed.

It is the same demo as the Claude/ChatGPT MCP connector in
[aws-lambda-microvms](https://github.com/mamonaco1973/aws-lambda-microvms). The
difference is where the agent lives: here it runs inside your own app, as a
Bedrock tool loop you can read end to end.

---

## What it showcases

1. **A MicroVM as an agent sandbox.** Each conversation gets its own VM, with
   its own kernel, filesystem and endpoint. Model-written code runs there and
   never in your Lambda.
2. **Launch on demand.** Creating a chat launches nothing. The VM starts the
   first time the agent runs code. Launching restores a snapshot with Python,
   numpy and matplotlib already loaded in memory, so it takes seconds.
3. **State that survives.** The VM runs two persistent sessions, Python and
   bash, over one shared filesystem. Variables, imports, the shell's `cd` and
   exports, and files all persist between messages. After 30 idle minutes
   the VM suspends and costs nothing for compute. The next message wakes it
   with both sessions intact.
4. **Context that carries over.** Each new message replays the earlier ones
   *with their tool calls*, so the agent remembers what it ran and what went
   wrong, not just what it said. It also gets an inventory of the sandbox
   (files, Python functions and data, the shell's `cwd`) taken when the last
   message finished, so it reuses what's there instead of rebuilding it.
   Bedrock prompt caching makes the replay cheap.
5. **An agent that checks its work.** `show_file` sends the rendered PNG back
   to the model as an image. The model reviews what it drew and re-renders if
   something is off.

## Architecture

```
Browser (SPA) ── POST /conversations/{id}/queries ──► API Lambda ──► SQS
      ▲                                                               │
      │ poll every 2s (live progress + final answer, trace, files)    ▼
      └──────────── DynamoDB / S3 ◄──────────────────────── Worker Lambda
                                                           Converse tool loop
                                                             │        │
                                              Claude on Bedrock    MicroVM sandbox
                                                                   (one per conversation)
                                                                   supervisor :8080 / hooks :8081
                                                                   persistent Python + bash sessions
```

**The tool loop** (`02-core/code/worker.py`) calls Bedrock **Converse** with
four tools and runs each tool the model asks for:

| Tool | What it does |
|---|---|
| `run_code(code)` | Runs Python in the conversation's persistent session and returns the output. The worker waits for the cell, so the model never polls. |
| `run_shell(command)` | Runs bash in the conversation's persistent shell: `cd`, exports and variables carry over between calls. The model uses it for installs (`pip3`, `dnf`), git, files and builds. |
| `get_result(job)` | Keeps waiting on a job that is still running after 4 minutes (for example, a big install). |
| `show_file(path)` | Fetches a file from the VM and stages it in S3 as an attachment on the answer. An image is also returned to the model so it can check it. Showing the same path again replaces the attachment. |

**The sandbox** (`01-sandbox/image/`) is a MicroVM image built remotely by
Lambda from a Dockerfile, so you need no Docker or ECR. A stdlib HTTP
supervisor accepts cells as jobs: `POST /execute` returns a job id and
`GET /result/<id>` returns the output. Jobs run in one of two persistent
sessions that share `/workspace`: a Python kernel that imported numpy and
matplotlib *before* the snapshot was taken, and a bash shell. A session that
dies (a `set -e` failure, `os._exit()`) restarts itself on the next command,
and the output says what was reset.

**Security boundary:** the VM. The sandbox's IAM role has **no policies**, so
code the model writes can reach the internet (for `pip`) but cannot call a
single AWS API. Files leave the VM only through the worker.

## Deploy

Prerequisites: Linux with AWS CLI v2 recent enough to have `lambda-microvms`,
Terraform ≥ 1.7, Python 3 with pip, `zip`, `jq`, `curl` and `envsubst`. Your
account also needs Bedrock access to the model in `bedrock-config.sh`
(default: Claude Sonnet 4.6). MicroVMs are available in us-east-1, us-east-2,
us-west-2, eu-west-1 and ap-northeast-1.

```bash
./apply.sh      # build the sandbox image, deploy the backend, upload the SPA
./destroy.sh    # terminate every sandbox, then tear everything down
```

`apply.sh` runs three phases:

| Phase | Directory | Creates |
|---|---|---|
| 1 | `01-sandbox` | Source bucket, build role, **the MicroVM image** (takes several minutes) |
| 2 | `02-core` | API Gateway, API + worker Lambdas, boto3 layer, Cognito, SQS, DynamoDB, S3, CloudFront, sandbox role |
| 3 | `03-webapp` | Generated `config.js` and the static SPA, uploaded to S3 |

It finishes with `validate.sh`. That script launches a sandbox directly,
renders a fractal tree, fetches the PNG, then suspends the VM and resumes it
with a plain HTTPS request, and checks the Python state survived. Last, it
prints the app URL.

Optional environment variables: `AWS_AGENTOPS_GOOGLE_CLIENT_ID` / `_SECRET`
(Google sign-in via Cognito) and `AWS_AGENTOPS_CUSTOM_DOMAIN`.

## Try it

Sign in, then click a starter or type:

1. **"Build me a fractal tree and get me the results"**: the headline demo.
   The trace shows *Launched MicroVM…*, the code, its output, and the image.
2. **"Now make it an autumn tree with depth 14"**: this reuses the same VM,
   and the earlier function is still defined in the session.
3. Leave it for 30 minutes and ask again. The trace shows *Resuming suspended
   MicroVM… with its Python state intact*.
4. **"Install pandas in the sandbox, then chart some made-up sales data"**:
   `pip3 install` in bash, then the chart in Python, in the same VM.
5. **"Install git, clone https://github.com/mamonaco1973/aws-lambda-microvms
   and count its lines of Python and Terraform"**: a shell-driven task. The
   trace shows `dnf install`, `git clone`, and a `cd` that carries over.
6. **"What is your sandbox?"**: the agent inspects its own OS, kernel, CPU
   and memory.

Deleting a conversation terminates its VM.

## Cost

| Item | Cost |
|---|---|
| Sandbox while running (0.5 GB / 0.25 vCPU ARM) | ~$0.0315/hour |
| Sandbox while suspended (after 30 idle minutes) | $0 compute |
| Suspend / resume snapshot I/O | $0.0038/GB written, $0.00155/GB read |
| Sandbox image storage | $0.08/GB-month, **one-week minimum per image** |
| Model | Bedrock tokens per query (images add ~1–2k input tokens each) |

The API, worker, DynamoDB, SQS and S3 are all serverless and scale to zero.
Each sandbox lives for 8 hours at most. Sign-up is self-service, so every new
Cognito user can launch sandboxes. The cost bounds are auto-suspend, the
lifetime cap and the per-user token budget (1M tokens, `TOKEN_LIMIT_DEFAULT` in
`02-core/code/users.py`), not the user list. Run
`./destroy.sh` when you are done.

## Layout

```
01-sandbox/          MicroVM image (Terraform + image source)
  image/             Dockerfile, server.py (supervisor), kernel.py (Python), shell.sh (bash)
02-core/             Backend Terraform + Lambda code
  code/              handler / conversations / users / worker / sandbox
03-webapp/           Vanilla-JS SPA (chat, live progress, trace, inline images)
```
