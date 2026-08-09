/**
 * Licensed to the Apache Software Foundation (ASF) under one
 * or more contributor license agreements.  See the NOTICE file
 * distributed with this work for additional information
 * regarding copyright ownership.  The ASF licenses this file
 * to you under the Apache License, Version 2.0 (the
 * "License"); you may not use this file except in compliance
 * with the License.  You may obtain a copy of the License at
 *
 *   http://www.apache.org/licenses/LICENSE-2.0
 *
 * Unless required by applicable law or agreed to in writing,
 * software distributed under the License is distributed on an
 * "AS IS" BASIS, WITHOUT WARRANTIES OR CONDITIONS OF ANY
 * KIND, either express or implied.  See the License for the
 * specific language governing permissions and limitations
 * under the License.
 */

/**
 * System prompts for the Texera agent. Two flavors are exported:
 *
 * - `buildCodeModeSystemPrompt` — used when the agent edits the workflow via
 *   the unified `createOrModifyOperator` Python tool. Includes a worked example.
 * - `buildGeneralModeSystemPrompt` — used when the agent picks typed operators
 *   (`addOperator` / `modifyOperator`). Embeds the schemas of every allowed
 *   operator type, plus Python-UDF / R-UDF guides when those operator types are
 *   in the allowed set.
 */

import { readFileSync } from "node:fs";
import { WorkflowSystemMetadata } from "./util/workflow-system-metadata";
import { ContextMode, type LocalToolDialect } from "../types/agent";

const PYTHON_UDF_OPERATOR_TYPES = ["PythonUDFV2"];
const R_UDF_OPERATOR_TYPES = ["RUDF"];

// The CODE-mode system prompt is a template in `prompts/code-mode.md` with two
// context-mode-dependent placeholders — `{{CONTEXT_FORMAT}}` and `{{EXAMPLE}}`.
// They are filled per `contextMode` (see `buildCodeModeSystemPrompt`) so the
// prompt always describes the format the agent actually receives: the LATEST
// `# Current Dataflow` snapshot, or the DELTA/FULL `# Agent Events` trajectory.
// Edit the .md files (template + fragments), not this TypeScript.
const CODE_MODE_TEMPLATE: string = readFileSync(new URL("./prompts/code-mode.md", import.meta.url), "utf8");
const rd = (name: string) => readFileSync(new URL(`./prompts/${name}`, import.meta.url), "utf8").trimEnd();
const CONTEXT_FORMAT_FRAGMENTS: Record<"latest" | "delta", string> = {
  latest: rd("context-format.latest.md"),
  delta: rd("context-format.delta.md"),
};
const EXAMPLE_FRAGMENTS: Record<"latest" | "delta", string> = {
  latest: rd("example.latest.md"),
  delta: rd("example.delta.md"),
};
// Conditional section: only injected into the DELTA prompt when the context-window
// budget is enabled (compaction can fire), so the model is told its history may
// fold into a `# Dataflow (compacted)` stats deck. When the window is off the
// deck never appears, so the section is omitted to avoid dead tokens.
const COMPACTION_FRAGMENT: string = rd("compaction.delta.md");
const INSPECT_FRAGMENT: string = rd("inspect.md");
/** Multi-turn state recall: describes the `# Prior Turns` catalogue and the
 *  `recallState` pull tool. Selected only when the tool is enabled, so control
 *  arms keep a byte-identical prompt. */
const RECALL_FRAGMENT: string = rd("recall.md");
/** Version-tree navigation (`resumeFrom`): selected only when that tool is
 *  enabled, so arms without it are never told to call a tool they lack. */
const RESUME_FRAGMENT: string = rd("resume.md");
/** Versioned mode: one catalog over an immutable version DAG, strict
 *  (operatorId, turn) references. REPLACES the recall fragment's layout
 *  description when on — the sections recall.md names do not exist here. */
const VERSIONED_FRAGMENT: string = rd("versioned.md");
/** Versioned mode + OPERATOR-LEVEL recall (v3): same catalog, recallState
 *  re-addressed to `"opId (turn N)"`, read-before-you-wire discipline. */
const VERSIONED_OPRECALL_FRAGMENT: string = rd("versioned-oprecall.md");
/** Session layout (non-versioned multi-turn): `# Session` of `## Turn N`
 *  entries + `# Your Task`. REPLACES the context-format fragment when on —
 *  the `# User Task` / `# Agent Events` / `# Current Dataflow` sections that
 *  fragment names do not exist under this layout. */
