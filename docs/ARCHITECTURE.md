# Architecture

This document describes how `google-sheets-mcp-and-skill` is structured and why. It is
the public-facing version of the project's design contract. If you are contributing
code, read this alongside [`CONTRIBUTING.md`](../CONTRIBUTING.md).

## Thesis

An AI understands an existing, heavily-formatted spreadsheet primarily by **reading**
it: its formulas, its cell formatting, and especially its **conditional-format rules**.
Screenshots are lossy; reading the actual formulas + formats + rules is lossless and is
the highest-signal way to build a correct mental model of a live sheet. So the design
bias is **read-side richness**, delivered token-efficiently, with full CRUD symmetry
(anything writable is readable back).

Five invariants follow from that thesis and are not negotiable:

1. **Shared pure core, two thin adapters.** One implementation of every behavior; the
   MCP server and the CLI map 1:1 to it; behavior is identical from either entrypoint.
2. **Read-side richness.** Values **and** formulas side by side; both
   `userEnteredFormat` (intent) and `effectiveFormat` (what renders, including
   conditional results); conditional-format rules serialized to terse, round-trippable
   lines.
3. **Token efficiency.** Never `includeGridData`. Always `ranges[]` + a tight `fields`
   mask. Offer compact reads. Flatten Google's nested objects.
4. **Full CRUD symmetry.** If you can write it, you can read it back.
5. **Safe write defaults.** `USER_ENTERED` by default; every formatting/properties write
   auto-builds its `fields` mask from the payload.

---

## Layers

```
                ┌──────────────────────┐      ┌──────────────────────┐
                │   MCP adapter        │      │   CLI adapter        │
                │   mcp_server.py      │      │   cli.py             │
                │   (FastMCP, stdio)   │      │   (argparse)         │
                │   + models.py        │      │                      │
                └──────────┬───────────┘      └──────────┬───────────┘
                           │  one-line tool/subcommand bodies
                           │  (resolve services → call core → return)
                           ▼                             ▼
                ┌─────────────────────────────────────────────────────┐
                │                  PURE CORE  (gsheets.core)           │
                │  values · reads · formatting · rules · structure ·   │
                │  charts · batch · data_ops · dimensions · comments · │
                │  export · multiread                                  │
                │    +   helpers:                                      │
                │  addressing · colors · fieldsmask · flatten ·        │
                │  condformat · errors · service · format   +          │
                │                          serializers:                │
                │  richtext · pivot · tables · filters · banding ·     │
                │  slicers · comments                                  │
                │                                                      │
                │  ZERO imports of fastmcp / mcp / argparse / pydantic │
                └───────────────────────┬─────────────────────────────┘
                                        │ receives a SheetsServices handle
                                        ▼
                ┌─────────────────────────────────────────────────────┐
                │                  AUTH  (gsheets.auth)                │
                │  resolve credentials (SA · OAuth desktop · ADC) →    │
                │  build_services() → SheetsServices                   │
                │  reads ONLY env vars; least-privilege scopes         │
                └───────────────────────┬─────────────────────────────┘
                                        ▼
                          Google Sheets API v4  (+ optional Drive v3)
```

### Core (`gsheets.core`) — pure

The core is a pure library. It imports **only** the standard library plus
`googleapiclient` / `google.auth*`. It must never import `fastmcp`, `mcp`, `argparse`,
`pydantic`, or `gsheets.models`. This boundary is enforced by a test that runs in a
fresh subprocess and asserts `import gsheets.core` (and `import gsheets.auth`) pulls none
of those into `sys.modules`.

Every core function:

- takes `services: SheetsServices` (the authed handle) as its first parameter and
  `spreadsheet_id` as its second;
- accepts A1 ranges everywhere and resolves sheet name → `sheetId` and A1 → `GridRange`
  internally — callers never fetch a `sheetId` first;
- returns plain JSON-serializable `dict` / `list`, with `"ok": True` on success;
- raises `SheetsError` on failure (it never returns an error dict).

Helper modules with disjoint responsibilities back the function surface:

| Helper | Responsibility |
|---|---|
| `service` | `SheetsServices` — the frozen authed handle (sheets resource, optional drive resource, optional account email). |
| `errors` | `SheetsError` + `classify_google_error()` — maps a Google `HttpError` to a coded, hinted error. |
| `addressing` | A1 ↔ `GridRange` and sheet-name → `sheetId` (per-call cached); `gridranges_intersect()` — the geometric overlap test `describe` uses to scope conditional-format rules to a requested range. |
| `colors` | hex ↔ `ColorStyle` (`rgbColor` / `themeColor`); reads flatten to hex. |
| `fieldsmask` | `build_fields_mask(payload)` — the minimal `fields` mask covering exactly the keys present. |
| `flatten` | `flatten_cell_format()` — Google's nested `CellFormat` → flat shape. |
| `condformat` | (de)serialize conditional-format rules ↔ readable lines (see grammar below). |

