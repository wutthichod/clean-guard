# Harness: Session 2 starter code

Source code for **Session 2: Harness Foundation & Tools** (Sat 10 Oct 2026).
It implements modules **M1–M7** and **M14 (logging)** on top of a local Ollama model.
Session 3 adds the agent loop, state machine and router on top of this code.

## Setup (Windows, PowerShell)

```powershell
python -m venv .venv
.venv\Scripts\activate
pip install -r requirements.txt

ollama pull qwen3:4b-q4_K_M
ollama pull qwen3:8b-q4_K_M
ollama pull gemma3:12b-it-q4_K_M      # fallback profile (optional, slow on 8 GB)

python scripts/check_setup.py          # checks Ollama, models, prompts, one test call
python -m unittest discover -s tests   # offline tests, no Ollama needed
```

Requires Python 3.10+ and a running Ollama.
To use other models, edit `config.yaml`. No code changes are needed.

## Folder layout

| Path | Module | Slide |
|---|---|---|
| `harness/llm_client.py` | **M1** Runtime connector: native `/api/chat` or OpenAI-compatible `/v1` | M1 |
| `config.yaml`, `harness/config.py` | **M2** Model config: profiles `fast`, `reasoning`, `fallback` | M2 |
| `prompts/*.txt`, `harness/prompts.py` | **M3** Prompt manager: versioned templates `name@vN.txt`, ordered from stable to variable | M3 |
| `harness/schemas.py` | **M4** Structured output: `Ticket` Pydantic model → JSON schema in `format` | M4 |
| `harness/validation.py` | **M5** Validation & recovery: schema check → domain rules → retry / repair / fallback / safe failure | M5 |
| `harness/logger.py` | **M14** Logging: one JSONL line per LLM call and per tool call (`logs/calls.jsonl`) | Logging |
| `harness/tools.py` | **M6** Tool registry: `@tool(permission=...)`, `tool_defs()` | M6 |
| `harness/executor.py` | **M7** Tool executor: look up → validate → permission → timeout → ok/err | M7 |
| `harness/sample_tools.py` | `calculator`, `lookup_customer`, `current_datetime`, plus `update_credit_limit` (write, blocked by default) | Hands-on 3a |
| `harness/harness.py` | `Harness` facade: `h.llm(profile, messages, schema=..., tools=...)` | — |
| `harness/data_store.py`, `data/customers.csv` | Sample customer data used by tools and domain rules | — |
| `data/ticket_inputs.jsonl` | 20 test inputs with expected values (Hands-on 2) | Hands-on 2 |
| `data/tool_prompts.jsonl` | 10 tool-calling prompts with the expected tool (homework) | Homework |
| `scripts/` | Demos, hands-on and homework runners (below) | — |
| `tests/test_offline.py` | 15 offline tests using a fake client | — |

## Live demos (teacher)

```powershell
python scripts/demo_structured.py                      # M1–M5 on one message
python scripts/demo_structured.py "c-105: refund still not received after 30 days"
python scripts/demo_structured.py --prompt extract_ticket@v1 --no-repair "..."   # weaker prompt, no repair

python scripts/demo_tool_call.py                       # one tool-calling round trip
python scripts/demo_tool_call.py --profile reasoning "Which tier is C-103?"
python scripts/demo_tool_call.py --failure             # made-up tool, bad args, unknown customer,
                                                       # unsafe expression, permission denied
```

## Hands-on 2: validated structured output (30 min)

1. Read `llm_client.py`, `config.yaml` and `validation.py`.
2. Run the evaluation on 20 inputs with two models:
   ```powershell
   python scripts/hands_on2_eval.py                          # fast (4B) vs reasoning (8B)
   python scripts/hands_on2_eval.py --no-repair              # plain retry, to compare
   python scripts/hands_on2_eval.py --prompt extract_ticket@v1   # weaker prompt, to compare
   ```
3. Report **first-try validity**, **validity after repair**, field accuracy and mean latency.
   Per-input results are saved to `logs/hands_on2_results.csv`.
4. Extension: add one domain rule of your own to `check_ticket()` in `validation.py`.

Inputs `t14`, `t15` and `t19` are designed to trigger the domain rules or the ID pattern.

**Checkpoint:** show the TA one validated output and your `logs/calls.jsonl`.

## Hands-on 3a: your first tool call (20 min)