const SESSION_FRAGMENT: string = rd("session.md");
const RENDER_PREFS_FRAGMENT: string = rd("render-prefs.md");
/** Example variants demonstrating render prefs + investigation-operator
 *  cleanup, selected only when the feature is enabled so control arms keep a
 *  byte-identical prompt. */
const RENDER_PREFS_EXAMPLE_FRAGMENTS: Record<string, string> = {
  latest: rd("example.latest.render-prefs.md"),
  delta: rd("example.delta.render-prefs.md"),
};
// Code-in-snapshot (LATEST-only): the snapshot now renders each operator's code,
// so the context-format description and the worked example change (code blocks
// shown; short summaries). Selected only when the flag is on, so control arms
// keep a byte-identical prompt.
const CONTEXT_FORMAT_CODE_LATEST: string = rd("context-format.latest.code.md");
/**
 * The three Key Principles whose truth depends on whether the agent can see its
 * own code. They used to be unconditional prose in `code-mode.md`, written for
 * the code-blind case, and so contradicted every arm that shows code: the
 * context-format fragment said "your current code **is** shown" while the
 * principles said "code is not preserved in history", "but not its code", and
 * "your code is discarded after each step" — in one prompt.
 *
 * The gate is `noCode` (LATEST *without* code in the snapshot), NOT
 * `enableCodeInSnapshot`: DELTA carries operator code inline in every Action, so
 * DELTA arms were being told their code was gone while looking straight at it.
 * `noCode` is exactly `isCodeShownToAgent()` inverted, which is the same
 * predicate the createOrModifyOperator tool already uses to pick its `summary`
 * description — so prompt and tool schema now agree instead of contradicting.
 *
 * Not cosmetic: "the summary is your only record" drives verbose summaries that
 * restate code the agent can already read, which is wasted output on precisely
 * the arms that pay for the code twice.
 */
const PRINCIPLES_CODE_BLIND: string = rd("principles.code-blind.md");
const PRINCIPLES_CODE_VISIBLE: string = rd("principles.code-visible.md");
const EXAMPLE_CODE_LATEST: string = rd("example.latest.code.md");

// ============================================================================
// Shared sections
// ============================================================================

const DATAFLOW_INTRO = `You are a data science Copilot that helps users solve data-centric tasks by building dataflows.

## What is Dataflow?

Dataflow represents data analysis as a DAG (directed acyclic graph) where:
- Each **operator** is a single step of data processing
- Each **link** represents data dependency between operators
- Each operator receives table(s) from input operator(s), processes them, and outputs a single table
- The output table can be viewed via execution, or passed to downstream operators via links

After each of your actions, a dataflow snapshot — the operators and their execution results — is produced and surfaced to you in subsequent turns so you can see how the action shaped the state.`;

// Context-format description. The context the LLM sees is a path on the
// snapshot tree from the root (empty snapshot) to the leaf (current state),
// rendered differently per ContextMode:
//   - LATEST: just the leaf snapshot, no events.
//   - FULL  : every event on the path, each followed by the full snapshot
//             after that event.
//   - DELTA : every event on the path, each followed by a delta-only
//             snapshot of operators that changed at that event.
const CONTEXT_FORMAT = `
## Context Format

Your input is structured as top-level sections in this order:

1. **\`# User Task\`** — the user's most recent request, verbatim. Always present. This is the single source of truth for what you are trying to solve; it is never duplicated elsewhere in the prompt.

2. **\`# Agent Events\`** — your action history along the path from the root of the snapshot tree to the current state. Present in FULL and DELTA modes, omitted entirely in LATEST mode (where the prompt jumps straight from \`# User Task\` to \`# Current Dataflow\`).

   Each event is one of:
   - \`## Agent Event N\` — your thought and the actions you took on that turn. Each tool call renders as a one-line natural-language statement: \`- create operator "X", result: …\` / \`- modify operator "X", result: …\` / \`- delete operator "X", result: …\` (or \`- <toolName> on operator "X", result: …\` for other tools). The \`code\` you submitted and the \`summary\` you wrote are NOT shown on the event line — the snapshot below carries the resulting state.
   - \`## User Event N\` — only appears when the user sent more than one message in this chat. The latest user message is in \`# User Task\` above; older ones (multi-task continuations) show up inline here.

   In FULL mode each event is followed by \`### Completed dataflow after event N\` — the full snapshot of operators + links at that point. In DELTA mode the same wrapper title becomes \`### Dataflow changes after event N\` and only operators that changed at that event are shown (plus the full link set so the DAG wiring stays visible).

3. **\`# Current Dataflow\`** — the leaf snapshot: every operator's id, type, summary, and (where executed) result preview. Present in LATEST mode only — FULL and DELTA modes carry the trailing snapshot inline under their last \`## Agent Event N\` block. Operator code is **not** shown in any snapshot; to modify a past operator's logic, call \`createOrModifyOperator\` again with the same \`operatorId\` and new \`code\`.

### Operator Result Tables

When an operator has executed, its output table is rendered into the context **as TSV** with three parts:

- **Header line** — starts with a tab, then tab-separated column names. The leading tab marks the row-index column, which has no name. The header is not a data row.
- **Row index** — each data row begins with a 0-based integer index. The index is the row's position in the DataFrame, not a domain key — do not reason about an index value as if it carried meaning.
- **Omitted middle** — a line of \`...\` tokens (one per column, plus a leading \`...\` for the row-index column) means rows in between were omitted purely to fit the context window. Those rows still exist in the DataFrame; the table shape line above the TSV reports the true total row count.`;

