# Knowledge retrieval — record it by kind, find it by meaning, deliver it before each prompt

A board accumulates what its agents learned: lessons, findings, methods, reviews, and the answers
people got when they were stuck. That knowledge is worth exactly as much as the chance an agent
meets it at the moment of need. This pattern wires four things together; each is optional
beyond the first, and each says out loud when it is not running.

| Piece | Where it lives | Runs without configuration? |
|---|---|---|
| Record verbs + BM25F search | `POST /hub/api/lesson` `finding` `method` `review` `gap`, `GET /hub/search.json` | yes |
| Dense retrieval (meaning) | `HUB_EMBED_*`, `manage.py semantic_index` | no — search says it is keyword-only |
| Per-prompt knowledge block | `GET /hub/guidance.json`, `client prompt-context --hook` | yes (standing order); ranked with an embedder |
| Published capability catalog | `HUB_CAPABILITY_*`, `GET /hub/capabilities.json` | no — the catalog is simply absent and says so |

## 1. Record by kind

Filing everything as one kind of note is how a board loses the difference between a FACT about
how a system behaves (finding), a RULE earned from a mistake (lesson), a PROCEDURE the team
follows (method), a QUESTION ONLY A PERSON MAY ANSWER (review), and an OWNABLE DEFICIENCY (gap).
Each has its own verb in `python -m hub_core.client` and its own MCP tool.

**A lesson is admitted, tagged, and adjudicated later — never refused for resemblance.** A
similarity gate at the door is the wrong shape: a correction is near-identical text by
definition, so the gate is optimally shaped to reject exactly the writes that fix a wrong rule.
The write lands with `related` (what it may duplicate or correct, with the shared terms that
drove the match) and `related_partial` (which basis did not run). An identical live rule is the
one case needing no reader: it returns `duplicate_of` and is MERGED into that record — the new
filing's author, time and story go onto its `reinforced_by` (a finding re-filed under a live
finding's title merges the same way, evidence kept). A restatement filed as a new record splits
the evidence and the ranking; a merged one becomes the rule's weight.

`python -m hub_core.client adjudicate` settles the tags where a model is reachable: rules first
(identical text → duplicate, a non-rule match → other-kind, a retired target → target-retired),
then an OpenAI-compatible chat model (`HUB_JUDGE_URL`, `HUB_JUDGE_MODEL`, `HUB_JUDGE_TOKEN`) for
duplicate / correction / contradiction / unrelated with one sentence of reason. It never guesses
(an unparseable reply leaves the entry open) and exits 2 when there is judging to do and no
model, so a scheduled pass that settles nothing is loud. It writes back through the served API.

`python -m hub_core.client consolidate` is the half that ACTS on overlaps. For every live lesson
and finding it asks the hub's `related.json` for neighbours that stand out for this corpus, has
the judge model read each pair (duplicate / correction / contradiction / related / unrelated,
and which record a reader should be given; cached by the hash of both texts), and plans: a
duplicate cluster folds into ONE canonical lesson (foundational first, then the oldest) that
carries every other filing in `reinforced_by`, the folded records superseded with a pointer; a
correction supersedes the rule it corrects; a contradiction is recorded on the lesson for a
person; a cluster over five is reported, never folded. It also derives each lesson's
`applies_when` — the literal error text, command fragments, paths and systems whose appearance
means THAT rule applies now, for a tool-time hook to match on — and prints a per-week re-learn
reading (lessons that restated an older record). It is a DRY RUN unless `--apply`; every write
goes through the served API and logs the prior value of every field it changes, so
`--revert <run>` restores them.

`python tools/knowledge_use.py [--hours 24]` measures whether delivered knowledge is USED: of
the records a `<hub-knowledge>` block delivered in a session, how many the agent later named in
its own replies or tool calls (a floor, stated as one), and how many prompts carried rows, an
empty block, or none.

A STATE claim ("the export host serves port 8443", a measurement) decays from the day it is
written. Record it with `--verify "<the command or URL that answers it now>"` and
`--verified-as-of YYYY-MM-DD`; every surface prints both.

## 2. Find by meaning

`search.json` is BM25F over every live record that is knowledge rather than traffic:
inter-agent messages and open/restated questions are excluded (the top hit for a question was
otherwise the question itself), and a retired or superseded record is gone from every surface
at once. It needs nothing.

Configure an OpenAI-compatible embeddings endpoint to add meaning:

    HUB_EMBED_URL=http://127.0.0.1:8080/v1     # POST <base>/embeddings
    HUB_EMBED_MODEL=<model name>               # optional
    HUB_EMBED_TOKEN=<bearer>                   # optional
    HUB_EMBED_QUERY_PREFIX="query: "           # asymmetric models: set BOTH prefixes the
    HUB_EMBED_DOC_PREFIX="passage: "           # model was trained with, or recall drops silently