1. Read `tools.py`, `executor.py` and `sample_tools.py`.
2. Run `python scripts/demo_tool_call.py` with several prompts and both profiles.
3. Add a tool of your own in `sample_tools.py` (a Pydantic `args` class, a docstring and `@tool`).

**Checkpoint:** one end-to-end tool call, with `tool_call` events visible in the log.

## Homework: reliable tool calling (due before Session 3, Sat 17 Oct)

```powershell
python scripts/tool_call_eval.py                        # success rate per model on 10 prompts
python scripts/tool_call_eval.py --answer               # also generate the final answers
python scripts/tool_call_eval.py --tools lookup_customer,calculator   # offer fewer tools
```

Try at least two fixes (better tool descriptions, simpler argument schemas, prompt changes,
fewer tools, a larger model) and write a short note on which helped most.
Results are saved to `logs/tool_call_results.csv`.

## Reading the log

```python
import pandas as pd
df = pd.read_json("logs/calls.jsonl", lines=True)
df[df.event == "llm_call"].groupby("model")[["ttft_s", "gen_s", "wall_s"]].mean()
df[df.event == "llm_call"].groupby("model")["valid"].mean()
```

Events: `llm_call`, `tool_call`, `safe_failure`. Group rows from one task with `run_id`.

## Notes

- `think: false` in `config.yaml` turns off Qwen3 reasoning for faster, cleaner JSON.
  Remove the key for models without a reasoning mode (for example Gemma 3).
- Ollama durations are in nanoseconds. The client converts them to seconds.
  With non-streaming calls, `ttft_s` is approximated as load time + prompt time.
- Tool arguments may arrive as a dict (Ollama native) or a JSON string (OpenAI-compatible API).
  The executor accepts both.

---

# CleanGuard

A local, cross-platform storage-cleaning agent built on this harness (the `harness/` package is
unchanged). It **marks** files `keep` / `deletable` / `review`, protects private documents, and
only moves files the user approves into a restorable quarantine. Nothing is deleted permanently
and nothing leaves the machine. The design is in `../CleanGuard_Implementation.md`.

## Setup (macOS / Linux)

```bash
rm -rf .venv && python3 -m venv .venv && source .venv/bin/activate
pip install -r requirements.txt
ollama pull qwen3:8b-q4_K_M      # the model config.yaml uses now
python -m unittest discover -s tests      # offline, no Ollama needed
```

On macOS, the first scan of `~/Downloads` or `~/Documents` triggers a Files and Folders
privacy prompt for the terminal app. Grant it once.

## Use

```bash
python -m cleanguard ui                   # local web app: scan, files, quarantine, chat
python -m cleanguard clean ~/Downloads    # guided: scan, open the report, approve, show undo
python -m cleanguard scan ~/Downloads [--config C4] [--dry-run]   # mark files, write report
python -m cleanguard approve <run_id>     # pick files, type MOVE -> quarantine
python -m cleanguard restore <batch_id>   # move a batch back
python -m cleanguard runs                 # list runs and quarantine batches
python -m cleanguard resume <run_id>      # continue a run that FAILED (Ollama was down)
```

Each run keeps `runs/<run_id>/state.json`, `files.json`, `report.html` and `report.json`.
These hold file names, so `runs/` is git-ignored.

## Web app

`python -m cleanguard ui` (add `--port` or `--no-open`) serves the app from `cleanguard/web/`. It
uses the standard library and loads nothing from outside this computer.

- **Files:** scan a folder, read each label and reason, filter and sort, preview text, show a file
  in Finder or Explorer, and move what you select. Files marked Keep cannot be moved.
- **Quarantine:** see every batch and restore it.
- **Chat:** ask about a scan on the local model. It can look up results and suggest files or a
  folder, which appear as buttons. It cannot move, restore or select anything.

Safety rules are on the server, not only in the page:

| Rule | Where |
|---|---|
| Binds to 127.0.0.1 only; there is no option to expose it | `web/server.py` |
| Wrong `Host` is rejected (DNS rebinding); `/api` needs a per-start token; POST needs JSON and a matching `Origin` | `web/server.py` |
| A move needs the typed word `MOVE`, and `SENSITIVE` for sensitive files | `web/service.py` |
| Moves share one path with the CLI, the only place an approval token is issued | `cli.quarantine_selection` |
| Chat can only run the five tools in `CHAT_TOOLS`, all read-only | `web/chat.py` |
| Sensitive and Keep files are never suggested by chat | `web/chat.py` |
| "Show in folder" never runs a file; previews stay inside the scanned folder | `web/service.py` |
| Questions, answers and file names never reach `logs/calls.jsonl` | `web/chat.py` |