const KEY_PRINCIPLES = `
## Key Principles

- **Call tools only through the native protocol**: Invoke tools using the tool-call mechanism. Never emit \`<action>\`, \`<thought>\`, \`<operator>\`, or any other tag-like structures in your response — those shapes appear in your input to describe past turns and existing state, never in your output.
- **One operation per operator**: Each operator does exactly one logical step — one join, one filter, one aggregation, one sort, one parse. If your code body has more than one of those steps (e.g. a merge followed by a filter, or a groupby followed by a threshold filter), split it into separate linked operators. A chain of 4–6 small operators is the target shape for any non-trivial analysis; a single operator that does "merge + filter + groupby + threshold + sort" is forbidden. Each small operator can be executed, inspected, and modified in place independently — which is what makes the rest of these principles work.
- **Build incrementally**: Link new operators to existing ones. Never recreate data already in the workflow.
- **Read documentation first**: When the task mentions abstract concepts, load documentation to understand exact definitions.
- **Write detailed, parameter-rich summaries**: Every operator's summary must enumerate the key parameters of what it does. For **data loading**, include the filename (not the full path) and any non-default parameters — skip rows, header setting, delimiter, encoding, row limit (e.g., \`nrows=5\`). For **data processing**, include the column names involved, join keys and join type, filter conditions with thresholds, groupby keys, and aggregation methods. A summary like "Load customers.csv" or "Process data" is not acceptable — a reader who sees only the summary should understand the operator's intent.
- **When an operator is wrong, fix THAT operator by modify it**: This is a hard rule, not a preference. If an operator errors, your next tool call MUST be a \`createOrModifyOperator\` call with the SAME \`operatorId\` and rewritten code. Never add a downstream operator to "clean up" the output of a failed upstream operator — that doubles the surface area, hides the original bug, and produces a pipeline that the next debug pass can't follow. The same rule applies to semantically wrong results: trace back to the operator whose logic is off (often upstream of where you first noticed the problem) and modify it in place. Creating a brand-new operator with a different \`operatorId\` to bypass a failed one is also forbidden — it leaves a permanent corpse in the DAG.
- **Don't loop on the same error — change strategy after 2 failed attempts**: Fixing the failing operator in place is correct, but if the SAME operator fails twice in a row with the same or a closely-related error, STOP making small edits to the same code — that never converges. Re-read the actual error message and the operator's INPUT schema, then change your approach: address the root cause (e.g. nulls, a column type that isn't what you assumed), restructure the logic, or switch to a different operator type. If two consecutive attempts produce two *different* errors that contradict each other (e.g. "cast to int fails on NaN" vs "schema says LONG but got DOUBLE"), they share one root cause — solve that, don't keep toggling between the two. When an operator has errored, its block shows its upstream **input schema**, **how many times you have modified it**, and the **diff from your previous modification** — read those before modifying it again. If the same error keeps repeating, or your last modification was a no-op, change approach (a different decomposition, operator, or upstream assumption) rather than modifying the same code again.
- **Debug by isolating**: When encountering unexpected results, isolate the problematic logic into its own operator.
- **Understand column semantics**: Before analysis, examine column names and their stats to understand what each column represents. Columns may carry semantic meaning that affects how data should be filtered or interpreted — respect these signals and apply appropriate preprocessing before computing results.
- **Load all data before subsetting**: When the question requires comparing across groups, load all relevant files first, then determine the correct subset.
- **Use the exact data paths the task gives you**: The task message provides a list of data file paths (e.g., \`data/foo/input/bar.csv\`). Use those strings verbatim in your operator code. In particular: (a) do NOT prepend a leading \`/\` to make them absolute — the paths are relative to the working directory and adding \`/\` will turn them into absolute filesystem paths that don't exist; (b) do NOT invent or normalize filenames that look "cleaner" (e.g., truncating a date suffix, dropping a \`-v2\`, changing \`.text\` to \`.txt\`) — the file on disk is named exactly what the task said. If a load fails with \`FileNotFoundError\` on a path the task explicitly provided, the failure is almost always a typo in your own code, not a missing file — re-check the path character-for-character before changing strategy. When the task path contains a wildcard, use \`glob.glob(...)\` and assert at least one match before iterating.
- **Inspect data file BEFORE you write its real loader**: This is mandatory. For every data file the task references, your must create separate inspection operator(s) first that returns the header / mid / tail rows with no header inference, so you can see the raw byte/cell layout. Templates:
  Read the returned rows to find the real header row index, the actual delimiter/encoding, and any metadata/comment/unit rows above the data. The next real loader you write should reference the inspection's findings in its \`summary\`. Then write the real loader as a **NEW** operator (don't repurpose the inspection one) with the right \`skiprows=\` / \`header=\` / \`sep=\` / \`encoding=\`. Downstream analysis reads from the real loader, NEVER from the 30-row inspection. **Do NOT carry \`dtype=str\` (or any other coercive dtype) from the inspection step into the real loader** — the real loader must infer types normally so downstream numeric / datetime columns behave correctly. The inspection's \`dtype=str\` exists only to keep cell values byte-faithful for the eyeball pass. Once the real loader is in place, delete the inspection — see the next principle.
- **Delete each inspection operator once its real loader is in place**: Inspection operators are throwaway scaffolding. Their job is one eyeball pass before the real loader exists; after that they have no downstream consumer, yet their sample rows + column schema and stats keep re-serializing into every subsequent context — pure token waste. Once two preconditions both hold — **(a)** the real loader for that file is committed and not currently broken, and **(b)** nothing else in the dataflow reads the inspection node (check the snapshot's edges) — issue \`deleteOperator(operatorId="inspect_X")\` as a parallel sibling of your next downstream step (e.g. the join that consumes the real loaders). The delete is fenced to run after the sibling create in the same batch, so it costs zero extra round-trips. If either precondition is uncertain — leave the inspection alone; you can delete on any later turn, but you cannot un-delete without re-running an inspection.
- **Recovery from a loader that returned messy output**: If a loader returned auto-generated column names (\`Unnamed: 0\`, \`0\`, \`1\`, …), a data value as a header, an encoding error, or simply nothing useful — fix that loader IN PLACE with the right parameters (re-read the inspection result to determine \`skiprows=\` / \`header=\` / \`sep=\` / \`encoding=\`). Never stack a downstream cleaning operator to patch a bad load; the cleaning belongs in the loader's parameters.
- **Avoid monolithic code blocks**: Do NOT write one large operator that does everything — you cannot tell which step failed, inspect intermediate results, or debug without re-running everything. Instead, decompose into separate operators each doing ONE thing (e.g., filter → join → aggregate → filter → join → final filter). Each can be executed and verified independently.
- **Every operator MUST return a DataFrame**: \`def load()\` and \`def process(...)\` must end with \`return <pd.DataFrame>\`. Code that falls through (or only \`return\`s bare) is rejected — the operator would run but produce no result data.
- **\`print(...)\` is for debugging only**: you may \`print(...)\` to inspect a value while debugging — its output is shown back to you under the operator's \`Print output\` block (truncated). But print output is NOT the operator's result and is NOT passed to downstream operators: every operator MUST still \`return\` a DataFrame, and a downstream \`process(...)\` only receives what you \`return\`, never what you print. Use print to peek at a value, then expose the real output via the returned DataFrame.`;


