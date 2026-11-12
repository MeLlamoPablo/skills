---
name: summarize-pr
description: Builds a simplified overview of a pull request as a Claude Artifact, so that a human can check the high-level direction of the PR without reading all of its code. Use when asked to summarize a PR, make a simplified PR overview, or when invoked as /summarize-pr.
argument-hint: "[PR number, URL or branch; default: the PR of the current branch]"
disable-model-invocation: true
---

# Summarize PR

Make one page that gives a reviewer the same confidence in the PR as reading the full PR. AI agents already review the PR and find mechanical bugs better than humans do. The human only needs to check the high-level direction, so the page shows the direction and leaves out the mechanics.

The rules have two parts:

- **Content** is subjective. You decide what to show and how to say it.
- **Form** is objective. Do not deviate from it. `template.html` and `scripts/check.mjs` already hold most of it, and a harness will take over the rest later.

The page is HTML, not a form to fill in. The template gives the blocks that most PRs need: diffs, charts, decisions and a test list. Start from them, but do not stop at them. When a block of your own (for example a table of results) shows the point of a PR better, write it (see [Freeform blocks](#freeform-blocks)).

## Steps

`${CLAUDE_SKILL_DIR}` is the folder of this file. If your agent does not replace it, use that folder.

Before step 1, run `npx -y skills check`. If it says that `summarize-pr` has an update, tell the user that `npx skills update summarize-pr -g` installs it. Then continue with this version, also when the command fails.

1. Collect the PR facts: `bash ${CLAUDE_SKILL_DIR}/scripts/gather.sh <scratchpad>/<pr> [<pr>]`. Run it from the repo of the PR. It writes `pr.json`, `description.md`, `files.tsv`, `full.diff`, `threads.json` (the review threads on the diff), `avatars.json` (the avatars of the comment authors), `removed-tests.txt` (the tests that the PR removes) and `preview-url.txt` (the production preview of a FramerStudio PR, else empty).
2. Read `description.md`, `threads.json` and the diff. Then read the changed code at the head commit until you know the contracts, the moving parts and the hot paths.
3. Select the content (see [Content](#content)). For each new file, find the deleted code that it replaces. Show only the parts that are new or changed. Write the shortened old and new code for each diff. Then ask, for each part of the story: does a freeform block show this better than the standard block (see [Freeform blocks](#freeform-blocks))? For each test that you show, read its full body at the head commit and compare it with the name and with each claim that the page makes about it (see [Tests](#tests)).
4. Rewrite the code comments you show for a reader without context (with a skill that rewrites code comments, if the repo has one). Use the rewritten text only on the page. Do not edit the repo.
5. Copy `${CLAUDE_SKILL_DIR}/template.html` to `<scratchpad>/<pr>/overview.html` and replace every `{{…}}` slot (see [Form](#form)).
6. If the page shows review threads, run `node ${CLAUDE_SKILL_DIR}/scripts/avatars.mjs <page>`. Run it again after you add or remove a comment. Then run `node ${CLAUDE_SKILL_DIR}/scripts/check.mjs <page>`. Fix every error, then run it again.
7. If the page has a chart, run `node ${CLAUDE_SKILL_DIR}/scripts/render-charts.mjs <page>`. It renders the page in headless Chrome, saves `charts/chart-<n>.png` next to the page, and reports labels and lines that overlap. Fix every error, then run it again. Then read each PNG: the main path must read from top to bottom, and the secondary boxes must be at the side. If `puppeteer-core` is missing, run `npm install --prefix ${CLAUDE_SKILL_DIR}/scripts` one time.
8. If you have no Artifact tool (in an agent other than Claude), skip steps 8–10: open the page in the browser of the user and tell them its path.
   Else, publish with the Artifact tool (icon `code`). Publish each later change from the same file path, so the URL stays the same. Everyone in the organization of the user must be able to open the page, because reviewers open it from the PR. The Artifact tool publishes it as private, and it cannot change who can open it. Thus, after the first publish, tell the user to share the page with their organization from the page’s Share menu.
9. If `gather.sh` prints `Author: <login> (you). Summary link in the description: no`, put this block at the top of the PR description:
   ```markdown
   > [!TIP]
   > Review [the summary of this PR](<artifact URL>)
   ```
   Keep the rest of the description as it is: write the block, an empty line and the output of `gh pr view <pr> --json body | jq -j .body` to a file, then run `gh pr edit <pr> --body-file <file>`. Do this only for the user's own PRs, and only one time, because the URL stays the same when you publish again. `gather.sh` leaves the block out of `description.md`, so the page does not show it and `watch.sh` does not see it as a change.
10. Act on each artifact comment: make the change, reply in the thread, resolve it. If a comment applies to more than the place it is on (for example "revisit all wordings"), apply it to the full page.
11. Watch the PR, unless the user says not to. From the repo of the PR, run `bash ${CLAUDE_SKILL_DIR}/scripts/watch.sh <scratchpad>/<pr>` in the background. Do not use a monitor tool that expires: each expiry wakes you with no change. `watch.sh` prints nothing while the PR stays the same. When the head commit, base branch, title, description, human review threads or a linked PR's state changes, it prints what changed and exits, and this wakes you. Then run `gather.sh` again into the same folder, update the page (see [Discarded ideas](#discarded-ideas)), check it, publish it to the same URL, and start `watch.sh` again. When the PR is merged or closed, `watch.sh` says so and exits. Then stop watching.

## Content

### Tell a story

The page tells one story, in this order. Leave out the steps that the PR does not have:

1. **Header:** what changed and why, and the decisions about the full PR.
2. **Flow:** how the systems connect after the change, or before and after it when the PR changes an existing flow. Only when the PR needs a flow chart (see [Charts](#charts)).
3. **Use sites:** what uses the change, and what each use did before and does after.
4. **Contract:** the types and signatures between the moving parts.
5. **One section per system part,** in the order the data moves (producer before consumer). Name each section after the system part, not after a file.
6. **Tests:** how the automated tests verify the change.

### Freeform blocks

A freeform block is HTML that the template does not have, for example a table or a matrix. Write one when it shows the point of the PR better than the standard blocks: the reader then sees the pattern at once, and does not have to collect it from many diffs or list items.

- Look for a shape of the PR that the standard blocks hide or spread out. Examples:
  - The PR runs the same tests in more than one mode, configuration or environment. One table, with a row for each test, a column for each mode and pass or fail in each cell, shows which tests pass where. It replaces the test list.
  - The PR changes the result of a function for many inputs, or the behavior of many call sites. A table shows each input or call site with its old and its new result.
  - The PR changes a cost on a hot path. A small table shows the old and the new cost.
- A freeform block replaces the standard block that shows the same thing. Do not show the same thing two times.
- Do not write a freeform block that only decorates, or that shows what a diff, a chart or one sentence shows as well.
- All the other rules apply to a freeform block: the story order, the words, the budget (each test name in it counts as a shown line) and the look of the page (see [Form](#freeform-blocks-1)).

### Use the author's words

- The PR description is written by a human. You can copy its words into the page. Use only the parts that help the reviewer check the direction.
- Put each part next to the chart or code that it explains, not in one block:
  - tl;dr → the header lede. Use **Before** / **Now** lines when it compares the two.
  - Motivation and "what was done" → a header note.
  - `[!NOTE]` blocks → callouts, next to the topic they discuss.
  - Claims about safety or revert → next to the code that makes them true (a gate claim above the gate code, a "legacy path still works" claim above the legacy branch).
  - The why of a code decision → a page comment in the shown code, above the line that it explains (see [Diffs](#diffs)).
  - Each decision of the "Decisions" section → a decision, where it applies (see [Decisions](#decisions)).
  - A before/after table → the use-sites section, with the author's lead-in sentence above it.
  - Evidence (eval runs, benchmarks) → one short sentence with the result and what it shows, and a link to the run.
  - Out of scope and follow-up work → the header, with a link. When a follow-up has no PR or issue yet, write it as a plan, in the future tense ("A later PR will add a check for …"). Do this also when the author writes it in the present tense: "A follow-up PR adds the check …" tells the reader that the PR exists.
  - PRs that this PR needs ("Stacked on #X", "Depends on #X", "Deploys with #X") → a header note, only while the linked PR is open. `gather.sh` prints the state of each PR that the description links to. A merged PR is in the base branch, so leave out its mention. Mention a merged PR only when the reader needs it to understand this PR, and then write it as history ("#X made the response flat"), not as a pending base ("Stacked on #X").
  - "Alternatives considered", and sentences such as "Doing X instead would …" → a discarded idea (see [Discarded ideas](#discarded-ideas)).
  - QA steps → leave them out. They are for the people who test the PR, not for the reviewer.
- Keep the author's words. You can only fix typos and grammar, replace code names and jargon with plain words (see [Words](#words)), cut sentences that add nothing, and drop ceremony such as section headings ("What was done"), checkboxes and filler ("In the end this is just semantics").
- Also cut internal details from the author's words: IDs (of nodes, requests or commits), internal type names, model settings, step counts and commit history. Apply this to the full page.
- Rewrite a clipped label of the author as a full sentence that names what it is. For example, "Accepts: X until Y" becomes "Trade-off: until Y, X". A label word such as "Accepts:" or "Why:" has its meaning only in the author's template, so the reader stops on it. Apply this to the full page.

### Discarded ideas

A discarded idea is an approach that an earlier version of the PR had, or that its author considered, and then dropped. The page shows it in a muted block, so that the text about the current code stands out.

- Show a discarded idea when:
  - You update the page for a new version of the PR, and the reviewer already saw the earlier approach. To find it, compare the code at the earlier head commit (`data-head-sha` of the earlier page, or the commit of the last review) with the new head, and read the edit history of the description.
  - The reader must know why the author dropped the idea to understand why the PR uses its current approach.
- Do not show a discarded idea when:
  - The earlier approach is worse than the current one in all ways, with no trade-off.
  - The earlier approach does not help the reader understand the current code.
- Keep discarded ideas apart from the text about the current code. A lede, note, callout or page comment tells only what the PR does now. A discarded idea tells only the dropped approach and why the author dropped it. When a note says "instead of X" or "X would …", move X to a discarded idea.
- The **Before** / **Now** lede compares the base branch with the PR. It is not a discarded idea.
- Put each discarded idea at the end of the section of the system part that it is about, after the current code. A discarded idea about the full PR goes at the end of the header. An alternative that the author considered for a decision goes in that decision, after its trade-off.

### Decisions

A decision is a choice that shapes the PR, and that a reviewer can want done differently. The PR template asks for them in its "Decisions" section, and reviewers find most of their review points there. Thus the page shows each one, next to what it shapes.

- Take the decisions from the "Decisions" section of the description, in the author's words. Do not add a decision that the description leaves out. When you know of one (for example, because you wrote the PR), tell the user, so that the author can add it to the description first.
- Do not collect the decisions in a section of their own. Put each decision at the top of the section of the system part that it shapes, before its code. A decision about the full PR goes at the end of the header.
- Each part of the template's collapsible has its place in the decision:
  - The choice → the title.
  - "implicit" (made while implementing, without being discussed) → the "Implicit" label. Keep the template's word, because reviewers know it from the descriptions. An explicit decision (asked for or agreed on in the conversation) gets no label.
  - "Why" → the reason, below the title.
  - "Accepts" → the trade-off, after the reason.
  - "Alternatives considered" → a discarded idea in the decision, after the trade-off.
  - "Assumptions" → an "Assumption" box after the decision that relies on it, or at the top of the section that it is about.
- Find where people discussed each decision in Slack:
  - When the decision in the description links a Slack message, use that link.
  - Else, if you have the Slack tools, search Slack. Read the threads that the description links first, then search the channel of the project with the words of the decision. Search also for its earlier titles, because reviewers quote the description when they ask about a decision.
  - Link the message where the discussion of the decision starts. Do this also when the thread is older than the PR, if it discusses the same choice.
  - Show the link only as the Slack icon in the title row. Do not also link it in the text. When you find no discussion, leave out the icon.
- If a human made a decision in such a discussion, the decision is explicit. When the description marks it as implicit, keep the label on the page and tell the user, so that the author can update the description.
- The rules of [Words](#words) apply to decisions too.

### Review threads

- ✓ An open thread that a human started (not an AI reviewer) on the current diff is always important enough to show. Show its code in a diff, and the thread on its line. Its code counts toward the budget, so cut other code before you cut it.
- ✓ Leave out a thread that an AI reviewer started, also when a human replied in it.
- An AI reviewer is a GitHub App (its login ends with `[bot]` in `threads.json`), or a user account whose comments say that an AI tool wrote them. For such a user account, set `startedByHuman` to `false` on its threads in `threads.json`, so that the check agrees.
- ✓ Leave out resolved threads and outdated threads. A resolved thread needs no more attention, and the code of an outdated thread is not in the diff anymore.
- The comments are their authors' words, so the rules of [Use the author's words](#use-the-authors-words) apply. You can cut a long AI reply to its first paragraph and drop its labels (for example "**[Possible simplification]**"). The author link opens the full comment.

### Code

- **Show:** signatures, types and contracts; the dependencies between moving parts; code on _very_ hot paths; some comments (a why or a TODO that the reviewer must know).
- **Show the message of each assert or `throw` that you show,** because it tells why the state is invalid, and that is often subtle. Cut the message (`/* ... */`) only when the condition already says it, for example `assert(idsMatch, /* ... */)`.
- **Do not show:**
  - Imports and re-exports. They are never relevant.
  - Implementation that the contract names already describe.
  - Implementation details, and comments about them.
  - Guards on the inputs (an `assert` or an early `throw` for an unknown id), and their comments, unless the PR is about that guard. An assert that keeps a rule of the product (for example, a field that a plugin manages can’t link) is not a guard on the inputs: show it.
  - _Internal_ signatures, types and contracts. They do not leave their own system, and they are mechanical.
  - Test implementations, and helpers inside a test or an eval (for example, a function that finds a node for a check).
  - The same change in more than one place (for example, each caller passes the same new argument). Show it in one place, and put the page comment `//! Same for all other callers` (or the same words for what repeats) above it, on both sides, so that it is an unchanged row. Show another place only when its change is different, for example a store that gets the value through its constructor, or the code that wires that value into the store.
  - Code that moves or gets a new name, but does not change its behavior. Do not write about it in the text either. If moved code is important for the reviewer, show it as a move: the code in its old file on the old side, and the code in its new file on the new side. Never show moved code as a new file. When a file has both new code and moved code, split it into more than one diff, so that each moved part has its own move diff. Shorten the two sides in the same way, so that their lines align. In the diff of the old file, leave the place of the moved code empty: no `// ...` and no page comment. Put the move diff before the diff of the old file, in the same section, so that the reader already knows where the code went.
  - Code that the PR extracts or splits out of a function, in the same file or into another file, for example a body that moves into a new function with a new signature. When you show it, show it as an extract: the old function on the old side, and the result (the old function, shortened, and the new function) on the new side. Shorten the two sides in the same way, so that the moved lines are unchanged rows and only the new signature and the new call are changes. ✓ Never show only the new side of code whose body existed at the base: the reader then takes it for new logic, or for a copy of other code. Before you show a new function, search for its body in its file at the merge base (`git show <merge base>:<path>`) and in the removed lines of `full.diff`: git shows most of an extract within one file as unchanged lines.
- Show, don't tell: when a sentence or a table only says what code can show, cut it and show the code, shortened. For example, a table of checks becomes the check calls, with `/* ... */` for their bodies.
- This also applies to page comments: a page comment that tells what left-out code does (for example `//! Each "field_<id>" value → row[id] = convert(value)`) is wrong. Show that code, shortened (here, the loop and its assignment). Use a page comment only for a why, to name what a `// ...` leaves out when it repeats code that the page shows (for example `//! The same for "number" and "date"`), or to say that other places make the same change as the shown one (see above).
- It also applies to the text next to a diff, also when it is the author's words: do not repeat in words what the diff or its comments already show (for example "the cached value, else the stored value, else the default" above a call to `resolveValue`). Keep only what the diff cannot show: a why, a trade-off, a cost, or a fact about code that the page does not show.
- Each comment that you show must make sense with only the shown code. When it names code that the diff leaves out (for example `// Checked before process` without the `process` call), show that code, shortened, or leave out the comment. Leave it out when that code is an implementation detail.
- Full implementations that are not shortened must be extremely rare.
- Shorten for reading, not only for line count. Also cut what the reviewer does not need inside the lines that you show, for example the type of a local variable (`const row = {}`) or a filter that is an implementation detail.
- Show where each snippet is: keep the enclosing declaration (function, class, method or config object) around it, shortened, for example `export async function handle(/* ... */) {` … `}`. Do this when the snippet is not itself a top-level declaration.
- The page diffs only the code that it shows. When you show code that is also on the other side of the diff (at the base for the new side, at the head for the old side), show it on both sides, shortened in the same way (the same `// ...` in the same places). Else it looks added or removed, also when the PR changes only one line in it. Do this also when you add code to one side in a later update of the page.
- Show both ends of each contract: where the code makes the value and where the code reads it.
- When the PR keeps a legacy path, show that the legacy branch stays (shortened). Reviewers check that old data still works.
- When the PR removes a safety net (a try/catch, a fallback), show the removed code on the old side.
- For generated code, the generated output (for example a snapshot) can show the contract better than the generator. Show the one that is easier to read.
- If the page is over the budget, cut a full diff that repeats a pattern already on the page before you cut the lines that explain a diff.

### Tests

- Show only tests that state a non-obvious property of the system, grouped by file.
- ✓ Mark each test as added, modified or removed. A test is added when its name (with its subtest name) is new in the PR, and removed when the PR deletes its name. Else it is modified.
- ✓ Show each test in `removed-tests.txt`, also when its removal looks like a mistake: a removed test changes what the tests verify, and the reviewer must agree with it. The one exception is a test that a test with a new name replaces, and that checks the same behavior (a rename, also into another file). Then show the new name instead, as modified, with `data-renamed-from` (see [Form](#tests-1)). When one new test replaces several removed tests (for example, it checks the behaviors of 2 old tests), show it once, renamed from all of them.
- Show a modified test only when the behavior that it tests changes. Leave it out when the PR changes only how the test runs (its setup, inputs, helpers, or an expected value that follows from the new code, such as a new hash), and the test still checks the same behavior.
- **Never misrepresent a test.** A reviewer trusts each test name and each claim about a test without reading the test. Thus each one must agree with the test code at the head commit:
  - Before you show a test, read its full body: the setup, the inputs, the expected values and each assertion. Do not take what a test checks from its name, from the PR description or from a commit message.
  - Compare the name with the assertions. The name must say what the test checks. A name misrepresents the test when it says something that no assertion checks, or the opposite of an assertion (for example "returns a removed field" when the test expects rows without that field).
  - For a parameterized test (`test.each`, `it.each`), make each case's name from the title with that case's values, and compare each case separately. One title can fit some cases and misrepresent others.
  - Show one name for each case. Do not merge cases into one name that you write (for example "… with all and any" for the cases "… with all" and "… with any").
  - When a code name misrepresents its test, do not show that name. Write a name in words from the assertions, as close to the code name as the assertions permit. Below the test list, add a Note callout that gives the code name and says what the test expects. Tell the user, so that the author can rename the test.
  - Take each pass, fail or skip claim (for example in a mode table) from the test markers in the code (`it.failing`, `it.skip`, the modes of the test): at the merge base for "before", and at the head commit for "now". Do not guess a result.
  - Text about the tests (notes, tables, the lede) obeys the same rules: it must agree with the assertions.
  - When you update the page for a new head commit, do these checks again for each shown test, also when its name did not change: a commit can change the body of a test and keep its name.
- ✓ Write each test name in words, as close as possible to its code name. Do not write a new name in your words, except for a code name that misrepresents its test (see above). Remove the `Test` prefix, split the name into words, use lowercase (keep acronyms such as AWS), write out abbreviations (`Cmd` → "command"), and put a subtest after a colon: `TestUpsertAliasPreservesExistingDescription` → "Upsert alias preserves existing description", `TestPreviewOrchestration/build once for both` → "Preview orchestration: build once for both". A name that is already in words (for example a Jest `it("…")` name) stays as it is.
- Do not show test code.
- When the tests run in more than one mode, show them in a table with a column for each mode (see [Freeform blocks](#freeform-blocks)). In such a table, one row can stand for a group of tests with the same result (for example the cases of parameterized tests), when their names do not help the reviewer. That row has no test name, so it cannot stand for a test in `removed-tests.txt`. Do not write a merged name in it: say what the group is (for example "2 cases of “… using %s”: all, any").

### Charts

- Charts show high-level systems, not code. If a chart reads like pseudocode, it is wrong.
- Not every page needs a chart. Add a flow chart only when the two conditions that follow are true:
  1. The PR adds or changes a link between system parts. Adding a leaf to a system that does not change is not sufficient. A new eval scenario, test or config entry usually does not change a link. A new service, a changed call path or a moved responsibility does.
  2. The link is more than a straight line: it has branches, a cycle, or many parts that interact. If the chart reads as "A, then B, then C", a sentence is better.
- A small structure (for example, a tree of a few nodes) is too simple for a chart, also when it compares the expected shape with the actual shape. Write one sentence for each shape.
- Usually 1 chart for the flow across systems. Add a second chart only if it shows a different thing, for example which job calls which new function.
- Show the flow as a before/after pair only when the PR changes a flow that already exists: it removes, reroutes or adds links between parts that exist before the PR, or moves a responsibility between them. The pair then counts as one chart. Use one chart when the PR builds a new system (the Before chart would be almost empty), adds only a leaf, or keeps the flow (a refactor). If you are not sure, use one chart.
- When arrows have the same kind of link (for example two type-only imports), give each arrow its full label. If only one arrow has the label, the reader thinks that the other arrow is a different kind of link.
- Show only the main path. Leave out edge cases such as error responses (`404`, `413`), retries and limits. If an edge case is very important for the reviewer, decide if it needs its own chart. Do not add it to the main chart.
- Box and arrow labels use plain words that a reader without context understands:
  - No code shorthand. `fn(…, config)` → "calls with the config".
  - No type notation. `config: unknown` → "config (the server does not read it)".
  - No local jargon (for example "shard", "gate") unless the page explains it (see [Words](#words)). Use the code's own name only when that name is the point.
- An arrow label is the verb of a sentence from the source box to the target box, or the name of what moves along the arrow. `CART -> ORDER [label="creates"]` reads “cart service creates order”. Do not refer to the target box with a pronoun: "creates", not "creates it".
- Keep each arrow label to a few words: "order, total", not "order of the\ncustomer, total price". Put the why, the conditions and the details in the text or the diffs, not on the arrow.
- Check each label against the code before you publish.
- Use a dashed arrow (`style=dashed`) for a legacy or fallback path. Put a TODO on the arrow that it applies to.
- Show hierarchy: the boxes and arrows of the main path use the default style. Make secondary boxes (for example shared libraries or type sources) less prominent:
  - Use one box for each secondary system. Do not split one library into many boxes.
  - Give the box `class="muted"`. The template then makes the box and all its arrows gray and thin. Keep the arrow kinds (dashed or solid) and the full labels:
    ```
    LIB [label="library" class="muted"]
    LIB -> REQ [label="Config type\n(type import only)" style=dashed]
    ```
  - Declare secondary boxes and their arrows after the main path. Graphviz then usually puts them at the side. If a PNG of `render-charts.mjs` shows a secondary box in the main column, try a different declaration order.
  - ✓ Do not use `constraint=false`. Graphviz then places the arrow labels after the layout, so they overlap.

### Words

- Use **extremely few words**. **Show, don't tell.**
- Before you write a sentence, ask: can a diff or a chart show this better? Maybe the code needs a better contract, name or comment.
- The words that you write (not the author's words) are in ASD-STE100 Simplified Technical English.
- No text on the page has jargon: not your words, not the author's words, and not the code comments that you show. Write for an engineer of the same company who does not work on this project. They know the product, the language and common technical terms (SQL, index, query plan, CI), but not the terms, code names and plans of the project. Do not explain more than that reader needs.
- Jargon is not only special terms. It is also an abstract word that hides who does what ("counterparts", "exercise", "materialize", "seam", "hydration", "semantic reference"), and a chain of nouns ("schema-free server contract"). Write a concrete subject and verb instead. For example, "These counterparts exercise the persisted models" becomes "These tests run the same cases against the real database".
- Outside the diffs, name things in plain words, not with code names (camelCase, PascalCase or snake_case names, test names, and command, function or resource names). This also applies to the author's words and to chart labels. Make the plain name from the words of the code name: split it into words and write out abbreviations. Do not make up a new name. When the reader needs the code name to find the thing, add it one time in `<code>` after the plain name: "the image resize Lambda (`image-resize`)". Keep only the code name when that name is the point, for example a flag or a URL parameter that the PR adds.
- Explain each term of the PR's domain that a reader without context does not know (for example "shadow write", a term that the PR or its stack made), also in the author's words. Explain it one time, at its first use in the page text, in a tooltip (see [Terms](#terms)), not in parentheses in the sentence. Write the explanation as one short sentence: "A write to the new table next to the write to the old table, while the data moves." Take the meaning from the code (for example the doc comment of its type) or from the PR that added the term. Keep the term, because the reader sees it again in the code and in the author's words.
- A sentence whose only job is to explain a term (for example "The sweeper is the job that …") becomes the tooltip of that term.
- Do not write about the page itself: no "selected test names", no budget text, no file counts.
- Show a cost change on a hot path (for example, queries per job) as a small table, not as prose.

## Form

The rules marked ✓ are checked by `scripts/check.mjs` or `scripts/render-charts.mjs`.

### Page

- ✓ The page is a copy of `template.html`. Fill only the `{{…}}` slots and the content between them. Do not change the `<style>` block or the module script. Freeform blocks (see [Freeform blocks](#freeform-blocks-1)) are the only HTML that the template does not have.
- ✓ No `{{…}}` slot is left in the page.
- The page is one private Claude Artifact. `<title>` and `<h1>` are the PR title, exactly as on GitHub.
- ✓ `<main>` has `data-repo-url` (`https://github.com/<owner>/<repo>`), `data-pr` (the number) and `data-head-sha` (the full SHA of the head commit). The template makes all GitHub links from these values.

### Header

- ✓ No eyebrows (small labels above headings) anywhere on the page.
- No "Pull request" label, branch name, file count, budget meter or budget text.
- ✓ `.stats` has `data-pr-additions` and `data-pr-deletions` from `pr.json`. The template shows `+shown (PR additions, faint) −shown (PR deletions, faint)`, and test names count as shown additions (removed tests as shown deletions).
- The template puts a link to the PR (`<repo>#<number> ↗`, outlined in the accent color) at the top right of the header, with the `<h1>` flowing around it. In a narrow header, the link goes below the `<h1>`. Do not add another PR link.
- One `.chip` for each experiment or flag that gates the change: `experiment: <name>`.
- Author text:
  - tl;dr: `<div class="story">` with `<p class="lede">` lines. Start them with `<b>Before</b>` / `<b>Now</b>` when it is a before/after.
  - Prose: `<p class="note">`.
  - `[!NOTE]` → `<aside class="callout"><div class="callout-label">Note</div>…</aside>`.
- A discarded idea, in the header or in a section: `<aside class="discarded"><div class="discarded-label">Discarded idea</div><p>…</p></aside>`. The template shows it muted, with a dashed line on its left.
- A decision, in the header or in a section (see [Decisions](#decisions-1)).
- Convert the Markdown to HTML: `<code>`, `<em>`, and links with `target="_blank" rel="noopener"`. A `#123` reference becomes a link to that PR or issue.
- ✓ A GitHub link text leaves out the owner when it is the owner of the PR's repo: `api#502`, not `acme/api#502`. Keep the owner for a repo of another owner. Use typographic quotes and apostrophes (’ “ ”) and `→` for `->`.

### Decisions

- ✓ Each decision is a collapsible, closed by default (no `open`):
  ```html
  <details class="decision">
  	<summary>
  		<span class="decision-label">Decision</span>
  		<span class="decision-head">
  			<span class="decision-title">…</span>
  			<span class="decision-origin" title="Made while implementing, without being discussed.">Implicit</span>
  			<a class="decision-slack" href="…" target="_blank" rel="noopener" title="Slack discussion" aria-label="Slack discussion"><svg …>…</svg></a>
  		</span>
  	</summary>
  	<div class="decision-body">
  		<p class="decision-why">…</p>
  		<p class="decision-cost"><span class="decision-label">Trade-off</span><span>…</span></p>
  	</div>
  </details>
  ```
- ✓ The summary starts with the "Decision" label and has the title. ✓ Only an implicit decision has the `.decision-origin` label, with the text "Implicit". Leave it out for an explicit decision.
- ✓ A decision links Slack only with one `.decision-slack` icon, last in `.decision-head`. ✓ Its `href` is the URL of a Slack message. Copy the full `<a>` with its `<svg>` from `template.html`. Leave it out when no Slack discussion exists.
- ✓ The body has the reason (`.decision-why`) and then the trade-off (`.decision-cost`, with the "Trade-off" label).
- A discarded idea of the decision goes in `.decision-body`, after the trade-off.
- An assumption: `<div class="assumption"><div class="decision-label">Assumption</div><p>…</p></div>`, with one `<p>` for each assumption.
- The template shows a decision as a card, with an arrow at the end of the title row that points down when the decision is open. It shows the Slack icon in gray before the arrow, and in the accent color on hover. The Implicit label, the Slack icon and the arrow are centered on the first line of the title. It shows the reason in gray, and the "Trade-off" label in the accent color, above the trade-off. It shows an assumption with a dashed border.

### Terms

- Each term is `<dfn class="term" data-tip="<explanation>">term</dfn>`, at its first use in the page text (lede, notes, callouts or tables), as the reader sees it in the sentence: `<dfn class="term" data-tip="A write to the new table next to the write to the old table, while the data moves.">shadow write</dfn>`.
- ✓ Each `<dfn>` has `class="term"` and a `data-tip`. ✓ Each term has only one `<dfn>`: write the other uses as plain text. The template finds each other use in the page text (also the plural, in any case) and gives it the same dotted underline and tooltip.
- Write the term in the `<dfn>` in its singular form. When the first use is a plural, put the `s` after the `<dfn>`: `<dfn class="term" data-tip="…">shadow write</dfn>s`.
- `data-tip` is plain text, except inline code: put a code name between backticks, as in Markdown (`` data-tip="The image resize Lambda (`image-resize`)." ``). The template shows it as inline code. ✓ No HTML, and ✓ each backtick has its pair. Use no other Markdown. Use typographic quotes (’ “ ”), never a straight `"`.
- The template does not mark terms in headings, links, inline code, diffs, charts and test names. When a term is first used there, put its `<dfn>` at its first use in the page text.
- The template shows the explanation in a tooltip on hover, on keyboard focus and on tap, with the term name as a small label. Only the `<dfn>` is in the Tab order. Do not explain the term in the sentence too.

### Sidebar

- ✓ The sidebar index has one link per `<section id>`, in page order.
- ✓ When `preview-url.txt` has a URL, put it in the `.preview-link` slot (write `&` as `&amp;`). When it is empty, remove the `.preview-link` element. Link only the production preview, never the development preview or the commit preview.
- The template gives the rest: a sticky 12px index on the left with the current section marked, the Split/Unified diff layout control below it, and the preview link below that. Split is the default, and the page keeps each viewer's choice. Below 860px (for example on a phone), the index is a row above the content, the diffs are unified, and the layout control is hidden.

### Sizes

- All text is 16px. Only the sidebar index and the small labels (Note, Discarded idea, Decision, Implicit, Trade-off, Assumption, table headers, the layout control, the ↗ link, the preview link, the comment author, the term name in a tooltip) are 12px. h1 is 28–40px and h2 is 22px. Do not add other sizes.
- Inline `<code>` has a gray background. Test names are muted until hovered. The template does both.
- The text (lede, notes, callouts, discarded ideas and test names) ends where the first `<h1>` line ends, so it leaves the same space for the PR link. Charts and diffs use the wider column. In a narrow header, the link goes below the `<h1>` and the text uses the full width. The template does this.

### Budget

- ✓ The shown lines are at most **20%** of the PR's additions + deletions. The shown lines are the added and removed rows of each shown diff (a line diff of the shown old and new code), plus the test names. Unchanged rows, blank lines and the thread text do not count, so the budget uses the same counts as the page header. Unchanged rows are still not free: show only the context that the reader needs to place the change (for example the enclosing structure), shortened as the [Code](#code) rules say.

### Diffs

- Each diff is `<figure class="diff" data-path="<repo path>" data-lang="<language>">` with `<script type="text/plain" class="old">` and `<script type="text/plain" class="new">`. A new file has only `new`, and a deleted file has only `old`. A diff can show only a part of a file, and one file can have more than one diff. Add `data-name` only to show a shorter name than the path, or to show a move: for a move, `data-path` is the new path and `data-name` is `<old path> → <new path>`.
- The template renders each diff with @pierre/diffs@1.5.2: split by default (unified below 860px), wrapped lines, no line numbers (the code is shortened), simple hunk separators, and no collapsed lines. Before the library loads, it shows a plain unified diff.
- The diff viewer, the plain diff and the budget ignore leading and trailing whitespace, as GitHub’s “Hide whitespace” does. A line that only changes its indentation (for example, code that the PR wraps in a `try` or moves into a new function) is an unchanged row, and each side keeps its own indentation. Thus show such code with its real indentation on each side, and do not shorten it only because the PR re-indents it.
- If a diff still shows the same line as removed and as added (code that the PR moves to another place in the shown code) and the reader cannot easily follow it, split the diff into smaller diffs, so that each one shows one change.
- The diff header shows the path and only `↗`, which opens the file in the PR's "Files changed" tab.
- ✓ Each code line is at most 100 columns, with a tab as 2 columns. Break long lines as the repo formatter would.
- When possible and reasonable, wrap each comment in the shown code (code comments and page comments, on both sides) at 80 columns, with a tab as 2 columns, so that it fits one side of the split view. Break at a phrase boundary, so that a short last line (for example `// first.`) does not stay alone.
- Keep the repo's indentation (tabs).
- Make each diff easy to read, also when the PR code is not. Put blank lines in the shown code as [space-around.md](space-around.md) says, on both sides of the diff. A `// ...` counts as the code that it leaves out: put a blank line after it when that code ends a step (for example a guard). Blank lines do not count toward the budget.
- Do not let the indentation jump: when the shown code is inside a block that you leave out (for example a `try`), show the block's opening and closing lines, shortened.
- Shorten with `// ...` for left-out statements and `/* ... */` for left-out expressions, parameters and types. A shortened literal must not look complete: write `{ endpoint: /* ... */, siteId, root }`, not `{ endpoint, siteId, root }`.
- ✓ No `import` lines and no `export … from` lines.
- The code must not contain `</script`.
- A page comment is a comment that is only on the page, not in the PR. Start each of its lines with `//!`. The template shows `//`, in a dim accent color, with a tooltip that says the comment is not in the code.
- ✓ A page comment never points to other code on the page, or tells where code moved from or to (for example `//! Moved to Deploy (diff above)` or `//! Old side below`). Show that code in a diff in its place: a move diff for moved code.

### Review threads

- ✓ Each thread is in the `figure.diff` of its code, after the scripts:
  ```html
  <div class="thread" data-side="new" data-line="6">
  	<div class="comment" data-author="<login>" data-href="<comment URL>"><script type="text/markdown">
  <the comment Markdown, at column 0>
  </script></div>
  </div>
  ```
  One `.comment` for each comment that you show, in thread order. Take `data-author` and `data-href` from `threads.json`.
- ✓ `data-side` is `old` or `new` (the `side` in `threads.json`). ✓ `data-line` is a line of the shown code on that side, counted from 1 in the shortened code, not in the file. Use the last line of the thread's range, as GitHub does.
- ✓ Keep each comment in GitHub Markdown, as `body` in `threads.json` has it, with the edits that [Review threads](#review-threads) allows. Start its lines at column 0, because Markdown reads an indented line as code. The template renders it as GitHub does: quotes, lists, code blocks, links, and `#123` and `@login` references. It shows raw HTML as text, so cut HTML from the comment (for example a `<details>` block or a badge).
- The template shows the thread under its line (in the diff viewer and in the plain diff), and the author name links to the comment on GitHub.
- The template shows each author's GitHub avatar from the `#avatars` JSON block. The artifact host blocks external images, so `avatars.mjs` writes this block with the avatars as data URIs. Do not write or change it by hand. ✓ The check warns when a comment author has no avatar.

### Charts

- ✓ Each chart is `<div class="chart" data-links='{"<box id>": "<repo path>#L<n>"}'><script type="text/plain" class="dot">digraph { … }</script></div>`, in Graphviz DOT.
- The template draws each chart with Graphviz (@viz-js/viz@3.31.0) in the page colors. Graphviz lays out each arrow label like a box, so labels do not overlap. ✓ `render-charts.mjs` checks this on the rendered chart.
- Top to bottom by default. Add `rankdir=LR` only when top to bottom makes the chart too wide (for example, many long names side by side).
- Write only boxes and arrows: `ID [label="…"]` and `A -> B [label="…"]`. Write `\n` for a line break in a label. ✓ Do not set `shape`, `color`, `fillcolor`, `fontcolor`, `fontname`, `fontsize`, `penwidth` or `bgcolor`: the template sets how boxes and arrows look.
- Box ids are short and uppercase (`API`, `DB`, `UI`).
- `data-links` gives each box its link. ✓ Each id in `data-links` is a box in that chart.
- Link each box that is a code location. Link to a range with `#L<a>-L<b>`.
- A before/after pair is `<div class="chart-pair">` with two `<div>`s. Each `<div>` has `<p class="lede"><b>Before</b></p>` or `<p class="lede"><b>Now</b></p>`, and then its chart. Do not add a note that explains the colors: the labels and the colors already say it. The template puts the two charts side by side when they fit, else one above the other.
  - The Before chart has only the boxes of the old flow, and the Now chart has only the boxes of the new flow. ✓ Do not add a box with only hidden arrows to align the layouts: the reader sees each box as a part of that flow. The one exception is a box that the PR removes from the flow. The Now chart keeps it with `class="removed"` and only hidden arrows (`A -> B [style=invis]`), so that the reader sees what went away, and the box stays in its old place. When its code stays in the repo, say so in its label: `"Session cache\n(checkout no longer uses it)"`.
  - Declare the boxes in the same order in both charts, so that the layouts match. In the Before chart, write each arrow that the PR adds between two boxes of the old flow as `A -> B [style=invis]`.
  - ✓ Give `class="added"` to each arrow and box that the PR adds (in the Now chart), and `class="removed"` to each one that the PR removes (in the Before chart, and each removed box also in the Now chart). An arrow whose label changes is removed in Before and added in Now. Do not mark what does not change. ✓ Use these classes only in a pair.

### Tests

- Tests are `<div class="tests">` with one `<div data-path="<test file>">` for each file, containing `<ul><li data-line="<n>" data-change="added">plain test name</li></ul>`. ✓ `data-line` is the line of the test in the head commit. For a removed test, `data-path` and `data-line` are its path and line at the merge base, as in `removed-tests.txt`. ✓ `data-change` is `added`, `modified` or `removed`. ✓ A renamed test (see [Content](#tests)) is `modified` and has `data-renamed-from="<path>:<line>"` from its line in `removed-tests.txt`. A test that replaces several removed tests lists all of them, with a space between them. The template adds the file heading and the links, and puts a green `+` (added), an orange `~` (modified) or a red `−` (removed) in place of the bullet, with a tooltip that says which.
- A test table (see [Content](#tests)) is a `<table>` in place of the `<ul>`, in the same `<div data-path>`. Put each test name in its own `<td data-line="<n>" data-change="…">`, with the same attributes as the `<li>` and only the name in it. The template then gives the cell the same link and change mark as a list item, and ✓ the check counts it in the same way. The other cells and rows are yours.
- The section heading is "Tests", with no other label.

### Freeform blocks

- Write plain HTML at the place of the block in the story. Use the template's elements where they fit: `<table>` (in `<div class="table-wrap">` when it can be wider than a phone), `<code>`, `<dfn class="term">` and links.
- When the block needs its own CSS, put one `<style>` element right before the block. Start each selector with a class of the block (`.mode-results td`). Use only the template's color variables (`--ink`, `--muted`, `--rule`, `--accent`, `--accent-soft`, `--add`, `--del`, `--fb-add-bg`, `--fb-del-bg`, `--code-bg`), so that dark mode works, and only the sizes of [Sizes](#sizes).
- Do not change the template's `<style>` block or module script, and add no scripts. The template runs no code for a freeform block, except for the test names of a test table.
- Do not show a state only with color. Also write a word or a symbol (for example ✓ and ✗), with a `title` that says it in words.

### Links

- The PR link in the header opens the PR's conversation.
- The preview link in the sidebar opens the production preview deploy of the PR.
- Diffs link to the PR's "Files changed" tab, so they always show the latest code. Test names link to their line in that tab.
- Comment authors link to their comments on GitHub.
- Chart boxes link to permalinks at `data-head-sha`, with line numbers from that commit. When the PR gets new commits, update `data-head-sha`, the line numbers of chart boxes and tests, and `.stats`.

## Changing the template

- @pierre/diffs docs: https://diffs.com/llms-full.txt. A web fetch can return only part of it. The `.d.ts` files in the npm package are the full API (`curl` the registry tarball if `npm pack` fails).
- Viz.js API: https://viz-js.com/api/. Graphviz attributes: https://graphviz.org/doc/info/attrs.html. In the rendered SVG, a box is a `g.node` and an arrow with its label is a `g.edge`. Each has a `<title>` (the box id, or `<id>-><id>`), which the template reads and then removes.
- Do not let the artifact host render the charts: it renders `<pre class="mermaid">` with its own Mermaid runtime, and measures the text before the page font loads.
- After a change, run `node --check` on the module script, and `scripts/check.mjs` and `scripts/render-charts.mjs` on a real page.
