# Usage Guide

`llm-tokei` reads local coding-agent session data and prints aggregated usage.
It does not call provider APIs for your session history.

## Basic Shape

```sh
llm-tokei [OPTIONS]
llm-tokei graph [OPTIONS]
llm-tokei dump [OPTIONS] [FILES]...
```

The default report scans all discovered sources, groups by `source,model`, sorts
by `total` descending, and prints a table with cost columns.

```sh
llm-tokei
```

## Periods

Use period shortcuts for common windows.

| Flag | Meaning |
| --- | --- |
| `--24h` or `--period 24h` | Rolling last 24 hours |
| `--7d` or `--period 7d` | Rolling last 7 days |
| `--1m` or `--period 1m` | Rolling last 30 days |
| `--today` or `--period today` | Local midnight today through now |
| `--week` or `--period week` | Start of this local week through now |
| `--month` or `--period month` | Start of this local month through now |

Examples:

```sh
llm-tokei --24h
llm-tokei --week --group-by date,source
llm-tokei --period 1m --sort cost --limit 20
```

`--since` and `--until` provide explicit filters. They accept RFC3339 datetimes,
`YYYY-MM-DD`, and relative expressions such as `24h`, `7d`, `2w`, and `1mo`.
Date-only values use the local timezone, and a date-only `--until` includes that
complete calendar day.

```sh
llm-tokei --since 2026-05-01 --until 2026-05-12
llm-tokei --since 12h --model 'gpt-*'
```

If both `--period` and `--since` are supplied, `--since` wins.

## Activity Graph

`graph` visualizes hourly or daily activity across the selected sources and filters.
Without an explicit period it shows the trailing 365 calendar days, ending
today in the local timezone.

```sh
llm-tokei graph
llm-tokei graph --24h
llm-tokei graph --7d
llm-tokei graph --since 2026-01-01 --until 2026-06-30
```

The default `auto` layout depends on the requested time span:

- Less than 30 hours: an hourly bar plot with local-time labels.
- At least 30 hours and up to 30 dates: a daily bar plot with date labels.
- More than 30 dates: a Sunday-aligned calendar heatmap with month and weekday labels.

Exactly `--24h` uses hourly resolution; exactly 30 hours stays daily. Date-only
bounds cover complete local days, so ordinary, spring-forward, and fall-back
days render 24, 23, and 25 hourly buckets respectively.

Override the layout when needed:

```sh
# Plot keeps automatic hourly/daily resolution while forcing the plot layout.
llm-tokei graph --chart plot --month

# Heatmap forces daily resolution, even for a sub-30-hour range.
llm-tokei graph --chart heatmap --24h
```

Activity is measured in total tokens by default. `--unit bytes` measures
recorded input plus output bytes, while `--unit cost` uses the selected
`--cost actual|mixed|official` pricing mode.

```sh
llm-tokei graph --unit bytes --month
llm-tokei graph --unit cost --cost official
```

Heatmap and bar colors use quantiles of the nonzero buckets in the requested
range, so the four levels remain useful when usage has large spikes. Every
layout ends with total activity, active bucket count, best bucket, and longest
streak in hours or days.

Terminal output is the default (`--format table`, with `terminal` accepted as
an alias). `--width <N>` controls plot spacing without removing any buckets.
`--no-color` keeps the graph readable with
distinct Unicode intensity glyphs. Graph output currently supports terminal
and SVG; `--format json` is rejected before scanning session files.

Use `--format svg` for a native standalone chart with accessible labels and
per-hour or per-day SVG tooltips:

```sh
llm-tokei graph --format svg > activity.svg
llm-tokei graph --7d --format svg > recent-activity.svg
```

SVG output automatically follows the viewer's light or dark preference. Use
`--svg-theme dark` (the default) or `--svg-theme light` to choose the SVG's
default palette.

## Grouping

Use `--group-by` with a comma-separated list.

Available dimensions:

| Dimension | Description |
| --- | --- |
| `source` | Agent/source name |
| `model` | Canonicalized model name |
| `provider` | Provider ID when known |
| `project` | Project name or cwd basename |
| `date` | Date bucket label |
| `session` | Session ID, shortened in tables |

Examples:

```sh
llm-tokei --group-by project,source,model
llm-tokei --group-by session,source,model --sort cost --limit 10
llm-tokei --month --group-by date,source --date-bucket day
llm-tokei --group-by date,project --date-bucket week
```

`--date-bucket` supports `day`, `week`, and `month` when grouping by `date`.

## Filters

Filters reduce the records included in the report.

```sh
llm-tokei --model 'claude-*'
llm-tokei --provider openai
llm-tokei --cwd '*/work/project-*'
llm-tokei --source codex,claude
```