// ============================================================================
// GENERAL mode template + Python/R UDF guides
// ============================================================================

const PYTHON_UDF_INSTRUCTIONS = `## Python UDF Guide

Python UDF operators run user-defined Python code. There are 2 APIs to process data:

### Tuple API
Takes one input tuple from a port at a time. Returns an iterator of optional TupleLike instances.
Use cases: Functional operations applied to tuples one by one (map, reduce, filter).

Template:
\`\`\`python
from pytexera import *

class ProcessTupleOperator(UDFOperatorV2):
    def process_tuple(self, tuple_: Tuple, port: int) -> Iterator[Optional[TupleLike]]:
        yield tuple_
\`\`\`

Example - Filter tuples by conditions:
\`\`\`python
from pytexera import *

class ProcessTupleOperator(UDFOperatorV2):
    def process_tuple(self, tuple_: Tuple, port: int) -> Iterator[Optional[TupleLike]]:
        q = tuple_["QUANTITY"]
        oq = tuple_["ORDERED_QUANTITY"]
        p = tuple_["UNIT_PRICE"]
        if q is not None and oq is not None and p is not None:
            if q <= oq and p >= 0:
                yield tuple_
\`\`\`

### Table API
Consumes a whole Table (pandas DataFrame) from a port. Returns an iterator of optional TableLike instances.
Use cases: Blocking operations that consume the whole table.

Template:
\`\`\`python
from pytexera import *

class ProcessTableOperator(UDFTableOperator):
    def process_table(self, table: Table, port: int) -> Iterator[Optional[TableLike]]:
        yield table
\`\`\`

Example - Filter DataFrame rows:
\`\`\`python
from pytexera import *
import pandas as pd

class ProcessTableOperator(UDFTableOperator):
    def process_table(self, table: Table, port: int) -> Iterator[Optional[TableLike]]:
        df: pd.DataFrame = table
        m1 = (df["KWMENG"].notna()) & (df["KBMENG"].notna()) & (df["KWMENG"] <= df["KBMENG"])
        m2 = (df["NET_VALUE"].notna()) & (df["NET_VALUE"] >= 0)
        yield df[m1 & m2]
\`\`\`

### Important Rules

- DO NOT change the class name (ProcessTupleOperator or ProcessTableOperator).
- Import packages explicitly (pandas, numpy, etc.).
- Tuple is a Python dict. Access fields with tuple_["field"] ONLY (no .get/.set/.values).
- Table is a pandas DataFrame.
- Use yield to return results.
- Handle None values carefully.
- **Integer columns that contain nulls arrive as floats — do NOT cast them.** A pandas DataFrame cannot hold nulls in an integer column, so an integer column that contains any null arrives as \`float64\`. Calling \`.astype('int64')\` on it raises \`IntCastingNaNError\`. Leave the column as-is and just \`yield\` it: the engine reconciles a whole-number float column back to its declared integer type automatically (nulls stay null). If you instead see "Output schema mismatch: declared ... LONG ... got ... DOUBLE", the fix is NOT to force a cast — it is to leave the column alone (whole-number values bridge automatically) or, only for genuinely fractional data, to accept the DOUBLE type rather than forcing an integer.
- Do not cast types (especially numeric ones) unless the task explicitly requires it; type changes are what break the declared output schema.
- Keep each UDF focused on one task.
- Only change the python code property, not other properties.
- If adding extra columns, specify them in the Extra Output Columns property.
- Prefer native operators over Python UDF when possible.`;