Seven additional pure serializer modules (added in v0.2) flatten the richer read surface
into the same terse, structured, round-trippable line style. Each takes already-resolved
A1 strings (the owning read function resolves `GridRange → A1` first, mirroring the
condformat boundary) and returns plain dicts carrying a `line` field:

| Serializer | Responsibility |
|---|---|
| `richtext` | `serialize_text_runs()` — per-run styled segments (`textFormatRuns`) + in-cell links; `text_runs_line()` renders the terse `runs A1: …` line. |
| `pivot` | `serialize_pivot()` — flatten a `PivotTable` definition (source, rows/cols/values/filters) into a flat dict + terse line. |
| `tables` | `serialize_table()` + `build_{add,update,delete}_table_request()` — native Sheets `Table` read shape and the write requests. |
| `filters` | `serialize_basic_filter()` / `serialize_filter_view()` + `build_*` filter requests — basic-filter and filter-view state and writes. |
| `banding` | `serialize_banding()` + `build_{add,update,delete}_banding_request()` — alternating-color band ranges. |
| `slicers` | `serialize_slicer()` — slicer read shape — plus `build_{add,update,delete}_slicer_request()` for the slicer write CRUD. |
| `comments` | `serialize_comment()` — flatten a Drive `Comment` (author, content, replies); the `comments` core function (full CRUD over the Drive API) lives here too. |

Five additional top-level core functions live in their own modules and stay boundary-pure:

- `data_ops` (`core/dataops.py`) and `dimensions` (`core/dimensions.py`) are single-dispatch
  wrappers over the one-request `batchUpdate` data and dimension verbs.
- `comments` (`core/comments.py`) is full CRUD over Drive threaded comments (it does not touch
  the Sheets API).
- `export` (`core/export.py`) downloads a workbook (Drive) or a single sheet (Sheets) to a local
  file.
- `read_many` (`core/multiread.py`) fans a read across many spreadsheets, capturing per-file
  errors.

One boundary-sensitive detail lives in `export`. The Drive-backed formats stream bytes down with
`MediaIoBaseDownload` from `googleapiclient.http`, which transitively imports `httplib2` →
`argparse` — a module the pure-core guard forbids from a clean `import gsheets.core`. Since
`export` is re-exported from `gsheets.core`, a top-level import would leak `argparse` into the
package import, so `MediaIoBaseDownload` is bound lazily inside `_export_via_drive` (the
module-level name stays a monkeypatch seam for tests). It is the only place core imports anything
beyond module top.

### Auth (`gsheets.auth`) — credential resolution

The auth layer is the only place credentials are resolved. It reads **only** environment
variables (never hardcoded paths or IDs), supports three credential sources with a
least-privilege scope default, builds the Google API service objects, and hands a
`SheetsServices` to core. Core never resolves credentials itself.

Resolution order (under `auto`): **Service Account** → **OAuth 2.0 Desktop** → **ADC**.
The OAuth desktop path distinguishes two states: a present, refreshable token (no client
file needed) versus first-time consent (client file required). Interactive consent is a
**CLI-only** path; the MCP server never runs a browser prompt during its stdio lifespan
and instead requires a pre-existing valid/refreshable token.

Scopes default to the narrowest that work (`spreadsheets` + `drive.file`), with an
opt-in broad mode.

**Scope reconciliation for cached OAuth tokens.** A cached token is refreshed against
the scopes it was **originally granted**, never against whatever `GSHEETS_SCOPES`
currently asks for. Google's refresh grant rejects (with `invalid_scope`) any refresh
whose scope list isn't a subset of the original consent, so a token consented with the
broad `drive` scope would fail a refresh that requested the narrow `drive.file` — even
though `drive` is functionally broader. The resolver therefore (1) loads the token
without forcing the requested scope list onto it, letting the refresh re-grant against
the token's own scopes, then (2) checks that the granted scopes **cover** what the
current request needs (broad `drive` covers `drive.file`). If the grant doesn't cover
the request, the call fails with a clear `oauth_scope_insufficient` error telling the
user to re-run `gsheets auth login` with the scopes they need.