Glob filters are matched against the relevant field. Model filters also check
canonicalized aliases where pricing metadata knows them.

## Output

### Table

Table output is the default.

```sh
llm-tokei --format table
```

Interactive terminal reports end with one of 100 rotating tips. Tips change
every hour, mark command fragments with backticks, and skip suggestions already
covered by the current effective CLI options. If no suggestion applies, no tip
is added. Use `--no-tips` to disable the footer. Tips are never added to
redirected table output, JSON, or SVG.

Useful table flags:

| Flag | Description |
| --- | --- |
| `-h`, `--human` | Compact usage numbers, for example `5.0M` |
| `--bytes` | Show `input` and `output` in bytes instead of tokens |
| `--split-input` | Show uncached input as `input_u` |
| `--avg call\|round\|session` | Show per-unit averages for usage columns |
| `--table-width <N>` | Fit output to a fixed width |
| `--no-fit` | Disable automatic table fitting |
| `--no-color` | Disable ANSI colors |
| `--no-cost` | Hide cost columns |
| `--cost actual\|mixed\|official` | Select cost mode (default: `mixed`) |
| `--cost-per <dimension>` | Add top cost split columns, for example by provider |

By default, table numbers are exact and comma-separated. With `--human`, usage
columns use `K`, `M`, `B`, and `T` units and keep one decimal when a unit is
shown, such as `5.0M`. Count columns (`turns`, `rounds`, `sessions`) and cost
columns stay exact.

When color is enabled, human-readable values whose unit is smaller than the
largest unit in that column are gray. This makes scale differences easier to
scan without changing the number.

When a table has to fit a target width, lower-priority statistic columns are
hidden first and a `hidden columns:` footer is printed. Grouping columns remain
visible and long values are truncated if needed.

### JSON

JSON output is intended for scripts.

```sh
llm-tokei --format json --group-by source,model,project
```

JSON keeps raw numeric values even when `--human` would affect table output.
With `--bytes`, only the JSON `input` and `output` fields switch to bytes.

### SVG

For normal reports, SVG output renders the table view as a standalone
terminal-style image.

```sh
llm-tokei --format svg --group-by source,model > usage.svg
```

