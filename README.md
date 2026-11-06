**English** · [Українська](README.uk.md)

<div align="center">

# nollm-wiki

**A map of your project for coding agents: where each function lives, what calls it, and which lines to read, compiled without an LLM.**

[![CI](https://github.com/bambooplanedev/llm-wiki-nollm/actions/workflows/rust.yml/badge.svg?branch=main)](https://github.com/bambooplanedev/llm-wiki-nollm/actions/workflows/rust.yml)
[![Release](https://img.shields.io/github/v/release/bambooplanedev/llm-wiki-nollm)](https://github.com/bambooplanedev/llm-wiki-nollm/releases)
[![Rust 1.89+](https://img.shields.io/badge/rust-1.89%2B-orange?logo=rust)](https://www.rust-lang.org)
[![License: MIT](https://img.shields.io/badge/license-MIT-blue)](LICENSE)

</div>

`wiki` compiles a project — code, notes, docs — into a cross-linked Markdown wiki and a symbol map
with line ranges, then serves it to agents over MCP. An agent asks `search` where something is and
gets `path:start-end` lines back, asks `callers` who calls a function, and reads mostly those lines
instead of grepping and opening whole files. No model is called at compile time: the same input
gives byte-identical output on any machine.

Not a semantic search engine: matching is lexical, by names, words and imports. Not a language
server: calls are resolved by name and argument count, without types.

In the examples, long lines are shortened with `…`, and a `└` line names the parts of the line
above it; it is not output.

```
$ wiki callers calls.rs resolve_calls --dir .wiki
callers of resolve_calls  wiki/src/calls.rs:197-264 — 1 functions in 1 files
wiki/src/lib.rs
  145-464  fn  compile_inner  calls resolve_calls at 329
  └ the caller's lines        └ the line of the call
```

## Contents

- [Features](#features)
- [Requirements](#requirements)
- [Installation](#installation)
- [Quick start](#quick-start)
- [Usage](#usage) — [agents](#agents): [`wiki setup`](#wiki-setup) ·
  [Cursor](#cursor) · [Codex](#codex) · [others](#other-mcp-clients) — [MCP server](#mcp-server) ·
  [agent memory](#agent-memory) · [CLI](#cli)
- [Output](#output) — [a page](#a-page) · [artifacts](#artifacts) · [what agents read](#what-agents-read) ·
  [Obsidian and Quartz](#obsidian-and-quartz) · [page ids](#page-ids)
- [Measured](#measured)
- [Limitations](#limitations)
- [Development](#development)
- [License](#license)

## Features

- **Symbol search.** `search` ranks pages by names, words, docs and imports, a query word that is a
  file name or path suffix (`strategy_config.h`, `manager/mod.rs`) lifts that file, and under each code
  page lists its matching functions and types as `path:start-end  name  signature — doc`.
- **Outlines.** `page` prints one line per symbol of a file with its line range, so an agent reads
  forty lines instead of four thousand.
- **Calls both ways.** `callers` lists the functions that call a function, with the lines of each
  call; `neighbors --symbol` lists everything a function calls, level by level.
- **MCP server.** `wiki serve --source .` compiles the project, recompiles it on edits and serves
  `search`, `page`, `neighbors` and `callers` to Claude Code, pi, Cursor, Codex or any MCP client.
  Several servers on one `.wiki` are fine: one compiles, the others serve what it wrote.
- **One-command setup.** `wiki setup` installs the server and what tells the agent to use it, for
  Claude Code, pi, Cursor and Codex, and a hook that adds the matching code lines to each prompt.
- **Agent memory.** Notes in `.agents/memory/` and in the folders agents already write to (Claude
  Code's) become searchable pages, listed after the code hits, with dates, aliases and `supersedes:`.
- **Languages.** Rust, Python, C++, Go, JavaScript, TypeScript (with JSX/TSX), `.vue` and `.svelte`
  scripts, shell (`.sh`, `.bash`: functions only), Markdown and plain text.
- **Deterministic.** Byte-identical output across runs, machines and thread counts; incremental
  recompiles.
- **Opens in Obsidian.** The pages link each other with Obsidian wikilinks, so the output folder is
  a vault with a working graph and backlinks; see [what does not carry over](#obsidian-and-quartz).

## Requirements

- macOS (Apple silicon or Intel) or Linux x86_64 for the release binary. The Linux one is built on
  GitHub's `ubuntu-latest`, so an older distribution's glibc may need a build from source.
- Or Rust 1.89 or later to build from source. Windows is not tested.
- For agent use: an MCP client — Claude Code, pi, Cursor, Codex, Claude Desktop or another. `wiki setup --scope local`
  for Claude Code also needs the `claude` CLI on `PATH`.

## Installation

From a [release](https://github.com/bambooplanedev/llm-wiki-nollm/releases): download the tarball
for your platform (`aarch64-apple-darwin`, `x86_64-apple-darwin` or `x86_64-unknown-linux-gnu`) and
put the `wiki` binary in a directory on your `PATH`, since agents start it as plain `wiki`:

    curl -LO https://github.com/bambooplanedev/llm-wiki-nollm/releases/download/v0.6.6/wiki-v0.6.6-aarch64-apple-darwin.tar.gz
    tar -xzf wiki-v0.6.6-aarch64-apple-darwin.tar.gz
    sudo mkdir -p /usr/local/bin && sudo mv wiki /usr/local/bin/

Releases after v0.6.1 also carry `SHA256SUMS`. With the tarball and that file in one folder, run
`sha256sum -c --ignore-missing SHA256SUMS` (on macOS `shasum -a 256 -c --ignore-missing SHA256SUMS`).

From source:

    git clone https://github.com/bambooplanedev/llm-wiki-nollm
    cd llm-wiki-nollm
    cargo install --path wiki      # into ~/.cargo/bin

## Quick start

In the project you want agents to navigate:

    cd your-project
    wiki setup --scope local      # compiles .wiki, installs the MCP server, the prompt hook and (for pi) a skill

Then start Claude Code or pi in that directory: the `wiki` tools are there, and the server keeps
`.wiki/` in step with your edits. `--scope repo` writes committed files for the whole team instead,
and `wiki setup --remove` with the same `--scope` undoes it. Cursor and Codex:
`wiki setup --agent cursor,codex`; other clients: see [Agents](#agents).

To try the compiler on its own, on a generated corpus:

    wiki generate demo_raw --files 12 --seed 42
    wiki compile demo_raw demo_wiki
    wiki search gradient --dir demo_wiki --limit 2
    wiki neighbors gradient_descent --max-tokens 800 --dir demo_wiki

```
$ wiki compile demo_raw demo_wiki
Compiled 12 pages (12 written) -> demo_wiki
Lint: 0 broken links, 1 orphans, 0 large
                      └ a page no other page links to

$ wiki search gradient --dir demo_wiki --limit 2
gradient_descent  gradient_descent.txt  Gradient Descent — Gradient Descent is often paired with…
└ id              └ path                └ title — summary
    Gradient Descent is often paired with Learning Rate Schedule in prod…
    └ the matching text
layer_normalization  layer_normalization.txt  Layer Normalization — Layer Normalization builds…
    Layer Normalization builds directly on the ideas behind Gradient Descent. When debugging…
```

On code the same search names symbols with line ranges. Against this repository:

```
$ wiki search "call edges" --dir .wiki --limit 1
calls  wiki/src/calls.rs  Calls — Call edges between code items: matched by name at compile time…
└ id   └ path             └ title — summary
  wiki/src/calls.rs:286-310  callers_index  pub(crate) fn callers_index<'a>(…) -> BTreeMap<…>  — Every…
  └ path:lines               └ name         └ signature                                        └ doc
  wiki/src/calls.rs:343-481  Wiki::call_walk  fn call_walk(&self, …) -> Result<…>  — `calls`, or with…
  wiki/src/calls.rs:197-264  resolve_calls  pub fn resolve_calls(entities: &mut BTreeMap<…>, graph: &Graph)  — Fills every…
```

## Usage

### Agents

The workflow an agent follows is search → page → read lines: `search` finds the page and its
symbols, `page` lists a file's symbols with line ranges, and the agent reads just those lines with
its own file tool. `callers` answers "what breaks if this changes"; `neighbors` is for when the
surrounding pages matter. Handed a plan, spec or ledger, the agent passes its paths in `search`'s
`docs` to get a step's line range by its label (`T5k`) or title words (`wiki search T5k --docs plan.md`
on the command line). Each path is printed once, then `  start-end  label` per hit; `run-premise` and
`run premise` match alike, after the exact matches. When the limit cuts a label repeated in one
doc under the same head (`N11: …` in a ledger), both its first and last entries show. Pass the
plan, spec and ledger together, since an ID is often a label in only one of them; an empty query
lists the first 200 labels (`limit` lists more, and a final line says how many were cut); body text
is not searched, grep stays the tool for it.
An empty answer says the label must hold the words in a row and suggests fewer words or grep.

| agent | `wiki setup` writes | what tells it to use the wiki |
|---|---|---|
| Claude Code | `.mcp.json` (repo) or `claude mcp add-json` (local) | the server's instructions; tools load up front |
| pi | `.pi/mcp.json`, the `wiki-navigation` skill | the skill (pi does not show server instructions) |
| Cursor | `.cursor/mcp.json` | the tool descriptions (enough in our runs) |
| Codex | `codex mcp add` (global), the [navigation rules](#navigation-rules) in `AGENTS.md` | `AGENTS.md` |
| any other MCP client | — ([by hand](#other-mcp-clients)) | the navigation rules in its instructions file |

#### `wiki setup`

`wiki setup` makes the agents use the wiki on their own. Run it in the project root:

    wiki setup [--agent claude,pi,cursor,codex] [--scope repo|local] [--no-hook] [--remove]

It compiles `.` into `.wiki`, then installs the MCP server (`wiki serve --source .`) and what tells
each agent to use it. pi gets the `wiki-navigation` skill (how to find code, and the memory rules).
Claude Code gets no skill: it shows the server's instructions, which carry the same navigation
steps, and the server marks its tools to load up front instead of behind a `ToolSearch` call; its
own memory is read by the wiki. Codex reads neither, so it gets the navigation rules
in `AGENTS.md`, between `<!-- wiki:navigation -->` markers. Agents are detected (`.claude/`,
`CLAUDE.md` or `claude` on `PATH`; `.pi/` or `pi` on `PATH`; a `.cursor/` folder) unless `--agent`
names them. Codex is set up only when named: its MCP config is global.

- `--scope repo` — committed files for the whole team: `.mcp.json`, `.pi/mcp.json`,
  `.cursor/mcp.json`, `AGENTS.md`,
  `.agents/skills/wiki-navigation/SKILL.md`, and `.wiki/` in `.gitignore`.
- `--scope local` — this checkout only: Claude Code's server goes through
  `claude mcp add-json wiki … --scope local`, the other files are written and the ones setup
  created are listed in `.git/info/exclude`, `/.agents/memory/` included. A file git already tracks is skipped; use
  `--scope repo` for it.
- Either scope creates `.agents/memory/`. When Claude Code is set up, the
  `.claude/skills/wiki-navigation` and `.claude/skills/wiki-memory` skills an earlier release wrote
  are removed if untouched (in local scope, only if git does not track them).
- Either scope adds Codex's server with `codex mcp add wiki -- wiki serve --source .`, which writes
  `~/.codex/config.toml`: Codex has no per-project MCP config, and it starts the server in the
  directory it runs in, so the one entry serves every project.
- Without `--scope`, setup asks on a terminal and fails without one.
- The prompt hook adds the wiki's code lines for each prompt before the model runs. Claude Code gets
  a `UserPromptSubmit` entry (`wiki hint --claude-hook`) in `.claude/settings.json`
  (`settings.local.json` with `--scope local`); pi gets `.pi/extensions/wiki-hint/index.ts`. The
  hook is silent when there is no wiki, it cannot be read or nothing matches, and never blocks a
  prompt. `--no-hook` skips it; a hook installed earlier stays until `--remove`. Up to 0.4 the hook
  was opt-in with `--hook`, which is gone: rerunning setup after an upgrade adds the hook (in a
  committed `.claude/settings.json` with `--scope repo`), unless `--no-hook` is given.
- `--remove` deletes exactly what setup wrote, hooks included, and Codex's server only when it is
  the one setup added. Ignore lines, `.wiki/` and memory notes stay.

In a project with `CLAUDE.md` and no `AGENTS.md`, `--agent codex` adds Codex's server but skips the
navigation steps (exit 1) instead of creating `AGENTS.md`: pi reads only `AGENTS.md` when both
exist, so it would stop seeing `CLAUDE.md`. An `AGENTS.md` an earlier setup created there, holding
nothing but the steps, is removed for the same reason. To get them, rename `CLAUDE.md` to `AGENTS.md`, create a
new `CLAUDE.md` whose only line is `@AGENTS.md` so Claude Code still loads it, and run setup again;
Codex and Cursor then read the same rules. If `CLAUDE.md` is committed, that changes team files:
run setup with `--scope repo`, since local scope skips a tracked `AGENTS.md`.

Every agent runs the server as plain `wiki`, so `wiki` must be on `PATH`; setup warns when it is
not. Safe to run twice. An entry, file or block at the same place with other content is left alone
and reported; setup does the rest and exits 1. A JSON config setup edits is rewritten as 2-space
pretty JSON with its keys and their order kept.

After setup: pi loads project files only after you trust the project (`/trust`, or `--approve` in
print mode), and Cursor loads a new server only after you approve it (its MCP settings, or
`cursor-agent mcp enable wiki`).

#### Claude Code by hand

    claude mcp add-json wiki '{"command":"wiki","args":["serve","--source","."]}' --scope local

or the `mcpServers` entry of [MCP server](#mcp-server) in the project's `.mcp.json`. Claude Code
shows the server's instructions, which carry the navigation steps, so no skill is needed for
finding code; the wiki reads Claude Code's own memory, see [Agent memory](#agent-memory).

#### pi

`wiki setup --agent pi` writes `.pi/mcp.json` and the `wiki-navigation` skill; pi loads both after
`/trust` (`--approve` with `pi -p`). pi needs the skill: it does not show MCP server instructions
for `direct` servers, so all it learns about the wiki is the tool descriptions and the skill.
Without it, in our runs the model grepped, and when a user-installed extension made pi load a skill
before it answered (we ran one called skill-first), it picked an unrelated one
(`systematic-debugging` for "where is" questions).

By hand, `.pi/mcp.json` in the project:

```json
{ "mcpServers": { "wiki": { "command": "wiki", "args": ["serve", "--source", "."], "exposure": "direct" } } }
```

and the [navigation rules](#navigation-rules) in `.agents/skills/wiki-navigation/SKILL.md`, under a
front matter with `name: wiki-navigation` and a `description:` that says when to use it
(`wiki setup` writes "Find where something is or how it works in this project's code. Use before
grep, find or reading whole files, whenever the task needs a function, type, handler or module
location."); pi finds a skill by them.

Use only the project's server: if `~/.pi/agent/mcp.json` also has a wiki server, under any name,
remove it. With both, the model sees every wiki tool twice under two names (pi names them after the
server: `mcp__wiki__search` for this one), and the skill `wiki setup` writes names only
`mcp__wiki__*`. To try it without letting pi edit files:
`pi -p --approve --no-session --exclude-tools edit,write "where is …"`.

Measured once per question with Mellum2.1 12B-A2.5B on llama-server, on three questions about the
private project described in [Measured](#measured): all six answers were correct; with the skill
the three took 10 tool calls and 109 s, without it 19 and 160 s. With the skill, pi answered "what
calls X" with `search`, then `callers`, and did not load an unrelated skill in these runs. A
question whose words differ from the code's (`credentials` for `load_tenant_creds`) still ended in
grep.

#### Cursor

`.cursor/mcp.json` in the project (or `~/.cursor/mcp.json` for every project) takes the same entry:

```json
{ "mcpServers": { "wiki": { "command": "wiki", "args": ["serve", "--source", "."] } } }
```

Cursor starts the server in the project directory, so `--source .` works. A new server stays off
until you approve it, and Cursor drops that approval whenever the entry's command changes; the
server then silently does not load. In our runs the agent called `search` and `callers` with no
extra instructions.

`cursor-agent -p` (non-interactive) rejects every MCP tool call unless it runs with `--force`;
`--mode ask --force` lets the wiki tools run and still allows no edits. Checked with
`cursor-agent` 2026.10.22; the Cursor editor itself is not checked.

#### Codex

By hand, `codex mcp add wiki -- wiki serve --source .` writes this to `~/.codex/config.toml`:

```toml
[mcp_servers.wiki]
command = "wiki"
args = ["serve", "--source", "."]
```

The wiki's tools are marked read-only, so Codex runs them without asking, `codex exec` included.
Codex does not reach for them on its own, though: it needs the
[navigation rules](#navigation-rules) in the project's `AGENTS.md`. On three questions about this
repository (codex-cli 0.164.0, read-only sandbox), without them it made no wiki call and named the
wrong caller once; with them it used `search`, `page` and `callers` and answered all three.

#### Other MCP clients

Add the `mcpServers` entry of [MCP server](#mcp-server) to the client's config. A client that does
not start in the project directory, such as Claude Desktop, needs the project's absolute path in
`--source`. Put the navigation rules in its instructions file.

#### Navigation rules

What `wiki setup` puts in `AGENTS.md` for Codex, for any agent that needs them in its instructions
file:

```
## Find code with the project wiki

1. Call the wiki `search` tool with the words of what you are looking for and `kind: "code"`.
   Each symbol line is `path:start-end  name  signature`.
2. Read only those lines with your file tool. The start and end lines are exact — do not
   re-derive them with grep.
3. For a module's map, call `page` with the path; it lists every symbol with its lines. To follow
   a function through the code, call `neighbors` with the path and `symbol`. To see what calls a
   function, call `callers` with the path and `symbol` instead of grepping for its name.
4. Do not call grep, find or ls in the same turn as `search`. Wait for the `search` answer and
   read it first; most of the time it already holds what you need.
5. Pick the tool by the question: where something is defined or handled, `search`; who calls a
   function, `callers`; every occurrence of a literal string (an env var, a message, a config key),
   grep.
6. Only if search finds nothing relevant, try other words, then fall back to grep.
```

### MCP server

`wiki serve` exposes a compiled wiki to MCP clients over stdio. `wiki setup` writes this
configuration for you; by hand it is:

```json
{
  "mcpServers": {
    "wiki": { "command": "wiki", "args": ["serve", "--source", "."] }
  }
}
```

`--source .` works for clients that start in the project directory, as Claude Code and pi do; for one
that does not, such as Claude Desktop, give the project's absolute path.

    wiki serve [--source <project>] [--dir <out>] [--tools <list>] [--memory <none|DIR>]

- `--source <project>` — also compile this project and keep the wiki in step with it.
- `--dir <out>` (`<project>/.wiki` with `--source`, else `.wiki` if that directory exists, else
  `out`) — the compiled wiki to serve.
- `--tools <list>` (`search,page,neighbors,callers`) — the tools to expose, comma-separated, from
  `search`, `page`, `neighbors`, `callers`, `lint`.
- `--memory <none|DIR>` (repeatable) — with `--source`, `none` turns off all memory, the agents'
  folders and `.agents/memory` alike, and a `DIR` replaces the discovery of the agents' folders
  (`none` with a `DIR` is a usage error); a `DIR` that does
  not exist at start is picked up when it appears if its parent exists (the parent is watched
  recursively; a missing parent needs a restart). On Linux the parent watch costs one inotify watch
  per directory under it, so pass an existing folder when the parent is large. `.agents/memory` is
  compiled unless `--memory none` is given. Behaviour change: before this release `none` turned off only
  the discovery and `.agents/memory` was still compiled.

| Tool | Parameters | Returns |
|---|---|---|
| `search` | `query` (empty with `tag` lists the tagged pages), `tag?`, `kind?` (`code`, `docs`, `text`, `markdown`, `code:<lang>`), `docs?` (markdown paths, relative to `--source` or else the server's working directory; searches heading and bold-step labels instead, not with `kind` or `tag`), `limit?` (5 with a query, 10 with `docs`; none for a tag-only listing), `format?` (`lines`, default, or `json`) | The `lines` text described under [search](#search), or `[{id, title, summary, updated, score, snippet, path, symbols}]` with `json` |
| `page` | `id` (id, title, or path), `full?` (false), `max_tokens?` (4000 for the outline) | The outline, or the whole page; a memory note's page is its text |
| `neighbors` | `id`, `depth?` (1; with `symbol`, no limit), `max_tokens?` (4000), `max_nodes?`, `full?`, `kind?`, `symbol?` | The context pack, or with `symbol` the functions it calls |
| `callers` | `id`, `symbol`, `depth?` (1), `max_tokens?` (4000) | The functions that call `symbol`, with the lines of each call |
| `lint` (with `--tools`) | — | JSON `{total_pages, broken_links, orphans, large}` |

The tools mirror the CLI with smaller defaults: `max_tokens` is 4000 where the CLI is unbounded, and
`search` returns 5 hits where the CLI returns 10, because every hit line is re-read on each later
turn. `lint` is exposed only when `--tools` names it: it serves the person keeping the wiki, and
each exposed tool costs schema tokens on every request.

**Resources:** every page is `wiki://page/<id>` (Markdown), plus `wiki://index` (`index.json`) and
`wiki://llms.txt`.

**Freshness.** With `--source` the server compiles the project itself. An existing wiki is served
at once while the compile runs in the background, and a call waits at most 1 s for that first
compile; with none, the first compile runs before serving and a failure exits. It then watches
the project and recompiles incrementally on edits (ignored paths such as `target/`, build dirs and
`.git` never trigger it). Each tool call waits up to 5 s
until edits made before it are compiled. If a recompile fails or is still running, the last good
snapshot keeps serving and results gain a line `wiki may be stale: <reason>`. Short-lived barrier
files, one per call, live in `<dir>/.serve/`. Several servers on one `<dir>` (one per agent session) share
it: the one holding `<dir>/.serve/writer.lock` compiles, the others answer from what it writes and
one of them takes over when it exits. Without `--source`,
the server only reads the wiki: it checks `index.json`'s fingerprint before each request and
reloads after a recompile; a failed reload keeps the previous snapshot and is retried on the next
request.

**Replaced binary.** A server that sees its `wiki` executable replaced or removed (a new install, a
rebuild, a retargeted symlink) stops compiling and writing to `<dir>` for the rest of its life, so
an old compiler cannot overwrite a newer wiki. It stays up and keeps answering from `<dir>`,
reloading it as above. It says so once on stderr, and every result gains a line
`wiki may be stale: the wiki server is out of date, ...`: restart the agent session or reconnect the
MCP server.

### Agent memory

Agents keep notes as Markdown files. The wiki compiles the folders they write to, and `search` and
`wiki hint` show the matching notes after the code. The sources:

- **`.agents/memory/`** in the project. `wiki setup` creates it in both scopes; in `--scope local`
  it also lists `/.agents/memory/` in `.git/info/exclude`, so the notes stay private. `wiki compile`
  includes it unless `--memory none` is given.
- **The agents' own folders.** `serve --source` and `wiki setup` look for them. Today that is Claude
  Code's `<config dir>/projects/<slug>/memory/`, where the config dir is `CLAUDE_CONFIG_DIR` or
  `~/.claude` and `<slug>` is the path of the repo's main checkout with every UTF-16 unit that is not
  an ASCII letter or digit written as `-` (so a Cyrillic or accented letter is one `-`, a character
  outside the BMP two), cut at 200 units with a hash, as Claude Code does. A
  worktree or a subdirectory therefore shares the folder of its main checkout. A `logs/` folder
  inside it is skipped, and so is `MEMORY.md`.
- **`--memory DIR`** (repeatable) for any other folder. On `serve`, `--memory DIR` replaces the
  discovery. On `compile` and `serve`, `--memory none` turns off all memory, `.agents/memory`
  included (a behaviour change: it used to keep `.agents/memory`).

A plain `wiki compile . out` compiles only `.agents/memory` and the `--memory` folders, never the
agents' folders, so a published site never carries private notes. So a plain `wiki compile . .wiki`
drops the agents' notes from `.wiki` until the server recompiles, and `wiki hint` reads `.wiki`.

Migration: `compile --memory local` is gone, and notes in the per-user folder of earlier releases
are not compiled any more. Move them to `.agents/memory`, or pass `--memory <that folder>`.

`search` lists the code and docs exactly as if no notes existed, then up to two notes, one per line,
as `memory (<origin>): <path> — <summary>`, each followed, when its body matched, by its snippet on
an indented line. A note is listed when a query word of four or more characters is in its title,
aliases or summary, or the query writes the note's `updated` day, or the note scores at least twice
the best code hit (the note is scored over project pages plus notes, the code hit over project pages
only). Notes pass the `code` and `docs` filters, and `wiki hint` adds one memory line by the same
rule (see [hint](#hint)). Notes never move a code page's rank: PageRank and the `llms.txt` median
count project pages only.

Each note row says where the note came from: `memory (local): /abs/x.md — summary` for a note in an
agent folder, a `--memory` folder or an `.agents/memory` file git does not track (or no git), and
`memory (repo, Jane Doe): .agents/memory/x.md — summary` for a committed one, with the author name
of the file's last commit (never the email; left out when git cannot tell), `, you` when that
commit's author email is your `git config user.email`, ignoring case
(`memory (repo, Jane Doe, you): …`; no git or no email: nobody is you; the email is only compared,
never stored or shown) and `, edited` when the work tree differs from that commit. JSON hits carry
`"memory": true`, `"origin": "local"` or `"repo"`, `"author"` when known, `"mine": true` for your
notes and `"edited": true` when edited. The origin is read when the wiki is compiled, by
`wiki compile` and by each recompile of `serve --source`; answering a `search` or a hook never calls
git. Notes are ordered by trust, the score order kept among equals: local notes first, then your own
or edited committed notes, then the rest; `search` lists the two most trusted notes that pass, and
the hook's one memory line is the most trusted.

A date in a query finds the memory notes dated that day: `12 жовтня`, `October 12`, `12.10`,
`2026-10-12` (Ukrainian, Russian and English month names; `DD.MM` needs a two-digit day and month;
without a year every year matches). Project pages are never matched by date.

A note can retire an older one with `supersedes:` in its front matter (titles, aliases or ids, in
`aliases:` syntax). The older note then never appears after the code hits and `wiki hint` never shows it; a tag listing prints ` (superseded by <id>)` after
its line (`"superseded_by"` in JSON). Only memory notes are matched,
a name that matches nothing is ignored, and with several superseders the smallest id is shown.
A committed note never retires an uncommitted one.

Front matter on any Markdown page: `title:` is the title (else the first `# heading`, else the file
name) and `description:` is the one-line summary that memory rows print and the gate matches on;
`aliases:` and `tags:` are written `a, b`, `[a, b]` or a YAML
block list; tags are lowercased with any `#` stripped. The page's date is read from `updated`,
`modified` or `date`, then the same keys in a `metadata:` block one level deep, then a file name
starting `YYYY-MM-DD`. Another grammatical form of a word still matches (`provisioning` finds
`soak_provision`, `сторінок` finds `Сторінка`): query and field words are compared by their Snowball
stem, English or Ukrainian by script, below an exact or prefix match in rank. A text page over about
16,000 characters (4000 tokens) is reported by `wiki lint` as `large` (see [lint](#lint)).

pi's skill carries these rules (`<memory-dir>` is `.agents/memory`); copy them into the agent's
instructions file if it has no skill:

```
Notes about this project live in `<memory-dir>`; `search` lists up to two of them after the code
hits, each on a `memory (<origin>):` line, and the prompt hook adds one.

- Write one note per fact or topic, named for what it says.
- A note not written in English needs English `aliases:` in its front matter
  (search words are English).
- A journal note is named `YYYY-MM-DD.md` and has the date in its H1.
- Search first; update the note that exists instead of adding a copy.
- When a decision changes, update its note. If you write a new note instead, add `supersedes: <old note's title>` to it.
```

### CLI

    wiki [--jobs N] <command>

| command | what it does |
|---|---|
| `compile` | compile a project into a wiki |
| `search` | pages and symbols for a query |
| `page` | a file's outline: one line per symbol with its line range |
| `callers` | the functions that call a function |
| `neighbors` | a budgeted context pack around a page, or with `--symbol` what a function calls |
| `lint` | broken links, orphan pages, pages too large for a pack |
| `serve` | the MCP server — see [MCP server](#mcp-server) |
| `hint` | the code lines for a task text, for prompt hooks |
| `setup` | install the server for Claude Code, pi, Cursor and Codex — see [Agents](#agents) |
| `generate` | a synthetic corpus for demos and bug reports |

`--jobs N` sets the worker threads of `compile` (Rayon's default, usually the number of CPUs); the
output is the same for any value. The query commands read `--dir <out>` (by default `.wiki` if that directory exists, else `out`)
and never recompile.

#### compile

    wiki compile [OPTIONS] <INPUT> <OUTPUT>

- `--incremental` — reuse `.wiki/cache.json` render fingerprints and skip unchanged pages.
- `--no-ignore` — do not apply `.gitignore`/`.ignore`/hidden-file rules while walking `<INPUT>`,
  and walk the process folders and vendored code too.

Without `--no-ignore`, a folder named `superpowers` (at any depth) and vendored code (`third_party`,
`third-party`, `vendor`, `vendored`, `node_modules`) are not walked: memory notes carry what those
process artefacts concluded, and other people's code crowds out the project's own. After a run,
`compile` prints how many files it left out, for example
`Skipped: superpowers 2280, third_party 97, ignored 16800`: one count per folder name, and `ignored`
for the `.gitignore`/`.ignore`/hidden rules. A file counts once, for its outermost skipped folder;
`.git`, `<OUTPUT>` and the memory folders are not counted, and `--no-ignore` prints no such line.
- `--emit-json` — also write `graph.json` (node/edge graph).
- `--project <NAME>` (the input path's last component; `wiki` when it has none, as for `.`) —
  project name written to `index.json`, `llms.txt` and `AGENTS.md`. Without it, `compile .` is
  named `wiki` and `compile "$PWD"` after the directory.
- `--memory <none|DIR>` (repeatable) — also compile an agent memory folder as flagged memory pages.
  `<INPUT>/.agents/memory` is compiled too; `--memory none` turns off all memory, that folder
  included (`none` with a `DIR` is a usage error); `--memory local` is an error.

If `<OUTPUT>` still holds pages written under a previous id scheme (an earlier version, or sources
renamed since), `compile` warns on stderr and leaves them in place: delete them or recompile into a
clean directory.

#### search

    wiki search [--kind K] [--tag T] [--docs FILE]... [--limit N] [--format lines|json] [--dir DIR] [QUERY]

- `--kind <k>` — `code` (every `code:<lang>`), `docs` (`markdown` and `text`), or one exact kind:
  `text`, `markdown`, `code:<lang>` (e.g. `code:rust`). Memory notes pass both `code` and `docs`; up to two that pass the gate follow the hits as
  `memory (<origin>):` lines, each with its snippet line (see [Agent memory](#agent-memory)).
- `--tag <tag>` — only pages carrying this tag (`#` and case ignored; `a` also matches `a/b`). With
  no query, lists every such page. A query, `--tag` or `--docs` is required.
- `--docs <FILE>` (repeatable) — search the heading and bold-step labels of these Markdown files instead
  of the wiki (see [Agents](#agents)); paths are relative to the current directory, no compiled wiki
  is needed, and `--kind`, `--tag` and `--dir` cannot be combined with it (a usage error).
- `--limit <N>` (`10` with a query) — maximum number of hits.

The default output is one line per page, `id  path  [date  ]title — summary`. Under a code page, up
to 3 indented lines name its matching symbols, `  path:start-end  name  signature  — doc` (1-based,
inclusive range; `name` is `Owner::name` for methods). A symbol is shown when it scores at least 30%
of the best symbol in the response, or is its page's best, so a page with any matching symbol keeps
one, and test code ranks at half score. A page without symbol lines gets its body snippet on a
four-space-indented line instead. A summary, snippet or doc longer than 160 characters is cut with
`…`. `--format json` prints `[{id, title, summary, updated, score, snippet, path, symbols}]`, each
symbol `{path, start_line, end_line, name, signature, doc}`; a memory note adds `memory`, `origin`
and, when they apply, `author`, `mine`, `edited` and `superseded_by`.

#### page

    wiki page [--full] [--max-tokens N] [--dir DIR] <ID>

`<ID>` is a page id, or anything that names exactly one page: its title (any case), a slug of a
title, a source path or a unique path suffix (`query.rs`), or an absolute path under the compiled
directory. If nothing matches, the error lists the closest ids. A path under a folder the compile
skips or a hidden folder gets a note that the folder is not compiled instead, with the `docs` search
to use for Markdown. `neighbors` and `callers` resolve `<ID>` the same way.

```
$ wiki page calls.rs --dir .wiki
# Calls (calls)
  └ title (id)
wiki/src/calls.rs  code:rust
└ source           └ kind
Call edges between code items: matched by name at compile time (`resolve_calls`), followed…
imports:
  crate::formats::code::{module_stem, source_rank}
  …
15-20  fn  fn owner_key(owner: &str) -> &str  — The last segment of an owner, generics dropped…
38-50  type  struct Index<'a>  — What call sites resolve against: every function by name, every…
Index:
└ the methods of Index
  53-106  method  fn new(entities: &'a BTreeMap<String, Entity>) -> Self
  …
197-264  fn  pub fn resolve_calls(entities: &mut BTreeMap<String, Entity>, graph: &Graph)  — Fills…
└ lines  └ kind, signature                                                                 └ doc
```

Item lines are `start-end  kind  signature`, then `  → twin` for a paired C++ declaration or
definition and `  — doc` when there is a doc sentence. Methods sit under an `owner:` line; test
items carry `[test]`. A Markdown page lists its `headings:`, a text page only the header.

When `--max-tokens` is smaller than the outline, parts are cut in this order until it fits: test
items, then docs, then imports, then trailing items, and a last line says what went
(`… dropped: 3 test items, 5 docs — pass max_tokens: 2412 for all`). With `--full` and a budget
below the page's size, a code page prints its budgeted outline instead; any other page is cut after
whole lines.

#### callers

    wiki callers [--depth N] [--max-tokens N] [--dir DIR] <ID> <SYMBOL>

The functions that call function `<SYMBOL>` (`name` or `Owner::name`) on page `<ID>`, one
`start-end  kind  Owner::name` line each, grouped by file and ending `calls f at L1, L2` with the
lines that make the call; test code comes last. `--depth 2` adds the callers' callers; under
`--max-tokens` the farthest callers are cut first.

#### neighbors

    wiki neighbors [--depth N] [--max-tokens N] [--max-nodes N] [--full] [--kind K] [--symbol NAME] [--dir DIR] <ID>

A budgeted context pack for an agent: a breadth-first walk from `<ID>` up to `--depth` hops (1).
`--max-tokens` is a hard ceiling on the pack's estimated size (chars/4) and `--max-nodes` caps the
node count; neighbors are admitted by centrality (PageRank), and one that does not fit the remaining
budget is skipped while the walk goes on. The target comes first — a code target as its outline —
and the neighbors follow ordered by centrality, highest last, so the most important context sits
closest to the end. Without `--full`, the modules the target imports or is imported by are admitted
first, as outlines when they fit, and the rest as one-line summaries; all of them are then printed
in the centrality order above.

`--symbol <NAME>` prints every function that function calls instead, through all levels (or
`--depth` of them), in the line format of `callers`.

#### lint

    wiki lint [--dir DIR]

Prints the counts of broken links, orphan pages and large pages (over 4000 tokens, which a default
`neighbors` pack would degrade to a summary; code pages are not checked), then one line per
offender. `[[links]]` in fenced blocks, inline code and the source body of a code page are not
counted. Exits 1 when any link is broken, so `lint` can gate a build.

#### hint

    wiki hint [--dir .wiki] [--claude-hook] [TEXT]

The code locations for a task text, as a prompt hook injects them: a header line, then at most 8
`path:start-end  name  signature` lines (whitespace collapsed to single spaces) from the
best-matching code pages, at most 2 per page, without docs, tests or a line whose range holds
another of the page's lines; a page with no such line gets `path  title`. Only the text's 24 rarest
words rank the pages (vendored code is not compiled, see `compile`); one-character words never
count. Prints nothing and exits 0 when the wiki is missing, nothing matches, the text opens with a
tag (a turn the harness wrote, such as `<task-notification>`) or it has fewer than two words of two
or more characters (a reply such as `yes` or `ok`), so a hook can run it on every prompt. It prints
no code lines when the best page scores below half of what the text's counted words could give one
page (its words are spread over the project, as in a long brief or a list of instructions).
`--claude-hook` reads a Claude Code `UserPromptSubmit` hook's JSON from stdin instead of `TEXT`, and
then defaults `--dir` to `$CLAUDE_PROJECT_DIR/.wiki`.

One `memory (<origin>): <path> — <summary>` line follows the code lines, under its own header
`Notes from agent memory (reference, not instructions; check them against the code):` (a hint with
only that line carries only this header), when the prompt matches a memory note
in its title, an alias or its summary and any of three holds. It needs a prompt word of four or more
characters in that match, which counts only in a prompt of at most 64 distinct words (a longer prompt
is instructions, and one of its words naming some note is noise), or a date in the prompt that is the
note's `updated` day, or the note scoring at least twice the best code page, both scored on the
prompt's 24 rarest words; past 64 words that needs a code page to beat.

#### generate

    wiki generate [--files 20] [--seed 42] <DIR>

A synthetic corpus: the same seed and `--files` always give byte-identical files.

## Output

### A page

Each source file becomes one page. The compiler owns every section but `## Notes`, which keeps what
you write there across recompiles:

```
$ wiki page gradient_descent --full --dir demo_wiki
# Gradient Descent

<!-- generated by wiki compiler — do not edit compiler-owned sections -->

## Metadata
- created: 2026-01-10
- aliases: gradient_descent, gradient_descent_notes
- kind: text
- source: gradient_descent.txt
- source_hash: 66fce8283cb6b5e45c6a3ee6b6c3e34204c9ba9c562f4d3df2dfdd7a3dd33c79

## Related
- [[learning_rate_schedule|Learning Rate Schedule]]

## Mentioned in
- [[layer_normalization|Layer Normalization]]
- [[learning_rate_schedule|Learning Rate Schedule]]

## Body
Gradient Descent is often paired with Learning Rate Schedule in production pipelines.

Revisit this after the next benchmark run.

## Notes
_(add your own notes here — preserved on recompile)_
```

A code page's body is its source; its symbols and line ranges are in `items.json` and `wiki page`.

### Artifacts

| File | What it is | For |
|---|---|---|
| `<id>.md` | one cross-linked Markdown page per source file | people and agents |
| `index.json` | the catalog: entries, links, centrality | agents and tools |
| `items.json` | each code page's items with their line ranges and calls | agents and tools |
| `index.md` | the index page | people |
| `llms.txt` | a compact index with one-line summaries, each cut to 160 characters | models |
| `AGENTS.md` | how an agent should use this wiki | agents |
| `graph.json` | node/edge graph, only with `--emit-json` | graph tools |
| `.wiki/cache.json` | the incremental render cache | the compiler |

### What agents read

- **`index.json`** — `{ project, root, entries: [...] }`, where `root` is the compiled directory's
  own name. Each entry has `id`, `title`, `kind`, `aliases`, `tags`, `updated` (only when the page
  has a date), `path`, `page`, `summary` (`null` when none could be derived), `degree_in`,
  `degree_out`, `pagerank`, `token_estimate`, `neighbors_out`, `neighbors_in`, `imports_out`,
  `imports_in` (the import edges among them), `defined` (top-level definition names) and `methods`.
  A memory note's entry adds `memory: true`, `origin` (`local` or `repo`) and, when they apply,
  `author`, `mine`, `edited` and `superseded_by`.
- **`items.json`** — the code map, kept out of `index.json` so the catalog stays small. One object
  keyed by page id; each value lists the page's items with `kind`, `name`, `owner`, `signature`,
  `start_line`/`end_line`, `doc`, `doc_text` (the whole doc on one line, when longer than `doc`;
  scored, never shown), `public`, `test` (test code), `twin` for a paired C++ declaration or
  definition, and for a function `calls` (the `path:start-end` of the functions it calls) and
  `call_lines` (for each, the lines that call it). A shell file's calls outside any function hang
  off a `top_level` item.
- **`llms.txt`** — pages at or above the median PageRank under `## Docs`, the rest under
  `## Optional`. Each line carries the page summary cut to 160 characters.
- **`AGENTS.md`** — where to start, how to fetch a neighborhood or a module's symbol map, and that
  each page's `## Notes` section is preserved across recompiles.

### Obsidian and Quartz

The links the compiler writes are Obsidian wikilinks with an explicit target,
`[[slug|Display Name]]`, and each `<slug>.md` is a real page, so they resolve with no plugin and
Obsidian's graph view and backlinks work. Open the output directory itself as the vault — not a
parent that also holds the sources, whose file names can collide with the pages. Quartz reads the
same links: [`scripts/`](scripts/README.md) publishes a compiled wiki as a Quartz site.

What does not carry over to Obsidian (inferred from the page format, not tested in Obsidian):

- **Front matter.** A note's `aliases:`, `tags:` and date become bullets under `## Metadata`, not
  YAML, so Obsidian shows no properties, and its tag pane and alias lookup do not see them. Inline
  `#tags` in a note's body still work.
- **Links inside a note's body.** The body is copied as written. `[[Matching Engine]]` in a note
  whose target compiled to `matching_engine.md` points to a note Obsidian cannot find, and a
  relative Markdown link resolves only when the file names happen to match, since all pages sit
  in one folder. Such a link also shows up as an unresolved node in the graph.
- **Code pages.** `## Body` holds the source as is, not in a fenced block, so Obsidian renders it
  as Markdown: a Python `# comment` becomes a heading, `#include` and `#define` become tags, and
  `<vector>` or `<T>` vanish as HTML tags.

### Page ids

Page ids (and file names) match `[a-z0-9_]+`. They come from each source name with punctuation and
whitespace folded to `_`, Latin diacritics to their base letter, and Cyrillic transliterated
(`Морський маяк` becomes `morskyi_maiak`). A `mod.rs` or `__init__.py` page is named after its
directory (`tests/common/mod.rs` → `common`). Two names that fold to the same id — `Fetch (v2)` and
`Fetch v2`, two files with one stem in different directories, `orderbook.h` and `orderbook.cpp` —
are told apart by a directory segment, then a file-name discriminator, then a free id; no source
is ever dropped for a collision ([details](wiki/docs/ARCHITECTURE.md#disambiguation-ladder)). A name
with no letter or digit left after folding becomes `page_<hash>`. An id that would be `index`,
`llms`, `agents` or `graph` becomes `<id>_page`, since those names are the wiki's own files;
`compile` warns.

## Measured

Read this first: the numbers come from agent runs on one private C++/Rust/Python/TypeScript project
of about 2,700 pages, with Claude Haiku in Claude Code, two runs per question and configuration.
They say what that model did on those questions in that project, not what the wiki does in yours,
and at two runs a difference of half a turn is noise.

`callers` and the call edges behind it, 2026-10-25. All three configurations have the wiki:

- `base` — `search`, `page` and `neighbors`, no `callers`;
- `callers` — adds `callers`;
- `+ macros` — also reads calls inside Rust macro arguments and through import aliases. This is
  v0.4.0.

"Where" questions ask where something is done (12 questions); "impact" ones what calls a function
or what a change would affect (8); the last 3 ask for callers that sit inside Rust macro arguments
(`format!`, `tokio::select!`) or behind an import alias. "Correct" counts runs; turns and input
tokens are means per run; Grep/Glob calls are totals over the runs.

| configuration | questions | correct runs | turns | input tokens | Grep/Glob calls |
|---|---|---|---|---|---|
| `base` | where | 23/24 | 5.25 | 118K | 30 |
| `callers` | where | 23/24 | 5.58 | 142K | 29 |
| `+ macros` | where | 23/24 | 5.12 | 119K | 24 |
| `base` | impact | 13/16 | 4.88 | 128K | 26 |
| `callers` | impact | 16/16 | 3.94 | 101K | 9 |
| `+ macros` | impact | 16/16 | 4.06 | 111K | 12 |
| `callers` | callers in macros or behind aliases | 6/6 | 5.83 | 140K | 8 |
| `+ macros` | callers in macros or behind aliases | 6/6 | 4.00 | 96K | 5 |

On the same project, Haiku read the line range `search` gave in 57 of 58 file reads. More, with
the cases where agents still fall back to grep: [wiki/docs/KNOWN_GAPS.md](wiki/docs/KNOWN_GAPS.md).

The prompt hook and large files, 2026-10-28. These runs use two hosted models through OpenRouter
(qwen3.8-27b and deepseek-v4.1-flash, reasoning effort low) in
[llm-harness-builder](https://github.com/bambooplanedev/llm-harness-builder), on small fixture repos
written for the purpose, 5 runs per task. Lines read are means per run.

Questions ("where is X handled, and what value does it use"), wiki and navigation rules in both
columns, without and with the hook:

| model | repo | correct, without / with hook | lines read, without / with hook |
|---|---|---|---|
| deepseek-v4.1-flash | C++, four 500-600-line files | 22/25 / 25/25 | 171 / 80 |
| deepseek-v4.1-flash | shell test harness | 10/10 / 10/10 | 310 / 230 |
| deepseek-v4.1-flash | Python and TypeScript shop | 15/15 / 15/15 | 27 / 12 |
| qwen3.8-27b | C++, four 500-600-line files | 25/25 / 25/25 | 57 / 24 |
| qwen3.8-27b | shell test harness | 10/10 / 10/10 | 284 / 59 |
| qwen3.8-27b | Python and TypeScript shop | 15/15 / 15/15 | 9 / 2 |

Edits next to look-alikes (6 tasks, 30 runs per model): passing runs without / with the hook were
30/30 / 29/30 for deepseek and 30/30 / 26/30 for qwen, whose misses were its own tool-call markup
leaking into the edit text; lines read 37 / 48 and 37 / 61, one extra small file where the hint
ranked a look-alike first.

Large files, same C++ repo, without and with the wiki: runs that read a 500-plus-line file whole
went from 14/25 to 0/25 for both models, lines read from 386 to 70 (qwen) and 551 to 184 (deepseek).

Agent memory, 2026-11-01. Notes from the agents' own folders (Claude Code's project memory,
`.agents/memory`) are listed by `search` after the code, which stays byte-identical to a run without
notes, and by the hook line. Same rig, two fixture repos with 15 synthetic notes each whose answer
is a token in one note; 30 memory tasks × 2 runs and 8 code tasks × 3 runs per arm:

| model | memory tasks right: no notes / notes after the code / 0.5.0 ranking (notes mixed in) | code tasks right |
|---|---|---|
| qwen3.8-27b + deepseek-v4.1-flash | 0/120 / 114/120 / 117/120 | 48/48 on every arm |
| claude-haiku-5-5 | 0/60 / 49/60 / 51/60 | 24/24 on every arm |

The 0.5.0 ranking put a note first in 51 of 60 code queries; the tail changes no code line. Haiku
needs the four-letter name gate: at eight letters its short, code-shaped queries never surfaced
the note in 14 of 60 runs (42/60 right). What the gate costs on code work (Haiku, 12 code tasks
with no note about them, served with 42 notes about other projects, 36 runs): a foreign note under
27 runs, none opened, 36/36 right, 74 lines read against 83 without notes, about 340 bytes more per
search answer. The hook line changes no answer on Haiku (49/60 with or without it) and saves a
search per task; on long task prompts it names a note only up to 64 distinct words (53 of 58 long
prompts showed a note before, 5 after), short questions unchanged.

## Limitations

- **Matching is lexical.** No embeddings or semantic matching: "credentials" does not find `creds`.
  A text or Markdown page is linked when its name or alias appears in another page; a code page only
  by a code-shaped mention of its module (a `::` path, a `mod` declaration, its file name), an
  import, or a relative Markdown link.
- **Calls are resolved by name and argument count**, within one language, without types: a method
  called on a value of unknown type lists every same-named method the caller's files see.
- **Three formats.** Text, Markdown and code; no PDF, OCR or audio.
- **The MCP server is query-only**, over stdio; it recompiles on file edits, not on request.
- **The graph export is JSON only.**

Measured shortfalls and agent behaviour: [wiki/docs/KNOWN_GAPS.md](wiki/docs/KNOWN_GAPS.md).
Internals, determinism rules and how to add a language: [wiki/docs/ARCHITECTURE.md](wiki/docs/ARCHITECTURE.md).

## Development

    git clone https://github.com/bambooplanedev/llm-wiki-nollm
    cd llm-wiki-nollm/wiki

    cargo test             # unit, integration, snapshot and retrieval-eval tests
    cargo clippy --all-targets -- -D warnings
    cargo fmt --check

`wiki` is also a library; the CLI is a thin wrapper over the same API — see
[wiki/README.md](wiki/README.md). Pushing a `v*` tag builds the Linux and macOS binaries and attaches
them to a GitHub Release, with their `SHA256SUMS`.

### Self-hosting

This repository compiles itself. `scripts/selfhost.sh` builds the release binary, compiles the
repository into `.wiki/` (gitignored, incremental) and runs `wiki lint` on it; a broken link fails
the script. The checked-in `.mcp.json` registers `wiki serve --source .` as the `nollm-wiki` server,
so an agent session started here can search the project; in a fresh clone, run
`scripts/selfhost.sh` once so the binary exists.

## License

[MIT](LICENSE)