### Adapters — thin

Two adapters wrap the core, each mapping 1:1 to the core function surface:

- **MCP server** (`mcp_server.py`) — a FastMCP stdio server. It is the **only** module
  that imports `fastmcp` / `mcp` and the **only** one that imports `gsheets.models`. It
  builds `SheetsServices` once in its lifespan, registers one tool per core function
  (one-line bodies), attaches `ToolAnnotations`, honors an `ENABLED_TOOLS` allowlist, and
  surfaces errors through a single tool-error envelope. It never prints to stdout (that
  is the JSON-RPC channel).
- **CLI** (`cli.py`) — an `argparse` adapter. It is the **only** module that imports
  `argparse`. It exposes one subcommand per core function (flags map 1:1 to core kwargs),
  a global `--json`, and one auth-only `auth login | status` subcommand that touches the
  auth layer (not the Sheets core). It catches `SheetsError` at the top of `main()` and
  prints a clean envelope to stderr.

`models.py` (adapter-side only) holds Pydantic models that mirror each core return dict
field-for-field, giving the MCP server its output schema / structured content plus a
terse text rendering. The models are mechanical mirrors — adding a core field means
adding a model field, never reshaping.

---

## Data flow

A typical read (`inspect`) flows like this:

1. The user invokes a tool (MCP) or subcommand (CLI) with an A1 range and flags.
2. The adapter resolves the shared `SheetsServices` and calls the matching core function
   in one line.
3. Core resolves the sheet name / A1 range to the internal `GridRange`, issues a single
   `spreadsheets.get` with a **tight `fields` mask** (never `includeGridData`), trimmed
   further by the include flags.
4. Core **flattens** the nested Google response (colors → hex, `textFormat.bold` →
   `bold`, number format → pattern + type, borders → `"<style> <hex>"`), pads jagged
   arrays to a rectangle, and — when `compact=True` — collapses identical cells into
   rectangular runs.
5. Core returns a plain dict with `"ok": True`.
6. The MCP adapter wraps it in the mirror Pydantic model (structured content + terse
   text); the CLI prints it as JSON (`--json`) or terse text.

A typical write (`format`) flows the same way in reverse: the adapter passes a flat
payload to core; core translates flat → Google request shape, **auto-builds the `fields`
mask from the payload** (so unspecified subfields are never wiped and the write is never
a silent no-op), and issues a single `batchUpdate`. Writes default to `USER_ENTERED` so
formulas are interpreted rather than stored as literal text.

Two write-side subtleties worth knowing:

- **Auto fields mask.** A formatting/properties write must carry an exact `fields` mask
  or it no-ops or wipes unspecified subfields. Core derives the mask from the payload.
  Some Google sub-objects are **atomic leaves** — masked at the parent, never recursed
  into (`*ColorStyle`, `numberFormat`, `padding`, `textRotation`). `textFormat` is *not*
  atomic (its children mask individually, e.g. `textFormat.bold`).
- **Conditional-format addressing.** A conditional-format rule has no stable id; its
  position in the per-sheet `conditionalFormats[]` array **is** its priority (index 0 =
  highest). Writes address a rule by positional index. When several rule mutations are
  issued in one batch, core orders them **high index → low** so earlier edits do not
  shift the array position of later targets.

---

## The function surface

Twenty-one core functions, each exposed as one MCP tool and one CLI subcommand (the CLI adds an
auth-only `auth` subcommand that has no core function). The understanding path is
`overview → describe → inspect → read_conditional_formats` (`describe` is the unified one-call
region read that subsumes the latter three for a single region); the change path is the writers;
the raw escape hatch is presented last.

