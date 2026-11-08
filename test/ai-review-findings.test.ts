import { afterAll, beforeAll, describe, expect, test } from "bun:test";
import { mkdirSync, mkdtempSync, readFileSync, rmSync, writeFileSync } from "fs";
import { tmpdir } from "os";
import { join } from "path";

import { AI_REVIEW_REQUIRED_EXIT, buildReviewPrompt } from "../lib/scaffold/ai-review-step";
import { stripJsComments } from "../lib/strip-js-comments";
import type { AiReviewUnmeasuredReason } from "../lib/scaffold/ai-review-findings";
import {
  AI_REVIEW_BLOCKING_REQUIRED_FIELDS,
  AI_REVIEW_DETAIL_MAX,
  AI_REVIEW_FINDING_FIELDS,
  AI_REVIEW_FINDINGS_KEY,
  AI_REVIEW_SEVERITIES,
  AI_REVIEW_VERDICT_KEY,
  SEVERITY_RANK,
  UNTAGGED_RANK,
  tagOrder,
  advisoryNotice,
  aiReviewExitCode,
  aiReviewRefusal,
  aiReviewScopeLine,
  escapeAnnotation,
  findingTag,
  main,
  readAiReviewFindings,
  readAiReviewFindingsFile,
  scopeMeasured,
  renderFinding,
  severityBlocks,
  unrunTestClaim,
} from "../lib/scaffold/ai-review-findings";

/**
 * Covers AC-8a, AC-8b, AC-8c, AC-8d (#631 — the AI review findings contract).
 *
 * The defect this file exists against is #295, named in the issue: the reader
 * asked for `reading.broken`, a key no writer ever produced, so the list was
 * empty on every run and every FAIL fell through to "no broken ids were
 * recorded". An absent key reads as an empty list reads as clean. So the key
 * is declared ONCE in the module and asserted to be spelled once — a second
 * literal is a second contract, and the two can drift without either side
 * failing to compile.
 *
 * The blocking decision is computed from the findings' SEVERITIES. The agent's
 * verdict word never decides it; it is read only to notice that the agent
 * contradicted its own payload. `prevalidationViolations` in
 * `gates/workflow.test.ts` is the shape being copied: "a PASS carrying broken
 * ids is a contradiction, not a pass".
 */

const MODULE_PATH = join(import.meta.dir, "..", "lib", "scaffold", "ai-review-findings.ts");
const source = readFileSync(MODULE_PATH, "utf-8");

/**
 * The contract's declaring module — `ai-review-step.ts`, beside the prompt.
 *
 * AC-8a's claim is "one declaration, one spelling", and the population it has
 * to hold over is BOTH modules. Scanning only the reader would let the key be
 * re-typed in the writer, which is the two-contracts state the criterion is
 * about, pointing the other way. The pair is scanned as one document.
 */
const CONTRACT_PATH = join(import.meta.dir, "..", "lib", "scaffold", "ai-review-step.ts");
const contractSource = readFileSync(CONTRACT_PATH, "utf-8");
const bothSources = `${contractSource}\n${source}`;

let SCRATCH = "";

beforeAll(() => {
  SCRATCH = mkdtempSync(join(tmpdir(), "ai-review-findings-"));
});

afterAll(() => {
  if (SCRATCH) rmSync(SCRATCH, { recursive: true, force: true });
});

let fixtureSeq = 0;

/** Write a findings document to disk and return its path. */
function fixtureFile(body: string): string {
  const path = join(SCRATCH, `findings-${fixtureSeq++}.json`);
  writeFileSync(path, body);
  return path;
}

/**
 * The lines `main` writes to stderr, as GitHub's parser would see them.
 *
 * Counting LINES is the whole measurement. An in-process assertion that the
 * string "does not contain a newline" would be satisfied by a reader that
 * dropped the hostile value entirely, and asserting on the composed refusal
 * instead of on what reaches the stream would skip the one hop — the
 * `console.error` interpolation — where the encoding has to happen.
 */
function captureStderr(fn: () => unknown): string[] {
  const written: string[] = [];
  const original = console.error;
  console.error = (...args: unknown[]) => void written.push(args.map(String).join(" "));
  try {
    fn();
  } finally {
    console.error = original;
  }
  return written.join("\n").split("\n").filter(l => l.length > 0);
}

// ── AC-8a: one declaration, one spelling ─────────────────────────────────
//
// The scanner looks for the key as a QUOTED LITERAL or as a property access,
// over a comment-stripped copy: the word is all over the prose of that module
// and prose is not a contract. Every read of the key in the module goes
// through `obj[AI_REVIEW_FINDINGS_KEY]`, so the declaration's own initializer
// is the only spelling that survives the strip.