SVG uses the same table columns and table-specific flags as `--format table`.
It does not auto-fit to the terminal width, but `--table-width <N>` can be used
to create a narrower image. `llm-tokei graph --format svg` instead produces a
native plot or heatmap as described in [Activity Graph](#activity-graph). The
automatic light/dark behavior and `--svg-theme` default palette apply to both kinds of
SVG output.

## Sorting And Limits

```sh
llm-tokei --sort total
llm-tokei --sort input --asc
llm-tokei --sort cost --limit 10
```

Sort keys: `total`, `input`, `output`, `cost`, `date`, and `turns`.

## Token Semantics

Table and JSON rows include these fields:

| Field | Meaning |
| --- | --- |
| `input` | Displayed prompt total: uncached input plus cache reads and writes |
| `output` | Assistant output tokens |
| `reasoning` | Reasoning output tokens when available |
| `cache_r` / `cache_read` | Cached-read prompt tokens |
| `cache_w` / `cache_write` | Cache-write prompt tokens |
| `total` | `input + output + reasoning`, token-based |
| `turns` | API/model turns |
| `rounds` | User-initiated prompt rounds |
| `sessions` | Distinct sessions in the group |

`--split-input` changes table `input` to uncached input only and labels it
`input_u`.

`--bytes` changes only `input` and `output` to bytes. `reasoning`, cache fields,
`total`, and pricing remain token-based.

Some sources provide exact token counts. Some sources require estimates because
the local session files do not persist full token accounting. Estimated values
are marked with `~` in table output and `*_estimated` booleans in JSON output.

## Config

`llm-tokei` loads defaults from `~/.config/llm-tokei.toml` when present, or from
`$XDG_CONFIG_HOME/llm-tokei.toml` if `XDG_CONFIG_HOME` is set.
CLI flags always override config values.

```toml
[output]
format = "table"
cost = "mixed"

[grouping]
group-by = ["source", "model"]

[table]
human = true

[period]
period = "month"

[sources]
source = ["codex", "opencode"]
```

Use a custom config file or disable config loading:

```sh
llm-tokei --config ./llm-tokei.toml
llm-tokei --no-config
```

Save structured defaults from CLI args:

```sh
llm-tokei config args "--cost official --group-by provider --human"
llm-tokei config list
llm-tokei config args --reset
llm-tokei --cost actual --group-by source,model --save-default
llm-tokei --no-default
```

`config args "..."` and `--save-default` both parse normal main CLI flags and
write the corresponding structured TOML keys. `--save-default` then continues
to run the command normally. `--no-default` skips applying saved config defaults
for one run.

Config keys mirror the main CLI flags using kebab-case names inside sections, for
example `grouping.date-bucket`, `table.table-width`, `output.cost-per`,
`sources.codex-dir`, `sources.copilot-cli-dir`, `sources.pi-agent-dir`, and
`sources.dsh-dir`.
Subcommand-specific options are not read from config.

## Pricing

The binary embeds a compressed price-history and model-family snapshot plus
local policy metadata under `data/`. Bundled and updated model data use the same
manifest validation, CSV parsing, route mapping, and timestamp lookup, so cost
reporting works offline without any setup.

One cost column is reported:

| Column | Meaning |
| --- | --- |
| `cost($)` / `cost` | USD in the selected cost mode |

Cost modes:

| Mode | Meaning |
| --- | --- |
| `actual` | Provider-specific pricing with multipliers; included providers/models cost `$0` |
| `mixed` | Default. Provider-specific pricing, but included providers/models fall back to official model rates |
| `official` | Official model-provider rates only, ignoring the source provider |

Examples:

```sh
llm-tokei --cost actual
llm-tokei --cost mixed --cost-per provider
llm-tokei --cost official --group-by model --sort cost
```

`--cost-per <dimension>` appends the top 3 cost contributors for a dimension as
extra table columns. Table headers use the split value directly and truncate it
to 10 characters. JSON output includes a `cost_per` object with full keys.

Run `llm-tokei update` to replace the bundled snapshot with the latest published
price history and model-family mapping:

```sh
llm-tokei update
```

Normal reports never access the network. When the cache is present, each usage
record uses cached data only when its manifest `generated_at` is newer than the
bundled manifest. This prevents an older cache from overriding fresher data
shipped with a new llm-tokei release. If both manifests reference identical
price and family artifacts, the bundled copy is preferred.

Each usage record uses the latest provider-route price recorded at or before its
timestamp. Usage before the first recorded price uses the first known price,
because the catalog may have learned about a route after it became available. A
deletion does not create a zero-cost gap: the last known price continues until a
later upsert replaces it.

Price-history timestamps indicate when the source catalog recorded a change and
may differ from a provider's actual effective date. Both the embedded snapshot
and update command verify the immutable CSV artifacts against their manifest
sizes and SHA-256 checksums before parsing them.

Runtime pricing overrides are complete JSON pricing files. Explicit
`--pricing` replaces both the historical cache and bundled pricing:

```sh
llm-tokei --pricing ./pricing.json
```

Example override:

```json
{
  "providers": {
    "github-copilot": {
      "included": true,
      "models": {
        "claude-opus-4.7": { "multiplier": 10.0, "included": false }
      }
    }
  },
  "models": {
    "gpt-5": { "provider": "openai", "aliases": ["openai/gpt-5"] }
  },
  "prices": [
    {
      "provider": "openai",
      "model": "gpt-5",
      "input": 1.25,
      "output": 10.0,
      "cache_read": 0.125,
      "cache_write": null
    }
  ]
}
```

Pricing lookup checks the exact historical `(provider, model)` route first.
The family mapping then supplies canonical aliases for grouping and official
provider lookup. Multipliers and included status can be set per provider and
overridden per model.

## Sources

### Codex CLI

Default root:

```text
$CODEX_HOME/sessions
~/.codex/sessions
```

Override:

```sh
llm-tokei --source codex --codex-dir /path/to/sessions
```

Codex sessions are JSONL rollout files. Cumulative token snapshots are converted
to per-turn deltas. Response item text is used for byte-mode input/output.

### OpenCode

Default database:

```text
$OPENCODE_DATA_DIR/opencode.db
$XDG_DATA_HOME/opencode/opencode.db
~/.local/share/opencode/opencode.db
```

Override:

```sh
llm-tokei --source opencode --opencode-db /path/to/opencode.db
```

The database is opened read-only.

### Claude Code

Default root:

```text
$CLAUDE_HOME/projects
~/.claude/projects
```

Override:

```sh
llm-tokei --source claude --claude-dir /path/to/projects
```

Claude usage fields map raw `input_tokens` to uncached input,
`cache_read_input_tokens` to cache reads, and cache creation fields to cache
writes.

### GitHub Copilot Chat

Default discovery scans VS Code, Code Insiders, VSCodium, and Cursor
`workspaceStorage` directories.

Override or add roots:

```sh
llm-tokei --source copilot --copilot-dir /path/to/workspaceStorage
```

Copilot Chat does not always persist exact input/output token counts in chat
session files. `llm-tokei` estimates input/output from rendered text length and
uses exact reasoning tokens when `thinking.tokens` is present. Shutdown metrics
from transcript files are preferred when available.

### GitHub Copilot CLI

Default root:

```text
~/.copilot/session-state
```

Override:

```sh
llm-tokei --source copilot-cli --copilot-cli-dir /path/to/session-state
```

Shutdown metrics are used when present. Otherwise usage is estimated from event
content.

### Pi Agent

Default root:

```text
~/.pi/agent/sessions
```

Override:

```sh
llm-tokei --source pi-agent --pi-agent-dir /path/to/sessions
```

Pi Agent sessions are JSONL files. Assistant message `usage` fields provide
exact token counts, including cache reads/writes and source-reported total
tokens. Message content is used for byte-mode input/output.

`pi-web-access` `summary-review` tool results are also counted when present.
The plugin stores the summary model and output token estimate but not the
provider `usage` object, so these records are reconstructed from the stored
curated search results and marked as estimated.

For example, if the plugin uses `deepseek/deepseek-v4-flash` to polish search
results, those calls appear as estimated `deepseek-v4-flash` Pi Agent rows:

```sh
llm-tokei --source pi-agent --provider deepseek --group-by model
```

### DeepSeek Harness

Default root:

```text
$DSH_HOME/sessions or ~/.dsh/sessions
```

Override:

```sh
llm-tokei --source dsh --dsh-dir /path/to/sessions
```

DeepSeek Harness stores one session log below each project/session directory.
The default `session.jsonl.zstd` encoding and diagnostic plaintext
`session.jsonl` encoding are both supported.

DSH emits an early usage chunk and then repeats the committed sample on the
assistant message. `llm-tokei` follows DSH's own token-meter behavior: the last
sample for a `(turn, step)` replaces the earlier sample, while a usage chunk
without a committed assistant message remains countable. DSH reports uncached
input separately from cache traffic. Its output count includes reasoning, so
`llm-tokei` separates `reasoningTokens` from visible completion without adding
it to the total twice.

## Cache

By default, parsed records are cached under your OS cache directory as
`llm-tokei.db`. The cache is keyed by source file path, modification time, and
size. When a source file changes, `llm-tokei` reconciles its records by their
source-event identities: unchanged events keep their existing cache rows, new
events are inserted, changed events are updated, and events absent from a
complete parse are removed. The reconciliation is atomic.

A JSONL file that is still being written can still contribute its valid records
to the current report, but is not saved back to the cache until it can be read
completely without changing during parsing.

For OpenCode, the cache key also includes the active SQLite write-ahead log
(`opencode.db-wal`), so recent commits are not missed before SQLite checkpoints
them into the main database.

Use `--no-cache` to force a full re-parse:

```sh
llm-tokei --no-cache
```

To remove obsolete historical entries from older cache versions and compact
reusable free pages in the database:

```sh
llm-tokei cache prune
```

This affects only derived cache data, never the original session files.

Verbose mode prints cache stats:

```sh
llm-tokei -v
```

## Dumping Sessions

The `dump` subcommand emits replayable user-side JSONL message streams.

```sh
llm-tokei dump --codex ~/.codex/sessions/2026/05/12/rollout-example.jsonl
llm-tokei dump --codex --out ./dumped-codex
llm-tokei dump --copilot --out ./dumped-copilot
```

Use exactly one dump source flag: `--codex` or `--copilot`.

Without `--out`, output is written to stdout with comment headers when multiple
files are dumped. With `--out`, one `<session-id>.jsonl` file is written per
session.

## Maintenance Notes

Bundled model data is a gzip-compressed copy of the artifacts produced by the
Pages data pipeline:

```sh
cp site/public/models/manifest.json data/model-data/manifest.json
gzip -n -9 -c site/public/models/changes.csv > data/model-data/changes.csv.gz
gzip -n -9 -c site/public/models/families.csv > data/model-data/families.csv.gz
```

Generate the README showcase SVG from live CLI output:

```sh
cargo run --example gen-showcase -- --args "--24h --group-by source,model" --out docs/assets/showcase.svg
cargo run --example gen-showcase -- --args "--cost-per provider --cost official --month -h" --out docs/assets/showcase.svg
```

Bundled pricing inputs:

| File | Purpose |
| --- | --- |
| `data/models.json` | Canonical model names, official providers, aliases |
| `data/providers.json` | Provider/model included and multiplier metadata |
| `data/model-data/manifest.json` | Provenance and checksums for bundled CSV artifacts |
| `data/model-data/changes.csv.gz` | Bundled timestamped price changes |
| `data/model-data/families.csv.gz` | Bundled provider routes and canonical names |

A zero-price route is treated as included: `actual` cost is zero and `mixed`
cost falls back to the canonical model's official provider rate.