| Core fn | What it does | Kind |
|---|---|---|
| `overview` | Cheap orientation snapshot: title, tabs (dimensions, frozen, counts), named ranges, spreadsheet `locale`/`timeZone`. No grid data. | read |
| `inspect` | The primary rich read: values + formulas + both formats + merges + validation over a tight `fields` mask; optional compact runs; opt-in rich-text runs + in-cell links (`include_rich_text`) and pivot-table definitions (`include_pivot`). | read |
| `describe` | The unified "understand a region" read: ONE `spreadsheets.get(includeGridData=True)` over a tight union mask returns, per requested range, the cells (reusing `inspect`'s flatten), the sheet's merges, the conditional-format rules **intersecting** that range (range-scoped CF, via `addressing.gridranges_intersect`), its tables / banding / protected ranges (reusing the `structure` serializers), and a validation summary. Multi-range and multi-sheet; collapses 3-4 reads into one. No cache. | read |
| `read_values` | Values for one/more ranges with a render mode (`plain` / `unformatted` / `formula` / `all`). `diff_only` sparsifies the `render="all"` `computed` matrix against `values` (drops static-cell duplication); `max_cells` fails fast with `result_too_large` instead of blowing the caller's token cap. | read |
| `read_conditional_formats` | Per-sheet conditional-format rules serialized to readable lines (the priority feature). | read |
| `write_values` | Write/update one or more ranges; `USER_ENTERED` default; multi-range in one call. | write |
| `append_rows` | Append after the last row of a table (`INSERT_ROWS`, no overwrite). | write |
| `clear` | Clear values, and optionally formats / validation / notes, from ranges. | write |
| `format` | Apply cell formatting (background, font, number/date pattern, alignment, wrap, padding, borders, note) atomically with an auto fields mask. | write |
| `set_conditional_format` | Add / update / delete a boolean or gradient rule by positional index; index-shift-safe batch form. | write |
| `set_validation` | Set / clear data validation on a range (structured rule, round-trips from `inspect`). | write |
| `structure` | Read or modify merges, named ranges, protected ranges, frozen rows/cols, tab color, dimension groups — plus the v0.2 reads (native tables, basic filter, filter views, banding, slicers) and writes (table / banding / filter / slicer CRUD, spreadsheet `title`/`locale`/`timeZone`). One structural interface. | read/write |
| `manage_sheets` | Add / delete / duplicate / rename / reorder tabs; returns new ids. | write |
| `metadata` | Read / write developer metadata for durable row/column/sheet anchors. | read/write |
| `charts` | Create / update / delete / read embedded charts (read returns metadata only in v1). | read/write |
| `data_ops` | Single-request data verbs: `find_replace`, `delete_duplicates`, `trim_whitespace`, `sort_range`, `text_to_columns`, `auto_fill`, `copy_paste`, `cut_paste`. | write |
| `dimensions` | Row/column ops: `insert` / `delete` / `move` / `append`, `auto_resize`, `set_props` (height/width/hide), and `read` (which rows/cols are hidden). | read/write |
| `comments` | Drive threaded comments on the spreadsheet file (author, content, replies, resolved state). Full CRUD via an `action` dispatch (`read` / `create` / `reply` / `resolve` / `delete`); uses the Drive API, not the Sheets API. | read/write |
| `export` | Download the workbook (`pdf` / `xlsx` / `ods`, via Drive `files.export`) or one sheet (`csv` / `tsv`, serialized locally from values) to a local file. | read |
| `read_many` | Fan a values or summary read across many spreadsheets; a bad id is captured as a per-file `{ok: false, error}` entry instead of failing the batch. | read |
| `batch` | Power-user escape hatch: a raw ordered list of `batchUpdate` requests. | write |

The structure read and the conditional-format read share a **shape-stable multi-sheet
envelope**: top-level spreadsheet-scoped fields plus a `sheets: [...]` list that is
always a list (one entry for one sheet, every tab when unscoped), so consumers never fork
on object-vs-list. The v0.2 structural reads (`tables`, `basicFilter`, `filterViews`,
`bandedRanges`, `slicers`) ride that same per-sheet envelope as additional sheet-scoped
keys, emitted only when present.

---

## Conditional-format serialization grammar

The headline read feature serializes each conditional-format rule's **body** into one
terse, human- and AI-readable line that round-trips back into a write. The serialized
line is the rule body **only** — it carries no index. The positional index (priority)
lives separately in the structured output and is supplied separately on write, so there
is a single source of index truth.

### Grammar (EBNF-ish)

```
line          := "[" rangelist "] " body
rangelist     := a1range ("," a1range)*
body          := boolean_body | gradient_body
boolean_body  := "if " condition " -> " format
gradient_body := "gradient " gradstop (" | " gradstop)*
condition     := COND_TYPE [ "(" arg ("," arg)* ")" ]    # args verbatim; formulas kept exact incl. leading "="
format        := fmt_token (" " fmt_token)*              # space-separated; canonical order: bg, fg, text-styles, number, align, wrap
gradstop      := minmax_stop | mid_stop
minmax_stop   := ("min" | "max") "=" hexColor            # MIN/MAX interpolation type; NO value
mid_stop      := "mid:" interp "=" hexColor              # midpoint; carries an explicit value
interp        := "num:" number | "pct:" number | "pctile:" number   # -> NUMBER | PERCENT | PERCENTILE
fmt_token     := "bg " hex | "fg " hex | "bold" | "italic" | "underline" | "strike"
               | "num " pattern | "halign " H | "valign " V | "wrap " W
```

Notes:

- `COND_TYPE` is the Google `BooleanCondition.type` verbatim (`CUSTOM_FORMULA`,
  `NUMBER_GREATER`, `NUMBER_BETWEEN`, `TEXT_CONTAINS`, `TEXT_EQ`, `BLANK`, `NOT_BLANK`,
  `DATE_AFTER`, `ONE_OF_LIST`, …). Args map to the condition's `values[]`.
- Colors render as 6-digit uppercase hex (`#FFCDD2`); theme colors render as
  `theme:ACCENT1`.
- **Gradient stops are keyed by slot, exactly one `=` per stop.** A gradient rule has at
  most three slots: `min` → minpoint, `mid` → midpoint, `max` → maxpoint. `min` / `max`
  carry the implicit interpolation type `MIN` / `MAX` and never take a value (the slot
  keyword *is* the type). Only `mid` carries an explicit value, written
  `mid:<interp>=<hex>` where `<interp>` is `num:<n>` → `NUMBER`, `pct:<n>` → `PERCENT`,
  or `pctile:<n>` → `PERCENTILE`. Attaching an interp to `min` / `max` is invalid. Stops
  are joined by `" | "` and ordered `min`, `mid`, `max` (absent slots omitted).

### Examples — boolean

```
[Sheet1!A2:A100] if CUSTOM_FORMULA(=$B2>10) -> bg #FFCDD2 bold
[Sheet1!C2:C100] if NUMBER_GREATER(0) -> fg #1B5E20 bold
[Sheet1!D2:D100,Sheet1!F2:F100] if TEXT_CONTAINS(done) -> bg #C8E6C9
[Sheet1!E2:E100] if BLANK -> bg #ECEFF1 italic
```

### Examples — gradient

```
[Sheet1!G2:G100] gradient min=#FFFFFF | max=#1A73E8
[Sheet1!H2:H100] gradient min=#F44336 | mid:num:50=#FFEB3B | max=#4CAF50
[Sheet1!I2:I100] gradient min=#FFFFFF | mid:pct:50=#FFEB3B | max=#1A73E8
```

### Round-trip contract

`parse_rule_line(line)` returns a structured `{ranges, kind, condition, format}` dict
with no index; `serialize_rule(build_google_rule(parsed))` reproduces the input body line
exactly, up to canonical formatting (uppercase hex, canonical fmt-token order, canonical
gradient-slot order `min | mid | max`). A read line can be edited and written straight
back via `set_conditional_format`, with the target index passed separately. This
round-trip is golden-mastered in the test suite for the boolean case and the canonical
gradient case.

---

## v0.2 capabilities (richer reads, then files and cross-file)

The conditional-format line style generalizes. Every richer read added in v0.2 follows the
same discipline: **flattened hex colors**, a terse `[range] kind …` (or `kind … [range]`)
`line` for humans/AI, the structured fields alongside the line for round-trip, and
**omit-when-absent** so a sparse value stays token-cheap. Each serializer takes
already-resolved A1 strings; the owning read function resolves `GridRange → A1` first.
Per-cell rich data (runs, hyperlink, pivot) is attached **only to a cell that actually
carries it** — never emitted as an empty placeholder. The slicer and comment serializers gained
write builders in v0.2 (`structure` slicer CRUD; `comments` action CRUD). The last two
subsections (`export`, `read_many`) are not serializers — they are the file-output and
cross-file capabilities, documented here for completeness.

### Rich-text runs + cell hyperlink (`richtext`)

`inspect(include_rich_text=True)` adds `textFormatRuns` and `hyperlink` to the per-cell
mask. A cell with multiple styled segments gains a `runs` list; a cell with a single link
gains a flat `hyperlink`. A run carries its 0-based `start`, the substring `text`, a
flattened text-format subset, and a run-level `link` (which **takes precedence** over the
cell-level `hyperlink` — multi-link cells are recoverable only through the per-run links).

```jsonc
// per run, attached to a cell only when textFormatRuns are present
{ "start": 0, "text": "Click here", "format": { "bold": true, "fg": "#1155CC" },
  "link": "https://example.com" }
```

```
# terse line (one per cell with runs)
runs A1: "Click here"[0:10 fg #1155CC bold link https://example.com] + " then plain"[10:21]
```

Each segment is `"<text>"[<start>:<end> <fmt-tokens> link <uri>]`, fmt-tokens in the same
canonical order as the condformat format tokens. The flat `hyperlink` is omitted when a
cell holds multiple links (those live in the runs).

### Pivot-table definition (`pivot`)

`inspect(include_pivot=True)` adds `pivotTable` to the mask; only the **anchor (top-left)
cell** carries the definition, so `pivot` is attached only there. The `source` GridRange
is resolved to A1; rows/columns/values/filters are flattened.

```jsonc
{ "source": "Data!A1:F500",
  "rows":    [ { "field": "Region", "sourceColumnOffset": 0, "sortOrder": "ASCENDING" } ],
  "columns": [ { "field": "Quarter", "sourceColumnOffset": 2 } ],
  "values":  [ { "name": "Sum of Sales", "sourceColumnOffset": 4, "summarize": "SUM" } ],
  "filters": [ { "sourceColumnOffset": 1, "visibleValues": ["X", "Y"] } ],
  "valueLayout": "HORIZONTAL" }
```

```
pivot <- Data!A1:F500 | rows: Region | cols: Quarter | values: SUM(Sales)
```

A value renders as `SUMMARIZE(name)` (e.g. `SUM(Sales)`); each segment is omitted when its
slot is empty. Pivots are read-only — writing one stays in the `batch` escape hatch.

### Native tables (`tables`)

A `Table` (the 2024-GA native Sheets table) serializes to its name, A1 range, and typed
columns. A `DROPDOWN` column's data-validation rule renders with the **same**
`ValidationRule` one-liner `inspect` surfaces for cell validation.

```jsonc
{ "tableId": "abc", "name": "Sales", "range": "Sheet1!A1:F500",
  "columns": [ { "name": "Region", "type": "TEXT" },
               { "name": "Status", "type": "DROPDOWN", "validation": "ONE_OF_LIST(Open,Closed)" } ] }
```

```
table "Sales" [Sheet1!A1:F500] cols: Region:TEXT, Status:DROPDOWN(Open,Closed)
```

A column's flattened `type` key (Google's API field is `columnType`) is one of `TEXT | DOUBLE | CURRENCY | PERCENT | DATE | TIME | DATETIME |
DROPDOWN | CHECKBOX | SMART_CHIP | RATING`. Tables are full-CRUD via the `structure`
actions `add_table` / `update_table` / `delete_table`.