export function keySpellings(src: string): string[] {
  const code = stripJsComments(src);
  return (code.match(/(["'`])findings\1|\.findings\b|\bfindings\s*:/gi) || []).map(m => m.trim());
}

describe("AC-8a: the findings key is declared once and spelled once", () => {
  test("AC-8a: the constant is exported and assigned exactly once", () => {
    // Over the PAIR. An `export const` in each module compiles, reads
    // correctly in either diff, and is two contracts.
    const decls = stripJsComments(bothSources).match(/AI_REVIEW_FINDINGS_KEY\s*=/g) || [];
    expect(
      decls.length,
      "more than one assignment to AI_REVIEW_FINDINGS_KEY across the reader " +
        "and its contract module — a second one is a second contract, and the " +
        "writer can satisfy either",
    ).toBe(1);
    expect(contractSource).toContain("export const AI_REVIEW_FINDINGS_KEY");
    expect(AI_REVIEW_FINDINGS_KEY.length, "the key is empty").toBeGreaterThan(0);
  });

  test("AC-8a: the reader re-exports the contract rather than restating it", () => {
    // The direction is forced: ai-review-step.ts carries no relative imports,
    // because test/ai-review-scaffold.test.ts runs a mutant copy of it from a
    // temp directory. So the contract cannot live in the reader.
    expect(
      stripJsComments(contractSource),
      "the contract module imports the reader — the mutant copy will not resolve",
    ).not.toMatch(/from\s+["']\.\//);
    expect(stripJsComments(source)).toMatch(
      /import\s*\{[^}]*AI_REVIEW_FINDINGS_KEY[^}]*\}\s*from\s*["']\.\/ai-review-step["']/s,
    );
  });

  test("AC-8a: the key is spelled exactly once across both modules", () => {
    const spellings = keySpellings(bothSources);
    expect(
      spellings.length,
      `the key is spelled ${spellings.length} times (${spellings.join(", ")}) — ` +
        `every read must go through AI_REVIEW_FINDINGS_KEY`,
    ).toBe(1);

    // …and the one spelling is the declaration's own initializer, not some
    // other site that happens to be the only one left.
    expect(stripJsComments(contractSource)).toMatch(
      new RegExp(`AI_REVIEW_FINDINGS_KEY\\s*=\\s*["']${AI_REVIEW_FINDINGS_KEY}["']`),
    );
  });

  test("AC-8a: a second literal fails this case — the mutation, performed", () => {
    // Proving the guard above can fail. The cheapest way a second spelling
    // arrives is somebody inlining the key at a read site, so that is the
    // mutation: one `[AI_REVIEW_FINDINGS_KEY]` read replaced by the literal.
    //
    // The mutation is applied to the COMMENT-STRIPPED copy. Applied to the
    // raw source it lands on the first match, which is the constant's own
    // docstring, and a mutation the scanner strips back out is a mutation
    // that was never applied.
    const code = stripJsComments(bothSources);
    const mutated = code.replace(/\[\s*AI_REVIEW_FINDINGS_KEY\s*\]/, `["${AI_REVIEW_FINDINGS_KEY}"]`);
    expect(
      mutated,
      "could not build the mutant: no `[AI_REVIEW_FINDINGS_KEY]` read in the pair",
    ).not.toBe(code);
    expect(keySpellings(mutated).length).toBe(2);
  });
});

/**
 * A CONTRACT-COMPLETE finding, built from the field map (#1166).
 *
 * Every blocking fixture below is built from this rather than hand-typed,
 * and the reason is the paragraph under AC-8e: before #1166 the suite's
 * blocking fixtures carried a `severity` and a `title` the contract never
 * declares, and the reader adjudicated them BLOCKED anyway. So the cases
 * below asserted their properties over payloads no reviewer was ever asked
 * to write — the fixtures satisfied the assertion through a path the real
 * contract never takes, which is the sentence AC-8e was written to stop
 * being true and which was still true of the fixtures saying it.
 *
 * `over` is how a case removes or varies exactly one field, so the pair
 * discipline survives: `blockingFinding("high", { summary: undefined })`
 * differs from the control in one member and nothing else.
 */
function blockingFinding(
  severity: string,
  over: Record<string, unknown> = {},
): Record<string, unknown> {
  const f = AI_REVIEW_FINDING_FIELDS;
  const base: Record<string, unknown> = {
    [f.severity]: severity,
    [f.file]: "lib/scaffold/ai-review-findings.ts",
    [f.line]: 1,
    [f.summary]: "x",
    [f.failureScenario]: "a payload with no file, and a maintainer with nothing to read",
  };
  for (const [k, v] of Object.entries(over)) {
    if (v === undefined) delete base[k];
    else base[k] = v;
  }
  return base;
}

/** One payload, built from `blockingFinding`. */
function payloadOf(verdict: string, findings: Record<string, unknown>[]): string {
  return JSON.stringify({
    [AI_REVIEW_VERDICT_KEY]: verdict,
    [AI_REVIEW_FINDINGS_KEY]: findings,
  });
}

// ── AC-8e: the fields a finding carries are one contract, not two ────────
//
// Wave 2's HIGH finding, which is #295 again with a different key. The reader
// interpolated `finding.title`; the prompt never asks any writer for a
// `title`, so every real refusal read `finding 0 is critical: (untitled)` —
// no file, no line, no summary. Every fixture in this file hand-typed
// `title`, so none of them could witness it: the fixtures satisfied the
// assertion through a path the real contract never takes.

describe("AC-8e: a finding renders through the fields the prompt asks for", () => {
  test("AC-8e: a fixture built from the prompt's own field list renders in full", () => {
    // Built FROM the contract, not typed beside it. A fixture that spells its
    // own keys is a fixture that cannot notice the two drifting apart, which
    // is exactly how the defect survived a green suite.
    const f = AI_REVIEW_FINDING_FIELDS;
    const finding: Record<string, unknown> = {
      [f.severity]: "critical",
      [f.file]: "lib/scaffold/ai-review-findings.ts",
      [f.line]: 235,
      [f.summary]: "the reader interpolates a key no writer produces",
      [f.failureScenario]: "a real payload renders as (untitled)",
    };
    const r = readAiReviewFindings(
      JSON.stringify({ [AI_REVIEW_VERDICT_KEY]: "BLOCK", [AI_REVIEW_FINDINGS_KEY]: [finding] }),
    );
    expect(r.outcome).toBe("BLOCKED");

    const refusal = aiReviewRefusal(r) ?? "";
    expect(refusal, "the annotation names no file").toContain(String(finding[f.file]));
    expect(refusal, "the annotation names no line").toContain(String(finding[f.line]));
    expect(refusal, "the annotation names no defect").toContain(String(finding[f.summary]));
    expect(refusal, "a placeholder leaked into a fully-populated finding").not.toContain(
      "(no summary recorded)",
    );
  });

  test("AC-8e: the wave-2 payload — the one the prompt never asks for — is named as missing", () => {
    // The pair varies ONE thing: which key carries the sentence. A finding
    // whose summary lives under `title` is what the defective reader rendered
    // happily, so the reading must now say the summary is absent rather than
    // quietly printing a severity and nothing else.
    const f = AI_REVIEW_FINDING_FIELDS;
    const payload = (key: string) =>
      payloadOf("BLOCK", [
        blockingFinding("critical", { [f.summary]: undefined, [key]: "creds in a log" }),
      ]);
    const contract = payload(f.summary);
    const legacy = payload("title");

    // Compared as PARSED objects and not as strings. Both sides are now
    // built from the contract map (#1166), so the member the pair varies is
    // re-inserted at a different position on each side and a byte compare
    // reports an ordering difference as a second difference. The property is
    // about which KEY carries the sentence, so it is asserted over the key
    // sets: one member differs, and the value under it is the same.
    const keysOf = (doc: string) =>
      Object.keys((JSON.parse(doc)[AI_REVIEW_FINDINGS_KEY] as Record<string, unknown>[])[0]).sort();
    const only = (a: string[], b: string[]) => a.filter(k => !b.includes(k));
    expect(only(keysOf(contract), keysOf(legacy)), "the pair varies more than one member").toEqual([
      f.summary,
    ]);
    expect(only(keysOf(legacy), keysOf(contract))).toEqual(["title"]);

    expect(aiReviewRefusal(readAiReviewFindings(contract))).toContain("creds in a log");

    // #1166 strengthened the second half. The legacy finding used to render
    // as `(no summary recorded)` and still adjudicate BLOCKED, which is the
    // whole of #1166: a blocking finding with no summary cost a placeholder
    // in an annotation and decided exactly what a real one decided. It is
    // now a reading of its own and the refusal names the member that is
    // missing, so the reviewer is told what to produce rather than the
    // maintainer being told there is nothing to read.
    const legacyReading = readAiReviewFindings(legacy);
    expect(legacyReading.outcome).toBe("UNMEASURED");
    expect(legacyReading.unmeasuredReasons).toContain("BLOCKING_FINDING_INCOMPLETE");
    const legacyRefusal = aiReviewRefusal(legacyReading) ?? "";
    expect(
      legacyRefusal,
      "a finding carrying no contract field still reads as a reported defect",
    ).toContain(f.summary);
    expect(legacyRefusal, "the placeholder is back, so the contract is unenforced").not.toContain(
      "(no summary recorded)",
    );
  });

  test("AC-8e: every field the prompt declares is a field the reader reads", () => {
    // Both directions. The prompt's JSON shape is generated from the map, so
    // a field added to one end and not the other cannot appear here — but a
    // field dropped from the PROMPT while the reader still reads it would be
    // a reader looking for a key nobody is asked to produce, which is the
    // defect itself.
    const prompt = buildReviewPrompt();
    for (const name of Object.values(AI_REVIEW_FINDING_FIELDS)) {
      expect(prompt, `the prompt never asks any writer for '${name}'`).toContain(`"${name}"`);
    }
  });
});

// ── AC-8f: a finding cannot forge a workflow command ─────────────────────

describe("AC-8f: values are percent-encoded before reaching an annotation", () => {
  test("AC-8f: a newline-bearing finding produces exactly one log line", () => {
    // Measured on wave 2 at 22c9da89, not reasoned about: this payload made
    // the reader emit `::stop-commands::deadbeef` as its own line, which
    // disables all subsequent workflow-command processing — so the `::error`
    // the job depends on is never parsed and a BLOCKED review is
    // indistinguishable from a clean one.
    const f = AI_REVIEW_FINDING_FIELDS;
    const hostile = "benign\n::stop-commands::deadbeef\n::notice::all clear";
    const r = readAiReviewFindings(
      payloadOf("BLOCK", [blockingFinding("critical", { [f.summary]: hostile })]),
    );
    expect(r.outcome, "the hostile payload was not even read as blocking").toBe("BLOCKED");

    const lines = captureStderr(() =>
      main([fixtureFile(payloadOf("BLOCK", [blockingFinding("critical", { [f.summary]: hostile })]))]),
    );
    expect(lines.length, `the annotation spans ${lines.length} lines:\n${lines.join("\n")}`).toBe(1);

    // GitHub parses a workflow command only at the START of a line, so the
    // property is positional, not textual: the reviewer's words may contain
    // `::stop-commands::` and that is fine — what must never happen is a line
    // BEGINNING with one. Asserting mere absence of the substring would be a
    // detector narrower than what it detects, and would also pass over a
    // reader that silently dropped the finding's text.
    const commandLines = lines.filter(l => /^\s*::/.test(l));
    expect(commandLines.length, `${commandLines.length} workflow commands emitted`).toBe(1);
    expect(commandLines[0].startsWith("::error title=")).toBe(true);
    expect(lines[0], "the content was dropped rather than encoded").toContain("%0A");
    expect(lines[0], "the reviewer's own words were discarded").toContain("deadbeef");
  });

  test("AC-8f: nothing is double-encoded — one escaper, applied once", () => {
    // Two escapers in sequence turn `%` into `%2525`, which renders in the
    // annotation as literal `%25` and is invisible until someone reads a log.
    // So `renderFinding` deliberately does not escape, and this is the case
    // that notices if it starts.
    const f = AI_REVIEW_FINDING_FIELDS;
    const lines = captureStderr(() =>
      main([
        fixtureFile(payloadOf("BLOCK", [blockingFinding("critical", { [f.summary]: "100% of runs" })])),
      ]),
    );
    expect(lines.length).toBe(1);
    expect(lines[0], "the percent sign was encoded twice").not.toContain("%2525");
    expect(lines[0]).toContain("100%25 of runs");
  });

  test("AC-8f: the escaper is reachable and encodes all three characters", () => {
    // A unit over the binding, because the two cases above would also pass
    // over an implementation that stripped the characters instead of
    // encoding them — and stripping loses the reviewer's own words.
    expect(escapeAnnotation("a%b\rc\nd")).toBe("a%25b%0Dc%0Ad");
  });

  test("AC-8f: the detail of one finding is capped", () => {
    const f = AI_REVIEW_FINDING_FIELDS;
    const line = renderFinding(0, {
      [f.severity]: "critical",
      [f.file]: "x.ts",
      [f.line]: 1,
      [f.summary]: "y".repeat(5_000),
    });
    expect(line.length, "a megabyte of agent prose reached the annotation").toBeLessThanOrEqual(
      AI_REVIEW_DETAIL_MAX + 1,
    );
  });
});

// ── AC-8b: absent, unparseable, and missing-the-key are all UNMEASURED ───

describe("AC-8b: a findings file that cannot be read is UNMEASURED, and refuses", () => {
  const cases: Array<
    [string, () => ReturnType<typeof readAiReviewFindings>, AiReviewUnmeasuredReason]
  > = [
    [
      "absent",
      () => readAiReviewFindingsFile(join(SCRATCH, "no-such-file.json")),
      "FINDINGS_FILE_ABSENT",
    ],
    [
      "unparseable",
      () => readAiReviewFindingsFile(fixtureFile('{"verdict": "PASS", ')),
      "FINDINGS_UNPARSEABLE",
    ],
    [
      "well-formed, no declared key",
      () => readAiReviewFindingsFile(fixtureFile('{"verdict": "PASS", "results": []}')),
      "FINDINGS_KEY_ABSENT",
    ],
  ];

  for (const [label, read, reason] of cases) {
    test(`AC-8b: ${label} reads UNMEASURED and refuses`, () => {
      const r = read();
      expect(r.outcome, `${label} did not read UNMEASURED`).toBe("UNMEASURED");
      expect(r.unmeasuredReasons, `${label} named no reason`).toContain(reason);
      expect(r.blocked, `${label} derived a blocking decision it cannot have`).toBeNull();
      expect(aiReviewExitCode(r), `${label} did not refuse`).toBe(AI_REVIEW_REQUIRED_EXIT);
      const refusal = aiReviewRefusal(r);
      expect(refusal, `${label} refused without saying why`).not.toBeNull();
      expect(refusal).toContain("UNMEASURED");
    });
  }

  test("AC-8b: none of the three reads clean", () => {
    // Stated as its own case because that is the claim: three different
    // failures, zero of them indistinguishable from a review that found
    // nothing. A clean reading exits 0 and refuses nothing.
    for (const [label, read] of cases) {
      const r = read();
      expect(r.outcome, `${label} read CLEAN`).not.toBe("CLEAN");
      expect(aiReviewExitCode(r), `${label} exited 0`).not.toBe(0);
    }
  });

  test("AC-8b: an empty findings list is CLEAN, so UNMEASURED is not unconditional", () => {
    const r = readAiReviewFindings(`{"${AI_REVIEW_VERDICT_KEY}": "PASS", "findings": []}`);
    expect(r.outcome, `an honest clean review refused: ${r.unmeasuredReasons.join(", ")}`).toBe(
      "CLEAN",
    );
    expect(aiReviewExitCode(r)).toBe(0);
    expect(aiReviewRefusal(r)).toBeNull();
  });

  test("AC-8b: a finding with no severity is UNMEASURED, not non-blocking", () => {
    // The #295 trap one level down: an absent severity must not read as a
    // severity that does not block.
    const r = readAiReviewFindings('{"verdict": "PASS", "findings": [{"title": "x"}]}');
    expect(r.outcome).toBe("UNMEASURED");
    expect(r.unmeasuredReasons).toContain("SEVERITY_ABSENT");
    expect(r.blocked).toBeNull();
  });

  test("AC-8b: an unrecognised severity is UNMEASURED, not non-blocking", () => {
    const r = readAiReviewFindings(
      '{"verdict": "PASS", "findings": [{"severity": "spicy", "title": "x"}]}',
    );
    expect(r.outcome).toBe("UNMEASURED");
    expect(r.unmeasuredReasons).toContain("SEVERITY_UNRECOGNISED");
    expect(severityBlocks("spicy"), "an unknown severity must not classify").toBeNull();
  });
});

// ── AC-8c: a PASS carrying a blocking finding is a contradiction ─────────

describe("AC-8c: a verdict contradicting its own payload is refused", () => {
  test("AC-8c: PASS with a blocking finding is a contradiction, not a pass", () => {
    const r = readAiReviewFindings(
      payloadOf("PASS", [blockingFinding("critical", { summary: "creds in a log" })]),
    );
    expect(
      r.outcome,
      "a PASS carrying a blocking severity was waved through — this is the " +
        "fail-open that survives every test written only against the happy path",
    ).toBe("CONTRADICTION");
    expect(aiReviewExitCode(r)).toBe(AI_REVIEW_REQUIRED_EXIT);
    expect(aiReviewRefusal(r)).toContain("contradict");
    expect(r.blocked, "the severities still decide, contradiction or not").toBe(true);
  });

  test("AC-8c: BLOCK with nothing blocking is the same contradiction, other way round", () => {
    const r = readAiReviewFindings(
      '{"verdict": "BLOCK", "findings": [{"severity": "low", "title": "a nit"}]}',
    );
    expect(r.outcome).toBe("CONTRADICTION");
    expect(r.blocked).toBe(false);
    expect(aiReviewExitCode(r)).toBe(AI_REVIEW_REQUIRED_EXIT);
  });

  test("AC-8c: an agreeing verdict is not a contradiction", () => {
    // Without this the contradiction could be unconditional, and the word
    // would stop meaning anything.
    const blocking = readAiReviewFindings(payloadOf("BLOCK", [blockingFinding("high")]));
    expect(blocking.outcome).toBe("BLOCKED");
    const clean = readAiReviewFindings(
      '{"verdict": "PASS", "findings": [{"severity": "low", "title": "x"}]}',
    );
    expect(clean.outcome).toBe("CLEAN");
    expect(aiReviewExitCode(clean)).toBe(0);
  });
});

// ── AC-8d: the severities decide; the verdict word does not ──────────────

describe("AC-8d: the blocking decision is computed from the severities", () => {
  test("AC-8d: the verdict table declares at least one blocking and one advisory severity", () => {
    const values = Object.values(AI_REVIEW_SEVERITIES);
    expect(values.filter(Boolean).length, "no severity blocks anything").toBeGreaterThan(0);
    expect(values.filter(v => !v).length, "every severity blocks").toBeGreaterThan(0);
  });

  test("AC-8d: a pair varying ONLY the verdict word decides the same way", () => {
    // #585's pair discipline: one document is written, the other is DERIVED
    // from it by replacing the verdict word, so the pair cannot carry a second
    // difference. Two hand-written literals could.
    const blockDoc = payloadOf("BLOCK", [blockingFinding("critical")]);
    const passDoc = blockDoc.replace('"BLOCK"', '"PASS"');
    expect(passDoc, "the derivation changed nothing").not.toBe(blockDoc);
    expect(
      passDoc.replace('"PASS"', '"BLOCK"'),
      "the pair differs in more than the verdict word",
    ).toBe(blockDoc);

    const a = readAiReviewFindings(blockDoc);
    const b = readAiReviewFindings(passDoc);
    expect(a.blocked, "the verdict word changed the blocking decision").toBe(b.blocked);
    expect(a.blocked).toBe(true);
    expect(a.blockingReported?.length).toBe(1);
    expect(b.blockingReported?.length).toBe(1);
    // Both refuse. One is a block, one is a block plus a lie about it.
    expect(aiReviewExitCode(a)).toBe(AI_REVIEW_REQUIRED_EXIT);
    expect(aiReviewExitCode(b)).toBe(AI_REVIEW_REQUIRED_EXIT);
  });

  test("AC-8d: a fixture file on disk carrying a real blocking finding turns the case red", () => {
    const blocking = payloadOf("BLOCK", [
      { severity: "low", title: "a nit" },
      blockingFinding("critical", {
        summary: "the credentials file is echoed into the job log",
      }),
    ]);
    const path = fixtureFile(blocking);
    const r = readAiReviewFindingsFile(path);
    expect(r.outcome, `${path} did not block`).toBe("BLOCKED");
    expect(r.blocked).toBe(true);
    expect(r.blockingReported?.length, "the advisory finding was counted as blocking").toBe(1);
    expect(aiReviewExitCode(r)).toBe(AI_REVIEW_REQUIRED_EXIT);
    expect(aiReviewRefusal(r)).toContain("critical");

    // Vary exactly one field — the severity of the one blocking finding —
    // and the decision flips. Same verdict word, same number of findings.
    const advisory = blocking.replace('"critical"', '"low"');
    expect(advisory, "the derivation changed nothing").not.toBe(blocking);
    const lowered = readAiReviewFindingsFile(fixtureFile(advisory));
    expect(lowered.blocked, "the severity did not decide").toBe(false);

    // It still refuses, because the verdict now disagrees with its payload.
    // Bringing the verdict back into line is what makes the file green, and
    // that is a SECOND field, changed in its own step so the two are not one
    // assertion.
    const green = readAiReviewFindingsFile(fixtureFile(advisory.replace('"BLOCK"', '"PASS"')));
    expect(green.outcome, "lowering the severity did not clear the block").toBe("CLEAN");
    expect(aiReviewExitCode(green)).toBe(0);
  });
});

// ── #1178: a CONTRADICTION must emit the findings it counted ─────────────
//
// The reported shape is `BLOCK over 0 of 1 blocking finding(s)` — seen on
// run 39770912983 (PR #1150) and run 39795440261 (PR #1165), and measured at
// roughly 6 of the last 20 `ai-review` runs. The verdict word says BLOCK, the
// severities say nothing blocks, so the reading is CONTRADICTION and the job
// refuses. That part is correct and this section does not touch it.
//
// What was wrong is that the refusal printed the ARITHMETIC ALONE. `detail`
// is populated inside `if (blocks)` in the reader's loop, so a contradiction
// whose findings are all non-blocking carries an EMPTY detail list, and the
// annotation reads `0 of 1 finding(s) block.` and stops. Measured on
// `b7281397` before the fix, the whole refusal for that payload was:
//
//   The AI review's verdict "BLOCK" contradicts its own payload: 0 of 1
//   finding(s) block. A verdict that disagrees with the findings beneath it
//   is a contradiction, not a result.
//
// So every occurrence destroyed the one observation the reviewer made, and
// a re-run — which returns CLEAN, that being the non-determinism this issue
// also records — destroyed it permanently. #1170's finding is unrecoverable:
// the payload lives under `$RUNNER_TEMP`, which dies with the runner, and
// three retrieval attempts returned nothing.
//
// The annotation is therefore the only durable surface, and it already is
// one: the generated step captures the reader with `2>&1` and `printf`s the
// capture, so an `::error` the reader writes becomes an annotation on the
// check run and survives the job. Emitting the payload into the refusal is
// the whole fix, which is why it is a branch and not a new capability — the
// findings are already parsed into `reading.reported` by the time the
// contradiction is detected.
//
// NOT FIXED HERE, deliberately: the non-determinism itself. Without the
// payload you cannot tell a reviewer that emitted a DIFFERENT finding on the
// second run from one that emitted the SAME finding and mis-stamped the
// verdict, and those are different bugs. This section is the instrument.
//
// And NOT by resolving a contradiction to CLEAN. A verdict the adjudicator
// cannot explain is UNMEASURED and UNMEASURED fails
// (`.claude/rules/config-access.md`). Blocking is correct; being
// unexplainable is the defect. The control below holds that line.

describe("#1178: a CONTRADICTION emits the findings it counted", () => {
  const f = AI_REVIEW_FINDING_FIELDS;

  /** The reported shape, reproduced: BLOCK over a payload where nothing blocks. */
  const zeroOfOne = JSON.stringify({
    [AI_REVIEW_VERDICT_KEY]: "BLOCK",
    [AI_REVIEW_FINDINGS_KEY]: [
      {
        [f.severity]: "low",
        [f.file]: "lib/scaffold/ai-review-findings.ts",
        [f.line]: 42,
        [f.summary]: "the detail list is built inside the blocking branch",
      },
    ],
  });

  test("#1178 witness: `BLOCK over 0 of N` names the finding it counted", () => {
    const r = readAiReviewFindings(zeroOfOne);
    expect(r.outcome, "the reported shape no longer reproduces").toBe("CONTRADICTION");
    expect(r.blockingReported?.length).toBe(0);
    expect(r.reported?.length).toBe(1);

    const refusal = aiReviewRefusal(r);
    expect(refusal).not.toBeNull();
    // All four fields the acceptance criterion names. Asserted separately
    // rather than against one composed string, so a renderer that drops the
    // line number is distinguishable from one that drops everything.
    expect(refusal, "the file was discarded").toContain("lib/scaffold/ai-review-findings.ts");
    expect(refusal, "the line was discarded").toContain("42");
    expect(refusal, "the severity was discarded").toContain("low");
    expect(refusal, "the summary was discarded").toContain(
      "the detail list is built inside the blocking branch",
    );
    // …and the arithmetic it already carried is still there. The payload is
    // added to the refusal, not substituted for it.
    expect(refusal).toContain("0 of 1 finding(s) block");
  });

  test("#1178 witness: every reported finding appears exactly once, blocking or not", () => {
    // The other direction — PASS over a payload that does block — already
    // carried the BLOCKING finding through `detail`. So this case fails
    // today on the non-blocking one only, and its second half is the guard
    // against the obvious over-correction: appending the full payload to a
    // detail list that already holds the blocking renders prints those twice.
    const r = readAiReviewFindings(
      JSON.stringify({
        [AI_REVIEW_VERDICT_KEY]: "PASS",
        [AI_REVIEW_FINDINGS_KEY]: [
          {
            // #1166: `failure_scenario` is required on a BLOCKING finding, so
            // this fixture carries it. Everything these cases measure is
            // unchanged — the member is never rendered into the refusal.
            [f.severity]: "critical",
            [f.file]: "a.ts",
            [f.line]: 1,
            [f.summary]: "creds in a log",
            [f.failureScenario]: "any run with the key set writes it to the job log",
          },
          { [f.severity]: "low", [f.file]: "b.ts", [f.line]: 2, [f.summary]: "a naming nit" },
        ],
      }),
    );
    expect(r.outcome).toBe("CONTRADICTION");

    const refusal = aiReviewRefusal(r) ?? "";
    const occurrences = (hay: string, needle: string) => hay.split(needle).length - 1;
    expect(occurrences(refusal, "a.ts:1"), "the blocking finding was duplicated or lost").toBe(1);
    expect(occurrences(refusal, "b.ts:2"), "the non-blocking finding was discarded").toBe(1);
    expect(refusal).toContain("creds in a log");
    expect(refusal).toContain("a naming nit");
  });

  test("#1178 control: an ordinary BLOCKED refusal is byte-identical to today's", () => {
    // The issue's negative control, written as an EQUALITY and not a
    // `toContain`. The cheapest wrong fix here is moving
    // `detail.push(renderFinding(…))` out of `if (blocks)` in the reader's
    // loop — one line, and it does make the contradiction print its payload.
    // It also makes an ordinary BLOCKED refusal start enumerating findings
    // that do not block, which is a different annotation for a path this
    // issue is not about. Measured: applying that one-line move turns this
    // case red and leaves the two witnesses above green, which is why the
    // fix is scoped to the CONTRADICTION arm instead.
    const r = readAiReviewFindings(
      JSON.stringify({
        [AI_REVIEW_VERDICT_KEY]: "BLOCK",
        [AI_REVIEW_FINDINGS_KEY]: [
          {
            // #1166: `failure_scenario` is required on a BLOCKING finding, so
            // this fixture carries it. Everything these cases measure is
            // unchanged — the member is never rendered into the refusal.
            [f.severity]: "critical",
            [f.file]: "a.ts",
            [f.line]: 1,
            [f.summary]: "creds in a log",
            [f.failureScenario]: "any run with the key set writes it to the job log",
          },
          { [f.severity]: "low", [f.file]: "b.ts", [f.line]: 2, [f.summary]: "a naming nit" },
        ],
      }),
    );
    expect(r.outcome).toBe("BLOCKED");
    // The ` [Important]` suffix is CRC-B7's tag and arrived with it. The
    // property this control holds is unchanged and is still an EQUALITY: the
    // refusal names the blocking finding and ONLY it — `b.ts`, the `low`,
    // appears nowhere, which is what the one-line move above would break.
    expect(aiReviewRefusal(r)).toBe(
      "The AI review reported 1 blocking finding(s). " +
        "finding 0 is critical at a.ts:1: creds in a log [Important].",
    );
  });

  test("#1178 control: an ordinary CLEAN run still adjudicates exactly as today", () => {
    const r = readAiReviewFindings(
      JSON.stringify({
        [AI_REVIEW_VERDICT_KEY]: "PASS",
        [AI_REVIEW_FINDINGS_KEY]: [
          { [f.severity]: "low", [f.file]: "b.ts", [f.line]: 2, [f.summary]: "a naming nit" },
        ],
      }),
    );
    expect(r.outcome).toBe("CLEAN");
    expect(aiReviewRefusal(r), "a clean review acquired a refusal").toBeNull();
    expect(aiReviewExitCode(r)).toBe(0);
  });

  test("#1178 control: the contradiction still refuses — it does not resolve to CLEAN", () => {
    // The forbidden fix, as a case. Emitting the payload is an addition to
    // what the refusal says, never a change to whether there is one: a
    // verdict the adjudicator cannot explain is UNMEASURED, and UNMEASURED
    // fails. This case can move — it is exactly what "make the contradiction
    // go green" would turn red.
    const r = readAiReviewFindings(zeroOfOne);
    expect(r.outcome).not.toBe("CLEAN");
    expect(aiReviewExitCode(r)).toBe(AI_REVIEW_REQUIRED_EXIT);
    expect(aiReviewRefusal(r)).not.toBeNull();
  });

  test("#1178: the per-finding cap truncates the summary and never the location", () => {
    // AI_REVIEW_DETAIL_MAX is 300 characters per finding, so a long summary
    // IS cut. What the cap must never cost is the ability to find the
    // finding again, and the renderer puts severity, file and line ahead of
    // the summary — so the cut lands in the prose. Measured rather than
    // assumed: a 900-character summary renders to exactly 301 characters
    // (the cap plus the ellipsis) with the location intact.
    const summary = "x".repeat(900);
    const finding = {
      [f.severity]: "low",
      [f.file]: "lib/deep/path.ts",
      [f.line]: 7,
      [f.summary]: summary,
    };
    const rendered = renderFinding(0, finding);
    expect(rendered.length, "the cap is not being applied").toBe(AI_REVIEW_DETAIL_MAX + 1);
    expect(rendered.startsWith("finding 0 is low at lib/deep/path.ts:7: ")).toBe(true);
    expect(rendered).not.toContain(summary);

    const r = readAiReviewFindings(
      JSON.stringify({
        [AI_REVIEW_VERDICT_KEY]: "BLOCK",
        [AI_REVIEW_FINDINGS_KEY]: [finding],
      }),
    );
    expect(r.outcome).toBe("CONTRADICTION");
    // The refusal carries the capped render, not a second uncapped one.
    expect(aiReviewRefusal(r), "the contradiction emitted an uncapped finding").toContain(rendered);
  });

  test("#1178 witness: the finding reaches the annotation main() emits, escaped once", () => {
    // The payload file dies with the runner, so the annotation is the thing
    // that has to carry the finding. This asserts on what reaches the
    // STREAM — the composed refusal would skip the `console.error`
    // interpolation, which is the one hop where the encoding happens.
    const hostile = "100% broken\n::stop-commands::deadbeef";
    const lines = captureStderr(() => main([fixtureFile(JSON.stringify({
      [AI_REVIEW_VERDICT_KEY]: "BLOCK",
      [AI_REVIEW_FINDINGS_KEY]: [
        { [f.severity]: "low", [f.file]: "lib/x.ts", [f.line]: 9, [f.summary]: hostile },
      ],
    }))]));

    expect(lines.length, `the annotation spans ${lines.length} lines:\n${lines.join("\n")}`).toBe(1);
    expect(lines[0].startsWith("::error title=")).toBe(true);
    expect(lines[0], "the contradiction's finding never reached the annotation").toContain(
      "lib/x.ts:9",
    );
    expect(lines[0], "the reviewer's own words were discarded").toContain("deadbeef");
    // One escaper, applied once, at the single emission site.
    expect(lines[0], "the newline was dropped rather than encoded").toContain("%0A");
    expect(lines[0], "the percent sign was encoded twice").not.toContain("%2525");
    expect(lines[0]).toContain("100%25 broken");
  });
});


// ── #1166: the payload contract is read back on blocking findings ────────

/**
 * #1166. The prompt tells the reviewer "every one of those member names is
 * required on every finding" and, until this issue, nothing checked it.
 * `AI_REVIEW_FINDING_FIELDS` was consumed only by `renderFinding`, which
 * printed `(no file recorded)` and carried on, so a blocking finding with a
 * fabricated `failure_scenario`, no `file` and no `line` adjudicated
 * IDENTICALLY to one with real evidence under it. BLOCKED was BLOCKED.
 *
 * The exit code is the same before and after — a blocking finding failed the
 * job then and fails it now — and that is the point worth stating rather than
 * hiding: what changes is the READING, from "this pull request has a defect"
 * to "this review cannot be read". The first sends a maintainer to argue with
 * a finding that names no code; the second sends the reviewer back to produce
 * one. #1137 is the measured instance, where two of three claims were real,
 * none carried a file or a line, and the symbol was never written as a
 * literal anywhere in the tree.
 */
describe("#1166: a blocking finding that breaks the payload contract is its own reading", () => {
  const f = AI_REVIEW_FINDING_FIELDS;

  test("#1166: the control — a contract-complete blocking finding adjudicates as before", () => {
    // FIRST, and read before any case below. If the complete finding stopped
    // blocking, every red row underneath would be a red instrument rather
    // than a measurement of the contract.
    const r = readAiReviewFindings(payloadOf("BLOCK", [blockingFinding("critical")]));
    expect(r.outcome).toBe("BLOCKED");
    expect(r.blocked).toBe(true);
    expect(r.unmeasuredReasons).toEqual([]);
    expect(aiReviewExitCode(r)).toBe(AI_REVIEW_REQUIRED_EXIT);
  });

  test("#1166: each required member, removed one at a time, is caught", () => {
    // One case per member and not one case over all four, because a check
    // that fires on `file` alone and a check that fires on all four look
    // identical from a single fixture missing everything.
    for (const name of AI_REVIEW_BLOCKING_REQUIRED_FIELDS) {
      const r = readAiReviewFindings(
        payloadOf("BLOCK", [blockingFinding("critical", { [name]: undefined })]),
      );
      expect(r.outcome, `a blocking finding with no '${name}' still adjudicated`).toBe(
        "UNMEASURED",
      );
      expect(r.unmeasuredReasons).toContain("BLOCKING_FINDING_INCOMPLETE");
      expect(aiReviewRefusal(r) ?? "", `the refusal does not name '${name}'`).toContain(name);
      expect(r.blocked, "a withheld decision was defaulted").toBeNull();
    }
    // Non-vacuity: the loop must have run over something.
    expect(AI_REVIEW_BLOCKING_REQUIRED_FIELDS.length).toBe(4);
    expect(AI_REVIEW_BLOCKING_REQUIRED_FIELDS).not.toContain(f.severity);
  });

  test("#1166: null and blank are the same fact as absent", () => {
    // The cheapest wrong fix is `name in finding`, which is satisfied by
    // `"file": ""`. A reviewer that writes an empty string has produced a
    // member name and no evidence, and the annotation a maintainer reads is
    // the same either way — so the three are one reading, measured rather
    // than asserted to be equivalent.
    for (const empty of [null, "", "   "]) {
      const r = readAiReviewFindings(
        payloadOf("BLOCK", [blockingFinding("high", { [f.file]: empty })]),
      );
      expect(r.outcome, `file ${JSON.stringify(empty)} satisfied the contract`).toBe("UNMEASURED");
    }
    // And the control for that repair: a present, non-blank value passes.
    expect(
      readAiReviewFindings(payloadOf("BLOCK", [blockingFinding("high", { [f.file]: "a.ts" })]))
        .outcome,
    ).toBe("BLOCKED");
  });

  test("#1166: a NON-blocking finding is not held to the contract", () => {
    // The scope line, and it is deliberate. A non-blocking finding costs a
    // line in an annotation; the tail of them is already being lost (#1162)
    // and reddening a run over an incomplete `info` would lose more. What
    // the contract protects is the one output worth forging: a red required
    // check.
    for (const severity of Object.keys(AI_REVIEW_SEVERITIES).filter(s => !AI_REVIEW_SEVERITIES[s])) {
      const r = readAiReviewFindings(
        payloadOf("PASS", [{ [f.severity]: severity, title: "a nit and nothing else" }]),
      );
      expect(r.outcome, `an advisory '${severity}' was held to the blocking contract`).toBe(
        "CLEAN",
      );
      expect(aiReviewExitCode(r)).toBe(0);
    }
  });

  test("#1166: an unreadable payload does not become 'contract satisfied'", () => {
    // The UNMEASURED-safety line. The contract check runs over a parsed list
    // of objects, so every state that never gets that far must keep its own
    // reason — a payload that could not be read reporting the contract as
    // met would be the fail-open one level out from the one being closed.
    const unparseable = readAiReviewFindings('{"findings": [');
    expect(unparseable.unmeasuredReasons).toEqual(["FINDINGS_UNPARSEABLE"]);
    expect(unparseable.unmeasuredReasons).not.toContain("BLOCKING_FINDING_INCOMPLETE");

    const noSeverity = readAiReviewFindings(payloadOf("BLOCK", [{ file: "a.ts" }]));
    expect(noSeverity.unmeasuredReasons).toContain("SEVERITY_ABSENT");
    expect(
      noSeverity.unmeasuredReasons,
      "a finding with no severity was also graded against the blocking contract, " +
        "which is two deciders over one input",
    ).not.toContain("BLOCKING_FINDING_INCOMPLETE");
  });

  test("#1166: the check can fail — the binding, zeroed", async () => {
    // `.claude/rules/checks-must-be-able-to-fail.md`. One exported binding,
    // so the removal is performed rather than described: with
    // `blockingContractViolations` returning nothing, the incomplete finding
    // must adjudicate exactly as the complete one does, which is the
    // pre-#1166 behaviour and the defect. A case that stayed red under the
    // mutation would be red for some other reason.
    const incomplete = payloadOf("BLOCK", [blockingFinding("critical", { [f.file]: undefined })]);
    expect(readAiReviewFindings(incomplete).outcome).toBe("UNMEASURED");

    const source = readFileSync(
      join(import.meta.dir, "..", "lib", "scaffold", "ai-review-findings.ts"),
      "utf-8",
    );
    const needle = "return AI_REVIEW_BLOCKING_REQUIRED_FIELDS.filter(name => {";
    expect(
      source.split(needle).length - 1,
      "could not build the mutant: the contract binding is not spelled once",
    ).toBe(1);
    const path = join(SCRATCH, "mutant-ai-review-findings.ts");
    writeFileSync(
      path,
      source
        .replace(needle, "return [].filter((name: string) => {")
        .replace(/from "\.\/ai-review-step"/g, `from "${join(import.meta.dir, "..", "lib", "scaffold", "ai-review-step")}"`),
    );
    const mutant = (await import(path)) as typeof import("../lib/scaffold/ai-review-findings");

    expect(
      mutant.readAiReviewFindings(incomplete).outcome,
      "zeroing the contract binding changed nothing, so the case witnesses nothing",
    ).toBe("BLOCKED");
    expect(mutant.readAiReviewFindings(payloadOf("BLOCK", [blockingFinding("critical")])).outcome)
      .toBe("BLOCKED");
  });
});

/**
 * Covers CRC-B7 (CODE-REVIEW-CONVERGENCE-SPEC.md).
 *
 * > Surviving findings are sorted by severity and tagged Important / Nit /
 * > Pre-existing, so a pre-existing bug does not read as the change's fault.
 *
 * ## The mechanism existed and nothing called it
 *
 * `severityOf` in `lib/finding-jury.ts` has computed `Pre-existing` since
 * #1187 — `cited.length > 0 && !cited.some(p => changed.has(p))`, which is
 * exactly "this finding names no file the PR touched". Measured on `main`
 * 2026-10-23: **zero production callers** outside its own module. Meanwhile
 * this reader blocked on the reviewer's self-declared severity with no notion
 * of pre-existing at all. Two deciders, one dead — the fourth shape in
 * `.claude/rules/checks-must-be-able-to-fail.md`.
 *
 * The cost was not theoretical. Nine PRs sat BLOCKED on findings naming files
 * their diffs did not contain, because `ai-review` reads the MERGE REF and so
 * adjudicates `main`'s defects against whichever PR is standing closest.
 *
 * ## Why the finding's own `file`, and not `citedPaths`
 *
 * `citedPaths` text-mines a path out of prose because the arbiter's findings
 * arrive as prose. This contract **declares** `file`, and
 * `blockingContractViolations` already refuses a blocking finding without
 * one. Mining a declared field would be a second decider for a question the
 * payload answers.
 *
 * ## The direction this is allowed to be wrong in
 *
 * Toward BLOCKING. An absent changed-file list does not silently tag
 * everything in-scope: it is said out loud, and everything blocks as before.
 * A pre-existing tag computed from a reading nobody took would turn a real
 * finding into an advisory line, which is the one outcome worse than the jam
 * this fixes.
 */
describe("CRC-B7: a finding naming no file this PR touched is Pre-existing, not blocking", () => {
  const f = AI_REVIEW_FINDING_FIELDS;
  const at = (file: string, severity = "critical") => ({
    [f.severity]: severity,
    [f.file]: file,
    [f.line]: 12,
    [f.summary]: `a defect in ${file}`,
    [f.failureScenario]: `calling it with 0 returns 1 in ${file}`,
  });

  test("B7-1: a critical naming an UNTOUCHED file does not block", () => {
    const r = readAiReviewFindings(payloadOf("BLOCK", [at("lib/bash-write-guard.ts")]), scopeMeasured([
      "lib/cli-commands.ts",
      "test/ai-review-finding-scope.test.ts",
    ]));
    expect(r.outcome).toBe("CLEAN");
    expect(r.blocked).toBe(false);
    expect(r.blockingReported).toEqual([]);
  });

  test("B7-2 CONTROL: the same critical naming a TOUCHED file still blocks", () => {
    // The only axis that moves between B7-1 and this row is whether the
    // declared file is in the list. Without it B7-1 would be witnessing "a
    // changed-file list makes findings go away".
    const r = readAiReviewFindings(payloadOf("BLOCK", [at("lib/bash-write-guard.ts")]), scopeMeasured([
      "lib/bash-write-guard.ts",
    ]));
    expect(r.outcome).toBe("BLOCKED");
    expect(r.blockingReported).toHaveLength(1);
  });

  test("B7-3: the pre-existing finding is still REPORTED, never dropped", () => {
    // CRC-B8 — a finding is never silently dropped. Demoted is not deleted:
    // it leaves `blockingReported` and stays in `reported`, so the advisory
    // tail still carries it and a maintainer still sees it.
    const r = readAiReviewFindings(payloadOf("BLOCK", [at("lib/other.ts")]), scopeMeasured(["lib/mine.ts"]));
    expect(r.reported).toHaveLength(1);
    expect(r.blockingReported).toEqual([]);
  });

  test("B7-4: the demotion is said out loud, naming the file and the tag", () => {
    const r = readAiReviewFindings(payloadOf("BLOCK", [at("lib/other.ts")]), scopeMeasured(["lib/mine.ts"]));
    const said = `${advisoryNotice(r) ?? ""}\n${r.detail.join("\n")}`;
    expect(said).toContain("Pre-existing");
    expect(said).toContain("lib/other.ts");
  });

  test("B7-5: a mixed payload blocks on the touched one and demotes the other", () => {
    const r = readAiReviewFindings(
      payloadOf("BLOCK", [at("lib/untouched.ts"), at("lib/touched.ts")]),
      scopeMeasured(["lib/touched.ts"]),
    );
    expect(r.outcome).toBe("BLOCKED");
    expect(r.blockingReported).toHaveLength(1);
    expect((r.blockingReported?.[0] as Record<string, unknown>)[f.file]).toBe("lib/touched.ts");
  });

  test("B7-6: NO changed-file list means everything blocks, exactly as before", () => {
    // The whole existing suite is this case, so the regression surface is
    // every other test in this file. Stated here as its own row anyway: an
    // absent reading must not become a permissive one.
    const r = readAiReviewFindings(payloadOf("BLOCK", [at("lib/anything.ts")]));
    expect(r.outcome).toBe("BLOCKED");
    expect(r.blockingReported).toHaveLength(1);
  });

  test("B7-7: an EMPTY changed-file list is UNMEASURED, not 'nothing was touched'", () => {
    // `[]` and absent are different facts and neither is "no file in this PR
    // matches". A PR always touches something, so an empty list is a reading
    // that failed — and under it every finding would demote, which is the
    // fail-open this module exists to refuse.
    const r = readAiReviewFindings(payloadOf("BLOCK", [at("lib/anything.ts")]), scopeMeasured([]));
    expect(r.outcome).toBe("UNMEASURED");
    expect(r.unmeasuredReasons).toContain("CHANGED_FILES_EMPTY");
  });

  test("B7-8: the comparison is case-insensitive, as the jury's already is", () => {
    const r = readAiReviewFindings(payloadOf("BLOCK", [at("Lib/Mixed.TS")]), scopeMeasured(["lib/mixed.ts"]));
    expect(r.outcome, "a case difference is not a different file on this platform").toBe("BLOCKED");
  });

  /**
   * B7-10..B7-16 — the demotion fails CLOSED on anything it cannot read.
   *
   * The first cut of this stage did `String(finding[file]).toLowerCase()` and
   * compared it to a raw list. Every input below then DEMOTED a `critical` to
   * CLEAN, because a spelling the comparison cannot read is a spelling that
   * is never in the set:
   *
   *     CLEAN  0 blocking   file: {}
   *     CLEAN  0 blocking   file: 123
   *     CLEAN  0 blocking   "./lib/mine.ts"
   *     CLEAN  0 blocking   "lib/mine.ts:12"
   *     CLEAN  0 blocking   "lib\\mine.ts"
   *     CLEAN  0 blocking   "/lib/mine.ts"
   *
   * Six for six, against a changed-file list containing `lib/mine.ts`. The
   * docblock already said the direction this may be wrong in is TOWARD
   * blocking; the code said the opposite for every input it could not parse.
   *
   * This is the same lesson as the one about matching a parser rather than a
   * spelling, applied to paths: `./x`, `x`, `/x` and `x:12` are one file and
   * four strings, and an equality test over raw strings is a different
   * question from the one being asked.
   */
  const undecidable = (file: unknown) =>
    readAiReviewFindings(
      JSON.stringify({
        verdict: "BLOCK",
        findings: [
          {
            [f.severity]: "critical",
            [f.file]: file,
            [f.line]: 1,
            [f.summary]: "s",
            [f.failureScenario]: "fs",
          },
        ],
      }),
      scopeMeasured(["lib/mine.ts"]),
    );

  test("B7-10: a non-string file is UNMEASURED, never a demotion", () => {
    for (const file of [{}, 123, [], true]) {
      const r = undecidable(file);
      expect(r.outcome, `file: ${JSON.stringify(file)}`).toBe("UNMEASURED");
      expect(r.unmeasuredReasons).toContain("BLOCKING_FINDING_INCOMPLETE");
    }
  });

  test("B7-11: a path spelt differently is the SAME file, and still blocks", () => {
    // Each of these is `lib/mine.ts`, which the list contains. A demotion
    // here would be the gate answering a question nobody asked.
    for (const file of ["./lib/mine.ts", "/lib/mine.ts", "lib\\mine.ts", "  lib/mine.ts  "]) {
      const r = undecidable(file);
      expect(r.outcome, `file: ${JSON.stringify(file)}`).toBe("BLOCKED");
      expect(r.blockingReported).toHaveLength(1);
    }
  });

  test("B7-11b: dot segments COLLAPSE — one strip is a bypass, not a normalisation", () => {
    // Round two's own fail-open, found by the push review. Measured on this
    // file before the fix, against a list containing `lib/mine.ts`:
    //
    //   "././lib/mine.ts"    -> "./lib/mine.ts"
    //   "lib/./mine.ts"      -> "lib/./mine.ts"
    //   "lib/../lib/mine.ts" -> "lib/../lib/mine.ts"
    //
    // `.replace(/^\.\//, "")` strips ONE leading `./`, and `.` and `..` are
    // both legal matches for `[\w.@+-]+`, so each survived the shape test,
    // compared unequal to the path it names, and demoted a critical finding
    // to CLEAN. B7-11's four spellings all happened to be one-step fixes.
    for (const file of [
      "././lib/mine.ts",
      "./././lib/mine.ts",
      "lib/./mine.ts",
      "lib/../lib/mine.ts",
      "./lib/../lib/./mine.ts",
      "lib//mine.ts",
    ]) {
      const r = undecidable(file);
      expect(r.outcome, `file: ${JSON.stringify(file)}`).toBe("BLOCKED");
      expect(r.blockingReported, `file: ${JSON.stringify(file)}`).toHaveLength(1);
    }
  });

  test("B7-11c: a `..` leaving the repository root is refused, not clamped", () => {
    // Clamping `../outside.ts` to `outside.ts` would invent a path, and the
    // invented one may well be in the change list. Undecidable keeps blocking.
    for (const file of ["../outside.ts", "lib/../../outside.ts", ".."]) {
      expect(undecidable(file).outcome, `file: ${file}`).toBe("BLOCKED");
    }
  });

  test("B7-12: a trailing :line or :line:col is stripped before comparing", () => {
    for (const file of ["lib/mine.ts:12", "lib/mine.ts:12:4"]) {
      expect(undecidable(file).outcome, `file: ${file}`).toBe("BLOCKED");
    }
  });

  test("B7-13: a file that normalises to nothing readable KEEPS BLOCKING", () => {
    // Undecidable is not pre-existing. If the path cannot be resolved to a
    // repo-relative shape at all, the honest answer is "I could not tell",
    // and the direction that is allowed to be wrong in is toward blocking.
    const r = undecidable('"lib/\\303\\251.ts"'); // git C-quoted, not comparable
    expect(r.outcome).toBe("BLOCKED");
    expect(r.detail.join(" ")).toContain("could not be read as a repository path");
  });

  test("B7-13b: the SHAPE refusal is reachable too, not only the C-quote one", () => {
    // Added because a mutation said so. Replacing the shape test's refusal
    // with `return p.toLowerCase()` moved ZERO rows: B7-13 and B7-14 both
    // refuse at the C-quote branch one line earlier, so the regex arm was
    // uncovered and a mutation of it was green by construction — the seventh
    // shape in `.claude/rules/checks-must-be-able-to-fail.md`.
    //
    // These are not C-quoted and are not repository paths. Each must keep
    // blocking rather than demote.
    for (const file of ["lib/my file.ts", "$HOME/x.ts", "lib/<generated>.ts", "???"]) {
      const r = undecidable(file);
      expect(r.outcome, `file: ${JSON.stringify(file)}`).toBe("BLOCKED");
    }
  });

  test("B7-14: an UNREADABLE entry in the changed-file list is UNMEASURED", () => {
    // The mirror of B7-13 on the other side of the comparison. A list the
    // reader cannot normalise is a list it cannot compare against, and
    // comparing anyway would demote every finding.
    const r = readAiReviewFindings(
      JSON.stringify({
        verdict: "BLOCK",
        findings: [
          {
            [f.severity]: "critical",
            [f.file]: "lib/mine.ts",
            [f.line]: 1,
            [f.summary]: "s",
            [f.failureScenario]: "fs",
          },
        ],
      }),
      scopeMeasured(['"lib/\\303\\251.ts"']),
    );
    expect(r.outcome).toBe("UNMEASURED");
    expect(r.unmeasuredReasons).toContain("CHANGED_FILES_UNREADABLE");
  });

  test("B7-15 CONTROL: normalising did not make everything match", () => {
    // The risk in B7-11 is a normaliser so eager that two different files
    // collide. This is the row that would catch it: a genuinely different
    // path must still demote.
    const r = undecidable("./lib/other.ts");
    expect(r.outcome).toBe("CLEAN");
    expect(r.blockingReported).toEqual([]);
  });

  test("B7-16 CONTROL: a path-shaped list entry is normalised the same way", () => {
    // Both SIDES go through one function. If only the finding were
    // normalised, a list spelt `./lib/mine.ts` would stop matching.
    const r = readAiReviewFindings(
      JSON.stringify({
        verdict: "BLOCK",
        findings: [
          {
            [f.severity]: "critical",
            [f.file]: "lib/mine.ts",
            [f.line]: 1,
            [f.summary]: "s",
            [f.failureScenario]: "fs",
          },
        ],
      }),
      scopeMeasured(["./lib/mine.ts"]),
    );
    expect(r.outcome).toBe("BLOCKED");
  });

  test("B7-9: a non-blocking severity is unaffected by the DEMOTION", () => {
    // `info` never blocked, so demoting it changes nothing and must not be
    // counted as this stage having done something. It is still TAGGED
    // `Pre-existing` — that is B7-23 below, and the two are different jobs:
    // the demotion changes what blocks, the tag changes what a reader is
    // told whose defect it is.
    const r = readAiReviewFindings(payloadOf("PASS", [at("lib/untouched.ts", "info")]), scopeMeasured([
      "lib/mine.ts",
    ]));
    expect(r.outcome).toBe("CLEAN");
    expect(r.reported).toHaveLength(1);
  });
});

/**
 * Covers CRC-B7 (CODE-REVIEW-CONVERGENCE-SPEC.md) — the two clauses the
 * demotion above does not reach.
 *
 * > Surviving findings are **sorted by severity** and tagged **Important /
 * > Nit / Pre-existing**, so a pre-existing bug does not read as the author's
 * > fault.
 *
 * ## Why sorting and tagging are one change and not two
 *
 * The block above ships the third clause for BLOCKING findings only: a
 * `critical` naming a file outside the diff stops blocking. Nothing told a
 * reader what any surviving finding WAS. `renderFinding` printed the
 * reviewer's own magnitude word — `critical`, `low`, `info` — which is the
 * question "how bad", and the criterion asks "whose". An `info` about code on
 * `main` read exactly like an `info` about the author's own change, and the
 * advisory tail arrived in whatever order the model happened to write.
 *
 * ## One vocabulary, and the input that proves there are two questions
 *
 * `SEVERITY_RANK` already tagged Important / Nit / Pre-existing in
 * `lib/finding-jury.ts` and the CI path could not import it. It is now
 * declared in `lib/scaffold/ai-review-step.ts` — the contract module, which
 * has no relative imports and so is the one thing the mutation batteries can
 * carry — and `finding-jury.ts` re-exports it. One declaration, no third
 * vocabulary.
 *
 * It does NOT merge with `AI_REVIEW_SEVERITIES`, and B7-24 is the input that
 * says why: a `critical` naming a file the pull request does not touch must
 * read `critical` to the severity table (it blocks; magnitude is a property
 * of the defect) and `Pre-existing` to the tag (attribution is a property of
 * the diff). Two answers, both right, about one finding. Folding them would
 * need the reviewer to write `Pre-existing` itself, and the reviewer is
 * deliberately not given the file list — which is why `readPayload` measures
 * verdict agreement BEFORE the demotion.
 *
 * ## The vacuous shapes this block is written against
 *
 * A sort that never reorders and a payload that arrived sorted are the same
 * observation, so `OUT_OF_ORDER` below is planted in the exact reverse of tag
 * order and B7-21 is the already-sorted control beside it. The battery at the
 * end performs the removals and states predicted membership per row.
 */
describe("CRC-B7: surviving findings are sorted by tag and carry it", () => {
  const f = AI_REVIEW_FINDING_FIELDS;
  const DIFF = ["lib/touched.ts"];
  const at = (file: string, severity: string, summary: string) => ({
    [f.severity]: severity,
    [f.file]: file,
    [f.line]: 1,
    [f.summary]: summary,
    [f.failureScenario]: `calling it with 0 returns 1 in ${file}`,
  });

  /**
   * Planted in the EXACT REVERSE of tag order, against a diff of
   * `lib/touched.ts`:
   *
   *   payload 0  low       lib/touched.ts     alpha  -> Nit           rank 2
   *   payload 1  critical  lib/elsewhere.ts   beta   -> Pre-existing  rank 1
   *   payload 2  critical  lib/touched.ts     gamma  -> Important     rank 0
   *
   * So the rendered order must be 2, 1, 0 and the payload numbering must
   * stay 0, 1, 2. A comparator that does nothing leaves 0, 1, 2 and reds.
   */
  const OUT_OF_ORDER = [
    at("lib/touched.ts", "low", "alpha"),
    at("lib/elsewhere.ts", "critical", "beta"),
    at("lib/touched.ts", "critical", "gamma"),
  ];

  /** Where each `finding <n> is` label sits in a rendered annotation. */
  const order = (said: string, howMany: number): number[] =>
    Array.from({ length: howMany }, (_, i) => ({ i, at: said.indexOf(`finding ${i} is`) }))
      .filter(e => e.at >= 0)
      .sort((a, b) => a.at - b.at)
      .map(e => e.i);

  test("B7-20: the rendered order is TAG order, and the labels stay payload order", () => {
    const r = readAiReviewFindings(payloadOf("PASS", OUT_OF_ORDER), scopeMeasured(DIFF));
    // PASS over a payload with a blocking finding — the contradiction arm,
    // which is the one place every counted finding is printed together.
    expect(r.outcome).toBe("CONTRADICTION");
    const said = aiReviewRefusal(r)!;

    expect(order(said, 3), "the display was not reordered by tag").toEqual([2, 1, 0]);
    // And the numbering is the PAYLOAD's. `renderFinding` prints
    // `finding <index>` and the refusal and the advisory notice share it, so
    // a sort that renumbered would make `finding 0` mean two findings.
    expect(said).toContain("gamma [Important]");
    expect(said).toContain("beta [Pre-existing]");
    expect(said).toContain("alpha [Nit]");
    expect(said).toContain("finding 2 is critical at lib/touched.ts:1: gamma [Important]");
  });

  test("B7-21 CONTROL: a payload that ARRIVED in tag order is left alone", () => {
    // Without this row B7-20 is satisfied by a comparator that reverses, and
    // by one that sorts on anything correlated with the plant. Same three
    // findings, supplied already sorted: the order out must equal the order
    // in, which a reverse fails and a correct sort passes.
    const sorted = [OUT_OF_ORDER[2], OUT_OF_ORDER[1], OUT_OF_ORDER[0]];
    const r = readAiReviewFindings(payloadOf("PASS", sorted), scopeMeasured(DIFF));
    expect(r.outcome).toBe("CONTRADICTION");
    expect(order(aiReviewRefusal(r)!, 3)).toEqual([0, 1, 2]);
  });

  test("B7-22: the advisory tail is ordered too, Pre-existing above Nit", () => {
    const r = readAiReviewFindings(
      payloadOf("PASS", [
        at("lib/touched.ts", "low", "alpha"),
        at("lib/elsewhere.ts", "medium", "beta"),
      ]),
      scopeMeasured(DIFF),
    );
    expect(r.outcome).toBe("CLEAN");
    const notice = advisoryNotice(r)!;
    expect(order(notice, 2), "the advisory tail printed in payload order").toEqual([1, 0]);
    expect(notice).toContain("beta [Pre-existing]");
    expect(notice).toContain("alpha [Nit]");
    // The tail is still indexed against the WHOLE payload — AD-2's property,
    // restated here because the sort is the thing that would break it.
    expect(notice).toContain("finding 1 is");
    expect(notice).toContain("finding 0 is");
  });

  test("B7-23: an ADVISORY finding outside the diff is tagged Pre-existing", () => {
    // The clause the demotion cannot reach. `readPayload` only compares
    // BLOCKING findings against the changed-file list, because demoting an
    // `info` changes nothing it could change. Misattributing one costs
    // exactly as much as misattributing a `critical`, so the TAG is wider
    // than the demotion on purpose.
    const r = readAiReviewFindings(
      payloadOf("PASS", [at("lib/elsewhere.ts", "info", "beta")]),
      scopeMeasured(DIFF),
    );
    expect(r.findingTags).toEqual(["Pre-existing"]);
    expect(advisoryNotice(r)).toContain("beta [Pre-existing]");
  });

  test("B7-24: each of the three tags, from the input that must produce it", () => {
    // The disagreement that proves `AI_REVIEW_SEVERITIES` and the tag are two
    // questions: payload 1 is `critical` — the severity table's own answer is
    // "this blocks" — and `Pre-existing`. Both are correct and neither can be
    // derived from the other.
    const r = readAiReviewFindings(payloadOf("BLOCK", OUT_OF_ORDER), scopeMeasured(DIFF));
    expect(r.findingTags).toEqual(["Nit", "Pre-existing", "Important"]);
    expect(severityBlocks(OUT_OF_ORDER[1][f.severity])).toBe(true);
    expect(r.outcome).toBe("BLOCKED");
  });

  test("B7-25: with no changed-file list nothing is Pre-existing, and it says so", () => {
    // The direction this is allowed to be wrong in. An unread diff must not
    // silently tag everything in-scope OR everything pre-existing — the
    // attribution axis is simply unavailable, and the scope line is where
    // that is said out loud rather than inferred from a missing bracket.
    const r = readAiReviewFindings(payloadOf("BLOCK", OUT_OF_ORDER));
    expect(r.findingTags).toEqual(["Nit", "Important", "Important"]);
    expect(r.findingTags).not.toContain("Pre-existing");
    expect(aiReviewScopeLine(r)).toContain("NOT_SUPPLIED");
  });

  test("B7-26: an unrecognised severity has NO tag, and untagged sorts last", () => {
    const r = readAiReviewFindings(
      payloadOf("BLOCK", [
        at("lib/touched.ts", "critical", "alpha"),
        at("lib/touched.ts", "catastrophic", "beta"),
      ]),
      scopeMeasured(DIFF),
    );
    expect(r.outcome).toBe("UNMEASURED");
    // `null`, not a guessed `Important`. A word nobody declared is a word
    // nobody has decided about, and the reading is already UNMEASURED.
    expect(r.findingTags).toEqual(["Important", null]);
    expect(UNTAGGED_RANK).toBeGreaterThan(Math.max(...Object.values(SEVERITY_RANK)));
    expect(tagOrder(["Nit", "Important", null], [0, 1, 2])).toEqual([1, 0, 2]);
  });

  test("B7-27: ties break on the payload index, so the order is total", () => {
    // Not `Array.prototype.sort`'s stability — the comparator says it. A run
    // that printed one order and a re-run that printed another would be two
    // readings of one payload.
    expect(tagOrder(["Nit", "Nit", "Nit"], [2, 0, 1])).toEqual([0, 1, 2]);
    expect(tagOrder(null, [2, 0, 1])).toEqual([0, 1, 2]);
  });

  test("B7-28: a long summary cannot truncate the tag away", () => {
    // The tag is appended AFTER the cap. The finding whose attribution a
    // reader most needs is the verbose one, and "this is not your bug" cut
    // off reads as "this is your bug".
    const line = renderFinding(
      0,
      {
        [f.severity]: "low",
        [f.file]: "lib/a.ts",
        [f.line]: 1,
        [f.summary]: "x".repeat(AI_REVIEW_DETAIL_MAX * 2),
      },
      "Pre-existing",
    );
    expect(line.endsWith("[Pre-existing]")).toBe(true);
    expect(line).toContain("…");
  });

  test("B7-29: the tag and the order decide nothing", () => {
    // Behavioural: the same payload, tagged and untagged, exits the same.
    // Structural: neither binding is named inside the exit code's body, so
    // "does not decide" is not "happens to agree today".
    const scoped = readAiReviewFindings(payloadOf("PASS", OUT_OF_ORDER), scopeMeasured(DIFF));
    expect(aiReviewExitCode(scoped)).toBe(AI_REVIEW_REQUIRED_EXIT);
    const body = /export function aiReviewExitCode[\s\S]*?\n}/.exec(source)?.[0];
    expect(body, "the exit code's body was not found, so this witnesses nothing").toBeDefined();
    expect(body).not.toContain("tagOrder");
    expect(body).not.toContain("findingTag");
  });

  test("B7-30: the tag reaches the annotation through the one escaper", () => {
    // The tag is appended AFTER the cap, which moved where the join happens,
    // and the line it joins is attacker-shaped. Both streams, because the
    // generated step captures the reader with `2>&1`: a case watching one
    // could be satisfied by output the runner groups with the other.
    const hostile = at("lib/elsewhere.ts", "info", "benign\n::stop-commands::deadbeef");
    const changed = join(SCRATCH, `changed-${fixtureSeq++}.txt`);
    writeFileSync(changed, `${DIFF.join("\n")}\n`);

    const written: string[] = [];
    const log = console.log;
    const err = console.error;
    console.log = (...a: unknown[]) => void written.push(a.map(String).join(" "));
    console.error = (...a: unknown[]) => void written.push(a.map(String).join(" "));
    try {
      main([fixtureFile(payloadOf("PASS", [hostile])), changed]);
    } finally {
      console.log = log;
      console.error = err;
    }
    const lines = written.join("\n").split("\n").filter(l => l.length > 0);

    expect(lines.filter(l => l.startsWith("::stop-commands::"))).toEqual([]);
    expect(lines.some(l => l.includes("[Pre-existing]"))).toBe(true);
  });
});

/**
 * CRC-B7's battery — the sort and the tag, removed and observed.
 *
 * `.claude/rules/checks-must-be-able-to-fail.md`. Four observations, three
 * mutants, and the predicted membership written down BEFORE the run because
 * rows that all match usually mean the battery varied the wrong axis:
 *
 * | mutant                            | O1 order | O2 Important/Nit | O3 Pre-existing | O4 demotion |
 * |-----------------------------------|----------|------------------|-----------------|-------------|
 * | (none — the baseline)             | holds    | holds            | holds           | holds       |
 * | M-A comparator removed            | FAILS    | holds            | holds           | holds       |
 * | M-B tag's severity arm → `null`   | FAILS    | FAILS            | holds           | holds       |
 * | M-C scope never says PRE_EXISTING | FAILS    | holds            | FAILS           | FAILS       |
 *
 * No two rows are identical, which is what makes the three mutants three
 * measurements rather than one repeated. M-A moves only the display; M-B
 * moves only the two tags the severity table decides, and it moves the order
 * as a CONSEQUENCE (an untagged finding sorts last), which is why O1 is
 * predicted to fail there too; M-C moves the one decider shared by the tag
 * and the demotion, which is the whole reason there is one of it.
 *
 * The baseline row is read first and on its own: a row of zeros under an
 * empty baseline is an instrument that stopped reporting, not a finding.
 */
describe("CRC-B7: the sort and the tag can fail", () => {
  const f = AI_REVIEW_FINDING_FIELDS;
  const DIFF = ["lib/touched.ts"];
  const at = (file: string, severity: string, summary: string) => ({
    [f.severity]: severity,
    [f.file]: file,
    [f.line]: 1,
    [f.summary]: summary,
    [f.failureScenario]: `calling it with 0 returns 1 in ${file}`,
  });
  const OUT_OF_ORDER = [
    at("lib/touched.ts", "low", "alpha"),
    at("lib/elsewhere.ts", "critical", "beta"),
    at("lib/touched.ts", "critical", "gamma"),
  ];
  const LONE_PRE_EXISTING = [at("lib/elsewhere.ts", "critical", "delta")];

  interface Row {
    O1: boolean;
    O2: boolean;
    O3: boolean;
    O4: boolean;
  }

  /** The four observations, re-made against whichever module is handed in. */
  function observe(mod: typeof import("../lib/scaffold/ai-review-findings")): Row {
    const r = mod.readAiReviewFindings(payloadOf("PASS", OUT_OF_ORDER), mod.scopeMeasured(DIFF));
    const said = mod.aiReviewRefusal(r) ?? "";
    const seen = [0, 1, 2]
      .map(i => ({ i, at: said.indexOf(`finding ${i} is`) }))
      .filter(e => e.at >= 0)
      .sort((a, b) => a.at - b.at)
      .map(e => e.i);
    const lone = mod.readAiReviewFindings(
      payloadOf("BLOCK", LONE_PRE_EXISTING),
      mod.scopeMeasured(DIFF),
    );
    return {
      O1: JSON.stringify(seen) === JSON.stringify([2, 1, 0]),
      O2: said.includes("[Important]") && said.includes("[Nit]"),
      O3: said.includes("[Pre-existing]"),
      O4: lone.outcome === "CLEAN" && lone.blockingReported?.length === 0,
    };
  }

  const MUTANTS: { id: string; needle: string; with: string; expect: Row }[] = [
    {
      id: "M-A the comparator is removed",
      needle: "return [...indices].sort((a, b) => rankOf(a) - rankOf(b) || a - b);",
      with: "return [...indices];",
      expect: { O1: false, O2: true, O3: true, O4: true },
    },
    {
      id: "M-B the tag's severity arm returns null",
      needle: 'return blocks === null ? null : blocks ? "Important" : "Nit";',
      with: "return null;",
      expect: { O1: false, O2: false, O3: true, O4: true },
    },
    {
      id: "M-C the scope decider never says PRE_EXISTING",
      needle: 'touched.has(named) ? "IN_DIFF" : "PRE_EXISTING"',
      with: '"IN_DIFF"',
      expect: { O1: false, O2: true, O3: false, O4: false },
    },
  ];

  test("B7-B0 BASELINE: every observation holds on the real module", async () => {
    const real = (await import(
      "../lib/scaffold/ai-review-findings"
    )) as typeof import("../lib/scaffold/ai-review-findings");
    expect(observe(real)).toEqual({ O1: true, O2: true, O3: true, O4: true });
  });

  for (const m of MUTANTS) {
    test(`B7-B: ${m.id}`, async () => {
      expect(
        source.split(m.needle).length - 1,
        `could not build the mutant: ${m.id}'s binding is not spelled exactly once`,
      ).toBe(1);
      // A directory PER MUTANT, as the advisory battery does. Bun resolves a
      // dynamic import against a cached listing of the containing directory,
      // so a second file written into a directory something has already
      // imported from is `Cannot find module` — measured here: row one
      // loaded and row two did not, with `existsSync` true for both. That
      // failure reads exactly like a mutant being rejected on the merits.
      const dir = join(SCRATCH, `b7-${m.id.split(" ")[0]}`);
      mkdirSync(dir, { recursive: true });
      const path = join(dir, "ai-review-findings.ts");
      writeFileSync(
        path,
        source
          .replace(m.needle, m.with)
          .replace(
            /from "\.\/ai-review-step"/g,
            `from "${join(import.meta.dir, "..", "lib", "scaffold", "ai-review-step")}"`,
          ),
      );
      const mutant = (await import(path)) as typeof import("../lib/scaffold/ai-review-findings");
      expect(
        typeof mutant.readAiReviewFindings,
        "the mutant did not load, which reads exactly like the mutation being rejected",
      ).toBe("function");
      expect(observe(mutant), `${m.id}: observed membership differs from the prediction`).toEqual(
        m.expect,
      );
    });
  }
});

/**
 * #1472 — one changed path with a space turned the WHOLE scope reading
 * UNMEASURED, so a consumer with one awkward filename got a permanently red
 * required `ai-review` check.
 *
 * `normaliseRepoPath` ends in `/^(?:[\w.@+-]+\/)*[\w.@+-]+$/`, and `\w` is
 * `[A-Za-z0-9_]`, so a tracked path containing a space, a parenthesis, a
 * bracket, a comma, a `#`, a `~` or a `=` is `null`. `docs/my file.md` was
 * enough. #1356's `core.quotePath=false` does not reach it: git does not
 * quote a space, it emits it literally and the regex rejects it literally.
 *
 * ## Why dropping one entry is not the fail-open it looks like
 *
 * `touched` losing a member can only ever demote MORE findings, never fewer —
 * and the set of findings a dropped entry could falsely demote is EMPTY, for
 * a mechanical reason rather than an optimistic one. **Both sides of the
 * comparison go through the same normaliser.** A changed-file entry is
 * dropped exactly when it normalises to `null`, and a finding naming that
 * same path normalises to `null` too, which is the `undecidable` branch —
 * *"it keeps blocking: undecidable is not pre-existing"*. So the findings a
 * drop could touch are precisely the findings the drop cannot reach. B7-1472-4
 * is that property asserted rather than argued.
 *
 * What the drop IS allowed to be is unreported, and it is not: `scopeDropped`
 * names the entries and `aiReviewScopeLine` prints them on every run, beside
 * the counts. A reading over a narrowed set that does not say it was narrowed
 * is Silent Default Substitution (`.claude/rules/config-access.md`), and the
 * three states — no list, a full list, a list this reader could read part of
 * — are three different facts here rather than one green check.
 *
 * The all-or-nothing refusal survives where it is honest: a list with NO
 * readable entry is `CHANGED_FILES_UNREADABLE` exactly as before, because an
 * empty `touched` tags every finding Pre-existing, which is the fail-open the
 * original refusal was written against (B7-1472-6).
 */
describe("#1472: an unnormalisable changed-file entry is DROPPED and NAMED, not fatal", () => {
  const f = AI_REVIEW_FINDING_FIELDS;
  const at = (file: string, severity = "critical") => ({
    [f.severity]: severity,
    [f.file]: file,
    [f.line]: 12,
    [f.summary]: `a defect in ${file}`,
    [f.failureScenario]: `calling it with 0 returns 1 in ${file}`,
  });

  /** The issue's own path. A space, and nothing else exotic about it. */
  const AWKWARD = "docs/my file.md";
  const READABLE = "lib/mine.ts";

  const read = (file: string, list: readonly string[]) =>
    readAiReviewFindings(payloadOf("BLOCK", [at(file)]), scopeMeasured(list));

  test("B7-1472-1: a finding on a readable path is adjudicated beside an unreadable entry", () => {
    // The issue's "what would have to fail": a changed-file list carrying
    // `docs/my file.md` alongside one normalisable path and a blocking
    // finding naming the normalisable one. Before #1472 this returned
    // CHANGED_FILES_UNREADABLE and the finding was never adjudicated at all.
    const r = read(READABLE, [READABLE, AWKWARD]);
    expect(r.outcome).toBe("BLOCKED");
    expect(r.blocked).toBe(true);
    expect(r.blockingReported).toHaveLength(1);
    expect(r.unmeasuredReasons).toEqual([]);
  });

  test("B7-1472-2: the dropped entry is NAMED in output printed on every run", () => {
    // Named, not counted. "one entry was dropped" is not something an
    // operator can act on; the path is. And the scope line is the channel
    // because it is the one `main` prints unconditionally — `detail` reaches
    // an annotation only under BLOCKED, CONTRADICTION or UNMEASURED, so a
    // CLEAN reading over a narrowed set would say nothing at all.
    const r = read(READABLE, [READABLE, AWKWARD]);
    expect(r.scopeDropped).toEqual([AWKWARD]);
    expect(aiReviewScopeLine(r), "the scope line does not name the dropped path").toContain(
      AWKWARD,
    );
  });

  test("B7-1472-3: THE PAIR — one entry varies, and the two readings differ", () => {
    // One axis moves: whether the second entry is readable. The verdict must
    // NOT move with it — that is the whole point of the change — so the only
    // thing left to carry the difference is the reported coverage.
    //
    // The control list is TWO entries, not one, and that is the pair rather
    // than a detail of it. `scopeMeasured`'s own detail is `N changed path(s)
    // supplied directly`, so a one-against-two comparison produces two
    // different scope lines whatever this issue did, and the assertion below
    // would hold over a reader that reported the drop nowhere. With both
    // lists at length two every other term on the line is equal by
    // construction — asserted, not assumed — and the inequality can only
    // come from the drop.
    const full = read(READABLE, [READABLE, "lib/other.ts"]);
    const partial = read(READABLE, [READABLE, AWKWARD]);

    expect(full.outcome, "the control reading is not the one being compared").toBe("BLOCKED");
    expect(partial.outcome, "the drop changed the verdict").toBe(full.outcome);
    expect(full.scope.detail, "the pair varies the list LENGTH as well").toBe(partial.scope.detail);
    expect(full.reported?.length).toBe(partial.reported?.length);
    expect(full.blockingReported?.length).toBe(partial.blockingReported?.length);
    expect(full.unlocatableReported?.length).toBe(partial.unlocatableReported?.length);

    expect(full.scopeDropped, "a complete reading reports an empty drop, not a null one").toEqual(
      [],
    );
    expect(partial.scopeDropped).toEqual([AWKWARD]);
    expect(
      aiReviewScopeLine(partial),
      "a partial reading is indistinguishable from a complete one",
    ).not.toBe(aiReviewScopeLine(full));
  });

  test("B7-1472-4: a finding naming the DROPPED path keeps blocking", () => {
    // The property that makes the drop safe, asserted rather than argued.
    // The entry left the comparison set; the finding that names it does not
    // become Pre-existing, because it reaches `normaliseRepoPath` and gets
    // the same `null` the entry did. A demotion here would be the fail-open
    // the all-or-nothing refusal was protecting against, arriving by the
    // change that removed it.
    const r = read(AWKWARD, [READABLE, AWKWARD]);
    expect(r.outcome).toBe("BLOCKED");
    expect(r.blockingReported).toHaveLength(1);
    expect(r.unlocatableReported, "the dropped path's own finding was demoted").toEqual([]);
    expect(r.detail.join(" ")).toContain("could not be read as a repository path");
  });

  test("B7-1472-5 CONTROL: a genuinely untouched path is still demoted", () => {
    // Without this row B7-1472-1 would be satisfied by a reader that stopped
    // comparing altogether — every finding blocking is also "the finding was
    // adjudicated". The comparison still runs over the entries that survived.
    const r = read("lib/other.ts", [READABLE, AWKWARD]);
    expect(r.outcome).toBe("CLEAN");
    expect(r.blockingReported).toEqual([]);
    expect(r.unlocatableReported).toHaveLength(1);
    expect(r.scopeDropped, "the drop is reported on a CLEAN reading too").toEqual([AWKWARD]);
  });

  test("B7-1472-6: a list with NO readable entry still REFUSES", () => {
    // The refusal is narrowed, not deleted. An empty `touched` makes every
    // finding Pre-existing and reports a green check for a review that found
    // something, so the one input the original refusal was right about keeps
    // refusing — and both of these are unreadable for different reasons
    // (git's C-quoted form, and a `..` leaving the root), so the case is not
    // witnessing one branch of `normaliseRepoPath` twice.
    const r = read(READABLE, ['"lib/\\303\\251.ts"', "../outside.ts"]);
    expect(r.outcome).toBe("UNMEASURED");
    expect(r.unmeasuredReasons).toContain("CHANGED_FILES_UNREADABLE");
    expect(aiReviewRefusal(r) ?? "", "the refusal names neither unreadable entry").toContain(
      "../outside.ts",
    );
  });

  test("B7-1472-7: no list supplied is 'not checked', never 'nothing dropped'", () => {
    // Three states, and `[]` is the middle one. A run nobody handed a list
    // has not read a complete changed-file list — it has not read one — and
    // `null` is what keeps that apart from a list every entry of which was
    // readable.
    const none = readAiReviewFindings(payloadOf("BLOCK", [at(READABLE)]));
    expect(none.scope.status).toBe("NOT_SUPPLIED");
    expect(none.scopeDropped).toBeNull();

    const complete = read(READABLE, [READABLE]);
    expect(complete.scopeDropped).toEqual([]);

    // Asserted on the TERM and not on the whole line. These two readings
    // differ in their `scope.status` and in their detail sentence as well, so
    // a `not.toBe` over the whole string is satisfied by a line that reports
    // the drop nowhere at all.
    expect(aiReviewScopeLine(none)).toContain("entries dropped: not checked");
    expect(aiReviewScopeLine(complete)).toContain("entries dropped: 0");
  });
});

/**
 * Covers #1879 — a blocking finding whose claim is a test's OUTCOME.
 *
 * The premise, measured rather than assumed: `.github/workflows/ai-review.yml`
 * contains no `bun test`, no `npm test`, and no other test invocation of any
 * kind. The reviewer reads source and a diff; it never sees a result. So
 * every one of these sentences is an inference, and on #1878 the same
 * inference blocked three rounds running and was wrong all three times.
 *
 * The direction this is allowed to be wrong in is stated in
 * `unrunTestClaim`'s docblock and is asserted below in both directions: the
 * ordinary review sentence that merely contains the word "fails" must keep
 * blocking, or the demotion is wider than the defect.
 */
describe("#1879 — a claim about a test's outcome does not block", () => {
  const f = AI_REVIEW_FINDING_FIELDS;

  const payload = (summary: string, failureScenario: string, verdict = "BLOCK") =>
    JSON.stringify({
      [AI_REVIEW_VERDICT_KEY]: verdict,
      [AI_REVIEW_FINDINGS_KEY]: [
        { [f.severity]: "critical", [f.file]: "a.ts", [f.line]: 1, [f.summary]: summary, [f.failureScenario]: failureScenario },
      ],
    });

  test("the claim is demoted, stays reported, and the refusal says no test ran", () => {
    const r = readAiReviewFindings(
      payload("the ratchet test fails on this branch", "CI goes red at test/ratchet.test.ts"),
    );
    expect(r.blocked, "an unobserved test outcome still reddened the required check").toBe(false);
    expect(r.outcome).toBe("CLEAN");
    // CRC-B8's half: demoted is not dropped. One finding in, one finding out.
    expect(r.reported).toHaveLength(1);
    expect(r.blockingReported).toEqual([]);
    expect(r.detail.join("\n")).toContain("claims a test outcome, and no test ran");
  });

  test("the reviewer's own BLOCK is not turned into a CONTRADICTION by the demotion", () => {
    // The same reasoning CRC-B7 carries at the `demoted` counter: the
    // reviewer is not told the job runs no tests, so its BLOCK is honest.
    // Scoring the demotion against its word would make the mechanism WORKING
    // the loudest possible failure. Without `demoted += 1` this reads
    // CONTRADICTION and the check is red for a different reason — green on
    // `blocked` alone would not have caught it.
    const r = readAiReviewFindings(payload("test/foo.test.ts is red", "the suite fails"));
    expect(r.outcome).toBe("CLEAN");
  });

  test("control: \"the suite fails to <verb>\" is about code and keeps blocking", () => {
    // The over-correction this is pointed at. `fails to <verb>` is a
    // statement about what the CODE does. Dropping the `(?!\s+to\s+\w)`
    // lookahead in `TEST_OUTCOME` turns this case red, and turns the two
    // above green for the wrong reason. The subject is a word the detector
    // DOES read, or the lookahead would not be the thing under test.
    const r = readAiReviewFindings(
      payload(
        "the test harness fails to escape the path it is handed",
        "a path with a quote in it reaches the shell",
      ),
    );
    expect(r.blocked, "a finding about code behaviour was demoted").toBe(true);
    expect(r.outcome).toBe("BLOCKED");
  });

  test("control: #1914 round 1 — \"check\", \"case\" and \"spec\" are not test subjects", () => {
    // Three sentences the reviewer wrote against the first version of this,
    // verbatim. Each is a well-evidenced finding about what PRODUCTION code
    // does, and the first version demoted all three: `TEST_SUBJECT` listed
    // `checks?` and `cases?`, which are what a CI job and a branch are
    // called in this repository, and `TEST_OUTCOME` listed `broken`.
    //
    // This is the population, not one example. Restoring any one of those
    // three words to the pattern turns the matching row red.
    const sentences = [
      "the required check is broken when the payload omits the severity field",
      "the check fails silently when given an empty changed-file list",
      "it does not pass large payloads through its size check",
      "the error case is red-flagged but never reported to the caller",
      "the spec does not pass its own frontmatter requirement",
    ];
    for (const s of sentences) {
      const r = readAiReviewFindings(payload(s, "a maintainer merges over a live defect"));
      expect(r.blocked, `demoted a finding about code behaviour: ${s}`).toBe(true);
    }
  });

  test("\"broken\" is an outcome word once the subject is a test", () => {
    // This case exists because a mutation found nothing. Excluding `broken`
    // from `TEST_OUTCOME` — which the first version did — turned zero cases
    // red, so the exclusion was a decision nothing could see. Removing
    // `broken` from the pattern now turns THIS red, in both directions.
    const r = readAiReviewFindings(
      payload("the budget suite is broken on this branch", "CI will not go green"),
    );
    expect(r.blocked).toBe(false);
    expect(r.detail.join("\n")).toContain("claims a test outcome, and no test ran");
  });

  test("control: the two halves must land in ONE sentence", () => {
    // Named because it is what the detector holds fixed. A finding may
    // mention a test file and, separately, that something does not pass,
    // without ever claiming an outcome — matching across a sentence boundary
    // would demote most of the payloads this module sees.
    const r = readAiReviewFindings(
      payload(
        "test/ratchet.test.ts is new. The config it reads does not pass validation.",
        "a reader of the ratchet gets an empty list",
      ),
    );
    expect(r.blocked, "the detector matched across a sentence boundary").toBe(true);
  });

  test("control: a non-blocking finding is untouched — this decides blocking only", () => {
    const r = readAiReviewFindings(
      JSON.stringify({
        [AI_REVIEW_VERDICT_KEY]: "PASS",
        [AI_REVIEW_FINDINGS_KEY]: [
          { [f.severity]: "low", [f.file]: "b.ts", [f.line]: 2, [f.summary]: "the test fails" },
        ],
      }),
    );
    expect(r.outcome).toBe("CLEAN");
    expect(r.reported).toHaveLength(1);
    // It never reached the branch, so nothing was demoted and nothing says so.
    expect(r.detail.join("\n")).not.toContain("claims a test outcome");
  });

  test("#1914 round 2: the maintainer is told WHY it did not block", () => {
    // The reviewer's finding, and it was right. The demotion's sentence goes
    // to `reading.detail`, and `aiReviewRefusal` only reads `detail` back for
    // BLOCKED, CONTRADICTION and UNMEASURED. A payload whose only blocking
    // finding is demoted here is CLEAN — so the refusal is `null` and the
    // sentence reached nobody. `advisoryNotice` is the only output left, and
    // before this it printed the finding as `[Important]`, indistinguishable
    // from one that genuinely blocks.
    const r = readAiReviewFindings(
      payload("the ratchet test fails on this branch", "CI goes red at test/ratchet.test.ts"),
    );
    expect(aiReviewRefusal(r), "a CLEAN reading has no refusal to carry the sentence").toBeNull();

    const notice = advisoryNotice(r) ?? "";
    expect(notice, "the demoted finding still reads as a blocking one").toContain("[Unobserved]");
    expect(notice).not.toContain("[Important]");
    expect(notice, "the tag arrived with no legend").toContain("this job runs no test command");
  });

  test("#1914 round 2: the order legend is derived, not restated", () => {
    // The sentence used to be the literal "Important / Pre-existing / Nit".
    // Adding a fourth tag left it naming an order it no longer described —
    // the defect this module spends most of its length guarding against,
    // in its own output. Asserted against SEVERITY_RANK so the two cannot
    // drift again.
    const r = readAiReviewFindings(
      JSON.stringify({
        [AI_REVIEW_VERDICT_KEY]: "PASS",
        [AI_REVIEW_FINDINGS_KEY]: [
          { [f.severity]: "low", [f.file]: "b.ts", [f.line]: 2, [f.summary]: "a naming nit" },
        ],
      }),
    );
    const expected = (Object.keys(SEVERITY_RANK) as (keyof typeof SEVERITY_RANK)[])
      .sort((a, b) => SEVERITY_RANK[a] - SEVERITY_RANK[b])
      .join(" / ");
    expect(expected, "the rank table lost a tag").toBe("Important / Pre-existing / Unobserved / Nit");
    expect(advisoryNotice(r) ?? "").toContain(`in ${expected} order`);
  });

  test("#1914 round 2: Pre-existing outranks Unobserved, and the tag agrees with the demotion", () => {
    // The tag and the demotion must not disagree about one finding. Both ask
    // attribution first, so a finding that is BOTH reads Pre-existing in the
    // annotation and is demoted down the pre-existing branch. Swapping the
    // two checks in `findingTag` turns this red.
    const both = {
      [f.severity]: "critical",
      [f.file]: "untouched.ts",
      [f.line]: 1,
      [f.summary]: "the ratchet test fails on this branch",
      [f.failureScenario]: "CI goes red",
    };
    const touched = new Set(["a.ts"]);
    expect(findingTag(both, touched)).toBe("Pre-existing");
    // …and with no changed-file list, attribution is undecidable and the
    // unrun claim is the tag that remains.
    expect(findingTag(both, null)).toBe("Unobserved");
  });

  test("the predicate returns the sentence it matched, not a boolean", () => {
    // So the refusal quotes what it read instead of asserting that it read
    // something. A boolean here is the cheapest wrong fix and it is silent.
    expect(
      unrunTestClaim({ [f.summary]: "fine. the budget test is red. also fine." }),
    ).toBe("the budget test is red.");
    expect(unrunTestClaim({ [f.summary]: "an unchecked index" })).toBeNull();
    // A non-string field is not an input it may crash on.
    expect(unrunTestClaim({ [f.summary]: 7, [f.failureScenario]: null })).toBeNull();
  });
});
