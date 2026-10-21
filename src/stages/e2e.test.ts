// End to end: the brownfield slice with a scripted model and a fake container runtime.
import { cardView } from "./card-summary.js";
import { stepsFor } from "./modes.js";
import { decideCard } from "../ui/start.js";
import { testsView } from "../ui/tests.js";
import { createRequire } from "node:module";
import { execFileSync } from "node:child_process";
import { existsSync, mkdirSync, mkdtempSync, readFileSync, writeFileSync } from "node:fs";
import { tmpdir } from "node:os";
import { join } from "node:path";
import { beforeEach, describe, expect, it, vi } from "vitest";
import { parse, stringify } from "yaml";
import "../gates/predicates.js";
import { verifyEvidence } from "../gates/engine.js";
import { decide } from "../ledger/human.js";
import { HUMAN_WRITER, Ledger } from "../ledger/ledger.js";
import { replay } from "../ledger/state.js";
import type { Conversation, Provider, Turn } from "../runners/api.js";
import { setSkipInfra } from "../runners/netinfra.js";
import type { ContainerRuntime, ContainerSpec } from "../verify/runtime.js";
import { trx } from "../verify/testutil.js";
import { createRun, execute } from "./executor.js";
import { lockOf } from "./build.js";
import { setProviderFactory } from "./think.js";
import { setRuntime } from "./workspace.js";
import { _resetEnvCache } from "../config/env.js";
import http from "node:http";
import type { AddressInfo } from "node:net";

const GREETER = `namespace Api;
public class Greeter
{
    public string Greet(string name) => "Hi " + name;
}
`;
const AC_ID = "Api.Tests::Api.Tests.GreetTests.AC_1_1_GreetsWithHello";
const CHAR_ID = "Api.Tests::Api.Tests.ExistingTests.CHAR_Works";

const { DatabaseSync } = createRequire(import.meta.url)("node:sqlite") as { DatabaseSync: new (path: string) => { exec(sql: string): void; close(): void } };
/** the scripted plan's one table as Entity Framework creates it, with a column of the code's own */
const GREETINGS_DB = `CREATE TABLE "Greetings" ("Id" INTEGER NOT NULL CONSTRAINT "PK_Greetings" PRIMARY KEY AUTOINCREMENT, "Text" TEXT NOT NULL, "CreatedAt" TEXT NOT NULL);`;

function makeRepo(): string {
  const dir = mkdtempSync(join(tmpdir(), "factory-e2e-repo-"));
  const env = { ...process.env, GIT_CONFIG_GLOBAL: "/dev/null", GIT_AUTHOR_NAME: "t", GIT_AUTHOR_EMAIL: "t@t", GIT_COMMITTER_NAME: "t", GIT_COMMITTER_EMAIL: "t@t" };
  execFileSync("git", ["init", "-q", "-b", "main"], { cwd: dir, env });
  mkdirSync(join(dir, "src/Api"), { recursive: true });
  mkdirSync(join(dir, "tests/Api.Tests"), { recursive: true });
  writeFileSync(join(dir, "src/Api/Greeter.cs"), GREETER);
  writeFileSync(join(dir, "tests/Api.Tests/ExistingTests.cs"), "namespace Api.Tests; public class ExistingTests { }\n");
  writeFileSync(join(dir, "src/Api/Api.csproj"), '<Project Sdk="Microsoft.NET.Sdk.Web"><PropertyGroup><TargetFramework>net8.0</TargetFramework></PropertyGroup></Project>\n');
  execFileSync("git", ["add", "-A"], { cwd: dir, env });
  execFileSync("git", ["commit", "-q", "-m", "init"], { cwd: dir, env });
  return dir;
}

// ---------- scripted model ----------
const U = { inputTokens: 2000, outputTokens: 300, cacheRead: 0, cacheWrite: 0 };
/** Three tasks, one criterion each: Greeter says Hello, Farewell says Bye, Third says Three. */
let multi = false;
/** multi: how many times the planner sends a plan that does not match its schema */
let planBadShape = 0;
/** multi: the plan's tasks do not build on each other (no task waits for another's files) */
let unchained = false;
/** how many times the multi-task planner leaves REQ-3 out of its plan */
let planMisses = 0;
/** what the scripted reviewer reports (non-blocking) */
let reviewFindings: unknown[] = [];
/** intake's risk: "low" takes the light lane, "medium" the full one */
let intakeRisk = "low";
/** what the scripted spec critic reports; a repair (the "Repair this spec" task) answers repairSpec when set */
let criticFindings: unknown[] = [];
let repairSpec: unknown;
let repairCalls = 0;
/** the spec-question writer asks one question about the first open problem */
let settleAsks = false;
let reviseCalls = 0;
/** the spec drafters' whole prompt, as last sent */
let draftPrompt = "";
const MULTI_FILES = ["src/Api/Greeter.cs", "src/Api/Farewell.cs", "src/Api/Third.cs"];
const MULTI_TESTS = ["AC_1_1_GreetsWithHello", "AC_2_1_SaysBye", "AC_3_1_CountsThree"];
function multiAnswer(system: string): unknown {
  if (system.includes("Senior engineer writing a behaviour spec")) {
    const one = answerFor(system, false) as { requirements: unknown[] };
    const req = (n: number, then: string) => ({ id: `REQ-${n}`, ears: `When called, the service shall ${then}.`, op: "ADDED", sources: ["I-1"], anchors: [],
      acceptance: [{ id: `AC-${n}.1`, given: "a call", when: "it runs", then: `the returned value is ${then.replace("say ", "")}`, level: "api" }] });
    return { ...one, requirements: [...one.requirements, req(2, "say Bye"), req(3, "say Three")] };
  }
  if (system.includes("Merge three independent")) {
    const one = answerFor(system, false) as Record<string, unknown>;
    return { ...one, spec: multiAnswer("Senior engineer writing a behaviour spec"), alignment: [1, 2, 3].map((n) => ({ mergedReq: `REQ-${n}`, from: [`d1:REQ-${n}`, `d2:REQ-${n}`, `d3:REQ-${n}`] })) };
  }
  if (system.includes("plan the implementation")) {
    const one = answerFor(system, false) as { tasks: { reqs: string[]; fileScope: string[] }[] };
    const t = (n: number) => ({ id: `TASK-${n}`, title: `Part ${n}`, reqs: [`REQ-${n}`], fileScope: [MULTI_FILES[n - 1]!], exemplars: [], conventions: [], dependsOn: n > 1 && !unchained ? [`TASK-${n - 1}`] : [], plannedLoc: 3, approach: "small edit" });
    // a plan that failed its checks is asked for as a patch: only the missing task comes back
    if (system.includes("THE PLAN IS FIXED, NOT REWRITTEN")) return { tasks: [t(3)] };
    if (planMisses-- > 0) return { ...one, tasks: [t(1), t(2)] };
    // a plan in the wrong shape: the third task's size is a word
    if (planBadShape-- > 0) return { ...one, tasks: [t(1), t(2), { ...t(3), plannedLoc: "three lines" }] };
    return { ...one, tasks: [t(1), t(2), t(3)] };
  }
  return undefined;
}
/** the clarifier's last instructions, as the model received them */
let clarifierPrompt = "";
/** what the scripted reviewer says about every locked test, and how many reviews were paid for */
let reviewVerdict: "proves-it" | "weak" | "no-test" = "proves-it";
let reviewCalls = 0;
/** what the scripted check before the lock says about every new test (unscripted when unset), and how often it was asked */
let proofVerdict: "proves-it" | "weak" | "no-test" | undefined;
let proofCalls = 0;
/** what the scripted test-or-code check says about every locked test it is asked about, and how often it was asked */
let judgeVerdict: "code" | "test" | "scope" | "unclear" = "code";
let judgeCalls = 0;
/** "scope": the files the scripted check says the test needs */
let judgeFiles: string[] = [];
/** what the scripted check of a rewritten test says, and how often it was asked */
let rewriteVerdict: "keeps" | "loosened" | "partial" = "keeps";
let rewriteChecks = 0;
/** the spec also carries a criterion only a person can check */
let manualCriterion = false;
/** how many of the next runs of the new test on the old code crash in its own set-up instead of failing an assertion */
let baseCrashes = 0;
/** A scripted review must now account for every acceptance criterion, as a real one must. */
function scriptedReview(user: string, findings: unknown[] = []) {
  reviewCalls += 1;
  const acIds = [...new Set([...user.matchAll(/"id":\s*"(AC-[\w.-]+)"/g)].map((m) => m[1]!))];
  return { findings, coverage: acIds.map((acId) => ({ acId, testId: "", verdict: reviewVerdict, why: "scripted" })) };
}