### Filter views and basic filter (`filters`)

A sheet's `basicFilter` (at most one) and its `filterViews` (an array) flatten to a sort
list plus a per-column criterion list. The column is rendered as a **letter** (`B`),
`hidden` normalizes `hiddenValues` / `visibleValues`, and a criterion's condition reuses
the **same** condition serializer as the condformat grammar.

```jsonc
// basicFilter (one per sheet, or null)
{ "range": "Sheet1!A1:F500", "sorted": [ { "col": "C", "order": "ASCENDING" } ],
  "criteria": [ { "col": "B", "hidden": ["Closed"], "condition": "NUMBER_GREATER(0)" } ] }
// filterView (array per sheet)
{ "filterViewId": 123, "title": "Open only", "range": "Sheet1!A1:F500",
  "criteria": [ { "col": "B", "hidden": ["Closed"] } ] }
```

```
basicFilter [Sheet1!A1:F500] sort C asc | B: hide Closed, NUMBER_GREATER(0)
filterView 123 "Open only" [Sheet1!A1:F500] B: hide Closed
```

Writable via the `structure` actions `set_basic_filter` / `clear_basic_filter` and
`add_filter_view` / `update_filter_view` / `delete_filter_view`.

### Banding (`banding`)

An alternating-color `BandedRange` flattens to its id, A1 range, and per-axis band colors
(header / first / second / footer), each as a hex string.

