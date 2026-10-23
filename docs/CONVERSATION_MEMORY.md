# Conversation memory

[Back to the project guide](../README.md) · [Usage examples](USAGE.md#5-memory-percakapan)

Run shell commands below from the repository root with the project's Python
environment. Enter `/memory` commands at Ember's `You>` prompt.

The interactive CLI saves requests, displayed answers, tool arguments, reported
outcomes, and UTC timestamps in `data/conversation.sqlite3`. History survives
restarts and stays local; `data/` is excluded from Git. Existing logs are not
imported. Saved user text and tool output are historical records, not verified
facts or instructions to execute again.

At the `You>` prompt:

```text
/memory
/memory search scholarship
/memory clear
```

These explicit CLI commands show recent history, search by topic words, and
clear conversation history. They do not need model inference. Clearing history
does not clear separate tool logs, notes, tasks, or backups. Set `EMBER_MEMORY=0`
before starting Ember to disable history reads and writes without deleting it:

```bash
EMBER_MEMORY=0 ./venv/bin/python run_ember.py
```

In PowerShell, set `$env:EMBER_MEMORY = '0'` before running Ember; remove the
variable with `Remove-Item Env:EMBER_MEMORY` to enable memory on the next launch.

Each input is a fresh request. The experimental numbered memory menus and
pending-answer state have been removed. Device-information tools do not request
a conversation-versus-RAM choice. An unresolved request does not capture the
next message as a search topic.

With memory enabled, a small Needle selection view checks for conversation
recall. It can prevent a conflicting live action but cannot execute tools or
turn the full question into a search query. The main Needle router must select
the history tool and generate valid arguments at the existing confidence
threshold. A disagreement or uncertain result returns an unresolved status
with `/memory` command guidance, without opening a menu. Both views use the
existing engine and weights. The selection descriptions distinguish remembered
conversation contents from physical RAM capacity. In the Windows regression
check, "what's in memory now?" now declines instead of reading hardware;
it still does not successfully retrieve history through natural language.

Natural-language history and time interpretation remain unreliable. Removing
the menus restores independent input handling; it does not solve semantic
retrieval. Use `/memory` and `/memory search <topic>` for direct access to the
stored history while model-based conversation handling is evaluated separately.

Lookup is literal: every topic word must match a whole word in a saved request,
answer, or arguments. Matching results precede failed attempts, with duplicate
excerpts suppressed. Failed response text is excluded from matching; failures
remain searchable by their request/arguments and retain their original status.
A no-match result never falls back to unrelated recent history. However, pasted
tracebacks stored as user requests can still match a word in a directory name.
Such a match is not evidence of a meaningful discussion about that subject.

The backend supports all, current, and previous saved sessions. The previous
session is the latest earlier session containing retained non-recall turns,
not necessarily yesterday or the latest discussion of a particular topic.
Session filtering happens before ranking; the old UI no longer selects it.

Brief outcome replies can now be rephrased by the existing local model after
execution. The displayed answer is stored in history; debug comparisons are
not stored as extra conversations. This presentation layer does not resolve
history intent, reference resolution or multi-step clarification. Evaluate
faithfulness, latency and total RAM on the physical Pi before relying on it.

Evaluate storage and actual fresh-request routing separately:

```bash
python scripts/evaluate_memory.py --output logs/memory-content.json
python scripts/evaluate_memory.py --with-routing --output logs/memory-routing.json
```

These checks use disposable history and stub all non-history tools. They never
open the user's database. A nonzero exit code reports unmet expectations;
known history-routing failures are not counted as successes. The routing-only
suite is `scripts/evaluate_routing.py`; `--without-memory` disables storage
while preserving production intent guards. `--catalogue-only` bypasses the
history guard for an isolated catalogue diagnostic.

History is not automatically appended to OS-action prompts. Bounded file-reference
resolution and opt-in multi-step execution exist, but arbitrary action chains
and general conversational reference resolution are not reliable.

Memory uses Python's standard SQLite library, with no embedding model or
SmolLM worker. It retains up to 1,000 turns, caps each request/answer/arguments
field at 2/4/2 KiB (previews are marked), and returns at most five excerpts within
6,000 bytes. SQLite's page cache target is 256 KiB and database page allocation
is capped at 16 MiB; these are not limits on total process RAM. SQLite journals
may temporarily take additional disk space. Topic search uses bounded text
matching, not semantic embeddings or model training. A storage failure reports
that the turn was not saved and does not rerun the tool.