function answerFor(system: string, allowMulti = true, user = ""): unknown {
  if (multi && allowMulti) { const m = multiAnswer(system); if (m !== undefined) return m; }
  if (system.includes("intake step")) return { source: "cli", spans: [{ id: "I-1", text: "greet with Hello" }], changeClass: "feature", risk: intakeRisk, riskTags: [], rigor: "light", touchesUi: false };
  if (system.includes("grounding step")) return { claims: [{ id: "C-1", text: "Greeter says Hi", spans: ["I-1"], anchors: [{ path: "src/Api/Greeter.cs", lineStart: 4, lineEnd: 4, quote: 'public string Greet(string name) => "Hi " + name;', symbol: "Greeter.Greet" }] }], notFound: [] };
  if (system.includes("independently reading a change request")) return { spans: [{ id: "I-1", behaviours: [{ text: system.length % 2 ? "Hello Ann" : "Hello, Ann!", kind: "happy" }, { text: "empty name returns Hello", kind: "error" }] }] };
  if (system.includes("Three engineers independently")) return { differences: [{ id: "D-1", span: "I-1", topic: "punctuation", readings: [{ sketch: 1, behaviour: 0, summary: "Hello Ann" }, { sketch: 2, behaviour: 0, summary: "Hello, Ann!" }] }] };
  // the spec's open problems are settled by questions in a build too: none to ask here, so they are carried as open risks
  if (system.includes("these problems are still open")) return { questions: settleAsks ? [{ problems: [1], text: "What does an empty name return?", options: ["Hello", "An error"], recommended: "Hello", reason: "simplest", impact: 2, impactReason: "visible text" }] : [], inRequest: [] };
  if (system.includes("Requirements analyst")) clarifierPrompt = system;
  if (system.includes("Requirements analyst")) return system.includes("already answered") ? { questions: [], conflicts: [] } : {
    questions: [{ id: "q1", category: "scope", text: "Keep the comma?", options: ["Hello Ann", "Hello, Ann!"], recommended: "Hello Ann", reason: "shortest", spans: ["I-1"], impact: 2, impactReason: "visible text", difference: "D-1" }], conflicts: [] };
  if (system.includes("Merge three independent")) return { spec: answerFor("Senior engineer writing a behaviour spec"), alignment: [{ mergedReq: "REQ-1", from: ["d1:REQ-1", "d2:REQ-1", "d3:REQ-1"] }], conflicts: [] };
  if (system.includes("State, as numbered")) return { sentences: [{ n: 1, text: "Greetings start with Hello." }] };
  if (system.includes("Map each restated")) return { mapping: [{ n: 1, spans: ["I-1"], answers: [] }] };
  if (system.includes("Senior engineer writing a behaviour spec")) return {
    requirements: [{ id: "REQ-1", ears: "When a name is given, the Greeter shall return a greeting that starts with Hello.", op: "MODIFIED", sources: ["I-1"],
      anchors: [{ path: "src/Api/Greeter.cs", lineStart: 4, lineEnd: 4, quote: 'public string Greet(string name) => "Hi " + name;' }],
      acceptance: [{ id: "AC-1.1", given: "a name Ann", when: "Greet is called", then: "the returned value is Hello Ann", level: "api" },
        ...(manualCriterion ? [{ id: "AC-1.2", given: "the greeting on the home page", when: "a person reads it", then: "it shows Hello Ann in the heading", level: "manual" }] : [])] }],
    nfrs: [], outOfScope: ["other greetings"], assumptions: [], suggestions: [],
  };
  if (system.includes("Adversarial reviewer")) return { findings: criticFindings };
  if (system.includes("plan the implementation")) return {
    tasks: [{ id: "TASK-1", title: "Say Hello", reqs: ["REQ-1"], fileScope: ["src/Api/Greeter.cs"], exemplars: [], conventions: [], dependsOn: [], plannedLoc: 3, approach: "change the literal" }],
    options: [{ id: "O-1", summary: "change the literal", simplest: true, tradeoffs: "none" }, { id: "O-2", summary: "make it configurable", simplest: false, tradeoffs: "more code" }],
    chosen: "O-1", adr: "Change the literal; configuration isn't asked for.", protectedPathsDeclared: [], newDependencies: [], stubs: planStubs.length > 1 ? planStubs.shift()! : planStubs[0] ?? [],
    // a backend that must give its data model (a new product's API) gets one
    ...(!planGivesNoModel && (system.includes("DATA MODEL. Give") || system.includes("The database as it is now")) ? { dataModel: { tables: [{ name: "Greetings", purpose: "the greeting text", columns: [{ name: "Id", type: "int", required: true, pk: true }, { name: "Text", type: "string", required: true }] }] } } : {}),
  };
  if (system.includes("review a finished change")) return scriptedReview(user, reviewFindings);
  if (system.includes("A locked acceptance test failed on two attempts")) {
    judgeCalls += 1;
    return { verdicts: [...new Set([...user.matchAll(/"testId":\s*"([^"]+)"/g)].map((m) => m[1]!))].map((testId) => ({ testId, verdict: judgeVerdict, why: "scripted verdict", files: judgeFiles })) };
  }
  if (system.includes("has been rewritten. Check the rewrite")) {
    rewriteChecks += 1;
    return { verdicts: [...new Set([...user.matchAll(/"testId":\s*"([^"]+)"/g)].map((m) => m[1]!))].map((testId) => ({ testId, verdict: rewriteVerdict, why: "scripted rewrite check" })) };
  }
  if (proofVerdict && system.includes("check acceptance tests before they are locked")) {
    proofCalls += 1;
    return { coverage: [...new Set([...user.matchAll(/"id":\s*"(AC-[\w.-]+)"/g)].map((m) => m[1]!))].map((acId) => ({ acId, testId: "", verdict: proofVerdict, why: "scripted check" })) };
  }
  throw new Error(`unscripted system prompt: ${system.slice(0, 80)}`);
}
const modelCalls: string[] = [];
/** the planner's whole prompt, as last sent */
let planPrompt = "";
/** the plan changes no stored data: it gives no data model even where it is shown a database */
let planGivesNoModel = false;
/** the stubs each plan answer gives, in order (the last repeats) */
let planStubs: { path: string; content: string }[][] = [];
const provider: Provider = {
  start(model, _e, system, user): Conversation {
    modelCalls.push(model);
    if (system.includes("plan the implementation")) planPrompt = `${system}\n${user}`;
    const repair = user.includes("Repair this spec");
    if (repair) repairCalls++;
    if (user.includes("Revise this spec so it addresses")) reviseCalls++;
    if (system.includes("Senior engineer writing a behaviour spec") && !repair && !user.includes("Revise this spec")) draftPrompt = `${system}\n${user}`;
    return {
      async next(): Promise<Turn> { return { calls: [{ id: "s", name: "submit_result", input: repair && repairSpec ? repairSpec : answerFor(system, true, user) }], text: "", stop: "tool_use", usage: U }; },
      toolResults() {}, say() {},
    };
  },
};

// ---------- fake containers: tests pass once Greeter says Hello ----------
class Lab implements ContainerRuntime {
  binary = "fake";
  specs = new Map<string, ContainerSpec>();
  n = 0;
  crashOnImplement = false;
  /** the OpenAPI document the API's build writes (a project with a locked contract), from the checkout being built */
  builtDoc?: (src: string) => string;
  /** the schema the app creates in its SQLite file when it starts (a backend with an approved data model), as SQL */
  builtDb?: string;
  /** the schema the untouched code creates on startup (an existing backend), as SQL; without it the first start makes an empty database */
  existingDb?: string;
  appStarted = false;
  /** the repo has a test that fails on its main branch too (a known failure) */
  knownBroken = false;
  /** multi: per file scope, the files each implement attempt writes (the last entry repeats) */
  edits: Record<string, Record<string, string>[]> = {};
  /** multi: what each implement attempt found before it edited */
  seen: { scope: string; head: string; task: string; files: Record<string, string | null> }[] = [];
  /** multi: the test writer leaves the last criterion out of this many attempts, and stops out of budget in this many after */
  missAc = 0;
  testsOverBudget = 0;
  /** multi: what each test-writer attempt found before it wrote (its own earlier files, the briefing) */
  testSeen: { task: string; kept: string[] }[] = [];
  /** every coding-agent job as the container got it (model, limits, scope) */
  jobs: { model: string; maxTurns: number; maxUsd: number; fileScope: string[]; system: string }[] = [];
  async version() { return "fake"; }
  async create(s: ContainerSpec) { const id = `c${++this.n}`; this.specs.set(id, s); return id; }
  async start(id: string) {
    const s = this.specs.get(id);
    // the first start is the code before the run (the tests commit): a new product, so its database is there with no table yet
    const first = s?.role === "app" && !this.appStarted;
    if (s?.role === "app") this.appStarted = true;
    if (s?.role === "app" && (this.builtDb || first)) {
      const db = new DatabaseSync(join(s.mounts.find((m) => m.dst === "/src")!.src, "src/Api/app.db"));
      db.exec(first ? this.existingDb ?? "PRAGMA user_version = 1" : this.builtDb!);
      db.close();
    }
  }
  async wait(id: string) {
    const s = this.specs.get(id)!;
    const mount = (dst: string) => s.mounts.find((m) => m.dst === dst)?.src;
    if (s.role === "agent") {
      const work = mount("/work")!;
      const job = JSON.parse(readFileSync(mount("/job/in.json")!, "utf8")) as { fileScope: string[] };
      this.jobs.push(job as never);
      const out = mount("/job/out")!;
      if (multi && job.fileScope.includes("tests/**")) {
        const mine = ["tests/Api.Tests/GreetTests.cs", "tests/Api.Tests/ThirdTests.cs"];
        this.testSeen.push({ task: (job as unknown as { task: string }).task, kept: mine.filter((f) => existsSync(join(work, f))) });
        const miss = this.missAc-- > 0;
        writeFileSync(join(work, "tests/Api.Tests/GreetTests.cs"), "namespace Api.Tests; public class GreetTests { }\n");
        if (!miss) writeFileSync(join(work, "tests/Api.Tests/ThirdTests.cs"), "namespace Api.Tests; public class ThirdTests { }\n");
        if (!miss && this.testsOverBudget-- > 0) {
          writeFileSync(join(out, "result.json"), JSON.stringify({ status: "over-budget", error: "Reached maximum budget ($0.50)", instructionsLoaded: [], deniedEdits: [], usage: { input_tokens: 8000, output_tokens: 900 }, costUsd: 0.5, turns: 9 }));
          return 0;
        }
        writeFileSync(join(out, "result.json"), JSON.stringify({ status: "ok", output: { tests: MULTI_TESTS.slice(0, miss ? -1 : undefined).map((name, i) => ({ acId: `AC-${i + 1}.1`, file: "tests/Api.Tests/GreetTests.cs", name })), characterisation: [{ target: "Greeter", file: "tests/Api.Tests/ExistingTests.cs", name: "CHAR_Works" }], probes: [], notes: "" }, instructionsLoaded: [], deniedEdits: [], usage: { input_tokens: 5000, output_tokens: 800 }, costUsd: 0.05, turns: 6 }));
      } else if (multi) {
        const job2 = JSON.parse(readFileSync(mount("/job/in.json")!, "utf8")) as { fileScope: string[]; task: string };
        const scope = job2.fileScope[0]!;
        const read = (f: string) => (existsSync(join(work, f)) ? readFileSync(join(work, f), "utf8") : null);
        this.seen.push({ scope, head: execFileSync("git", ["rev-parse", "HEAD"], { cwd: work, encoding: "utf8" }).trim(), task: job2.task,
          files: Object.fromEntries([...MULTI_FILES, "src/Api/Extra.cs"].map((f) => [f, read(f)])) });
        const list = this.edits[scope]!;
        const edit = list.length > 1 ? list.shift()! : list[0]!;
        for (const [f, text] of Object.entries(edit)) writeFileSync(join(work, f), text);
        writeFileSync(join(out, "result.json"), JSON.stringify({ status: "ok", output: { done: true, filesChanged: Object.keys(edit), notes: "" }, instructionsLoaded: [], deniedEdits: [], usage: { input_tokens: 8000, output_tokens: 900 }, costUsd: 0.08, turns: 9 }));
      } else if (job.fileScope.includes("tests/**")) {
        writeFileSync(join(work, "tests/Api.Tests/GreetTests.cs"), "namespace Api.Tests; public class GreetTests { /* AC-1.1 */ }\n");
        writeFileSync(join(out, "result.json"), JSON.stringify({ status: "ok", output: { tests: [{ acId: "AC-1.1", file: "tests/Api.Tests/GreetTests.cs", name: "AC_1_1_GreetsWithHello" }], characterisation: [{ target: "Greeter", file: "tests/Api.Tests/ExistingTests.cs", name: "CHAR_Works" }], probes: [{ acId: "AC-1.1", method: "GET", path: "/greet/Ann", expectStatus: 200 }], notes: "" }, instructionsLoaded: [], deniedEdits: [], usage: { input_tokens: 5000, output_tokens: 800 }, costUsd: 0.05, turns: 6 }));
      } else {
        if (this.crashOnImplement) { this.crashOnImplement = false; throw new Error("simulated crash"); }
        writeFileSync(join(out, "progress.jsonl"), [
          { ts: 1, kind: "start", model: "claude-sonnet-5-5" },
          { ts: 2, kind: "tool", tool: "Edit", target: "src/Api/Greeter.cs" },
          { ts: 3, kind: "end", status: "ok", turns: 9, costUsd: 0.08 },
        ].map((x) => JSON.stringify(x)).join("\n") + "\n");
        writeFileSync(join(work, "src/Api/Greeter.cs"), GREETER.replace('"Hi "', '"Hello "'));
        writeFileSync(join(out, "result.json"), JSON.stringify({ status: "ok", output: { done: true, filesChanged: ["src/Api/Greeter.cs"], notes: "" }, instructionsLoaded: [], deniedEdits: [], usage: { input_tokens: 8000, output_tokens: 900 }, costUsd: 0.08, turns: 9 }));
      }
      return 0;
    }
    if (s.cmd[1] === "build" && this.builtDoc) {
      const src = mount("/src")!;
      mkdirSync(join(src, "src/Api/openapi"), { recursive: true });
      writeFileSync(join(src, "src/Api/openapi/built.json"), this.builtDoc(src));
    }
    if (s.cmd[1] === "build" && this.buildLog && readFileSync(join(mount("/src")!, "src/Api/Greeter.cs"), "utf8").includes("IMissing")) { this.failedBuilds++; return 1; }
    if (multi && s.cmd[1] === "build") {
      const src = mount("/src")!;
      return MULTI_FILES.some((f) => existsSync(join(src, f)) && readFileSync(join(src, f), "utf8").includes("SYNTAX")) ? 1 : 0;
    }
    if (s.cmd[1] === "test") {
      const src = mount("/src")!;
      const results = [{ name: "CHAR_Works", outcome: "Passed" }];
      let code = 0;
      if (multi && existsSync(join(src, "tests/Api.Tests/GreetTests.cs"))) {
        const read = (f: string) => (existsSync(join(src, f)) ? readFileSync(join(src, f), "utf8") : "");
        // Greeter's test also breaks when Farewell says BREAK: a later task can break an earlier one
        // the third test asks for "Three", or for what a rewritten test file says it wants (WANTS:<text>)
        const wants = /WANTS:(\w+)/.exec(read("tests/Api.Tests/GreetTests.cs"))?.[1] ?? "Three";
        const pass = [read("src/Api/Greeter.cs").includes('"Hello "') && !read("src/Api/Farewell.cs").includes("BREAK"), read("src/Api/Farewell.cs").includes("Bye"), wants === "ANYTHING" || read("src/Api/Third.cs").includes(`"${wants}"`)];
        MULTI_TESTS.forEach((name, i) => results.push(pass[i] ? { name, outcome: "Passed" } : { name, outcome: "Failed", message: `Assert.Equal() Failure: ${name}` } as never));
        if (pass.includes(false)) code = 1;
      } else if (existsSync(join(src, "tests/Api.Tests/GreetTests.cs"))) {
        const done = readFileSync(join(src, "src/Api/Greeter.cs"), "utf8").includes('"Hello "');
        const crash = !done && baseCrashes > 0 && baseCrashes--;
        results.push(done ? { name: "AC_1_1_GreetsWithHello", outcome: "Passed" } : crash ? { name: "AC_1_1_GreetsWithHello", outcome: "Failed", message: "System.InvalidOperationException : no greeting row" } as never : { name: "AC_1_1_GreetsWithHello", outcome: "Failed", message: "Assert.Equal() Failure: Expected Hello Ann, Actual Hi Ann" } as never);
        if (!done) code = 1;
      }
      if (this.knownBroken) { results.push({ name: "Old_Broken", outcome: "Failed", message: "broken on main too" } as never); code = 1; }
      const withCls = results.map((r) => ({ ...r, cls: r.name === "CHAR_Works" ? "ExistingTests" : "GreetTests" }));
      writeFileSync(join(mount("/results")!, "r_Api.Tests.trx"), trx(withCls, "Api.Tests", "Api.Tests"));
      return code;
    }
    return 0;
  }
  appRequests: string[] = [];
  async exec(id: string, cmd: string[]) {
    const s = this.specs.get(id)!;
    if (s.role === "app" && cmd[0] === "curl") {
      const url = cmd[cmd.length - 1]!;
      if (cmd.includes("-o")) return { code: 0, stdout: "404", stderr: "" }; // ready check: any answer
      this.appRequests.push(url);
      const src = s.mounts.find((m) => m.dst === "/src")!.src;
      const hello = readFileSync(join(src, "src/Api/Greeter.cs"), "utf8").includes('"Hello "');
      return { code: 0, stdout: hello ? "Hello Ann\n200" : "Hi Ann\n500", stderr: "" };
    }
    return { code: 0, stdout: "", stderr: "" };
  }
  async isRunning() { return true; }
  /** what a build that fails on an undeclared type prints */
  buildLog?: string;
  failedBuilds = 0;
  async logs(id: string) { return this.buildLog && this.specs.get(id)?.cmd[1] === "build" ? this.buildLog : "info: Now listening on: http://127.0.0.1:5080"; }
  async stop() {}
  async remove() {}
  async listByLabel() { return []; }
  async imageDigest(i: string) { return `${i}@sha256:fake`; }
}

/** First execute stops at the question card; answer it; the next stops at the approval card. */
async function toApproval(runId: string) {
  const r1 = await execute(runId);
  expect(r1.status).toBe("waiting");
  const ledger = Ledger.open(runId);
  const q = replay(ledger.events()).openCard!;
  expect(q.kind).toBe("question");
  expect(ledger.readCard(q.cardId)).toContain("Keep the comma?");
  await decide(ledger, { decision: "answer", hashPrefix: q.artifactSha.slice(0, 6), by: "ahsan", data: { answers: { "Q-1": "A" } } });
  const r2 = await execute(runId);
  expect(r2.status, r2.message).toBe("waiting");
  return ledger;
}

let lab: Lab;
beforeEach(() => {
  planGivesNoModel = false;
  planStubs = [];
  baseCrashes = 0;
  const home = mkdtempSync(join(tmpdir(), "factory-e2e-"));
  process.env.FACTORY_HOME = home;
  writeFileSync(join(home, ".env"), "ANTHROPIC_API_KEY=sk-ant-test-not-real-000000000000\nOPENAI_API_KEY=sk-openai-test-not-real-0000000000\n", { mode: 0o600 });
  _resetEnvCache();
  const repo = makeRepo();
  mkdirSync(join(home, "projects"), { recursive: true });
  writeFileSync(join(home, "projects", "demo.yaml"), stringify({ project: "demo", repo, stack: "dotnet", database: { producerEnv: { ConnectionStrings__Default: "Host={{DB_HOST}};Password={{DB_PASSWORD}}" } } }));
  lab = new Lab();
  setRuntime(lab);
  setSkipInfra(true);
  setProviderFactory(() => provider);
  modelCalls.length = 0;
  multi = false;
  unchained = false;
  planBadShape = 0;
  planMisses = 0;
  intakeRisk = "low";
  reviewFindings = [];
  reviewVerdict = "proves-it";
  reviewCalls = 0;
  proofVerdict = undefined;
  proofCalls = 0;
  judgeVerdict = "code";
  judgeCalls = 0;
  judgeFiles = [];
  rewriteVerdict = "keeps";
  rewriteChecks = 0;
  manualCriterion = false;
  criticFindings = [];
  repairSpec = undefined;
  repairCalls = 0;
  settleAsks = false;
  reviseCalls = 0;
  draftPrompt = "";
});

describe("brownfield slice end to end (fakes)", () => {
  it("runs to the approval card, then to a locally delivered branch", async () => {
    clarifierPrompt = "";
    lab.knownBroken = true;
    const runId = await createRun("Greet people with Hello instead of Hi", "demo", "tester");
    const ledger = await toApproval(runId);
    const s1 = replay(ledger.events());
    expect(s1.openCard?.kind).toBe("approval");
    const card = ledger.readCard(s1.openCard!.cardId);
    expect(card).toContain("> Greet people with Hello instead of Hi");
    expect(card).toContain("src/Api/Greeter.cs");
    expect(card).toContain("Q-1 Keep the comma? → **Hello Ann**");
    // the clarifier recommends the smallest change; bigger machinery is an option a person picks, never the default
    expect(clarifierPrompt).toMatch(/recommended option is always the smallest change that fully does what the request asks\. Never recommend new database schema, migrations, indexes/);
    expect(card).toContain("Round trip: the spec restated back matches");

    await expect(decide(ledger, { decision: "approve", hashPrefix: "ffff" })).rejects.toThrow();
    await decide(ledger, { decision: "approve", hashPrefix: s1.openCard!.artifactSha.slice(0, 6), by: "ahsan", data: { note: "low risk" } });

    const done = await execute(runId);
    expect(done.status).toBe("delivered");
    const s2 = replay(ledger.events());
    expect(s2.status).toBe("delivered");
    for (const step of ["discover", "intake", "ground", "clarify", "clarify-2", "drafts", "merge", "specify", "plan", "approve", "stub-commit", "author-tests", "implement/TASK-1", "integrate", "accept", "design-fidelity", "design-check", "review", "deliver"]) {
      expect(s2.steps.get(step)?.status, step).toBe("completed");
    }
    // author-tests ran the AC test on base twice and it failed for the right reason
    const gates = s2.gates.map((g) => `${g.gateId}:${g.passed}`);
    expect(gates).toContain("author-tests.fails-on-base:true");
    expect(gates).toContain("tests.expectations:true");
    expect(gates).toContain("deliver.sha-binding:true");
    // test lab: finding the new tests is the first run on the old code, and integrate reuses the
    // task's full run on the same commit instead of building and testing it again
    const testKeys = [...lab.specs.values()].filter((sp) => sp.cmd[1] === "test").map((sp) => sp.labels?.key);
    expect(testKeys).not.toContain("author-tests/find");
    expect(testKeys).not.toContain("integrate");
    expect(testKeys.filter((k) => k?.startsWith("author-tests/base-"))).toEqual(["author-tests/base-1", "author-tests/base-2"]);
    expect(s2.steps.get("integrate")!.data).toMatchObject({ reusedRunFrom: "implement/TASK-1" });
    expect(s2.steps.get("integrate")!.outputs[0]).toBe(s2.steps.get("implement/TASK-1")!.outputs[1]);
    // each commit is built once: fail check #2 reuses the tests commit's build, accept the fix commit's
    const builds = [...lab.specs.values()].filter((sp) => sp.cmd[1] === "build").map((sp) => sp.labels.key);
    expect(builds).toEqual(["discover", "author-tests/base-1", "implement/TASK-1/1"]);
    expect(readFileSync(join(ledger.dir, "run.log"), "utf8")).toMatch(/lab: reused the build of .* from an earlier lab run/);
    expect(existsSync(join(process.env.FACTORY_HOME!, "tmp", runId, "builds"))).toBe(false); // freed once delivered
    // the full-suite run leaves out the known failure; the targeted runs don't use the skip filter
    const OLD = "Api.Tests::Api.Tests.GreetTests.Old_Broken";
    const testCmd = (key: string) => [...lab.specs.values()].find((sp) => sp.cmd[1] === "test" && sp.labels.key === key)!.cmd.join(" ");
    expect(testCmd("implement/TASK-1/1")).toContain("--filter FullyQualifiedName!=Api.Tests.GreetTests.Old_Broken");
    expect(testCmd("accept")).not.toContain("!=");
    expect(testCmd("discover")).not.toContain("--filter");
    expect(ledger.getJson<{ skippedKnownFailures?: string[] }>(s2.steps.get("implement/TASK-1")!.outputs[1]!).skippedKnownFailures).toEqual([OLD]);
    // the branch holds the change, the locked test and exactly one manifest commit on top
    const repo = s2.info.repoPath!;
    const log = execFileSync("git", ["log", "--format=%s", `main..factory/${runId}`], { cwd: repo, encoding: "utf8" }).trim().split("\n");
    expect(log[0]).toMatch(/evidence manifest/);
    expect(log.some((l) => l.includes("TASK-1"))).toBe(true);
    // cost recorded per model call; every decision re-checks
    expect(s2.costUsd).toBeGreaterThan(0);
    expect(verifyEvidence(ledger).every((c) => c.ok)).toBe(true);
    // thinking steps used Opus 5.5 for ground/spec/plan
    expect(modelCalls).toContain("claude-opus-5-5");
    // the ledger says which model each step was given and why: saved once with the run, then on every step and every call
    const evs = ledger.events();
    // nobody picked a model for the critic: it is off, and no call is made on its route
    expect((evs[0]!.data!.routes as Record<string, unknown>).critic).toMatchObject({ source: "off" });
    expect((evs[0]!.data!.routes as Record<string, unknown>).implement).toMatchObject({ model: "claude-sonnet-5-5", source: "default", tier: "standard" });
    expect(evs.find((e) => e.type === "step.started" && e.key?.startsWith("intake"))!.data!.route).toMatchObject({ model: "claude-haiku-5-5", effort: "low", source: "default", tier: "light" });
    expect(evs.filter((e) => e.type === "usage" && e.data!["factory.route"] === "critic")).toEqual([]);
    expect(ledger.readCard(`pr-${runId}`)).toContain("AC-1.1");
    expect(ledger.readCard(`pr-${runId}`)).toContain("Security review (OWASP Top 10): nothing found");
    // the trace shows every level: steps, model turns, lab phases, containers, gates, the coding agent's actions
    const trace = readFileSync(join(ledger.dir, "run.log"), "utf8");
    for (const want of [/▶ intake/, /intake turn 1 claude-haiku-5-5 .*→ answered/, /lab: build ok/, /lab: tests ran/, /container producer started/,
      /gate author-tests.fails-on-base passed/, /implementer: Edit src\/Api\/Greeter.cs/, /implementer: agent finished: ok after 9 turns/, /lab: app started/, /lab: probe GET \/greet\/Ann → 200/]) {
      expect(trace, String(want)).toMatch(want);
    }
    expect(trace).not.toContain("sk-ant-test-not-real");
    // the scorecard covers every step, with cost where a model ran
    const { scoreRun, formatRun } = await import("../report.js");
    const score = scoreRun(ledger);
    expect(score.steps.find((x) => x.step === "plan")).toMatchObject({ outcome: "completed", firstTimePass: true, attempts: 1 });
    expect(score.steps.find((x) => x.step === "plan")!.costUsd).toBeGreaterThan(0);
    expect(score.steps.find((x) => x.step === "clarify")!.human).toMatchObject({ questionsAsked: 1, answersChanged: 0 });
    expect(score.steps.find((x) => x.step === "approve")!.human.decisions).toEqual(["approve"]);
    expect(formatRun(score)).toMatch(/implement\/TASK-1 +completed/);
    expect(existsSync(join(ledger.dir, "report.json"))).toBe(true);
    // created/delivered times and every card asked, for the outcome numbers
    expect(Date.parse(score.deliveredAt!)).toBeGreaterThanOrEqual(Date.parse(score.createdAt!));
    expect(score.humanCards).toEqual(["question", "approval"]);
    // accept booted the app next to the test db and replayed the locked probe as evidence
    const app = [...lab.specs.values()].find((sp) => sp.role === "app")!;
    expect(app.cmd).toEqual(["dotnet", "run", "--no-build", "--no-launch-profile", "--project", "src/Api/Api.csproj", "--urls", "http://127.0.0.1:5080"]);
    expect(app.network).toMatch(/^container:/);
    expect(lab.appRequests).toEqual(["http://127.0.0.1:5080/greet/Ann"]);
    const ev = ledger.getJson<{ items: { ac: string; kind: string; passed: boolean; http: { status: number; bodySha: string }[] }[]; app: { ok: boolean } }>(s2.steps.get("accept")!.outputs[0]!);
    expect(ev.app.ok).toBe(true);
    expect(ev.items[0]).toMatchObject({ ac: "AC-1.1", kind: "http", passed: true });
    expect(ledger.getArtifact(ev.items[0]!.http[0]!.bodySha).toString()).toBe("Hello Ann");
  });

  it("carries on when its card is answered while it still holds the lock", async () => {
    const runId = await createRun("Greet people with Hello instead of Hi", "demo", "tester");
    // the answer lands the moment the card is asked, before the executor has let go of the repo
    const append = Ledger.prototype.append;
    let answered = false;
    const spy = vi.spyOn(Ledger.prototype, "append").mockImplementation(async function (this: Ledger, ev, writer) {
      const full = await append.call(this, ev, writer);
      if (ev.type === "human.requested" && !answered) {
        answered = true;
        await decide(this, { decision: "answer", hashPrefix: String((ev.data as { artifactSha: string }).artifactSha).slice(0, 6), by: "ahsan", data: { answers: { "Q-1": "A" } } });
      }
      return full;
    });
    try {
      const r = await execute(runId);
      expect(r.status, r.message).toBe("waiting");
      expect(replay(Ledger.open(runId).events()).openCard?.kind).toBe("approval");
    } finally {
      spy.mockRestore();
    }
  });

  it("asks a person about a change over the size limit instead of parking for good", async () => {
    const file = join(process.env.FACTORY_HOME!, "projects", "demo.yaml");
    writeFileSync(file, stringify({ ...parse(readFileSync(file, "utf8")), policy: { maxDiffLines: 1 } }));
    const runId = await createRun("Greet people with Hello instead of Hi", "demo", "tester");
    const ledger = await toApproval(runId);
    await decide(ledger, { decision: "approve", hashPrefix: replay(ledger.events()).openCard!.artifactSha.slice(0, 6), by: "ahsan" });
    const r = await execute(runId);
    expect(r.status, r.message).toBe("waiting");
    const card = replay(ledger.events()).openCard!;
    expect(card.kind).toBe("waiver");
    expect(readFileSync(join(ledger.dir, "cards", `${card.cardId}.md`), "utf8")).toMatch(/integrate\.diff-size: Diff too large/);
    await decide(ledger, { decision: "waive", hashPrefix: card.artifactSha.slice(0, 6), by: "lead", data: { reason: "one feature, reviewed as a whole" } });
    expect((await execute(runId)).status).toBe("delivered");
    expect(replay(ledger.events()).steps.get("integrate")!.data!.waivers).toMatchObject([{ gateIds: ["integrate.diff-size"], human: "lead" }]);
  });

  it("a locked test the reviewer calls weak does not stop the run: it is named on the pull request and the Tests page", async () => {
    reviewVerdict = "weak";
    const runId = await createRun("Greet people with Hello instead of Hi", "demo", "tester");
    const ledger = await toApproval(runId);
    await decide(ledger, { decision: "approve", hashPrefix: replay(ledger.events()).openCard!.artifactSha.slice(0, 6), by: "ahsan" });
    const r = await execute(runId);
    expect(r.status, r.message).toBe("delivered");
    expect(reviewCalls).toBe(1);
    const s = replay(ledger.events());
    // the gate that stops a run passed, so the merge gate has no failed gate to replay
    expect(s.gates.filter((g) => g.gateId === "review.tests-prove-criteria")).toEqual([]);
    expect(s.gates.filter((g) => g.gateId === "review.criteria-have-tests").map((g) => g.passed)).toEqual([true]);
    expect(s.steps.get("review")!.data!.weakTests).toEqual([{ acId: "AC-1.1", verdict: "weak", testId: "", why: "scripted" }]);
    expect(s.steps.get("review")!.data!.waivers).toBeUndefined();
    const pr = ledger.readCard(`pr-${runId}`);
    expect(pr).toContain("1 locked test the review judged not to prove its criterion. It passes, and the run did not stop for it:");
    expect(pr).toContain("  - AC-1.1: the test is too weak (scripted)");
    expect(testsView(ledger)).toMatchObject({ stage: "reviewed", proof: { passed: false, flagged: 1 }, metrics: { weak: 1, proven: 0, lockedTests: 1, passing: 1 } });
  });

  it("a criterion the reviewer finds no test for stops the run for a person, who accepts it by name without paying for a second review", async () => {
    reviewVerdict = "no-test";
    const runId = await createRun("Greet people with Hello instead of Hi", "demo", "tester");
    const ledger = await toApproval(runId);
    await decide(ledger, { decision: "approve", hashPrefix: replay(ledger.events()).openCard!.artifactSha.slice(0, 6), by: "ahsan" });
    const r = await execute(runId);
    expect(r.status, r.message).toBe("waiting");
    const card = replay(ledger.events()).openCard!;
    expect(card.kind).toBe("waiver");
    expect(readFileSync(join(ledger.dir, "cards", `${card.cardId}.md`), "utf8")).toMatch(/review\.criteria-have-tests: AC-1\.1: no locked test covers it \(scripted\)/);
    expect(replay(ledger.events()).gates.filter((g) => g.gateId === "review.criteria-have-tests").map((g) => g.passed)).toEqual([false]);
    // the Tests page shows the verdict while the person decides, from the review the card is holding
    expect(testsView(ledger)).toMatchObject({ stage: "reviewed", proof: { passed: false }, metrics: { noTest: 1, proven: 0, lockedTests: 1, passing: 1 } });
    expect(testsView(ledger).proof!.flagged).toBeUndefined();
    await decide(ledger, { decision: "waive", hashPrefix: card.artifactSha.slice(0, 6), by: "lead", data: { reason: "the probe covers it" } });
    expect((await execute(runId)).status).toBe("delivered");
    expect(reviewCalls).toBe(1);
    const s = replay(ledger.events());
    expect(s.steps.get("review")!.data!.waivers).toMatchObject([{ gateIds: ["review.criteria-have-tests"], human: "lead", reason: "the probe covers it" }]);
    expect(s.steps.get("review")!.data!.weakTests).toBeUndefined();
    expect(ledger.readCard(`pr-${runId}`)).toContain("Waived by lead: review.criteria-have-tests (the probe covers it)");
    expect(testsView(ledger).proof).toMatchObject({ passed: false, waivedBy: "lead", reason: "the probe covers it" });
  });

  it("a test that crashes on the old code is sent back on the first run alone: no second run (run b587)", async () => {
    baseCrashes = 1;
    const runId = await createRun("Greet people with Hello instead of Hi", "demo", "tester");
    const ledger = await toApproval(runId);
    await decide(ledger, { decision: "approve", hashPrefix: replay(ledger.events()).openCard!.artifactSha.slice(0, 6), by: "ahsan" });
    const r = await execute(runId);
    expect(r.status, r.message).toBe("delivered");
    const base = ledger.events().filter((e) => e.type === "gate.result" && (e.data as { gateId?: string }).gateId === "author-tests.fails-on-base");
    expect(base.map((e) => (e.data as { passed: boolean }).passed)).toEqual([false, true]);
    // the failed check was decided on the first run alone, given as both runs; the passing one ran twice (lab runs below)
    const inputs = base.map((e) => (e.data as { inputs: { run1: string; run2: string } }).inputs);
    expect(inputs[0]!.run1).toBe(inputs[0]!.run2);
    expect(JSON.stringify(base[0]!.data)).toMatch(/fails with exception/);
    const keys = [...lab.specs.values()].filter((sp) => sp.cmd[1] === "test").map((sp) => sp.labels?.key).filter((k) => k?.startsWith("author-tests/base-"));
    expect(keys).toEqual(["author-tests/base-1", "author-tests/base-1", "author-tests/base-2"]);
    expect(verifyEvidence(ledger).every((c) => c.ok)).toBe(true);
  });

  it("tests the check before the lock calls weak go back to the writer, then are locked as they are: the run never waits for a person", async () => {
    proofVerdict = "weak";
    const runId = await createRun("Greet people with Hello instead of Hi", "demo", "tester");
    const ledger = await toApproval(runId);
    await decide(ledger, { decision: "approve", hashPrefix: replay(ledger.events()).openCard!.artifactSha.slice(0, 6), by: "ahsan" });
    const r = await execute(runId);
    expect(r.status, r.message).toBe("delivered");
    const sent = ledger.events().filter((e) => e.type === "step.failed" && String(e.key).startsWith("author-tests/") && (e.data as { signature?: string }).signature === "author-tests:proof");
    // sent back at least once, never more than three times, and each time the ladder had somewhere to go
    expect(sent.length).toBeGreaterThanOrEqual(1);
    expect(sent.length).toBeLessThanOrEqual(3);
    expect(sent.every((e) => (e.data as { action?: string }).action === "retry")).toBe(true);
    expect(proofCalls).toBe(sent.length + 1);
    expect(replay(ledger.events()).steps.get("author-tests")!.data!.weakTests).toEqual([{ acId: "AC-1.1", verdict: "weak", testId: "", why: "scripted check" }]);
  });

  it("a criterion nothing tests stops the run before the build, and once a person accepts it nobody is asked again", async () => {
    proofVerdict = "no-test";
    // the final review reads it the same way: the person's answer before the lock covers it
    reviewVerdict = "no-test";
    const runId = await createRun("Greet people with Hello instead of Hi", "demo", "tester");
    const ledger = await toApproval(runId);
    await decide(ledger, { decision: "approve", hashPrefix: replay(ledger.events()).openCard!.artifactSha.slice(0, 6), by: "ahsan" });
    const r = await execute(runId);
    expect(r.status, r.message).toBe("waiting");
    const waiting = replay(ledger.events());
    const card = waiting.openCard!;
    expect(card.kind).toBe("waiver");
    expect(readFileSync(join(ledger.dir, "cards", `${card.cardId}.md`), "utf8")).toMatch(/tests\.cover-every-criterion: AC-1\.1: no test covers it \(scripted check\)/);
    // it stopped before any code was written
    expect([...waiting.steps.keys()].some((k) => k.startsWith("implement"))).toBe(false);
    const asked = proofCalls;
    await decide(ledger, { decision: "waive", hashPrefix: card.artifactSha.slice(0, 6), by: "lead", data: { reason: "checked by hand at release" } });
    const r2 = await execute(runId);
    expect(r2.status, r2.message).toBe("delivered");
    // the tests the card held were locked as they were: not written or checked again
    expect(proofCalls).toBe(asked);
    const s = replay(ledger.events());
    expect(s.steps.get("author-tests")!.data).toMatchObject({ acceptedUntested: ["AC-1.1"], waivers: [{ gateIds: ["tests.cover-every-criterion"], human: "lead", reason: "checked by hand at release" }] });
    expect(s.gates.filter((g) => g.gateId === "review.criteria-have-tests").map((g) => g.passed)).toEqual([true]);
    expect(ledger.readCard(`pr-${runId}`)).toContain("Waived by lead: tests.cover-every-criterion (checked by hand at release). No test covers AC-1.1");
  });

  it("a criterion with no automated test waits for a person's sign-off after the review, and the pull request names who checked it", async () => {
    manualCriterion = true;
    const runId = await createRun("Greet people with Hello instead of Hi", "demo", "tester");
    const ledger = await toApproval(runId);
    await decide(ledger, { decision: "approve", hashPrefix: replay(ledger.events()).openCard!.artifactSha.slice(0, 6), by: "ahsan" });
    const r = await execute(runId);
    expect(r.status, r.message).toBe("waiting");
    const card = replay(ledger.events()).openCard!;
    expect(card.kind).toBe("manual-check");
    const md = ledger.readCard(card.cardId);
    expect(md).toContain("## AC-1.2 (REQ-1)");
    expect(md).toContain(`factory sign-off ${runId} ${card.artifactSha.slice(0, 8)} --pass AC-1.2`);
    expect(testsView(ledger)).toMatchObject({ signOff: { hash: card.artifactSha.slice(0, 8), criteria: ["AC-1.2"] }, metrics: { byHand: 1, signedOff: 0, automated: 1, proven: 1 } });
    await decide(ledger, { decision: "sign-off", hashPrefix: card.artifactSha.slice(0, 8), by: "sara", data: { checks: { "AC-1.2": { result: "pass", note: "" } } } });
    expect((await execute(runId)).status).toBe("delivered");
    expect(reviewCalls).toBe(1);
    expect(replay(ledger.events()).steps.get("review")!.data!.manualChecks).toEqual({ by: "sara", criteria: ["AC-1.2"] });
    expect(ledger.readCard(`pr-${runId}`)).toContain("AC-1.2: checked by hand and signed off by sara (no automated test)");
    const v = testsView(ledger);
    expect(v.metrics).toMatchObject({ byHand: 1, signedOff: 1, failedByHand: 0 });
    expect(v.requirements![0]!.criteria.map((c) => [c.id, c.state])).toEqual([["AC-1.1", "proven"], ["AC-1.2", "signed"]]);
  });

  it("a criterion a person tries and fails parks the run: nothing is delivered", async () => {
    manualCriterion = true;
    const runId = await createRun("Greet people with Hello instead of Hi", "demo", "tester");
    const ledger = await toApproval(runId);
    await decide(ledger, { decision: "approve", hashPrefix: replay(ledger.events()).openCard!.artifactSha.slice(0, 6), by: "ahsan" });
    await execute(runId);
    const card = replay(ledger.events()).openCard!;
    await decide(ledger, { decision: "sign-off", hashPrefix: card.artifactSha.slice(0, 8), by: "sara", data: { checks: { "AC-1.2": { result: "fail", note: "the heading still says Hi" } } } });
    const r = await execute(runId);
    expect(r.status).toBe("parked");
    expect(r.message).toBe("sara checked by hand and this criterion does not hold: AC-1.2 (the heading still says Hi)");
    expect(replay(ledger.events()).steps.get("deliver")?.status).not.toBe("completed");
    expect(reviewCalls).toBe(1);
    expect(testsView(ledger).requirements![0]!.criteria[1]).toMatchObject({ state: "failed-by-hand", manual: { by: "sara", result: "fail", note: "the heading still says Hi" } });
  });

  it("resumes after a crash mid-implement without redoing finished steps", async () => {
    const runId = await createRun("Greet people with Hello instead of Hi", "demo", "tester");
    const ledger = await toApproval(runId);
    const card = replay(ledger.events()).openCard!;
    await decide(ledger, { decision: "approve", hashPrefix: card.artifactSha.slice(0, 6), by: "ahsan" });

    lab.crashOnImplement = true;
    const r = await execute(runId);
    // the agent error is a normal failed attempt; the ladder retries and the run still delivers
    expect(r.status).toBe("delivered");
    const s = replay(ledger.events());
    expect(s.steps.get("implement/TASK-1")?.attempts).toBe(2);
    expect(s.steps.get("plan")?.attempts).toBe(1);

    // a torn write at the end of the ledger is repaired on the next append
    const { appendFileSync } = await import("node:fs");
    appendFileSync(ledger.eventsPath, '{"seq":999,"ty');
    await ledger.append({ type: "run.pause-requested" }, HUMAN_WRITER);
    expect(ledger.events().some((e) => e.type === "ledger.repaired")).toBe(true);
  });

  it("parks, never swaps, when a step's model isn't in the policy's allowed models", async () => {
    const home = process.env.FACTORY_HOME!;
    const file = join(home, "projects", "demo.yaml");
    const { parse } = await import("yaml");
    writeFileSync(file, stringify({ ...parse(readFileSync(file, "utf8")), policy: { allowedModels: ["claude-haiku-5-5", "claude-sonnet-5-5"] } }));
    const runId = await createRun("Greet people with Hello instead of Hi", "demo", "tester");
    const r = await execute(runId);
    expect(r.status).toBe("parked");
    expect(r.message).toMatch(/needs claude-opus-5-5 but this run's policy allows only claude-haiku-5-5, claude-sonnet-5-5/);
    expect(modelCalls.some((m) => /opus/.test(m))).toBe(false);
  });

  it("parks when a coding step keeps failing a safety gate", async () => {
    const runId = await createRun("Greet people with Hello instead of Hi", "demo", "tester");
    const ledger = await toApproval(runId);
    const card = replay(ledger.events()).openCard!;
    await decide(ledger, { decision: "approve", hashPrefix: card.artifactSha.slice(0, 6), by: "ahsan" });
    // make the implementer also edit the locked test
    const orig = lab.wait.bind(lab);
    lab.wait = async (id: string) => {
      const s = lab.specs.get(id)!;
      const code = await orig(id);
      if (s.role === "agent" && !JSON.parse(readFileSync(s.mounts.find((m) => m.dst === "/job/in.json")!.src, "utf8")).fileScope.includes("tests/**")) {
        writeFileSync(join(s.mounts.find((m) => m.dst === "/work")!.src, "tests/Api.Tests/GreetTests.cs"), "// weakened\n");
      }
      return code;
    };
    const r = await execute(runId);
    expect(r.status).toBe("parked");
    expect(r.message).toMatch(/Safety check failed twice/);
    // every attempt left one summary, and the checks its refused change never reached are on record with the reason
    const events = ledger.events();
    const sums = events.filter((e) => e.type === "attempt.summary" && e.key?.startsWith("implement/TASK-1/")).map((e) => e.data as { attempt: number; result: string; checks: { gateId: string; passed: boolean }[]; skipped: { gateId: string; reason: string }[]; decision: { action: string; ladder?: { rule: string } }; parked?: string; ms: number });
    expect(sums.map((x) => [x.attempt, x.result])).toEqual([[1, "retry"], [2, "parked"]]);
    expect(sums[0]!.checks.find((c) => !c.passed)?.gateId).toBe("task.lock-set-unchanged");
    expect(sums[0]!.skipped.find((k) => k.gateId === "tests.expectations")?.reason).toMatch(/the change itself was refused first \(.*\), so the code was not built or run/);
    expect(sums[0]!.decision).toMatchObject({ action: "retry", ladder: { rule: "safety", attempts: 1 } });
    expect(sums[1]!).toMatchObject({ decision: { action: "park", ladder: { rule: "safety", attempts: 2 } }, parked: expect.stringMatching(/Safety check failed twice/) });
    // each check result says which attempt it belongs to
    expect(events.filter((e) => e.type === "gate.result" && (e.data as { step?: string }).step === "implement/TASK-1").map((e) => (e.data as { attempt?: number }).attempt)).toEqual(expect.arrayContaining([1, 2]));
    // a step that passed has its summary too, and the summaries change nothing a re-check or a replay reads
    expect(events.some((e) => e.type === "attempt.summary" && e.key === "author-tests/1" && (e.data as { result: string }).result === "passed")).toBe(true);
    expect(verifyEvidence(ledger).every((c) => c.ok)).toBe(true);
    const { explainRun } = await import("../cli/explain.js");
    expect(explainRun(events, { step: "implement/TASK-1" })).toMatch(/attempt 2 .*→ {2}PARKED[\s\S]*rule: a safety check failed\. Attempts 2 of/);
  });

  it("a rejection revises the spec and plan and shows a new card; a second rejection parks", async () => {
    const runId = await createRun("Greet people with Hello instead of Hi", "demo", "tester");
    const ledger = await toApproval(runId);
    const card1 = replay(ledger.events()).openCard!;
    const before = modelCalls.length;
    await decide(ledger, { decision: "reject", hashPrefix: card1.artifactSha.slice(0, 6), by: "ahsan", data: { reason: "Keep 'Hi' for admins" } });
    const r2 = await execute(runId);
    expect(r2.status).toBe("waiting");
    const card2 = replay(ledger.events()).openCard!;
    expect(card2.kind).toBe("approval");
    expect(card2.artifactSha).not.toBe(card1.artifactSha);
    expect(modelCalls.length).toBeGreaterThan(before); // spec + plan re-ran
    const s = replay(ledger.events());
    expect(s.steps.get("specify")?.attempts).toBe(2);
    expect(s.steps.get("plan")?.attempts).toBe(2);
    expect(s.steps.get("clarify")?.attempts).toBe(1); // earlier steps untouched
    // an old hash can't approve the new card
    await expect(decide(ledger, { decision: "approve", hashPrefix: card1.artifactSha.slice(0, 6) })).rejects.toThrow();
    await decide(ledger, { decision: "reject", hashPrefix: card2.artifactSha.slice(0, 6), by: "ahsan", data: { reason: "still wrong" } });
    const r3 = await execute(runId);
    expect(r3.status).toBe("parked");
    expect(r3.message).toMatch(/Rejected 2 times/);
  });

  it("a request can come from a Markdown file; its name shows on the card", async () => {
    const { readRequestFile, MAX_REQUEST_FILE_BYTES } = await import("./executor.js");
    const dir = mkdtempSync(join(tmpdir(), "factory-req-"));
    const md = join(dir, "request.md");
    writeFileSync(md, "# Greeting\n\nGreet people with Hello instead of Hi.\n\n- keep the name after the greeting\n");
    const file = readRequestFile(md);
    expect(file.name).toBe("request.md");
    const runId = await createRun(file.text, "demo", "tester", { requestFile: file.name });
    const ledger = Ledger.open(runId);
    const s = replay(ledger.events());
    expect(s.info.requestFile).toBe("request.md");
    expect(s.info.request).toBe(file.text);
    const withCard = await toApproval(runId);
    const card = withCard.readCard(replay(withCard.events()).openCard!.cardId);
    expect(card).toContain("## Your request (word for word, from request.md)");
    expect(card).toContain("> - keep the name after the greeting");
    // too big or empty files are refused before a run exists
    const big = join(dir, "big.md");
    writeFileSync(big, "x".repeat(MAX_REQUEST_FILE_BYTES + 1));
    expect(() => readRequestFile(big)).toThrow(/split the request/);
    writeFileSync(join(dir, "empty.md"), "  \n");
    expect(() => readRequestFile(join(dir, "empty.md"))).toThrow(/empty/);
    expect(() => readRequestFile(join(dir, "missing.md"))).toThrow(/No such file/);
  });
});

// a full-stack product's API repo: the contract file is in the repo (approved with the web app's plan), and the API is held to it
describe("a guided run: autonomous off (fakes)", () => {
  const REQ = "Greet people with Hello instead of Hi";
  /** Runs on and returns the card it stops at. */
  const stop = async (ledger: Ledger) => {
    const r = await execute(ledger.runId);
    expect(r.status, r.message).toBe("waiting");
    return replay(ledger.events()).openCard!;
  };
  const answer = (ledger: Ledger, card: { artifactSha: string }, decision: "approve" | "reject", reason = "") =>
    decide(ledger, { decision, hashPrefix: card.artifactSha.slice(0, 8), by: "ahsan", data: decision === "reject" ? { reason } : { note: "" } });
  /** A guided run answered up to its "what I understood" card. */
  const toUnderstood = async () => {
    const ledger = Ledger.open(await createRun(REQ, "demo", "tester", { autonomous: false }));
    const q = await stop(ledger);
    expect(q.kind).toBe("question");
    await decide(ledger, { decision: "answer", hashPrefix: q.artifactSha.slice(0, 6), by: "ahsan", data: { answers: { "Q-1": "A" } } });
    const card = await stop(ledger);
    expect(card.kind).toBe("understood");
    return { ledger, card };
  };

  it("stops at what was understood, then the spec, then the plan; each card has a plain top and its detail below", async () => {
    const { ledger, card: u } = await toUnderstood();
    expect(replay(ledger.events()).info.autonomous).toBe(false);
    const understood = ledger.readCard(u.cardId);
    expect(understood).toContain("- greet with Hello");
    expect(understood).toContain("Keep the comma? → **Hello Ann**");
    // nothing of the spec exists while this card waits
    expect(replay(ledger.events()).steps.has("drafts")).toBe(false);
    await answer(ledger, u, "approve");
    const sc = await stop(ledger);
    expect(sc.kind).toBe("spec-review");
    const s1 = replay(ledger.events());
    expect(s1.steps.has("impact")).toBe(false);
    expect(s1.steps.has("plan")).toBe(false);
    const spec = ledger.readCard(sc.cardId);
    expect(spec).toContain("- When a name is given, the Greeter shall return a greeting that starts with Hello. Checked by: an API test. (REQ-1)");
    expect(spec).toContain("- other greetings");
    expect(spec).toMatch(/Spent so far: \$\d+\.\d\d of a \$\d+\.\d\d limit\./);
    // the technical part is one step away: left out of the short view, kept with the commands in the full one
    expect(cardView(spec, false)).not.toContain("AC-1.1 [api]");
    expect(cardView(spec, false)).toContain(`factory approve ${ledger.runId}`);
    expect(cardView(spec, true)).toContain("AC-1.1 [api] Given a name Ann");
    await answer(ledger, sc, "approve");
    const pc = await stop(ledger);
    expect(pc.kind).toBe("approval");
    const plan = ledger.readCard(pc.cardId);
    expect(plan).toMatch(/- \*\*Say Hello\*\* \(TASK-1\)\n {2}- When a name is given, the Greeter shall/);
    expect(cardView(plan, false)).not.toContain("## Files the plan will touch");
    expect(cardView(plan, true)).toContain("## Files the plan will touch");
    await answer(ledger, pc, "approve");
    const r = await execute(ledger.runId);
    expect(r.status, r.message).toBe("delivered");
    expect(replay(ledger.events()).decisions.map((d) => d.cardId.replace(/-[0-9a-f]+$/, ""))).toEqual(["questions-1", "understood", "spec-review", "approval"]);
  });

  it("a correction on what was understood reaches the spec writers and runs nothing again; the page can send it", async () => {
    const { ledger, card } = await toUnderstood();
    const before = modelCalls.length;
    // from the run page, as the terminal's reject does
    await decideCard(ledger, { hash: card.artifactSha.slice(0, 8), decision: "reject", by: "Ahsan", reason: "Admins keep Hi" }, { execute: () => undefined });
    expect((await stop(ledger)).kind).toBe("spec-review");
    expect(draftPrompt).toContain("Admins keep Hi");
    const s = replay(ledger.events());
    expect(s.steps.get("clarify")!.attempts).toBe(1);
    expect(s.steps.get("drafts")!.attempts).toBe(1);
    expect(modelCalls.length).toBeGreaterThan(before);
  });

  it("the spec sent back is revised alone and shown again; the plan never sees the reason; a second time parks", async () => {
    const { ledger, card: u } = await toUnderstood();
    await answer(ledger, u, "approve");
    const c1 = await stop(ledger);
    await answer(ledger, c1, "reject", "Admins keep Hi");
    const c2 = await stop(ledger);
    expect(c2.kind).toBe("spec-review");
    expect(c2.artifactSha).not.toBe(c1.artifactSha);
    expect(reviseCalls).toBe(1);
    const s = replay(ledger.events());
    expect(s.steps.get("specify")!.attempts).toBe(2);
    expect(s.steps.get("drafts")!.attempts).toBe(1);
    expect(s.steps.has("plan")).toBe(false);
    await answer(ledger, c2, "approve");
    expect((await stop(ledger)).kind).toBe("approval");
    expect(planPrompt).not.toContain("Admins keep Hi");
    expect(replay(ledger.events()).steps.get("plan")!.attempts).toBe(1);

    const other = await toUnderstood();
    await answer(other.ledger, other.card, "approve");
    await answer(other.ledger, await stop(other.ledger), "reject", "one");
    await answer(other.ledger, await stop(other.ledger), "reject", "two");
    const r = await execute(other.ledger.runId);
    expect(r.status).toBe("parked");
    expect(r.message).toMatch(/Rejected 2 times/);
  });

  it("each card can be sent back once: a rejected plan after a rejected spec does not park, and the spec is reviewed on the plan card", async () => {
    const { ledger, card: u } = await toUnderstood();
    await answer(ledger, u, "approve");
    await answer(ledger, await stop(ledger), "reject", "Admins keep Hi");
    await answer(ledger, await stop(ledger), "approve");
    const p1 = await stop(ledger);
    expect(p1.kind).toBe("approval");
    await answer(ledger, p1, "reject", "Keep it to one task");
    // the spec and plan are revised as a rejected plan always was; the spec card is not shown a third time
    const p2 = await stop(ledger);
    expect(p2.kind).toBe("approval");
    expect(p2.artifactSha).not.toBe(p1.artifactSha);
    expect(planPrompt).toContain("Keep it to one task");
    expect(replay(ledger.events()).steps.get("spec-review")!.status).toBe("completed");
  });

  it("the project's autonomous: false guides every run, and --autonomous on one run overrides it", async () => {
    const file = join(process.env.FACTORY_HOME!, "projects", "demo.yaml");
    writeFileSync(file, stringify({ ...parse(readFileSync(file, "utf8")), autonomous: false }));
    expect(replay(Ledger.open(await createRun(REQ, "demo", "tester")).events()).info.autonomous).toBe(false);
    const own = Ledger.open(await createRun(`${REQ}.`, "demo", "tester", { autonomous: true }));
    expect(own.events()[0]!.data).not.toHaveProperty("autonomous");
  });

  it("an autonomous run is as it was: no new step, no new input, no summary on its card", async () => {
    const ledger = await toApproval(await createRun(REQ, "demo", "tester"));
    const s = replay(ledger.events());
    expect(ledger.events()[0]!.data).not.toHaveProperty("autonomous");
    expect(stepsFor(s).map((x) => x.key)).toEqual(["discover", "intake", "ground", "clarify", "clarify-2", "drafts", "merge", "specify", "impact", "plan", "approve", "stub-commit", "author-tests", "implement/TASK-1", "integrate", "accept", "design-fidelity", "design-check", "review", "deliver"]);
    const inputs = (key: string) => Object.keys(stepsFor(s).find((x) => x.key === key)!.inputs(s, ledger)!);
    expect(inputs("drafts")).toEqual(["intent", "cb", "c1", "c2"]);
    expect(inputs("specify")).toEqual(["merged", "rejections"]);
    expect(inputs("approve")).toEqual(["spec", "plan", "rejections"]);
    const card = ledger.readCard(s.openCard!.cardId);
    expect(card).not.toContain("## Technical detail");
    expect(cardView(card, false)).toBe(card);
  });
});

describe("a .NET API held to a locked API contract (fakes)", () => {
  // the document a real .NET 9 build wrote (the spike); the contract says the same
  const doc = readFileSync(new URL("../gates/fixtures/dotnet9-built.json", import.meta.url), "utf8");
  const start = async () => {
    const repo = makeRepo();
    const env = { ...process.env, GIT_CONFIG_GLOBAL: "/dev/null", GIT_AUTHOR_NAME: "t", GIT_AUTHOR_EMAIL: "t@t", GIT_COMMITTER_NAME: "t", GIT_COMMITTER_EMAIL: "t@t" };
    mkdirSync(join(repo, "contracts"));
    writeFileSync(join(repo, "contracts/openapi.yaml"), doc);
    execFileSync("git", ["add", "-A"], { cwd: repo, env });
    execFileSync("git", ["commit", "-q", "-m", "the approved API contract"], { cwd: repo, env });
    writeFileSync(join(process.env.FACTORY_HOME!, "projects", "demo.yaml"), stringify({ project: "demo", repo, stack: "dotnet", contract: { built: "src/Api/openapi/built.json" } }));
    // the product's request talks about its screens; this side still draws no design
    const runId = await createRun("Greet people with Hello instead of Hi, on the web app's sign-in screen", "demo", "tester");
    const ledger = await toApproval(runId);
    expect(replay(ledger.events()).steps.has("design")).toBe(false);
    await decide(ledger, { decision: "approve", hashPrefix: replay(ledger.events()).openCard!.artifactSha.slice(0, 6), by: "lead" });
    return { runId, ledger, repo };
  };

  it("delivers when the document the build wrote says what the contract says; the contract is locked with the tests", async () => {
    lab.builtDoc = () => doc;
    lab.builtDb = GREETINGS_DB;
    const { runId, ledger } = await start();
    const r = await execute(runId);
    expect(r.status, r.message).toBe("delivered");
    const s = replay(ledger.events());
    expect(s.gates.filter((g) => g.gateId === "contract.matches").map((g) => g.passed)).toEqual(expect.arrayContaining([true]));
    expect(s.gates.some((g) => g.gateId === "contract.matches" && !g.passed)).toBe(false);
    expect(ledger.getJson<{ lock: { file: string }[] }>(s.steps.get("author-tests")!.outputs[0]!).lock.map((l) => l.file)).toContain("contracts/openapi.yaml");
    // the planner and both agents were given the locked contract
    expect(planPrompt).toContain("API CONTRACT (locked, contracts/openapi.yaml)");
    expect(lab.jobs.every((j) => j.system.includes("API CONTRACT (locked: contracts/openapi.yaml)"))).toBe(true);
    // a new product's backend: the plan gives the data model, the card shows it as a diagram, and its file is locked with the tests
    expect(planPrompt).toContain("DATA MODEL. Give");
    const card = ledger.events().map((e) => (e.data as { cardId?: string; kind?: string } | undefined)).filter((d) => d?.cardId && d.kind === "approval").map((d) => ledger.readCard(d!.cardId!)).find((t) => t.includes("## Data model"));
    expect(card).toContain("## Data model (contracts/data-model.yaml; 1 table");
    expect(card).toContain("- **Greetings**: Id int [PK], Text string");
    expect(card).toContain("```mermaid\nerDiagram\n  Greetings {\n    int Id PK");
    expect(ledger.getJson<{ lock: { file: string }[] }>(s.steps.get("author-tests")!.outputs[0]!).lock.map((l) => l.file)).toContain("contracts/data-model.yaml");
    expect(lab.jobs.every((j) => j.system.includes("DATA MODEL (approved and locked: contracts/data-model.yaml)"))).toBe(true);
    // the lab started the built app, read the database it created, and it has what the approved model has; the app's own column passes
    expect(s.gates.filter((g) => g.gateId === "data-model.matches").map((g) => g.passed)).toEqual(expect.arrayContaining([true]));
    expect(s.gates.some((g) => g.gateId === "data-model.matches" && !g.passed)).toBe(false);
    expect(readFileSync(join(ledger.dir, "run.log"), "utf8")).toMatch(/read the database the app created \(src\/Api\/app\.db\): 1 table\(s\)[\s\S]*1 column\(s\) the model does not name \(allowed\): Greetings\.CreatedAt/);
    // the pull request text carries the diagram too
    expect(ledger.readCard(`pr-${ledger.runId}`)).toMatch(/## Data model\n1 table, approved with the plan[^\n]*\n\n```mermaid\nerDiagram\n\s+Greetings \{/);
  });

  it("an existing backend: the plan starts from the database the untouched code creates, and the whole database is the model", async () => {
    const USERS_DB = `CREATE TABLE "Users" ("Id" INTEGER NOT NULL CONSTRAINT "PK_Users" PRIMARY KEY AUTOINCREMENT, "Email" TEXT NOT NULL); CREATE UNIQUE INDEX "IX_Users_Email" ON "Users" ("Email");
      CREATE TABLE "Logins" ("Id" INTEGER NOT NULL CONSTRAINT "PK_Logins" PRIMARY KEY AUTOINCREMENT, "UserId" INTEGER NOT NULL, CONSTRAINT "FK_Logins_Users" FOREIGN KEY ("UserId") REFERENCES "Users" ("Id") ON DELETE CASCADE);`;
    lab.builtDoc = () => doc;
    lab.existingDb = USERS_DB;
    lab.builtDb = `${USERS_DB} ${GREETINGS_DB}`;
    const { runId, ledger } = await start();
    // the planner is shown the database as it is, and asked only for what it adds or changes
    expect(planPrompt).toContain("The database as it is now (2 tables");
    // the impact step found no stored data touched here, so each table is one short line (in full when it did)
    expect(planPrompt).toContain("- Users: key Id (2 columns; read its entity for the rest)");
    expect(planPrompt).toContain("- Logins: key Id; points at Users (2 columns; read its entity for the rest)");
    expect(planPrompt).toContain("Give a table only when this plan adds it");
    let s = replay(ledger.events());
    // the plan gave one table; the model kept is the whole database, each table marked by comparing, not by the plan's word
    const model = ledger.getJson<{ dataModel: { tables: { name: string; change: string }[] } }>(s.steps.get("plan")!.outputs[0]!).dataModel;
    expect(model.tables.map((t) => `${t.name} ${t.change}`)).toEqual(["Users unchanged", "Logins unchanged", "Greetings new"]);
    // nothing joins the new table to the old ones, so the card shows it alone and says how many stay as they are
    const card = ledger.events().map((e) => (e.data as { cardId?: string; kind?: string } | undefined)).filter((d) => d?.cardId && d.kind === "approval").map((d) => ledger.readCard(d!.cardId!)).find((t) => t.includes("## Data model"))!;
    expect(card).toContain("## Data model (contracts/data-model.yaml; 3 tables");
    expect(card).toContain("2 other tables stay as they are; the whole database is on the run's Data model page.");
    expect(card).not.toContain("**Users**");
    // the page shows every table
    const { dataModelView } = await import("../ui/erd.js");
    const view = dataModelView(ledger);
    expect("none" in view ? [] : view.layout.boxes.map((b) => `${b.name} ${b.change}`)).toEqual(expect.arrayContaining(["Users unchanged", "Logins unchanged", "Greetings new"]));
    expect("none" in view ? undefined : view.existing).toEqual({ added: 1, changed: 0, unchanged: 2 });
    const r = await execute(runId);
    expect(r.status).toBe("delivered");
    s = replay(ledger.events());
    expect(s.gates.some((g) => g.gateId === "data-model.matches" && !g.passed)).toBe(false);
    expect(readFileSync(join(ledger.dir, "run.log"), "utf8")).toMatch(/database: the untouched code creates 2 table\(s\) \(src\/Api\/app\.db\): Users, Logins[\s\S]*read the database the app created \(src\/Api\/app\.db\): 3 table\(s\)/);
  });

  it("an existing backend: a build that loses one of the old tables is caught, though the plan never named it", async () => {
    const USERS_DB = `CREATE TABLE "Users" ("Id" INTEGER NOT NULL CONSTRAINT "PK_Users" PRIMARY KEY AUTOINCREMENT, "Email" TEXT NOT NULL);`;
    lab.builtDoc = () => doc;
    lab.existingDb = USERS_DB;
    lab.builtDb = GREETINGS_DB;
    const { runId, ledger } = await start();
    const r = await execute(runId);
    expect(r.status).not.toBe("delivered");
    expect(readFileSync(join(ledger.dir, "run.log"), "utf8")).toMatch(/The database does not match the approved data model: Table Users is in the model but not in the database/);
  });

  it("an existing backend, a fix that changes no stored data: no model is written, and the database is still held to what it was", async () => {
    const USERS_DB = `CREATE TABLE "Users" ("Id" INTEGER NOT NULL CONSTRAINT "PK_Users" PRIMARY KEY AUTOINCREMENT, "Email" TEXT NOT NULL);`;
    lab.builtDoc = () => doc;
    lab.existingDb = USERS_DB;
    lab.builtDb = USERS_DB;
    planGivesNoModel = true;
    const { runId, ledger, repo } = await start();
    const r = await execute(runId);
    expect(r.status).toBe("delivered");
    const s = replay(ledger.events());
    expect(ledger.getJson<{ dataModel?: unknown }>(s.steps.get("plan")!.outputs[0]!).dataModel).toBeUndefined();
    // nothing about a data model on the card or in the repo, and the model is not pasted to the agents: one line instead
    expect(ledger.events().map((e) => (e.data as { cardId?: string; kind?: string } | undefined)).filter((d) => d?.cardId && d.kind === "approval").map((d) => ledger.readCard(d!.cardId!)).some((t) => t.includes("## Data model"))).toBe(false);
    expect(execFileSync("git", ["-C", repo, "ls-tree", "-r", "--name-only", s.info.branch ?? "HEAD"], { encoding: "utf8" })).not.toContain("contracts/data-model.yaml");
    expect(lab.jobs.some((j) => j.system.includes("STORED DATA. This plan changes no stored data"))).toBe(true);
    expect(lab.jobs.some((j) => j.system.includes("DATA MODEL (approved and locked"))).toBe(false);
    // the check ran all the same, against the database as it was
    const checks = s.gates.filter((g) => g.gateId === "data-model.matches");
    expect(checks.length).toBeGreaterThan(0);
    expect(checks.every((g) => g.passed)).toBe(true);
    // the Data model page shows the database as it is, with the result of that check
    const view = (await import("../ui/erd.js")).dataModelView(ledger);
    expect("none" in view ? undefined : [view.source, view.built?.matches, view.built?.details]).toEqual(["database", true, "The database (src/Api/app.db) has the tables, keys and relations it had before this run"]);
  });

  it("an existing backend, a fix that changes no stored data: a table lost or added by accident is caught", async () => {
    const USERS_DB = `CREATE TABLE "Users" ("Id" INTEGER NOT NULL CONSTRAINT "PK_Users" PRIMARY KEY AUTOINCREMENT, "Email" TEXT NOT NULL);`;
    lab.builtDoc = () => doc;
    lab.existingDb = USERS_DB;
    lab.builtDb = `${USERS_DB.replace('"Email" TEXT NOT NULL', '"Email" TEXT')} CREATE TABLE "Audit" ("Id" INTEGER NOT NULL CONSTRAINT "PK_Audit" PRIMARY KEY);`;
    planGivesNoModel = true;
    const { runId, ledger } = await start();
    const r = await execute(runId);
    expect(r.status).not.toBe("delivered");
    const said = JSON.stringify(ledger.events());
    expect(said).toContain("This plan has no data model, so the database must stay as it was, and it did not: Users.Email: the database before this run has it required, the database now optional.");
    expect(said).toContain("Table Audit is in the database now but not in the database before this run");
  });

  it("a database with a table the approved data model does not have is caught, with the difference as the failure", async () => {
    lab.builtDoc = () => doc;
    lab.builtDb = `${GREETINGS_DB} CREATE TABLE "Audit" ("Id" INTEGER NOT NULL CONSTRAINT "PK_Audit" PRIMARY KEY);`;
    const { runId, ledger } = await start();
    const r = await execute(runId);
    expect(r.status).not.toBe("delivered");
    const s = replay(ledger.events());
    expect(s.gates.some((g) => g.gateId === "data-model.matches" && !g.passed)).toBe(true);
    expect(s.steps.get("implement/TASK-1")?.status).not.toBe("completed");
    expect(readFileSync(join(ledger.dir, "run.log"), "utf8")).toMatch(/The database does not match the approved data model: Table Audit is in the database but not in the model/);
  });

  it("an app that creates no database on startup is not delivered: the model cannot be checked", async () => {
    lab.builtDoc = () => doc;
    const { runId, ledger } = await start();
    const r = await execute(runId);
    expect(r.status).not.toBe("delivered");
    expect(readFileSync(join(ledger.dir, "run.log"), "utf8")).toMatch(/could not be compared with the approved data model: the app started but created no SQLite database file on startup/);
  });

  it("an API that renames a response field is caught by the contract gate, with the difference as the failure", async () => {
    lab.builtDoc = () => doc.replaceAll('"patient"', '"patientName"');
    const { runId, ledger } = await start();
    const r = await execute(runId);
    expect(r.status).not.toBe("delivered");
    const s = replay(ledger.events());
    expect(s.gates.some((g) => g.gateId === "contract.matches" && !g.passed)).toBe(true);
    expect(s.steps.get("implement/TASK-1")?.status).not.toBe("completed");
    expect(readFileSync(join(ledger.dir, "run.log"), "utf8")).toMatch(/The API does not match the locked contract: missing in the API: GET \/api\/appointments\/today 200 body\[\]\.patient/);
    // the check's record says how much it compared, and names the attempt
    const failed = ledger.events().find((e) => e.type === "gate.result" && (e.data as { gateId?: string }).gateId === "contract.matches" && !(e.data as { passed?: boolean }).passed)!;
    expect(failed.data).toMatchObject({ attempt: 1, facts: { operationsInContract: expect.any(Number), operationsInApi: expect.any(Number), differences: expect.any(Number), partial: true } });
    expect((failed.data as { facts: { differences: number } }).facts.differences).toBeGreaterThan(0);
  });

  it("a build that writes no document fails the gate plainly", async () => {
    const { runId, ledger } = await start();
    const r = await execute(runId);
    expect(r.status).not.toBe("delivered");
    expect(readFileSync(join(ledger.dir, "run.log"), "utf8")).toMatch(/did not write the API's OpenAPI document at src\/Api\/openapi\/built\.json/);
  });
});

describe("implement loop across tasks (fakes)", () => {
  const HELLO = GREETER.replace('"Hi "', '"Hello "');
  const cls = (text: string) => `namespace Api; public static class X { public const string S = "${text}"; }\n`;
  const failedAttempts = (ledger: Ledger, step: string) => ledger.events().filter((e) => e.type === "step.failed" && e.key?.startsWith(`${step}/`));

  it("holds each task to earlier tasks' tests, climbs on regressions, keeps code on same-rung retries", async () => {
    multi = true;
    lab.edits = {
      // TASK-1: first attempt also writes a file outside its scope → reset
      "src/Api/Greeter.cs": [{ "src/Api/Greeter.cs": HELLO, "src/Api/Extra.cs": cls("extra") }, { "src/Api/Greeter.cs": HELLO }],
      // TASK-2: breaks TASK-1's test twice (same rung, then stuck → climbs), then gets it right
      "src/Api/Farewell.cs": [{ "src/Api/Farewell.cs": cls("Bye BREAK") }, { "src/Api/Farewell.cs": cls("Bye BREAK") }, { "src/Api/Farewell.cs": cls("Bye") }],
      // TASK-3: its own locked test fails once, then a small fix on top of the kept code
      "src/Api/Third.cs": [{ "src/Api/Third.cs": cls("Thre") }, { "src/Api/Third.cs": cls("Three") }],
    };
    const runId = await createRun("Greet people with Hello instead of Hi", "demo", "tester");
    const ledger = await toApproval(runId);
    const card = replay(ledger.events()).openCard!;
    await decide(ledger, { decision: "approve", hashPrefix: card.artifactSha.slice(0, 6), by: "ahsan" });
    const r = await execute(runId);
    expect(r.status, r.message).toBe("delivered");
    const s = replay(ledger.events());
    expect(s.steps.get("implement/TASK-1")?.attempts).toBe(2);
    expect(s.steps.get("implement/TASK-2")?.attempts).toBe(3);
    expect(s.steps.get("implement/TASK-3")?.attempts).toBe(2);
    const ids = MULTI_TESTS.map((n) => `Api.Tests::Api.Tests.GreetTests.${n}`);
    // a task's run leaves out the locked tests of tasks not built yet; the last task has none to leave out
    const testCmd = (k: string) => [...lab.specs.values()].find((sp) => sp.cmd[1] === "test" && sp.labels.key === k)!.cmd.join(" ");
    expect(testCmd("implement/TASK-1/2")).toMatch(/--filter FullyQualifiedName!=Api\.Tests\.GreetTests\.AC_2_1_SaysBye&FullyQualifiedName!=Api\.Tests\.GreetTests\.AC_3_1_\w+$/);
    // and none of them is run a second time as a "failed test worth one more run"
    expect([...lab.specs.values()].filter((sp) => sp.cmd[1] === "test" && sp.labels.key.startsWith("implement/")).map((sp) => sp.labels.key)).toEqual(["implement/TASK-1/2", "implement/TASK-2/1", "implement/TASK-2/2", "implement/TASK-2/3", "implement/TASK-3/1", "implement/TASK-3/2-first", "implement/TASK-3/2"]);
    expect(testCmd("implement/TASK-2/1")).toMatch(/--filter FullyQualifiedName!=Api\.Tests\.GreetTests\.AC_3_1_\w+$/);
    expect(testCmd("implement/TASK-3/1")).not.toContain("!=");
    // a retry on kept code runs the test that failed last time first, alone, and the whole suite once it passes
    expect(testCmd("implement/TASK-3/2-first")).toMatch(/--filter [^!]*AC_3_1/);
    expect(testCmd("implement/TASK-3/2")).not.toContain("--filter");
    const start = (task: string) => String(s.steps.get(task)!.data!.commit);

    // TASK-1: out-of-scope edit → the retry starts from the task start commit, the stray file gone
    const t1 = lab.seen.filter((x) => x.scope === MULTI_FILES[0]);
    expect(failedAttempts(ledger, "implement/TASK-1")[0]!.data).toMatchObject({ category: "other", retryMode: "reset" });
    expect(t1[1]!.files["src/Api/Extra.cs"]).toBeNull();
    expect(t1[1]!.files["src/Api/Greeter.cs"]).toBe(GREETER);
    expect(t1[1]!.head).toBe(t1[0]!.head);
    expect(t1[1]!.task).not.toContain("Your previous change");

    // TASK-2: TASK-1's test is expected; TASK-3's is not
    const t2run = ledger.getJson<{ expectPass: string[] }>(s.steps.get("implement/TASK-2")!.outputs[1]!);
    expect(t2run.expectPass).toContain(ids[0]);
    expect(t2run.expectPass).toContain(ids[1]);
    expect(t2run.expectPass).not.toContain(ids[2]);
    // a regression names TASK-1, climbs the ladder (other, not locked-test), never parks on the "failed twice" rule
    const f2 = failedAttempts(ledger, "implement/TASK-2");
    expect(f2.map((e) => e.data!.category)).toEqual(["other", "other"]);
    expect(f2.map((e) => e.data!.lockedFailedIds ?? [])).toEqual([[], []]);
    expect(f2.map((e) => [e.data!.rung, e.data!.action, e.data!.nextRung])).toEqual([[0, "retry", 0], [0, "retry", 1]]);
    const why = ledger.getJson<{ check: string; message: string }[]>(f2[0]!.outputs![0]!);
    expect(why).toContainEqual(expect.objectContaining({ check: "regression", message: expect.stringMatching(/^Your change broke TASK-1's locked test .*AC_1_1_GreetsWithHello \(AC-1\.1\)/) }));
    // same rung → keeps the code; the climb to rung 1 keeps it too, and says a part may be replaced
    const t2 = lab.seen.filter((x) => x.scope === MULTI_FILES[1]);
    expect(t2[1]!.files["src/Api/Farewell.cs"]).toBe(cls("Bye BREAK"));
    expect(t2[1]!.task).toContain("Your previous change");
    expect(t2[1]!.task).toContain("don't rewrite it");
    expect(t2[2]!.files["src/Api/Farewell.cs"]).not.toBeNull();
    expect(t2[2]!.task).toContain("Your previous change");
    expect(t2[2]!.task).toContain("Replace a part only where its approach cannot pass the tests");
    expect(f2[1]!.data).toMatchObject({ retryMode: "keep" });
    expect(s.steps.get("implement/TASK-2")!.data).toMatchObject({ retryMode: "keep", retryReason: "moved from rung 0 to rung 1; the previous attempt failed only on regression" });

    // TASK-3: its own test failed once → the retry keeps the code, HEAD stays at the task start
    const t3 = lab.seen.filter((x) => x.scope === MULTI_FILES[2]);
    expect(t3[1]!.files["src/Api/Third.cs"]).toBe(cls("Thre"));
    expect(t3[1]!.head).toBe(start("implement/TASK-2"));
    expect(t3[1]!.task).toContain("Your previous change");
    expect(t3[1]!.task).toMatch(/\+.*Thre/);
    expect(s.steps.get("implement/TASK-3")!.data).toMatchObject({ retryMode: "keep" });
    // each task is still one commit on the branch; every gate decision re-checks
    const log = execFileSync("git", ["log", "--format=%s", `main..factory/${runId}`], { cwd: s.info.repoPath!, encoding: "utf8" });
    expect(log.match(/factory: TASK-/g)).toHaveLength(3);
    // the last task's run already required every task's locked test: integrate reuses it
    expect(s.steps.get("integrate")!.data).toMatchObject({ reusedRunFrom: "implement/TASK-3" });
    expect(verifyEvidence(ledger).every((c) => c.ok)).toBe(true);
    // the summary of a retry says whether the last attempt's code was kept, and why
    const kept = ledger.events().filter((e) => e.type === "attempt.summary" && e.key?.startsWith("implement/TASK-3/")).map((e) => e.data as { attempt: number; result: string; notes?: Record<string, string> });
    expect(kept[0]).toMatchObject({ attempt: 1, result: "retry" });
    expect(kept[1]).toMatchObject({ attempt: 2, result: "passed", notes: { previousCode: "kept", previousCodeWhy: expect.stringMatching(/failed only on locked-failed/) } });
  }, 30_000);

  it("a plan built in layers: a task that cannot reach its own test hands it to the last task, without parking or another paid attempt", async () => {
    multi = true;
    const MODEL = GREETER + "// data model\n";
    lab.edits = {
      // TASK-1 is a layer: nothing it writes makes its own test pass (the greeting comes with TASK-3)
      "src/Api/Greeter.cs": [{ "src/Api/Greeter.cs": MODEL }, { "src/Api/Greeter.cs": MODEL }],
      "src/Api/Farewell.cs": [{ "src/Api/Farewell.cs": cls("Bye") }],
      // TASK-3 completes it, with a fix in TASK-1's file
      "src/Api/Third.cs": [{ "src/Api/Third.cs": cls("Three"), "src/Api/Greeter.cs": HELLO }],
    };
    const runId = await createRun("Greet people with Hello instead of Hi", "demo", "tester");
    const ledger = await toApproval(runId);
    await decide(ledger, { decision: "approve", hashPrefix: replay(ledger.events()).openCard!.artifactSha.slice(0, 6), by: "ahsan" });
    const r = await execute(runId);
    expect(r.status, r.message).toBe("delivered");
    const s = replay(ledger.events());
    // TASK-1's test failed exactly as it did before the task: deferred on that first failure, not retried or parked, and the
    // second attempt judged the same code without the implementer
    expect(failedAttempts(ledger, "implement/TASK-1").map((e) => (e.data as { action: string }).action)).toEqual(["defer"]);
    expect(failedAttempts(ledger, "implement/TASK-1")[0]!.data).toMatchObject({ untouched: true, nextRung: 0 });
    expect(s.steps.get("implement/TASK-1")?.attempts).toBe(2);
    expect(lab.seen.filter((x) => x.scope === MULTI_FILES[0])).toHaveLength(1);
    // from then on the plan is layered: TASK-2 passed first time, and TASK-3 was held to all three tests and could change TASK-1's file
    expect(s.steps.get("implement/TASK-2")?.attempts).toBe(1);
    expect(s.steps.get("implement/TASK-3")?.attempts).toBe(1);
    const ids = MULTI_TESTS.map((n) => `Api.Tests::Api.Tests.GreetTests.${n}`);
    const expected = (task: string) => ledger.getJson<{ expectPass: string[] }>((s.steps.get(task)!.data!.named as { testRun: string }).testRun).expectPass;
    expect(expected("implement/TASK-1")).not.toContain(ids[0]);
    expect(expected("implement/TASK-3")).toEqual(expect.arrayContaining(ids));
    expect(readFileSync(join(ledger.dir, "run.log"), "utf8")).toMatch(/implement TASK-3: also held to the criteria of TASK-1, TASK-2/);
  }, 30_000);

  it("a plan in the wrong shape is fixed by a patch in the same attempt: the planner is not asked for the whole plan again", async () => {
    multi = true;
    planBadShape = 1;
    const runId = await createRun("Greet people with Hello instead of Hi", "demo", "tester");
    const ledger = await toApproval(runId);
    const s = replay(ledger.events());
    expect(s.steps.get("plan")?.attempts).toBe(1);
    expect(failedAttempts(ledger, "plan")).toHaveLength(0);
    expect(planPrompt).toContain("THE PLAN IS FIXED, NOT REWRITTEN");
    expect(planPrompt).toContain("it was not accepted because its shape does not match the schema");
    expect(planPrompt).toMatch(/The plan does not match its schema: [^\n]*tasks\.2\.plannedLoc/);
    // the plan as sent went back with the request, and what came out is that plan with the one task put right
    expect(planPrompt).toContain("three lines");
    const plan = ledger.getJson<{ tasks: { id: string; plannedLoc: number }[] }>(s.steps.get("plan")!.outputs[0]!);
    expect(plan.tasks.map((t) => [t.id, t.plannedLoc])).toEqual([["TASK-1", 3], ["TASK-2", 3], ["TASK-3", 3]]);
  }, 30_000);

  it("a plan that fails its checks is fixed by a patch: the retry returns only the missing task", async () => {
    multi = true;
    planMisses = 1;
    const runId = await createRun("Greet people with Hello instead of Hi", "demo", "tester");
    const ledger = await toApproval(runId);
    const s = replay(ledger.events());
    expect(s.steps.get("plan")?.attempts).toBe(2);
    const f = failedAttempts(ledger, "plan");
    expect(ledger.getJson<{ check: string; message: string }[]>(f[0]!.outputs![0]!)).toEqual([expect.objectContaining({ check: "plan-coverage", message: "REQ-3 isn't covered by any task" })]);
    expect(f[0]!.data).toMatchObject({ rejectedPlan: expect.any(String), patches: 0 });
    // the retry was given the rejected plan and the failure, and asked for the changes alone
    expect(planPrompt).toContain("THE PLAN IS FIXED, NOT REWRITTEN");
    expect(planPrompt).toContain("previous-plan");
    expect(planPrompt).toContain("REQ-3 isn't covered by any task");
    expect(planPrompt).toContain("Return the changes that fix the failures.");
    // the patched plan is the rejected one with the new task last, and it passed the same checks
    const plan = ledger.getJson<{ tasks: { id: string; reqs: string[] }[]; adr: string }>(s.steps.get("plan")!.outputs[0]!);
    expect(plan.tasks.map((t) => t.id)).toEqual(["TASK-1", "TASK-2", "TASK-3"]);
    expect(plan.adr).toBe(ledger.getJson<{ adr: string }>(String(f[0]!.data!.rejectedPlan)).adr);
  }, 30_000);

  it("the test writer's retry keeps its files: after a missed criterion, and after it ran out of budget", async () => {
    multi = true;
    lab.missAc = 1;
    lab.testsOverBudget = 1;
    lab.edits = { "src/Api/Greeter.cs": [{ "src/Api/Greeter.cs": HELLO }], "src/Api/Farewell.cs": [{ "src/Api/Farewell.cs": cls("Bye") }], "src/Api/Third.cs": [{ "src/Api/Third.cs": cls("Three") }] };
    const runId = await createRun("Greet people with Hello instead of Hi", "demo", "tester");
    const ledger = await toApproval(runId);
    const card = replay(ledger.events()).openCard!;
    await decide(ledger, { decision: "approve", hashPrefix: card.artifactSha.slice(0, 6), by: "ahsan" });
    const r = await execute(runId);
    expect(r.status, r.message).toBe("delivered");
    const s = replay(ledger.events());
    expect(s.steps.get("author-tests")?.attempts).toBe(3);
    const f = failedAttempts(ledger, "author-tests");
    expect(ledger.getJson<{ check: string; message: string }[]>(f[0]!.outputs![0]!)).toEqual([expect.objectContaining({ check: "ac-coverage", message: "No test for AC-3.1" })]);
    expect(ledger.getJson<{ check: string }[]>(f[1]!.outputs![0]!).map((x) => x.check)).toEqual(["agent-over-budget"]);
    // each failed attempt saved its commit; the answer of the first is carried past the one that never answered
    expect(f[0]!.data).toMatchObject({ retryMode: "reset", commit: expect.stringMatching(/^[0-9a-f]{40}$/), out: expect.any(String) });
    expect(f[1]!.data).toMatchObject({ retryMode: "keep", commit: expect.stringMatching(/^[0-9a-f]{40}$/), out: f[0]!.data!.out });
    // attempt 2 finds attempt 1's file and is told to keep it; attempt 3 finds the unfinished attempt's files too
    expect(lab.testSeen.map((x) => x.kept)).toEqual([[], ["tests/Api.Tests/GreetTests.cs"], ["tests/Api.Tests/GreetTests.cs", "tests/Api.Tests/ThirdTests.cs"]]);
    expect(lab.testSeen[0]!.task).not.toContain("previous-tests");
    expect(lab.testSeen[0]!.task).toContain("each of these needs at least one test in it: AC-1.1, AC-2.1, AC-3.1");
    expect(lab.testSeen[1]!.task).toContain("No test for AC-3.1");
    expect(lab.testSeen[1]!.task).toContain("keep them, change only what the failures name");
    expect(lab.testSeen[1]!.task).toContain("AC_1_1_GreetsWithHello");
    expect(lab.testSeen[2]!.task).toContain("Return the full list");
    expect(s.steps.get("author-tests")!.data).toMatchObject({ retryMode: "keep" });
    // the tests still end as one commit on the branch, with both files locked
    const log = execFileSync("git", ["log", "--format=%s", `main..factory/${runId}`], { cwd: s.info.repoPath!, encoding: "utf8" });
    expect(log.match(/acceptance tests/g)).toHaveLength(1);
    expect(ledger.getJson<{ lock: { file: string }[] }>(s.steps.get("author-tests")!.outputs[0]!).lock.map((l) => l.file)).toEqual(expect.arrayContaining(["tests/Api.Tests/GreetTests.cs", "tests/Api.Tests/ThirdTests.cs"]));
  }, 30_000);

  const TEST_FILE = "tests/Api.Tests/GreetTests.cs";
  const THIRD_ID = "Api.Tests::Api.Tests.GreetTests.AC_3_1_CountsThree";
  const approved = async () => {
    const runId = await createRun("Greet people with Hello instead of Hi", "demo", "tester");
    const ledger = await toApproval(runId);
    const card = replay(ledger.events()).openCard!;
    await decide(ledger, { decision: "approve", hashPrefix: card.artifactSha.slice(0, 6), by: "ahsan" });
    return { runId, ledger };
  };
  const judgedIn = (ledger: Ledger) => ledger.events().filter((e) => e.type === "test.judged").map((e) => e.data as Record<string, unknown>);

  it("a locked test that fails twice is read against its criterion; judged right, the task goes on and nobody is asked", async () => {
    multi = true;
    lab.edits = {
      "src/Api/Greeter.cs": [{ "src/Api/Greeter.cs": HELLO }],
      "src/Api/Farewell.cs": [{ "src/Api/Farewell.cs": cls("Bye") }],
      "src/Api/Third.cs": [{ "src/Api/Third.cs": cls("Thre") }, { "src/Api/Third.cs": cls("Thre ") }, { "src/Api/Third.cs": cls("Three") }],
    };
    const { runId, ledger } = await approved();
    const r = await execute(runId);
    expect(r.status, r.message).toBe("delivered");
    const f3 = failedAttempts(ledger, "implement/TASK-3");
    expect(f3.map((e) => [e.data!.category, e.data!.action, e.data!.testCheck])).toEqual([["locked-test", "retry", undefined], ["locked-test", "retry", [THIRD_ID]]]);
    expect(judgeCalls).toBe(1);
    expect(judgedIn(ledger)).toEqual([expect.objectContaining({ step: "implement/TASK-3", testId: THIRD_ID, acId: "AC-3.1", verdict: "code", why: "scripted verdict" })]);
    // the third attempt is told the test is right, and the test is as it was locked
    const t3 = lab.seen.filter((x) => x.scope === MULTI_FILES[2]);
    expect(t3).toHaveLength(3);
    expect(t3[2]!.task).toContain("The tests are right and the code is not");
    expect(t3[2]!.task).toContain(`- ${THIRD_ID} (AC-3.1): scripted verdict`);
    const s = replay(ledger.events());
    expect(execFileSync("git", ["show", `${s.steps.get("implement/TASK-3")!.data!.commit}:${TEST_FILE}`], { cwd: s.info.repoPath!, encoding: "utf8" })).not.toContain("WANTS");
    expect(ledger.events().some((e) => e.type === "run.parked")).toBe(false);
  }, 30_000);

  it("a locked test judged wrong is rewritten, must fail again before the task's code, is locked again, and the kept code is checked against it", async () => {
    multi = true;
    proofVerdict = "proves-it";
    judgeVerdict = "test";
    lab.edits = {
      "src/Api/Greeter.cs": [{ "src/Api/Greeter.cs": HELLO }],
      "src/Api/Farewell.cs": [{ "src/Api/Farewell.cs": cls("Bye") }],
      // the code is right twice; the test asks for something else
      "src/Api/Third.cs": [{ "src/Api/Third.cs": cls("Trois") }, { "src/Api/Third.cs": cls("Trois") }],
      [TEST_FILE]: [{ [TEST_FILE]: "namespace Api.Tests; public class GreetTests { /* WANTS:Trois */ }\n" }],
    };
    const { runId, ledger } = await approved();
    const r = await execute(runId);
    expect(r.status, r.message).toBe("delivered");
    const s = replay(ledger.events());
    // two paid coding attempts, one rewrite; the third attempt ran the lab on the kept code with no coding agent
    expect(lab.seen.filter((x) => x.scope === MULTI_FILES[2])).toHaveLength(2);
    expect(lab.seen.filter((x) => x.scope === TEST_FILE)).toHaveLength(1);
    expect(s.steps.get("implement/TASK-3")?.attempts).toBe(3);
    const rewrite = lab.jobs.find((j) => j.fileScope[0] === TEST_FILE)!;
    expect(rewrite.fileScope).toEqual([TEST_FILE]);
    expect(rewrite.system).toContain("A locked acceptance test was found to be wrong");
    const [j] = judgedIn(ledger) as { verdict: string; file: string; rewritten: { sha: string; was: string; commit: string; run: string } }[];
    expect(j).toMatchObject({ verdict: "test", file: TEST_FILE, testId: THIRD_ID });
    expect(j!.rewritten.sha).not.toBe(j!.rewritten.was);
    // it failed on the code before the task, and that run is in the ledger
    const proof = ledger.getJson<{ treeSha: string; valid: boolean; results: { id: string; outcome: string }[] }>(j!.rewritten.run);
    expect(proof).toMatchObject({ treeSha: j!.rewritten.commit, valid: true });
    expect(proof.results.find((x) => x.id === THIRD_ID)?.outcome).toBe("failed");
    // the task's commit carries the code and the rewritten test, and the lock later steps use has the new hash
    const commit = String(s.steps.get("implement/TASK-3")!.data!.commit);
    const changed = execFileSync("git", ["diff", "--name-only", `${commit}~1`, commit], { cwd: s.info.repoPath!, encoding: "utf8" }).trim().split("\n").sort();
    expect(changed).toEqual([MULTI_FILES[2], TEST_FILE].sort());
    expect(execFileSync("git", ["show", `${commit}:${TEST_FILE}`], { cwd: s.info.repoPath!, encoding: "utf8" })).toContain("WANTS:Trois");
    const { lock } = lockOf(s, ledger);
    expect(lock.lock.find((l) => l.file === TEST_FILE)?.sha).toBe(j!.rewritten.sha);
    expect(ledger.events().some((e) => e.type === "run.parked")).toBe(false);
    expect(verifyEvidence(ledger).every((c) => c.ok)).toBe(true);
  }, 30_000);

  it("a rewrite that does not fail on the code before the task is thrown away and the run stops for a person; resumed, the old test stays and is not asked about again", async () => {
    multi = true;
    proofVerdict = "proves-it";
    judgeVerdict = "test";
    lab.edits = {
      "src/Api/Greeter.cs": [{ "src/Api/Greeter.cs": HELLO }],
      "src/Api/Farewell.cs": [{ "src/Api/Farewell.cs": cls("Bye") }],
      "src/Api/Third.cs": [{ "src/Api/Third.cs": cls("Trois") }, { "src/Api/Third.cs": cls("Trois") }, { "src/Api/Third.cs": cls("Three") }],
      // bent to pass on anything, so it passes before the task's code too
      [TEST_FILE]: [{ [TEST_FILE]: "namespace Api.Tests; public class GreetTests { /* WANTS:ANYTHING */ }\n" }],
    };
    const { runId, ledger } = await approved();
    const r = await execute(runId);
    expect(r.status, r.message).toBe("parked");
    expect(r.message).toMatch(/failed twice and the test-or-code check did not settle it.*its rewrite was not accepted/);
    const [j] = judgedIn(ledger);
    expect(j).toMatchObject({ verdict: "test", rejected: expect.stringContaining("on the code before this task") });
    expect(j!.rewritten).toBeUndefined();
    const s = replay(ledger.events());
    const wt = execFileSync("git", ["worktree", "list", "--porcelain"], { cwd: s.info.repoPath!, encoding: "utf8" }).split("\n").filter((l) => l.startsWith("worktree ")).map((l) => l.slice(9)).find((d) => d !== s.info.repoPath && existsSync(join(d, TEST_FILE)))!;
    expect(readFileSync(join(wt, TEST_FILE), "utf8")).not.toContain("WANTS");
    expect(lockOf(s, ledger).lock.lock.find((l) => l.file === TEST_FILE)?.sha).toBe(ledger.getJson<{ lock: { file: string; sha: string }[] }>(s.steps.get("author-tests")!.outputs[0]!).lock.find((l) => l.file === TEST_FILE)!.sha);
    // resumed: the test is not asked about again, the old test stays, and the task finishes against it
    const r2 = await execute(runId);
    expect(r2.status, r2.message).toBe("delivered");
    expect(judgeCalls).toBe(1);
  }, 30_000);

  it("a lenient run: a test judged wrong whose rewrite is refused does not park; it is left out of the checks and named on the PR", async () => {
    multi = true;
    proofVerdict = "proves-it";
    judgeVerdict = "test";
    process.env.FACTORY_LENIENT_TESTS = "1";
    try {
      lab.edits = {
        "src/Api/Greeter.cs": [{ "src/Api/Greeter.cs": HELLO }],
        "src/Api/Farewell.cs": [{ "src/Api/Farewell.cs": cls("Bye") }],
        "src/Api/Third.cs": [{ "src/Api/Third.cs": cls("Trois") }, { "src/Api/Third.cs": cls("Trois") }, { "src/Api/Third.cs": cls("Trois") }],
        // both rewrites pass on anything, so both are refused
        [TEST_FILE]: [{ [TEST_FILE]: "namespace Api.Tests; public class GreetTests { /* WANTS:ANYTHING */ }\n" }, { [TEST_FILE]: "namespace Api.Tests; public class GreetTests { /* WANTS:ANYTHING */ }\n" }],
      };
      const { runId, ledger } = await approved();
      const r = await execute(runId);
      expect(r.status, r.message).toBe("delivered");
      const disputed = ledger.events().filter((e) => e.type === "test.disputed").map((e) => e.data as { testId: string; why: string });
      expect(disputed).toHaveLength(1);
      expect(disputed[0]!.why).toContain("rewrite not accepted");
      // left out of the checks from then on, its file still locked as it was
      const s = replay(ledger.events());
      expect(lockOf(s, ledger).lock.tests.map((t) => t.testId)).not.toContain(disputed[0]!.testId);
      expect(lockOf(s, ledger).lock.lock.some((l) => l.file === TEST_FILE)).toBe(true);
      expect(ledger.readCard(`pr-${runId}`)).toContain(`Not proven: locked test left out`);
    } finally { process.env.FACTORY_LENIENT_TESTS = "0"; }
  }, 30_000);

  it("a person disputes a locked test the run parked on: it leaves the checks, the run delivers, and the PR names who and why", async () => {
    multi = true;
    proofVerdict = "proves-it";
    judgeVerdict = "test";
    lab.edits = {
      "src/Api/Greeter.cs": [{ "src/Api/Greeter.cs": HELLO }],
      "src/Api/Farewell.cs": [{ "src/Api/Farewell.cs": cls("Bye") }],
      "src/Api/Third.cs": [{ "src/Api/Third.cs": cls("Trois") }, { "src/Api/Third.cs": cls("Trois") }, { "src/Api/Third.cs": cls("Trois") }],
      [TEST_FILE]: [{ [TEST_FILE]: "namespace Api.Tests; public class GreetTests { /* WANTS:ANYTHING */ }\n" }, { [TEST_FILE]: "namespace Api.Tests; public class GreetTests { /* WANTS:ANYTHING */ }\n" }],
    };
    const { runId, ledger } = await approved();
    expect((await execute(runId)).status).toBe("parked");
    const [j] = judgedIn(ledger);
    // what factory dispute-test records
    await ledger.append({ type: "test.disputed", data: { step: "person", testId: j!.testId, acId: j!.acId, file: j!.file, why: "it wants a value no correct code returns", by: "ahsan" } }, HUMAN_WRITER);
    const r = await execute(runId);
    expect(r.status, r.message).toBe("delivered");
    expect(ledger.readCard(`pr-${runId}`)).toMatch(/Not proven: locked test left out.*by ahsan, who disputed it: it wants a value no correct code returns/);
  }, 30_000);

  it("a refused rewrite goes back to the test writer once, and the second one is locked", async () => {
    multi = true;
    judgeVerdict = "test";
    lab.edits = {
      "src/Api/Greeter.cs": [{ "src/Api/Greeter.cs": HELLO }],
      "src/Api/Farewell.cs": [{ "src/Api/Farewell.cs": cls("Bye") }],
      "src/Api/Third.cs": [{ "src/Api/Third.cs": cls("Trois") }, { "src/Api/Third.cs": cls("Trois") }],
      // the first rewrite passes on any code; sent back, the second asks for what the criterion says
      [TEST_FILE]: [{ [TEST_FILE]: "namespace Api.Tests; public class GreetTests { /* WANTS:ANYTHING */ }\n" }, { [TEST_FILE]: "namespace Api.Tests; public class GreetTests { /* WANTS:Trois */ }\n" }],
    };
    const { runId, ledger } = await approved();
    const r = await execute(runId);
    expect(r.status, r.message).toBe("delivered");
    const rewrites = lab.jobs.filter((j) => j.fileScope[0] === TEST_FILE) as unknown as { task: string }[];
    expect(rewrites).toHaveLength(2);
    expect(rewrites[0]!.task).not.toContain("Your first rewrite was not accepted");
    expect(rewrites[1]!.task).toContain("Your first rewrite was not accepted");
    expect(rewrites[1]!.task).toContain("already passes before any change");
    // the second rewrite started from the test as it was locked, and only it is on the ledger
    expect(lab.seen.filter((x) => x.scope === TEST_FILE)).toHaveLength(2);
    const [j] = judgedIn(ledger);
    expect(j).toMatchObject({ verdict: "test", rewritten: expect.objectContaining({ sha: expect.any(String) }) });
    expect(j!.rejected).toBeUndefined();
    expect(judgedIn(ledger)).toHaveLength(1);
    expect(rewriteChecks).toBe(1);
    expect(ledger.events().some((e) => e.type === "run.parked")).toBe(false);
  }, 30_000);

  it("a rewrite is read against the locked test, not against its criterion again: one that asserts less twice stops the run", async () => {
    multi = true;
    // the check before the lock would call every test weak; a rewrite is not held to it (run 1679)
    proofVerdict = "weak";
    judgeVerdict = "test";
    lab.edits = {
      "src/Api/Greeter.cs": [{ "src/Api/Greeter.cs": HELLO }],
      "src/Api/Farewell.cs": [{ "src/Api/Farewell.cs": cls("Bye") }],
      "src/Api/Third.cs": [{ "src/Api/Third.cs": cls("Trois") }, { "src/Api/Third.cs": cls("Trois") }],
      [TEST_FILE]: [{ [TEST_FILE]: "namespace Api.Tests; public class GreetTests { /* WANTS:Trois */ }\n" }],
    };
    const { runId, ledger } = await approved();
    const before = proofCalls;
    const r = await execute(runId);
    expect(r.status, r.message).toBe("delivered");
    // the whole-test check was not asked about the rewrite; the check of the change was, once
    expect(proofCalls - before).toBe(proofCalls - before > 0 ? proofCalls - before : 0);
    expect(rewriteChecks).toBe(1);
    expect(judgedIn(ledger)[0]).toMatchObject({ verdict: "test", rewritten: expect.anything() });

    // and one that drops an assertion is refused, sent back once, and then the run stops with what was lost
    proofVerdict = "proves-it";
    rewriteVerdict = "loosened";
    rewriteChecks = 0;
    lab.edits[TEST_FILE] = [{ [TEST_FILE]: "namespace Api.Tests; public class GreetTests { /* WANTS:Trois */ }\n" }];
    lab.edits["src/Api/Third.cs"] = [{ "src/Api/Third.cs": cls("Trois") }, { "src/Api/Third.cs": cls("Trois") }];
    const second = await approved();
    const r2 = await execute(second.runId);
    expect(r2.status, r2.message).toBe("parked");
    expect(r2.message).toMatch(/its rewrite was not accepted: it asserts less than the locked test did.*scripted rewrite check/);
    expect(rewriteChecks).toBe(2);
    expect(judgedIn(second.ledger)[0]).toMatchObject({ verdict: "test", rejected: expect.stringContaining("it asserts less than the locked test did") });

    // and one that fixes the fault in one place and leaves it in another is refused the same way (run ae5c, TASK-10)
    rewriteVerdict = "partial";
    rewriteChecks = 0;
    lab.edits[TEST_FILE] = [{ [TEST_FILE]: "namespace Api.Tests; public class GreetTests { /* WANTS:Trois */ }\n" }];
    lab.edits["src/Api/Third.cs"] = [{ "src/Api/Third.cs": cls("Trois") }, { "src/Api/Third.cs": cls("Trois") }];
    const third = await approved();
    const r3 = await execute(third.runId);
    expect(r3.status, r3.message).toBe("parked");
    expect(r3.message).toMatch(/its rewrite was not accepted: the same fault is still in the test.*scripted rewrite check/);
    expect(rewriteChecks).toBe(2);
  }, 90_000);

  it("a locked test that is right but needs a later task's file opens that file to the task, and the pull request says so", async () => {
    multi = true;
    // the tasks do not build on each other, so a test of TASK-2 cannot wait for TASK-3: it has to pass at TASK-2
    unchained = true;
    judgeVerdict = "scope";
    judgeFiles = ["src/Api/Third.cs"];
    const SECOND_ID = "Api.Tests::Api.Tests.GreetTests.AC_2_1_SaysBye";
    lab.edits = {
      "src/Api/Greeter.cs": [{ "src/Api/Greeter.cs": HELLO }],
      // the third attempt also changes TASK-3's file (run 9fcb: a screen a later task builds), which the file-scope check would refuse without the opening
      "src/Api/Farewell.cs": [{ "src/Api/Farewell.cs": cls("By") }, { "src/Api/Farewell.cs": cls("By ") }, { "src/Api/Farewell.cs": cls("Bye"), "src/Api/Third.cs": cls("Early") }],
      "src/Api/Third.cs": [{ "src/Api/Third.cs": cls("Three") }],
    };
    const { runId, ledger } = await approved();
    const r = await execute(runId);
    expect(r.status, r.message).toBe("delivered");
    expect(judgedIn(ledger)).toEqual([expect.objectContaining({ step: "implement/TASK-2", testId: SECOND_ID, verdict: "scope", opened: ["src/Api/Third.cs"] })]);
    // no test was rewritten, and only the attempt after the check may change the opened file
    expect(lab.jobs.some((j) => j.fileScope[0] === TEST_FILE)).toBe(false);
    const jobs2 = lab.jobs.filter((j) => j.fileScope[0] === MULTI_FILES[1]);
    expect(jobs2.map((j) => j.fileScope.includes("src/Api/Third.cs"))).toEqual([false, false, true]);
    const t2 = lab.seen.filter((x) => x.scope === MULTI_FILES[1]);
    expect(t2[2]!.task).toContain("are right, but they could not pass with this task's own files");
    expect(t2[2]!.task).toContain(`- ${SECOND_ID} (AC-2.1): src/Api/Third.cs. scripted verdict`);
    const s = replay(ledger.events());
    const commit = String(s.steps.get("implement/TASK-2")!.data!.commit);
    expect(execFileSync("git", ["show", `${commit}:src/Api/Third.cs`], { cwd: s.info.repoPath!, encoding: "utf8" })).toBe(cls("Early"));
    // the later task builds on it
    expect(execFileSync("git", ["show", `${s.steps.get("implement/TASK-3")!.data!.commit}:src/Api/Third.cs`], { cwd: s.info.repoPath!, encoding: "utf8" })).toBe(cls("Three"));
    expect(ledger.readCard(`pr-${runId}`)).toContain("File opened to another task during the build: `src/Api/Third.cs` was changed by TASK-2");
    expect(ledger.events().some((e) => e.type === "run.parked")).toBe(false);
    expect(verifyEvidence(ledger).every((c) => c.ok)).toBe(true);
  }, 30_000);

  it("a file no task of the plan lists does not open: the run stops for a person, and goes on with the test as it is", async () => {
    multi = true;
    judgeVerdict = "scope";
    judgeFiles = ["src/Api/Extra.cs", TEST_FILE];
    lab.edits = {
      "src/Api/Greeter.cs": [{ "src/Api/Greeter.cs": HELLO }],
      "src/Api/Farewell.cs": [{ "src/Api/Farewell.cs": cls("Bye") }],
      "src/Api/Third.cs": [{ "src/Api/Third.cs": cls("Thre") }, { "src/Api/Third.cs": cls("Thre ") }, { "src/Api/Third.cs": cls("Three") }],
    };
    const { runId, ledger } = await approved();
    const r = await execute(runId);
    expect(r.status, r.message).toBe("parked");
    expect(r.message).toMatch(/the test is right but needs a file this task may not change.*src\/Api\/Extra\.cs \(no task of the plan lists it\)/);
    expect(judgedIn(ledger)[0]).toMatchObject({ verdict: "scope", rejected: expect.stringContaining("(locked)") });
    expect(judgedIn(ledger)[0]!.opened).toBeUndefined();
    const r2 = await execute(runId);
    expect(r2.status, r2.message).toBe("delivered");
    expect(judgeCalls).toBe(1);
    expect(lab.jobs.some((j) => j.fileScope.includes("src/Api/Extra.cs") || (j.fileScope[0] !== TEST_FILE && j.fileScope.includes(TEST_FILE)))).toBe(false);
  }, 30_000);

  it("a test said to need a file the task may already change is the code's fault: the task goes on", async () => {
    multi = true;
    judgeVerdict = "scope";
    // TASK-3 is built on TASK-1, so after a locked failure its file is open to it already
    judgeFiles = ["src/Api/Greeter.cs"];
    lab.edits = {
      "src/Api/Greeter.cs": [{ "src/Api/Greeter.cs": HELLO }],
      "src/Api/Farewell.cs": [{ "src/Api/Farewell.cs": cls("Bye") }],
      "src/Api/Third.cs": [{ "src/Api/Third.cs": cls("Thre") }, { "src/Api/Third.cs": cls("Thre ") }, { "src/Api/Third.cs": cls("Three") }],
    };
    const { runId, ledger } = await approved();
    const r = await execute(runId);
    expect(r.status, r.message).toBe("delivered");
    expect(judgedIn(ledger)).toEqual([expect.objectContaining({ verdict: "code", why: expect.stringContaining("already in this task's file scope") })]);
    // the second attempt kept the code: its failed test ran alone, still failed, and the rest of the suite was not run
    const testKeys = [...lab.specs.values()].filter((sp) => sp.cmd[1] === "test").map((sp) => sp.labels.key);
    expect(testKeys).toContain("implement/TASK-3/2-first");
    expect(testKeys).not.toContain("implement/TASK-3/2");
    expect(testKeys).toEqual(expect.arrayContaining(["implement/TASK-3/3-first", "implement/TASK-3/3"]));
    expect(readFileSync(join(ledger.dir, "run.log"), "utf8")).toMatch(/implement TASK-3: 1 of the 1 locked test\(s\) that failed last time still fail; the rest of the suite was not run/);
    expect(ledger.readCard(`pr-${runId}`)).not.toContain("File opened to another task");
  }, 30_000);

  it("two broken builds in a row climb the ladder instead of parking as a suspect test", async () => {
    multi = true;
    lab.edits = {
      "src/Api/Greeter.cs": [{ "src/Api/Greeter.cs": "SYNTAX" }, { "src/Api/Greeter.cs": "SYNTAX" }, { "src/Api/Greeter.cs": HELLO }],
      "src/Api/Farewell.cs": [{ "src/Api/Farewell.cs": cls("Bye") }],
      "src/Api/Third.cs": [{ "src/Api/Third.cs": cls("Three") }],
    };
    const runId = await createRun("Greet people with Hello instead of Hi", "demo", "tester");
    const ledger = await toApproval(runId);
    const card = replay(ledger.events()).openCard!;
    await decide(ledger, { decision: "approve", hashPrefix: card.artifactSha.slice(0, 6), by: "ahsan" });
    const r = await execute(runId);
    expect(r.status, r.message).toBe("delivered");
    const f1 = failedAttempts(ledger, "implement/TASK-1");
    expect(f1.map((e) => e.data!.category)).toEqual(["other", "other"]);
    expect(f1.map((e) => e.data!.lockedFailedIds ?? [])).toEqual([[], []]);
    expect(f1.map((e) => [e.data!.action, e.data!.nextRung])).toEqual([["retry", 0], ["retry", 1]]);
    // a broken build keeps the code on the same rung
    const t1 = lab.seen.filter((x) => x.scope === MULTI_FILES[0]);
    expect(t1[1]!.files["src/Api/Greeter.cs"]).toBe("SYNTAX");
    expect(t1[1]!.task).toContain("Your previous change");
  }, 30_000);
});

describe("light and full lanes (fakes)", () => {
  async function deliver() {
    const runId = await createRun("Greet people with Hello instead of Hi", "demo", "tester");
    const ledger = await toApproval(runId);
    const card = replay(ledger.events()).openCard!;
    await decide(ledger, { decision: "approve", hashPrefix: card.artifactSha.slice(0, 6), by: "ahsan" });
    const r = await execute(runId);
    expect(r.status, r.message).toBe("delivered");
    return replay(ledger.events());
  }
  const writer = () => lab.jobs.find((j) => j.fileScope.includes("tests/**"))!;
  /** A test project next to the tests; with two projects the solution is named in the config, as a real repo needs. */
  async function addTestProject() {
    const home = process.env.FACTORY_HOME!;
    const { parse } = await import("yaml");
    const cfg = parse(readFileSync(join(home, "projects", "demo.yaml"), "utf8"));
    const env = { ...process.env, GIT_CONFIG_GLOBAL: "/dev/null", GIT_AUTHOR_NAME: "t", GIT_AUTHOR_EMAIL: "t@t", GIT_COMMITTER_NAME: "t", GIT_COMMITTER_EMAIL: "t@t" };
    writeFileSync(join(cfg.repo, "tests/Api.Tests/Api.Tests.csproj"), '<Project Sdk="Microsoft.NET.Sdk"><ItemGroup><PackageReference Include="xunit" Version="2.9.2" /></ItemGroup></Project>\n');
    execFileSync("git", ["add", "-A"], { cwd: cfg.repo, env });
    execFileSync("git", ["commit", "-q", "-m", "test project"], { cwd: cfg.repo, env });
    writeFileSync(join(home, "projects", "demo.yaml"), stringify({ ...cfg, dotnet: { solution: "Api.sln" } }));
  }

  it("a small low-risk change: one draft, no merge call, a Sonnet test writer with tight limits", async () => {
    const s = await deliver();
    expect(s.steps.get("drafts")!.data!.models).toEqual(["claude-sonnet-5-5"]);
    expect(s.steps.get("merge")!.data!.singleDraft).toBe(true);
    expect(s.steps.get("specify")!.data!.lane).toBe("light");
    // one question round: what round 1 didn't settle is an assumption
    expect(s.steps.get("clarify-2")!.data).toMatchObject({ skipped: true, lightLane: true });
    // the fixture's criteria are api level: the test writer needs a test host, so 40 turns
    expect(writer()).toMatchObject({ model: "claude-sonnet-5-5", maxTurns: 40 });
    expect(writer().maxUsd).toBeLessThanOrEqual(4);
    expect(writer().system).toContain("At most 2 characterisation tests");
    expect(writer().system).toContain('Don\'t run "dotnet test"');
  });

  it("a run that locks its tests but isn't delivered teaches nothing", async () => {
    await addTestProject();
    const runId = await createRun("Greet people with Hello instead of Hi", "demo", "tester");
    const ledger = await toApproval(runId);
    const card = replay(ledger.events()).openCard!;
    await decide(ledger, { decision: "approve", hashPrefix: card.artifactSha.slice(0, 6), by: "ahsan" });
    // the implementer keeps touching the locked test: the run parks after the tests were locked
    const orig = lab.wait.bind(lab);
    lab.wait = async (id: string) => {
      const sp = lab.specs.get(id)!;
      const code = await orig(id);
      if (sp.role === "agent" && !JSON.parse(readFileSync(sp.mounts.find((m) => m.dst === "/job/in.json")!.src, "utf8")).fileScope.includes("tests/**")) {
        writeFileSync(join(sp.mounts.find((m) => m.dst === "/work")!.src, "tests/Api.Tests/GreetTests.cs"), "// weakened\n");
      }
      return code;
    };
    expect((await execute(runId)).status).toBe("parked");
    expect(replay(ledger.events()).steps.get("author-tests")?.status).toBe("completed");
    const { readLessons } = await import("../context/lessons.js");
    expect(readLessons("demo").tests).toEqual([]);
  });

  it("the first run on a repo teaches the next one where its tests go", async () => {
    await addTestProject();
    await deliver();
    const { readLessons } = await import("../context/lessons.js");
    expect(readLessons("demo").tests[0]).toMatchObject({ dir: "tests/Api.Tests", csproj: "tests/Api.Tests/Api.Tests.csproj", packages: ["xunit"] });
    expect(JSON.stringify(writer())).not.toContain("earlier runs on this repo");
    lab.jobs.length = 0;
    const second = await deliver();
    expect(JSON.stringify(writer())).toContain("earlier runs on this repo put tests in tests/Api.Tests");
    // the step records which lessons its test writer was given
    expect(second.steps.get("author-tests")!.data!.lessonsUsed).toEqual(["tests/Api.Tests/Api.Tests.csproj"]);
  });

  it("medium risk keeps the full lane: 3 drafts, a merge, 3 reworks allowed, an Opus test writer with $4 and 60 turns", async () => {
    intakeRisk = "medium";
    const s = await deliver();
    expect(s.steps.get("drafts")!.data!.models).toHaveLength(3);
    expect(s.steps.get("merge")!.data!.singleDraft).toBeUndefined();
    expect(s.steps.get("specify")!.data!.lane).toBe("full");
    expect(s.steps.get("clarify-2")!.data?.lightLane).toBeUndefined();
    expect(writer()).toMatchObject({ model: "claude-opus-5-5", maxTurns: 60, maxUsd: 4 });
    expect(writer().system).not.toContain("At most 2 characterisation tests");
  });
});

describe("spec repairs", () => {
  // the repairs answer the critic: these runs pick its model, which turns it on
  const CRITIC_ON = { models: { picks: { critic: "claude-opus-5-5" } } };
  const finding = { rubric: 2, reqId: "REQ-1", severity: "high", finding: "No path for an empty name." };
  it("stops repairing when a repair leaves the same findings, instead of paying for all 3", async () => {
    intakeRisk = "medium";
    criticFindings = [finding];
    const ledger = await toApproval(await createRun("Greet people with Hello instead of Hi", "demo", "tester", CRITIC_ON));
    const s = replay(ledger.events());
    expect(s.steps.get("specify")!.data).toMatchObject({ repairs: 1, lane: "full" });
    expect(repairCalls).toBe(1);
    expect(readFileSync(join(ledger.dir, "run.log"), "utf8")).toContain("the last repair left the same findings; stopping repairs");
    expect(ledger.readCard(s.openCard!.cardId)).toContain("## Still open after 1 repair");
    // a brownfield build asks nothing by default (brownfield.questions off): it settles no problems and asked no question
    expect(ledger.readCard(s.openCard!.cardId)).not.toContain("## Settled by questions");
    expect(replay(ledger.events()).info.asks).toBeUndefined();
    expect(ledger.events().some((e) => e.type === "human.requested" && (e.data as { settleKey?: string }).settleKey)).toBe(false);
    // approved as it stands, the build goes on to a delivered branch, as brownfield builds always have
    await decide(ledger, { decision: "approve", hashPrefix: s.openCard!.artifactSha.slice(0, 6), by: "ahsan" });
    expect((await execute(s.info.runId)).status).toBe("delivered");
  });

  it("a brownfield project with brownfield.questions settles the open problem by questions and shows it on the plan card", async () => {
    intakeRisk = "medium";
    criticFindings = [finding];
    const file = join(process.env.FACTORY_HOME!, "projects", "demo.yaml");
    writeFileSync(file, stringify({ ...parse(readFileSync(file, "utf8")), brownfield: { questions: true } }));
    const ledger = await toApproval(await createRun("Greet people with Hello instead of Hi", "demo", "tester", CRITIC_ON));
    const s = replay(ledger.events());
    expect(s.info.asks).toBe(true);
    // with none to ask, the finding is carried as an open risk and the plan approval card states it
    expect(readFileSync(join(ledger.dir, "run.log"), "utf8")).toContain("the run carries it as open risks");
    expect(ledger.readCard(s.openCard!.cardId)).toMatch(/## Settled by questions, and open risks\n- Open risk: No path for an empty name\./);
    // approved with the risk stated, the build goes on to a delivered branch
    await decide(ledger, { decision: "approve", hashPrefix: s.openCard!.artifactSha.slice(0, 6), by: "ahsan" });
    const r = await execute(s.info.runId);
    expect(r.status, r.message).toBe("delivered");
  });

  it("a rejection after the spec's own questions revises the spec with the reason, and does not pay for the answered round again", async () => {
    intakeRisk = "medium";
    criticFindings = [finding];
    settleAsks = true;
    const file = join(process.env.FACTORY_HOME!, "projects", "demo.yaml");
    writeFileSync(file, stringify({ ...parse(readFileSync(file, "utf8")), brownfield: { questions: true } }));
    const ledger = await toApproval(await createRun("Greet people with Hello instead of Hi", "demo", "tester", CRITIC_ON));
    const q = replay(ledger.events()).openCard!;
    expect(q.cardId).toMatch(/^spec-questions-1-/);
    criticFindings = [];
    await decide(ledger, { decision: "answer", hashPrefix: q.artifactSha.slice(0, 6), by: "ahsan", data: { answers: { "Q-2": "A" } } });
    expect((await execute(ledger.runId)).status).toBe("waiting");
    const card = replay(ledger.events()).openCard!;
    expect(card.kind).toBe("approval");
    const repairs = repairCalls;
    await decide(ledger, { decision: "reject", hashPrefix: card.artifactSha.slice(0, 6), by: "ahsan", data: { reason: "Keep 'Hi' for admins" } });
    expect((await execute(ledger.runId)).status).toBe("waiting");
    expect(reviseCalls).toBe(1);
    expect(repairCalls).toBe(repairs);
    // what the questions settled stays on the revised spec
    expect(ledger.getJson<{ settled?: unknown[] }>(replay(ledger.events()).steps.get("specify")!.outputs[0]!)!.settled).toHaveLength(1);
  });

  it("a retry goes on from the failed attempt's repaired spec, and a repair answers with changes only", async () => {
    intakeRisk = "medium";
    criticFindings = [finding];
    const base = answerFor("Senior engineer writing a behaviour spec") as { requirements: { acceptance: { then: string }[] }[] };
    // the repair returns one changed requirement (no nfrs, no lists) whose Then fails the observable check
    repairSpec = { requirements: base.requirements.map((r) => ({ ...r, acceptance: r.acceptance.map((a) => ({ ...a, then: "it works" })) })) };
    const runId = await createRun("Greet people with Hello instead of Hi", "demo", "tester", CRITIC_ON);
    await execute(runId);
    const ledger = Ledger.open(runId);
    const q = replay(ledger.events()).openCard!;
    await decide(ledger, { decision: "answer", hashPrefix: q.artifactSha.slice(0, 6), by: "ahsan", data: { answers: { "Q-1": "A" } } });
    await execute(runId);
    const fails = ledger.events().filter((e) => e.type === "step.failed" && e.key?.startsWith("specify/"));
    expect(fails.length).toBeGreaterThan(1);
    const d = fails[0]!.data as { signature: string; repairedSpec: string; repairedFrom: string };
    expect(d.signature).toBe("lint:L11 observable");
    const kept = ledger.getJson<{ requirements: { acceptance: { then: string }[] }[]; outOfScope: string[] }>(d.repairedSpec);
    expect(kept.requirements[0]!.acceptance[0]!.then).toBe("it works");
    expect(kept.outOfScope).toEqual(["other greetings"]);
    expect(readFileSync(join(ledger.dir, "run.log"), "utf8")).toContain("going on from the last attempt's repaired spec");
  });

  it("rejects a repair that drops a requested span and keeps the previous spec", async () => {
    intakeRisk = "medium";
    criticFindings = [finding];
    const base = answerFor("Senior engineer writing a behaviour spec") as { requirements: { sources: string[] }[]; outOfScope: string[] };
    repairSpec = { ...base, requirements: base.requirements.map((r) => ({ ...r, sources: ["Q-1"] })), outOfScope: ["I-1 greeting change, deferred to run 2"] };
    const ledger = await toApproval(await createRun("Greet people with Hello instead of Hi", "demo", "tester", CRITIC_ON));
    const s = replay(ledger.events());
    expect(s.steps.get("specify")!.data).toMatchObject({ repairs: 1, rejectedRepair: ["I-1"] });
    expect(repairCalls).toBe(1);
    const spec = ledger.getJson<{ requirements: { sources: string[] }[]; outOfScope: string[] }>(s.steps.get("specify")!.outputs[0]!);
    expect(spec.requirements[0]!.sources).toEqual(["I-1"]);
    expect(spec.outOfScope).toEqual(["other greetings"]);
  });
});

describe("from a Jira label to a reviewed pull request (fakes: models, containers, Jira, Slack, GitHub)", () => {
  const serve = (handler: (req: http.IncomingMessage, body: string) => { status: number; json?: unknown }) => {
    const server = http.createServer((req, res) => {
      let body = "";
      req.on("data", (c) => { body += c; });
      req.on("end", () => { const r = handler(req, body); res.writeHead(r.status, { "content-type": "application/json" }); res.end(JSON.stringify(r.json ?? {})); });
    });
    return new Promise<{ server: http.Server; url: string }>((ok) => server.listen(0, "127.0.0.1", () => ok({ server, url: `http://127.0.0.1:${(server.address() as AddressInfo).port}` })));
  };
  const ANN = { accountId: "acc-ann", displayName: "Ann" };
  const DESC = { type: "doc", content: [{ type: "paragraph", content: [{ type: "text", text: "Greet people with Hello instead of Hi, everywhere the Greeter is used, and keep the name after the greeting." }] }] };

  it("label → watch → cards in the terminal (Slack says which command) → delivered → draft PR, one review, ready; Jira told at each step", async () => {
    // fake Jira: one labelled ticket, comments, transitions
    const comments: string[] = [];
    const jira = await serve((req, body) => {
      const u = req.url ?? "";
      if (u.startsWith("/rest/api/3/search/jql")) return { status: 200, json: { issues: [{ key: "SHOP-7", fields: { summary: "Say Hello", description: DESC, issuetype: { name: "Story", hierarchyLevel: 0 }, labels: ["factory"], reporter: ANN } }] } };
      if (u.includes("/changelog")) return { status: 200, json: { isLast: true, values: [{ created: new Date(Date.now() - 60_000).toISOString().replace("Z", "+0000"), author: ANN, items: [{ field: "labels", fromString: "", toString: "factory" }] }] } };
      if (u.includes("/comment") && req.method === "POST") { comments.push(JSON.stringify(JSON.parse(body).body)); return { status: 201, json: { id: String(comments.length) } }; }
      if (u.includes("/comment")) return { status: 200, json: { comments: comments.map((c, i) => ({ id: String(i + 1), body: JSON.parse(c) })) } };
      if (u.includes("/transitions")) return { status: req.method === "GET" ? 200 : 204, json: { transitions: [] } };
      if (/\/rest\/api\/3\/issue\/SHOP-7\?/.test(u)) return { status: 200, json: { key: "SHOP-7", fields: { summary: "Say Hello", description: DESC, issuetype: { name: "Story" }, labels: ["factory"], status: { name: "To Do" }, comment: { comments: [] } } } };
      return { status: 404 };
    });
    const slackMsgs: string[] = [];
    const slack = await serve((_req, body) => { slackMsgs.push(body); return { status: 200 }; });
    // fake GitHub: PRs, reviews, ready-for-review
    const gh = { prs: [] as { number: number; head: string; title: string; draft: boolean; node_id: string }[], reviews: [] as { id: number; body: string; comments: { path: string; line: number }[] }[] };
    const github = await serve((req, body) => {
      const u = req.url ?? "";
      if (req.method === "GET" && /\/pulls\?head=/.test(u)) { const head = decodeURIComponent(/head=[^:]+:([^&]+)/.exec(u)![1]!); return { status: 200, json: gh.prs.filter((p) => p.head === head).map((p) => ({ html_url: `https://github.test/shop/api/pull/${p.number}`, number: p.number })) }; }
      if (req.method === "POST" && u.endsWith("/pulls")) { const b = JSON.parse(body); const pr = { number: gh.prs.length + 1, head: b.head, title: b.title, draft: b.draft, node_id: `PR_${gh.prs.length + 1}` }; gh.prs.push(pr); return { status: 201, json: { html_url: `https://github.test/shop/api/pull/${pr.number}`, number: pr.number } }; }
      if (req.method === "GET" && /\/pulls\/\d+\/reviews/.test(u)) return { status: 200, json: gh.reviews };
      if (req.method === "POST" && /\/pulls\/\d+\/reviews/.test(u)) { const b = JSON.parse(body); gh.reviews.push({ id: gh.reviews.length + 1, body: b.body, comments: b.comments }); return { status: 200, json: { id: gh.reviews.length } }; }
      if (req.method === "GET" && /\/pulls\/\d+$/.test(u)) { const pr = gh.prs[Number(/(\d+)$/.exec(u)![1]) - 1]!; return { status: 200, json: { node_id: pr.node_id, draft: pr.draft } }; }
      if (req.method === "POST" && u === "/graphql") { const id = JSON.parse(body).variables.id; gh.prs.find((p) => p.node_id === id)!.draft = false; return { status: 200, json: { data: {} } }; }
      return { status: 404 };
    });
    const closers: (() => void)[] = [];
    try {
      const home = process.env.FACTORY_HOME!;
      // a git remote over HTTP (the factory's hardened git refuses plain folder remotes)
      const root = mkdtempSync(join(tmpdir(), "factory-e2e-remote-"));
      const bare = join(root, "api.git");
      execFileSync("git", ["init", "-q", "--bare", bare]);
      execFileSync("git", ["config", "http.receivepack", "true"], { cwd: bare });
      const { spawn } = await import("node:child_process");
      const gitHttp = http.createServer((req, res) => {
        const u = new URL(req.url ?? "/", "http://x");
        const cgi = spawn("git", ["http-backend"], { env: { ...process.env, GIT_PROJECT_ROOT: root, GIT_HTTP_EXPORT_ALL: "1", PATH_INFO: u.pathname, QUERY_STRING: u.search.slice(1), REQUEST_METHOD: req.method ?? "GET", CONTENT_TYPE: req.headers["content-type"] ?? "", REMOTE_USER: "factory" } });
        req.pipe(cgi.stdin);
        const chunks: Buffer[] = [];
        cgi.stdout.on("data", (c: Buffer) => chunks.push(c));
        cgi.on("close", () => {
          const all = Buffer.concat(chunks);
          const split = all.indexOf("\r\n\r\n");
          const head = all.subarray(0, split).toString();
          const headers: Record<string, string> = {};
          let status = 200;
          for (const line of head.split("\r\n")) { const [k, ...v] = line.split(": "); if (k!.toLowerCase() === "status") status = Number(v.join(": ").split(" ")[0]); else headers[k!] = v.join(": "); }
          res.writeHead(status, headers);
          res.end(all.subarray(split + 4));
        });
      });
      const gitUrl = await new Promise<string>((ok) => gitHttp.listen(0, "127.0.0.1", () => ok(`http://127.0.0.1:${(gitHttp.address() as AddressInfo).port}/api.git`)));
      closers.push(() => gitHttp.close());
      writeFileSync(join(home, ".env"), `ANTHROPIC_API_KEY=sk-ant-test-not-real-000000000000\nOPENAI_API_KEY=sk-openai-test-not-real-0000000000\nGITHUB_TOKEN=ghp_testtoken0000000000\nJIRA_BASE_URL=${jira.url}\nJIRA_EMAIL=bot@shop.test\nJIRA_API_TOKEN=tok-0123456789\nSLACK_WEBHOOK=${slack.url}/hook\n`, { mode: 0o600 });
      _resetEnvCache();
      const { parse } = await import("yaml");
      const cfg = parse(readFileSync(join(home, "projects", "demo.yaml"), "utf8"));
      writeFileSync(join(home, "projects", "demo.yaml"), stringify({ ...cfg,
        forge: { kind: "github", repo: "shop/api", apiUrl: github.url, pushUrl: gitUrl },
        jira: { project: "SHOP", allowedReporters: ["acc-ann"], maxCostPerRun: 3 },
        notify: { slackWebhookEnv: "SLACK_WEBHOOK" } }));
      // one finding on a changed line, one outside the diff
      reviewFindings = [
        { id: "R-1", category: "convention-intent", file: "src/Api/Greeter.cs", line: 4, text: "consider a constant", confidence: 0.4, severity: "low" },
        { id: "R-2", category: "reuse", file: "src/Api/Other.cs", line: 99, text: "similar code elsewhere", confidence: 0.3, severity: "low" },
      ];

      const { watcherFor } = await import("../watch/start.js");
      const { startFromJira } = await import("../watch/start.js");
      const running: Promise<unknown>[] = [];
      const w = watcherFor("demo", { start: (key) => startFromJira("demo", key, 3, (id) => { running.push(execute(id)); }), execute: (id) => { running.push(execute(id)); }, lockFree: async () => true });
      const t1 = await w.tick();
      expect(t1.started).toMatch(/jira-shop-7/);
      const runId = t1.started!;
      await Promise.all(running.splice(0));
      // the run stopped at the question card; Slack got "started" and, next tick, the card with its command
      const ledger = Ledger.open(runId);
      expect(replay(ledger.events()).openCard?.kind).toBe("question");
      await w.tick();
      const card = slackMsgs.find((m) => m.includes("question card"))!;
      expect(card).toContain(`factory show-card ${runId}`);
      expect(comments.join()).toContain(`factory show-card ${runId}`);
      // a person answers and approves in the terminal (the watcher never does)
      const q = replay(ledger.events()).openCard!;
      await decide(ledger, { decision: "answer", hashPrefix: q.artifactSha.slice(0, 6), by: "ann", data: { answers: { "Q-1": "A" } } });
      await execute(runId);
      const a = replay(ledger.events()).openCard!;
      expect(a.kind).toBe("approval");
      await decide(ledger, { decision: "approve", hashPrefix: a.artifactSha.slice(0, 6), by: "ann" });
      const done = await execute(runId);
      expect(done.status, done.message).toBe("delivered");

      // GitHub: the branch carries the key; one draft PR titled with the key, one review, then ready
      const s = replay(ledger.events());
      expect(s.workspace!.branch).toBe(`factory/SHOP-7-${runId}`);
      expect(execFileSync("git", ["branch", "--list"], { cwd: bare, encoding: "utf8" })).toContain(`factory/SHOP-7-${runId}`);
      expect(gh.prs).toHaveLength(1);
      expect(gh.prs[0]!.title).toMatch(/^SHOP-7: /);
      expect(gh.prs[0]!.draft).toBe(false);
      expect(gh.reviews).toHaveLength(1);
      expect(gh.reviews[0]!.comments).toEqual([{ path: "src/Api/Greeter.cs", line: 4, side: "RIGHT", body: "R-1 [low/convention-intent] consider a constant" }]);
      expect(gh.reviews[0]!.body).toContain("R-2 [low/reuse] src/Api/Other.cs:99: similar code elsewhere");
      expect(s.steps.get("deliver")!.data!.prUrl).toBe("https://github.test/shop/api/pull/1");
      expect(verifyEvidence(ledger).every((c) => c.ok)).toBe(true);

      // Jira and Slack hear about the delivery, once
      await w.tick();
      await w.tick();
      expect(comments.filter((c) => c.includes("delivered a pull request"))).toHaveLength(1);
      expect(comments.find((c) => c.includes("delivered a pull request"))).toContain("https://github.test/shop/api/pull/1");
      expect(slackMsgs.filter((m) => m.includes("SHOP-7: delivered"))).toHaveLength(1);
      // no client code or diffs went to Jira or Slack
      for (const text of [...comments, ...slackMsgs]) expect(text).not.toMatch(/Greet\(string name\)|public class Greeter/);
    } finally {
      jira.server.close(); slack.server.close(); github.server.close();
      for (const c of closers) c();
    }
  }, 60_000);

  it("a failed push never shows the token, not even base64-encoded", async () => {
    const { git } = await import("../ledger/git.js");
    const dir = mkdtempSync(join(tmpdir(), "factory-push-"));
    execFileSync("git", ["init", "-q", "-b", "main", dir]);
    const token = "ghp_secret0123456789abcdef";
    const auth = Buffer.from(`x-access-token:${token}`).toString("base64");
    const err = await git(dir, ["push", "http://127.0.0.1:9/nowhere.git", "HEAD:refs/heads/x"], {
      env: { GIT_CONFIG_COUNT: "1", GIT_CONFIG_KEY_0: "http.extraHeader", GIT_CONFIG_VALUE_0: `Authorization: Basic ${auth}` },
    }).then(() => undefined, (e: Error) => e.message);
    expect(err).toBeDefined();
    expect(err).not.toContain(auth);
    expect(err).not.toContain(token);
  });
});

describe("the plan's stubs are built before approval", () => {
  it("a stub that does not compile goes back to the planner, not on to the test writer (run 2bf7)", async () => {
    const broken = "namespace Api; public class Greeter : IMissing { public string Greet(string name) => throw new System.NotImplementedException(); }\n";
    planStubs = [[{ path: "src/Api/Greeter.cs", content: broken }], [{ path: "src/Api/Greeter.cs", content: GREETER }]];
    lab.buildLog = "/src/src/Api/Greeter.cs(1,37): error CS0246: The type or namespace name 'IMissing' could not be found (are you missing a using directive or an assembly reference?) [/src/src/Api/Api.csproj]";
    const runId = await createRun("Greet people with Hello instead of Hi", "demo", "tester");
    const ledger = await toApproval(runId);
    const failed = ledger.events().filter((e) => e.type === "step.failed" && String(e.key).startsWith("plan"));
    expect(failed).toHaveLength(1);
    const said = JSON.stringify(ledger.getJson(failed[0]!.outputs![0]!));
    expect(said).toContain("plan-stub-build");
    expect(said).toContain("CS0246");
    expect(said).toContain("src/Api/Greeter.cs:1");
    expect(lab.failedBuilds).toBe(1);
    // the plan that reached the approval card is the one whose stubs compile
    const s = replay(ledger.events());
    expect(s.openCard!.kind).toBe("approval");
    const plan = ledger.getJson<{ stubs: { content: string }[] }>(s.steps.get("plan")!.outputs[0]!);
    expect(plan.stubs.map((x) => x.content)).toEqual([GREETER]);
  }, 30_000);
});