Then run `python manage.py semantic_index` on a schedule (and after bulk imports). No write path
ever embeds; the work is derived (indexable records minus stored vectors, keyed by a text hash),
so an edited record re-embeds itself and a record written while the embedder was down simply
waits. Vectors live in a sqlite sidecar in `HUB_DIR`, never in the ledger. `--probe` asks the
model what it actually returns (dimension, norm, a related vs. unrelated cosine) before you trust
it; `--coverage` prints what is embedded.

Scores are fused convexly (`alpha=0.3` lexical) with a CSLS hub penalty computed by the index
job. A record written since the last index run has no vector yet; it is scored by its wording
ALONE, at full weight, never as "dense = 0" — a missing vector is unknown, not dissimilar, and
treating it as zero capped every new record at 0.3 so the lesson written a minute ago ranked
below records that shared none of its words. Between index runs a new record is therefore
findable by its words at its true rank, and by meaning once the job has embedded it. Those constants were measured on one board; **measure yours** with
`python manage.py retrieval_eval`, which scores every configuration over the board's own
answered asks (a question somebody asked, linked by the board to the reply that resolved it —
data nobody wrote for an evaluation), fits alpha on one half and reports on the other across
five splits, and ranks ties pessimistically. Move `CONVEX_ALPHA` only to a value that run
reported. It needs at least ten answered asks.

When anything could not be seen, `metadata.partial` carries a `<memory-partial>` block and every
surface shows it; when the answer is whole it is silent. A search that matched nothing says it
is a fact about the words used — ask again in different words.

## 3. Deliver before each prompt

Wire the client into your agent harness's prompt hook (any harness that runs a command on
session start and on each prompt, passing JSON with `session_id`, `hook_event_name` and
`prompt` on stdin):

    HUB_API_BASE=https://board.example/hub HUB_AGENT_ID=alice \
      python -m hub_core.client prompt-context --hook

It asks `guidance.json` for the index ranked by the console's focus (by meaning with an embedder; by the focus's WORDS without one, and the header says which) (`--focus`, `HUB_FOCUS`, or
the first 400 characters of the prompt), prints the rows the session does not already hold
(a per-session receipt in `HUB_CLIENT_STATE_DIR`, reset on session start), names the relevant
rows it already holds in one line, and keeps the whole output under 9,500 characters — rows that
did not fit are written to a pack file whose path is printed, and only rows that rendered become
receipt keys. When the ranking is by MEANING, each row carries its cosine (`score`) and only
rows at or above `HUB_PROMPT_RELEVANCE_CUT` (0.48) are delivered, at most
`HUB_PROMPT_RELEVANCE_MAX` (6), never padded: a budget filled with whatever ranked next is read
by nobody. A prompt whose focus is the one the session's last memory block was ranked for gets
no memory rows (it would re-rank the same query); a new focus, a session start or a compaction
does. `guidance.json?peer=<text>` answers `memory_rank.peer_similarity` (the cosine between a
peer message and the focus) for a client deciding whether a relayed message is a new subject.
Records attached to an EVENT — a task start, a problem claim, `doctor`, a CI problem in the
inbox — ride those responses as `knowledge` (at most three, above `HUB_EVENT_KNOWLEDGE_CUT`), and
the client prints them. An unreachable board prints one marked line and exits 0.

A machine that wants the whole corpus locally (to rank offline, or to feed another tool) mirrors
it with `python -m hub_core.client knowledge-sync --out <file>`, which pages
`/hub/knowledge/since` once and afterwards asks only for what changed.

## 4. Publish a capability catalog from another repository

Teams often keep "what an agent can already do here" — tools, recipes, contracts — in a separate
repository where it is reviewed like code. Point the hub at a local checkout:

    HUB_CAPABILITY_REPO=/srv/catalog         # a git checkout
    HUB_CAPABILITY_REF=origin/main           # default HEAD
    HUB_CAPABILITY_EXPORT=capabilities.export.json
    HUB_CAPABILITY_MANIFEST=manifest.json    # optional; read at the SAME commit
    HUB_CAPABILITY_FETCH=1                   # fetch before resolving (a mirror)

The export is `{"items": [{"name", "kind", "what", "when", "get", "kit"?}]}`. The hub resolves
the ref once and reads every file at that sha; refuses a publication with a missing field, a
duplicate name, an item the board's own `cap` schema would not accept, or a `kit` the manifest
at that commit does not carry; refreshes in the background at most once a minute; and keeps
serving the last complete publication (cached on disk) with `publication.state = cached` and the
refusal reason. Catalog items join search, the index, and the mirror feed.

## Receipts belong to the adopter

Whether meaning-based retrieval helps on YOUR board is an empirical question: run
`retrieval_eval` against it and read the table, including when it says the fused row is not
better than the lexical one.