```jsonc
{ "bandedRangeId": 7, "range": "Sheet1!A1:F500",
  "rowBanding": { "header": "#4285F4", "first": "#FFFFFF", "second": "#E8F0FE", "footer": null },
  "columnBanding": null }
```

```
banding 7 [Sheet1!A1:F500] rows: hdr #4285F4 / #FFFFFF / #E8F0FE
```

Full-CRUD via the `structure` actions `add_banding` / `update_banding` / `delete_banding`.

### Slicers (`slicers`)

A `Slicer` flattens to its id, title, data range, filtered column index, dashboard anchor,
and a terse criterion.

```jsonc
{ "slicerId": 4, "title": "Region", "range": "Data!A1:F500", "columnIndex": 0,
  "anchor": { "sheet": "Dash", "row": 0, "col": 8 }, "criteria": "ONE_OF_LIST(...)" }
```

```
slicer 4 "Region" col 0 [Data!A1:F500] @ Dash!I1
```

The anchor reads back as `{sheet, row, col}` and renders as `@ <Sheet>!<cell>`. A 0-valued
index is meaningful (top row / first column), so a top-left, row-0 anchor still renders (e.g.
`@ Sheet!E1`); an index absent from the response is treated as 0.

Full-CRUD via the `structure` actions `add_slicer` / `update_slicer` / `delete_slicer`.
`add_slicer` takes the data range as the top-level A1 `range` (or `params.dataRange`) plus a
required single-cell `anchor`, and returns the new `slicerId` from the `addSlicer` reply.
`update_slicer` / `delete_slicer` address the slicer by `slicerId` in `params`; `delete_slicer`
maps to `deleteEmbeddedObject` since slicers share the embedded-object id space.