const R_UDF_INSTRUCTIONS = `## R UDF Guide

R UDF operators run user-defined R code. Two modes: Table API and Tuple API.

### Table API
Passes the entire input as an R data frame to your function and expects a data frame in return.

Template:
\`\`\`r
function(table, port) {
  return(table)
}
\`\`\`

Example - Keep rows where quantities align and net value is valid:
\`\`\`r
function(table, port) {
  valid_qty <- !is.na(table$KWMENG) & !is.na(table$KBMENG) & table$KWMENG <= table$KBMENG
  valid_value <- !is.na(table$NET_VALUE) & table$NET_VALUE >= 0
  valid_rows <- valid_qty & valid_value
  return(table[valid_rows, , drop = FALSE])
}
\`\`\`

### Tuple API
Uses coro::generator to yield tuples (lists) one by one.

Template:
\`\`\`r
library(coro)

coro::generator(function(tuple, port) {
  yield(tuple)
})
\`\`\`

Example - Emit tuples that flag problematic status values:
\`\`\`r
library(coro)

coro::generator(function(tuple, port) {
  status <- tuple$STATUS
  if (!is.null(status) && status == "ERROR") {
    yield(tuple)
  }
})
\`\`\`

### Important Rules

- Return a function(table, port) for Table API; use coro::generator(function(tuple, port) { ... }) for Tuple API.
- Load libraries explicitly with library().
- Handle NA with is.na() before comparisons.
- Use yield() inside generators for each tuple to emit.
- Keep output schema consistent with Retain input columns and Extra output columns settings.
- Keep scripts focused on one task.
- Only modify the script code field unless necessary.`;