## Evaluate

```bash
python eval/make_testbed.py --seed 7 --out testbed/      # 200 files + testbed/labels.csv
python eval/run_eval.py --config C4 --split test --runs 3
python eval/metrics.py eval/results/C4_macos_1.csv testbed/labels.csv --split test
python eval/metrics.py --kappa member_a.csv member_b.csv  # category -> label agreement
```

Configurations C0–C5 are in `eval/configs.yaml`. Results go to `eval/results/`.

## Implementation notes (where the code differs from or adds to the design document)

- **`escalate`** in `eval/configs.yaml` maps to `routing.escalate_on_review`. Recovery from an
  invalid batch always retries on the reasoning profile, because that is M5 recovery, not
  routing policy. C3 (`first_profile: reasoning`) has no review escalation.
- **Root refusal:** `"/usr/**"` does not match `"/usr"` itself, so `scan()` uses
  `OSProfile.covers_folder()`, which also tests the folder with a trailing `/`. Scanning a
  protected folder or sync root is refused. Subfolders are handled as the design describes.
- **Scanner:** entries are sorted by name so `file_id`s are stable between runs. Protected files
  are not hashed for duplicate detection.
- **Testbed:** files go under `testbed/files/` (the scanned root), with `labels.csv` beside it so
  the labels file is never scanned. The eval runner scans hidden files, so `.git/` and
  `.DS_Store` are included. Protected testbed files sit directly in `.git/` and `app_config/`,
  because the scanner never descends into a protected subfolder.
- **C0** labels every LLM-bound file `review` with `decided_by="fallback"`. **C5** turns off the
  domain check, the invariant pass and signal forcing. Extra or missing `file_id`s from the model
  still fall back to `review`. The CLI refuses C5 without `--dry-run`.
- **Tool errors are sanitised:** library exceptions can quote paths, and the harness logs
  `error`, so `scan_folder` and `read_snippet` re-raise without paths.
- **Approve:** sensitive files have their own group whatever their label (keep or review) and are
  never preselected. Adding one shows a warning and needs `SENSITIVE` typed, then `MOVE`; the
  choice is recorded in `state.json` and the log. Ctrl+C or end of input at any prompt ends the
  run in `DONE` with nothing moved.
- **Evidence rule (UAT issue 1, `evidence.py`):** `deletable` needs a positive reason: installer,
  exact duplicate, junk name, unfinished download, or a draft whose text was read and whose final
  is in the same folder. Anything else becomes `review`, and names with backup, archive or
  only-copy words do too. It is applied per file after the model answers, not as a batch-level
  domain check, so one doubtful verdict does not throw away a batch or cost another model call. The
  invariant pass enforces it again. It lowers the most C4 can reclaim on the testbed to about 86%
  (earlier C4 results: 99.8%), because course materials and old archives now go to `review`. Re-run
  the C4 evaluation before quoting new numbers.
- **Privacy sweep (UAT issue 2, `sweep.py`):** before TRIAGE, the first 1,500 characters of every
  txt, pdf and docx under 2 MB are read locally, with no model, and privacy signals run on them.
  Text goes to the model for privacy hits, generic names and drafts. The read step is skipped when
  a batch has nothing left to read. Text keywords must start a word (`tax` hits "taxpayer", not
  "syntax").
- **Grounded reasons (UAT issue 4):** a model's reason for a file it was not shown says "not
  opened", and a claim such as "empty" or "already extracted" about unseen content is replaced.
- **Secrets in logs (UAT issue 5):** `harness/logger.py` masks any tool argument named like a token,
  secret, password or key.
- **Refusal:** `scan` refuses a protected or cloud-sync folder before creating a run and says which
  of the two it is. Sync roots are tested first, since iCloud Drive is inside `~/Library`.
- **Timeouts and HTTP errors** during a batch degrade that batch to `review`. Only
  `LLMConnectionError` and `ModelNotFoundError` move the run to `FAILED`, which can be resumed.
- **Day-1 `$ref` check:** `VerdictBatch` and `PrivacyBatch` always inline their `$defs`, so no
  probe is needed.