### Drive comments (`comments`)

The `comments` tool reads and writes threaded comments on the spreadsheet **file** via the
Drive API (not the Sheets API — Sheets has no comment surface). An `action` dispatch (default
`read`) selects the operation: `read` paginates `comments.list`; `create` posts a top-level
comment; `reply` posts a reply; `resolve` resolves a comment by posting a reply with
`action="resolve"` (Drive has no standalone resolve endpoint); `delete` removes a comment (the
destructive action — the CLI requires `--confirm`). Each comment flattens its author display
name, content, timestamps, `resolved` state, an optional quoted snippet, and its replies (each
with an optional `action` such as `resolve`).

```jsonc
{ "id": "AAAA", "author": "Jane Doe", "content": "please verify Q3",
  "created": "2026-05-01T…", "modified": "2026-05-02T…", "resolved": false,
  "quoted": "1234",
  "replies": [ { "author": "Bob", "content": "done", "action": "resolve" } ] }
```

```
comment AAAA by Jane Doe: "please verify Q3" (open, 1 reply)
```

A Sheets comment `anchor` is an **opaque, document-type-specific** string with no documented
A1 mapping, so it is surfaced raw under `anchorRaw` at the document level only — it is never
claimed to map to a cell. The Drive `comments.list` call **requires** an explicit `fields`
mask (omitting it errors), so core always sends one and paginates. Every action requires Drive;
without it (no Drive scope), core raises `SheetsError("drive_unavailable")` with a hint to
enable a Drive scope.

### Export (`export`)

`export` is not a serializer — it writes a local file and returns
`{format, mimeType, path, bytes}`. Two backends, chosen by `format`:

- `pdf` / `xlsx` / `ods` — whole-workbook export via Drive `files.export`. Google renders the
  workbook server-side; the bytes stream down with `MediaIoBaseDownload` (the lazy import above).
  Requires a Drive scope; the `sheet` arg is ignored. No Drive service → `drive_unavailable`.
- `csv` / `tsv` — one sheet, serialized locally from `read_values(render="plain")` (Drive's csv
  export only emits the first sheet, so we never use it). The serialization itself is delegated to
  the shared output-format layer (`format.render_grid`, below), so `export`'s on-disk bytes are
  byte-identical to a CLI `--format csv` pipe / an MCP file output. Sheets scope only; `sheet` is
  required → `missing_sheet` if omitted.

The MCP tool is annotated as a **write** tool with `destructiveHint=True`: it mutates no
spreadsheet, but it writes to the local filesystem and silently overwrites an existing file
at `path`.

### Output-format layer (`format`)

`core/format.py` is a pure stdlib helper (`csv` · `io` · `json`) that serializes a core result
dict to a string in one shared place, so both adapters and `export` produce byte-identical output.
`render(result, fmt)` covers the data formats — `json` (pretty `json.dumps`), `jsonl` (one
`{range,row}` record per row for `read_values`, one list element per line otherwise), and `csv` /
`tsv` (the rectangular value grid via the stdlib `csv` module, RFC-4180 `\r\n`; a single range is
clean CSV, multiple ranges emit one `# range: <A1>` block each). A tabular format requested on a
structured result raises `SheetsError("format_unsupported")` — the agent learns to use a value
read. `text` is **not** handled here: it stays the adapters' existing terse renderer (the CLI text
renderer / the Pydantic model render), which differs by adapter and predates this layer.