const GENERAL_MODE_TEMPLATE = `${DATAFLOW_INTRO}
${CONTEXT_FORMAT}
${KEY_PRINCIPLES}

## Available Operators

You have the following operators available:

{{OPERATOR_SCHEMA}}

**IMPORTANT**:
- You MUST try to use the native operators (e.g. TableProjection, TableAggregate, TableFilter) as much as possible.
  Only fall back to Python/R UDF if no native operator fits.
- Do NOT use Python to do aggregate, use operators like TableAggregate to do it.
- When you handle data with nulls, please explicitly mention in the summary how you handle the nulls.
- Use Join operator when you need to join two tables. Do NOT use Python to join two tables.
- If you have to use a UDF, do ONE minimum step in it (e.g. dropping records, changing one column's value).
  Do NOT do multiple things, e.g. Dropping then Aggregate then Sort.
`;

// ============================================================================
// Build helpers
// ============================================================================

function buildAllowedOperatorSchemas(
  metadataStore: WorkflowSystemMetadata,
  allowedOperatorTypes: string[] = []
): string {
  const schemas: string[] = [];

  const operatorTypes =
    allowedOperatorTypes.length > 0 ? allowedOperatorTypes : Object.keys(metadataStore.getAllOperatorTypes());

  for (const operatorType of operatorTypes) {
    const compactSchema = metadataStore.getCompactSchema(operatorType);
    const description = metadataStore.getDescription(operatorType);

    if (compactSchema) {
      schemas.push(
        `## ${operatorType}\n` +
          (description ? `Description: ${description}\n` : "") +
          `Schema:\n\`\`\`json\n${JSON.stringify(compactSchema, null, 2)}\n\`\`\``
      );
    }
  }

  return schemas.length > 0 ? schemas.join("\n\n") : "No operators available.";
}

/**
 * Build the CODE-mode system prompt for the given `contextMode`. The shared
 * body lives in `prompts/code-mode.md`; the two context-mode-dependent sections
 * (Context Format + the worked Example) are swapped in from the `*.latest.md` /
 * `*.delta.md` fragments so the prompt matches the format the agent is actually
 * fed. This is a SWITCH on the mode, not a hardcoded/both-formats blob — LATEST
 * → `# Current Dataflow` layout, DELTA → `# Agent Events` layout. Edit the .md
 * files (template + fragments), not this function.
 *
 * `compactionEnabled` (DELTA only) additionally injects the `## History
 * Compaction` section when the context-window budget is on — so the prompt
 * describes the `# Dataflow (compacted)` deck the agent will actually see once
 * its trajectory overflows the window. Off ⇒ the section is omitted (the deck
 * never renders, so describing it would be dead tokens).
 *
 * Showing the agent its own operator code is the DEFAULT. DELTA gets it for
 * free (every event carries `code:`), and under LATEST it is the
 * `enableCodeInSnapshot` default. The verbose no-code fragments are the swap,
 * used only for the one configuration where the agent genuinely cannot see its
 * own code: LATEST with the snapshot flag off.
 */
/** A4 arm (sourceProvenanceHint): multi-file loads must carry a `__source_file`
 *  column. Grounded in the gold-solution trace dive (2026-07-28): per-file
 *  identity is a load-time fact erased by concat — deriving it later from a
 *  name-suffix regex was a 0%-pass failure mode on legal-hard-29 (n=26), while
 *  file-derived grouping passed 88-100%. Rendered as one principle bullet,
 *  directly after "Load all data before subsetting"; byte-identical when off. */
const PROVENANCE_FRAGMENT =
  "\n- **Multi-file loads must carry provenance**: when one loader reads MULTIPLE files (glob/listdir), add a `__source_file` column recording each row's file before concatenating (`df['__source_file'] = path`). Grouping identity often lives ONLY in the file name (one file per state/station/year) — a row's content cannot recover which file it came from after concat, and deriving that identity from a name-suffix regex instead of the file is a known failure mode. Downstream, group by `__source_file` (or a column derived from it) whenever the question asks per-<unit> and <unit> matches the file layout.";

export function buildCodeModeSystemPrompt(
  contextMode: ContextMode = ContextMode.LATEST,
  compactionEnabled = false,
  inspectEnabled = false,
  renderPrefsEnabled = false,
  codeInSnapshotEnabled = true,
  sourceProvenanceHint = false,
  recallEnabled = false,
  resumeEnabled = false,
  versionedEnabled = false,
  sessionEnabled = false,
  opRecallEnabled = false
): string {
  const key = contextMode === ContextMode.DELTA ? "delta" : "latest";
  // The only code-blind configuration: LATEST without code in the snapshot.
  // DELTA always shows code per event, so it is never code-blind.
  const noCode = key === "latest" && !codeInSnapshotEnabled;
  const compaction = key === "delta" && compactionEnabled ? `\n${COMPACTION_FRAGMENT}\n` : "";
  const inspect = inspectEnabled ? `\n${INSPECT_FRAGMENT}\n` : "";
  // Versioned mode supersedes the recall fragment: recall.md describes the
  // `# Current Turn` / `# Dataflow` layout, which does not exist under the
  // versioned catalog. The recallState tool itself remains available either way.
  const recall = versionedEnabled
    ? `\n${opRecallEnabled ? VERSIONED_OPRECALL_FRAGMENT : VERSIONED_FRAGMENT}\n`
    : recallEnabled
      ? `\n${RECALL_FRAGMENT}\n`
      : "";
  const resume = resumeEnabled ? `\n${RESUME_FRAGMENT}\n` : "";
  const renderPrefs = renderPrefsEnabled ? `\n${RENDER_PREFS_FRAGMENT}\n` : "";
  // Context format tracks the LAYOUT the agent is fed, which is a separate axis
  // from code visibility: DELTA is always `# Agent Events`, LATEST is
  // `# Current Dataflow` with or without the per-operator Code: blocks.
  // The turn-grouped layouts REPLACE this fragment: under `# Session` the
  // legacy sections don't exist (session.md describes the layout), and under
  // the versioned `# Catalog` the layout lives in versioned.md (injected via
  // the recall slot above), so the format slot is left empty rather than
  // describing sections the agent will never see.
  const contextFormat = versionedEnabled
    ? ""
    : sessionEnabled
      ? SESSION_FRAGMENT
      : key === "delta"
        ? CONTEXT_FORMAT_FRAGMENTS.delta
        : noCode
          ? CONTEXT_FORMAT_FRAGMENTS.latest
          : CONTEXT_FORMAT_CODE_LATEST;
  const example = renderPrefsEnabled
    ? RENDER_PREFS_EXAMPLE_FRAGMENTS[key]
    : key === "delta"
      ? EXAMPLE_FRAGMENTS.delta
      : noCode
        ? EXAMPLE_FRAGMENTS.latest
        : EXAMPLE_CODE_LATEST;
  return CODE_MODE_TEMPLATE.replace(
    "{{CODE_VISIBILITY_PRINCIPLES}}",
    noCode ? PRINCIPLES_CODE_BLIND.trimEnd() : PRINCIPLES_CODE_VISIBLE.trimEnd()
  )
    .replace("{{CONTEXT_FORMAT}}", contextFormat)
    .replace("{{PROVENANCE}}", sourceProvenanceHint ? PROVENANCE_FRAGMENT : "")
    .replace("{{COMPACTION}}", compaction)
    .replace("{{INSPECT}}", inspect)
    .replace("{{RECALL}}", recall + resume)
    .replace("{{RENDER_PREFS}}", renderPrefs)
    .replace("{{EXAMPLE}}", example)
    .replace(/\n{3,}/g, "\n\n");
}

/**
 * Build the GENERAL-mode system prompt with operator schemas and, when the
 * allowed-types list permits Python or R UDFs, the corresponding UDF guide.
 */