The adapters wire it identically: the CLI promotes `--json` to a global `--format
{text,json,jsonl,csv,tsv}` (`--json` is a permanent alias for `--format json`); the MCP read tools
take `output_format` (the rectangular-values `read_values` offers every format, the structured
reads offer only `text`/`json`/`jsonl`). For a data format the MCP tool returns the rendered string
wrapped in a `ToolResult` (which keeps the tool's structured `output_schema` while emitting a plain
string body — FastMCP refuses a bare string as `structured_content` when a schema is set).

### File-output escape valve (`out_path`, MCP-only) (`paths`)

The CLI pipes its rendered output (`> file`, `| pandas`); the MCP tool's output lands in the
agent's context, so for a large read the dominant cost is dumping the grid into the conversation.
The three big-read MCP tools — `sheets_read_values`, `sheets_inspect`, `sheets_read_many` — take an
optional `out_path`. When set, the adapter writes `render(result, output_format)` to that local file
(utf-8) and returns a small **handle** — `{ok, path, format, rows, cols, bytes, preview}`, with
`preview` the first ~5 rows (csv/tsv) or records (jsonl/json) — *instead of* the payload. It is the
same shared `render()` plus a file write, so the file is byte-identical to a CLI `--format` pipe.
`out_path` is the **only** sanctioned MCP-specific parameter (the CLI doesn't need it — its stdout
pipes); `output_format="text"` has no file representation, so under `out_path` it resolves to `json`.

The path safety and handle construction live in **pure core** (`core/paths.py`, stdlib `fnmatch` ·
`os` · `pathlib`): `resolve_out_path` resolves a relative path against the cwd, **errors**
(`bad_out_path`) if the parent directory does not exist (it never `mkdir`s), and **hard-refuses**
any path under `~/.config/google-sheets-mcp/` or `~/.secrets/`, or matching a credential glob
(`*token*.json`, `gcp-oauth.keys.json`, `service-account*.json`, `credentials.json`, `*.pem`,
`.env*`) — so a read can never clobber credentials. These tools keep `readOnlyHint=True` (the local
write is a caller-named, opt-in side effect that modifies no spreadsheet/remote state; the side
effect is documented in each tool's docstring — decision D-ANNOT).

### Read across files (`read_many`)

`read_many` fans one read across many spreadsheets in a single call. It takes a list of request
dicts, each naming a `spreadsheetId`; `mode` picks the per-file read — `summary` runs `overview`,
`values` runs `read_values` over that request's `ranges` (with an optional per-request `render`).
Validation of the request list is up front (a malformed batch is a caller bug), but a live Google
failure on one id (404, permission denied, bad range) is **caught per file** and recorded as a
`{spreadsheetId, ok: false, error}` entry — the other files still read. It is read-only by design:
the Sheets API has no cross-file atomic write, so a multi-file mutation could only half-apply.

---

## Addressing and color conventions

- **`GridRange` is 0-based, half-open** (`startRowIndex` inclusive, `endRowIndex`
  exclusive); **A1 is 1-based, inclusive**. The conversion is centralized in
  `addressing` so it is done once and correctly. Unbounded ranges (`A:A`, `2:2`, whole
  sheet) map by omitting the corresponding indices.
- **Writes always use `ColorStyle`** (`rgbColor` / `themeColor`), never the deprecated
  flat `Color`. **Reads flatten to a hex string.** Channel rounding is `round(channel *
  255)`.

---

## Error handling

Core raises a single exception type, `SheetsError(code, message, status?, reason?,
hint?)`, and never returns an error dict. `classify_google_error()` maps a Google
`HttpError` to a `SheetsError` with an actionable, **generic** hint (e.g. a permission
error suggests sharing the sheet with the authenticated account). Hints do not embed the
operator's account email by default — that is gated behind an opt-in verbose mode so a
public/masked deployment never leaks it.

Each adapter has one envelope:

- **MCP** raises a curated `ToolError` (the server runs with masked error details, so
  unexpected exceptions surface generically while curated messages pass through);
- **CLI** catches the `SheetsError` at the top of `main()` and prints a terse stderr
  line, or a structured `{"ok": false, "error": {…}}` object under `--json`, with exit
  code 1.

---

## Security and privacy

This project is public. Credentials and real spreadsheet IDs come **only** from
environment variables / local config at runtime — never the committed tree. All docs and
examples use the placeholder `<YOUR_SPREADSHEET_ID>`. See
[`CONTRIBUTING.md`](../CONTRIBUTING.md#security-and-privacy-this-repo-is-public) for the
full rules.