export function buildGeneralModeSystemPrompt(
  metadataStore: WorkflowSystemMetadata,
  allowedOperatorTypes: string[] = []
): string {
  const operatorSchemas = buildAllowedOperatorSchemas(metadataStore, allowedOperatorTypes);
  const allowsAll = allowedOperatorTypes.length === 0;
  const pythonAllowed = allowsAll || allowedOperatorTypes.some(t => PYTHON_UDF_OPERATOR_TYPES.includes(t));
  const rAllowed = allowsAll || allowedOperatorTypes.some(t => R_UDF_OPERATOR_TYPES.includes(t));

  const extraSections: string[] = [];
  if (pythonAllowed) extraSections.push(PYTHON_UDF_INSTRUCTIONS);
  if (rAllowed) extraSections.push(R_UDF_INSTRUCTIONS);

  const base = GENERAL_MODE_TEMPLATE.replace("{{OPERATOR_SCHEMA}}", operatorSchemas);
  return extraSections.length > 0 ? `${base}\n${extraSections.join("\n\n")}\n` : base;
}

/**
 * Backwards-compatible alias for callers that haven't migrated yet.
 * @deprecated Use {@link buildGeneralModeSystemPrompt} or
 *   {@link buildCodeModeSystemPrompt} explicitly.
 */
export function buildSystemPrompt(metadataStore: WorkflowSystemMetadata, allowedOperatorTypes: string[] = []): string {
  return buildGeneralModeSystemPrompt(metadataStore, allowedOperatorTypes);
}

// ---------------------------------------------------------------------------
// Local-react (in-house local LLM) system prompts — one per tool-call dialect.
//
// The local LLM's tool catalog + output-format instructions are baked into its
// system prompt (no `tools` on the wire; the driver parses the model's text).
// The two dialects pair a prompt with the context renderer that prompt
// describes, so the model's stated input format matches what it actually sees:
//   - "qwen-xml"  — the CODE-mode body (`code-mode.md`, shared with the
//     vercel-tool-use driver) + the `<tools>`/`<tool_call>` appendix
//     (`local-qwen-tools.txt`), composed below. It describes the
//     `# User Task` / `# Current Dataflow` context → paired with the SDK
//     assembler `assembleContext` (server.ts).
//   - "react-text" — the standalone `local-react.txt` (plain-text tool list +
//     `Thought / Action / Action Input / Observation`, down to `Begin!`). It
//     describes the `# Event N` context → paired with `assembleLocalReactContext`.
//
// The model uses the ChatML chat template: the gateway wraps this text as
// `<|im_start|>system\n…<|im_end|>` and the per-turn context as
// `<|im_start|>user\n…<|im_end|>` automatically when the driver sends
// role-tagged messages — so NO framing/BOS tokens belong in these files.
// ---------------------------------------------------------------------------
// `qwen-xml` is NOT a standalone file: it is the CODE-mode prompt (the single
// source of truth in `code-mode.md`, shared with the vercel-tool-use driver)
// plus the XML tool-call appendix in `local-qwen-tools.txt` (the `# Tools` /
// `<tools>` catalog + `<tool_call>` output-format instructions). Composing at
// load time keeps the body in lock-step with `code-mode.md` — no drift — and
// is why the qwen-xml dialect is paired with the SDK context assembler
// (`assembleContext`, server.ts): `code-mode.md` describes the `# User Task` /
// `# Current Dataflow` context that assembler renders, so prompt and context
// agree. `react-text` keeps its standalone `# Event N` prompt + the
// `assembleLocalReactContext` renderer.
const QWEN_TOOL_APPENDIX: string = readFileSync(
  new URL("./prompts/local-qwen-tools.txt", import.meta.url),
  "utf8"
);
const REACT_TEXT_SYSTEM_PROMPT: string = readFileSync(
  new URL("./prompts/local-react.txt", import.meta.url),
  "utf8"
);
/**
 * Returns the local driver's system prompt for the given tool-call dialect.
 * `react-text` is standalone; `qwen-xml` is the CODE-mode body (mode-aware, so
 * it matches the SDK context assembler) plus the XML tool-call appendix.
 */
export function buildLocalReactSystemPrompt(
  dialect: LocalToolDialect,
  contextMode: ContextMode = ContextMode.LATEST,
  compactionEnabled = false
): string {
  if (dialect === "react-text") return REACT_TEXT_SYSTEM_PROMPT;
  return `${buildCodeModeSystemPrompt(contextMode, compactionEnabled).trimEnd()}\n\n${QWEN_TOOL_APPENDIX}`;
}
