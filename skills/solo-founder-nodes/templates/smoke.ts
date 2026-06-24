// Turnkey proof of the local substrates. Run: npm i && npm run smoke
// Every S-mechanism is a pass/fail assertion; the process exits non-zero if any fails.
import { createClient } from "@libsql/client";
import { existsSync, mkdirSync, mkdtempSync, writeFileSync } from "node:fs";
import { tmpdir } from "node:os";
import { dirname, join } from "node:path";
import { SoloLedger } from "./ledger/ledger";
import { SoloMemory } from "./memory/localMemory";
import { sealGold, contentGate } from "./ledger/contentGate";
import { sha256 } from "./ledger/hash";
import { inspectGraphContext, graphQueryPlan } from "./context/graphContext";
import { SoloControlPlane, loopPhases } from "./control/controlPlane";
import { make3dAgentResearchPack, top3dComparisonRubric, verifyResearchPack, type ResearchPack } from "./research/researchSpine";
import { designSkillRegistry, makeDesignFullFlow, recommendDesignSkills, verifyDesignFullFlow, verifyDesignSkillPlan, type DesignFullFlowPlan } from "./design/designSkillBridge";
import { defaultDesignQualityCriteria, makeDesignQualityReceipt, verifyDesignQualityReceipt, type DesignQualityGateInput } from "./design/designQualityGate";
import { gstackRoleRegistry, recommendGstackLanes, verifyGstackPlan, type GstackReviewPlan } from "./gstack/gstackBridge";
import { defaultDeterministicPrework, makeExternalSetupGateReceipt, verifyExternalSetupGateReceipt } from "./setup/externalSetupGate";
import { makeOpenRouterAgentSetupPack, rankOpenRouterModelsFromCatalog, verifyOpenRouterAgentSetupPack } from "./setup/openrouterAgentHosts";
import { makeAgentApiContractMarkdown, makeAgentReadyToolContract, verifyAgentReadyToolContract, type AgentReadyToolContract } from "./agentApi/agentReadyApi";
import { makeLoopRunReceipt, verifyLoopRunReceipt, type LoopRunReceipt } from "./loop/loopRunner";
import { makeDashboardSnapshot, renderDashboard } from "./dashboard/dashboard";
import { formatAgentMatrix, makeAgentMatrixRows, makeHookInstallPlan, readSoloEvents, recordSoloEvent } from "./events/soloEventBus";
import {
  completeRalphMilestone,
  createRalphLedger,
  doctorRalphLoop,
  pauseRalphLoop,
  ralphPaths,
  startRalphMilestone,
  verifyRalphMilestone,
} from "./loop/ralphLedger";
import { verifyFreshRoomProofReceipt, type FreshRoomProofReceipt } from "./proof/freshRoomReceipt";
import { makeReworkLedger, verifyReworkLedger, type ReworkLedger } from "./rework/reworkLedger";

let pass = 0;
let fail = 0;
function check(name: string, cond: boolean, detail = "") {
  if (cond) {
    pass++;
    console.log(`  ✓ ${name}`);
  } else {
    fail++;
    console.log(`  ✗ ${name}${detail ? " — " + detail : ""}`);
  }
}

function clone<T>(value: T): T {
  return JSON.parse(JSON.stringify(value)) as T;
}

async function main() {
  console.log("\n=== Solo Founder Nodes — local substrate smoke ===\n");

  // ---------------- SoloLedger: derive-don't-accept ----------------
  console.log("SoloLedger (S9/S12/S14/S16 enforced; S10/S11/S15 wired):");
  const dbFile = join(tmpdir(), `solo-smoke-ledger-${process.pid}-${Date.now()}.db`);
  const ledger = new SoloLedger({ dbUrl: `file:${dbFile}`, salt: "smoke-salt" });
  await ledger.init();

  // S12 — tuned first, then seal a DISJOINT held-out manifest
  await ledger.markTuned(["t-tuned"]);
  const manifest = await ledger.sealHeldOut(["t1", "t2", "t3", "t4", "t5", "vt1"]);
  check("S12 sealed held-out manifest (HMAC)", /^[0-9a-f]{64}$/.test(manifest));
  let sealThrew = false;
  try {
    await ledger.sealHeldOut(["t-tuned"]);
  } catch {
    sealThrew = true;
  }
  check("S12 refuses to seal a tuned task as held-out", sealThrew);

  const { runId, nonce } = await ledger.startRun({
    iterationLabel: "smoke-iter",
    benchmark: "demo",
    model: "demo-model",
    materializerMode: "generic-only",
  });

  // a writer receipt tied to the actual deliverable bytes (S10)
  const deliv = (leaf: string, bytes: string) => {
    const h = sha256(bytes);
    return { writer: { firedWriterLeaf: leaf, deliverableHash: h }, deliverableHash: h };
  };

  // (a) HONEST: generic writer + model-in-loop + valid nonce + held-out
  const a = await ledger.recordTask(runId, { taskId: "t1", reward: 0.42, ...deliv("write_general", "t1 bytes"), transport: { tokensUsed: 4200, nonce }, claimedClean: true });
  check("S9 honest generic + model-in-loop + held-out COUNTS", a.counts === true, a.reasons.join(","));

  // (b) FAMILY writer but agent CLAIMS clean -> derived false -> disagreement -> quarantined
  const b = await ledger.recordTask(runId, { taskId: "t2", reward: 0.97, ...deliv("write_comcast_package", "t2 bytes"), transport: { tokensUsed: 50, nonce }, claimedClean: true });
  check("S10 family-writer excluded despite 0.97 reward", b.counts === false && b.reasons.some((r) => r.startsWith("non-generic-writer")));
  check("S9 quarantines agent-claim vs derived disagreement", b.quarantined === true);

  // (c) MODEL-OFF
  const c = await ledger.recordTask(runId, { taskId: "t3", reward: 0.40, ...deliv("write_general", "t3 bytes"), transport: { tokensUsed: 0, nonce }, claimedClean: true });
  check("S11 model-off (0 tokens) excluded", c.counts === false && c.reasons.includes("model-off"));

  // (d) FORGED transport nonce
  const d = await ledger.recordTask(runId, { taskId: "t4", reward: 0.41, ...deliv("write_general", "t4 bytes"), transport: { tokensUsed: 9999, nonce: "forged" }, claimedClean: true });
  check("S11 forged transport nonce excluded", d.counts === false && d.reasons.includes("unsigned-transport"));

  // (e) MEMORY-LEAK taint
  const e = await ledger.recordTask(runId, { taskId: "t5", reward: 0.55, ...deliv("write_general", "t5 bytes"), transport: { tokensUsed: 3000, nonce }, recalledMemoryLeak: true, claimedClean: true });
  check("S14 memory-leak taint excludes the row", e.counts === false && e.reasons.includes("memory-leak"));

  // (f) TUNED-REUSE
  const f = await ledger.recordTask(runId, { taskId: "t-tuned", reward: 0.99, ...deliv("write_general", "tuned bytes"), transport: { tokensUsed: 3000, nonce }, claimedClean: true });
  check("S12 tuned-task-reuse excluded", f.counts === false && (f.reasons.includes("tuned-task-reuse") || f.reasons.includes("not-held-out")));

  // headline = mean over the clean row ONLY (just t1)
  const fin = await ledger.finishRun(runId);
  check("S6/S9 headline counts ONLY the clean row", fin.headlineN === 1 && Math.abs((fin.headlineMean ?? -1) - 0.42) < 1e-9, `mean=${fin.headlineMean} n=${fin.headlineN}`);

  // S16 — chain verifies, then an out-of-band tamper breaks it
  check("S16 hash-chain verifies (clean)", (await ledger.verifyChain(runId)).ok === true);
  const raw = createClient({ url: `file:${dbFile}` });
  await raw.execute({ sql: `UPDATE ledger_tasks SET reward = 9.99 WHERE run_id = ? AND task_id = 't1'`, args: [runId] });
  const tampered = await ledger.verifyChain(runId);
  check("S16 DETECTS out-of-band tampering (chain breaks)", tampered.ok === false, JSON.stringify(tampered));

  // ---------------- S15 independent verifier ----------------
  console.log("\nSoloLedger S15 (independent refute-by-default verifier):");
  const r2 = await ledger.startRun({ iterationLabel: "verifier-iter", benchmark: "demo", materializerMode: "generic-only" });
  const g = await ledger.recordTask(r2.runId, { taskId: "vt1", reward: 0.80, ...deliv("write_general", "vt1 bytes"), transport: { tokensUsed: 5000, nonce: r2.nonce }, claimedClean: true });
  check("clean row counts before the verifier", g.counts === true, g.reasons.join(","));
  const finV = await ledger.finishRun(r2.runId, { verifier: async () => true });
  check("S15 refute-by-default verifier demotes the row", finV.headlineN === 0, `n=${finV.headlineN}`);

  // ---------------- SoloMemory: S13 content gate ----------------
  console.log("\nSoloMemory (S13 content gate — the honor-system label is no longer enough):");
  const goldText = "Project Comcast take-private teaser: TEV 6538.0M, EV/EBITDA 17.0x, COTY 902.90M diluted shares, premium 35%.";
  const sealedGold = sealGold([goldText]);
  const mem = new SoloMemory({ dbUrl: ":memory:", heldOutGuard: (inp) => contentGate(sealedGold, `${inp.summary}\n${inp.content}`) });
  await mem.init();

  let benignOk = false;
  await mem.remember({ projectId: "smoke", phase: "build", kind: "decision", summary: "Use a design brief before any Figma write.", content: "Gate design calls behind a human approval.", benchmarkSafety: "safe" });
  benignOk = true;
  check("S13 benign write accepted", benignOk);

  let goldThrew = false;
  try {
    await mem.remember({ projectId: "smoke", phase: "iterate", kind: "decision", summary: "Methodology note", content: "EV/EBITDA 17.0x, TEV 6538.0M, COTY 902.90M diluted shares, premium 35% — reuse for the next comp.", benchmarkSafety: "safe" });
  } catch {
    goldThrew = true;
  }
  check("S13 rejects laundered held-out gold despite 'safe' label", goldThrew);

  let labelThrew = false;
  try {
    await mem.remember({ projectId: "smoke", phase: "iterate", kind: "run_result", summary: "held-out answer", content: "x", benchmarkSafety: "heldout_forbidden" });
  } catch {
    labelThrew = true;
  }
  check("honor-system heldout_forbidden label still rejected", labelThrew);

  await mem.remember({
    projectId: "smoke",
    phase: "iterate",
    kind: "run_result",
    summary: "held-out aggregate score only",
    content: "heldout_n=10 mean=0.42 failure_class=export-missing",
    benchmarkSafety: "aggregate_only",
    metadata: { aggregateOnly: true },
  });
  const aggregateHits = await mem.search({ projectId: "smoke", query: "aggregate score export missing", limit: 3, minScore: 0 });
  check("memory allows aggregate scores with aggregateOnly receipt", aggregateHits.some((hit) => hit.summary.includes("aggregate score")));

  let aggregateMissingMetadataThrew = false;
  try {
    await mem.remember({
      projectId: "smoke",
      phase: "iterate",
      kind: "run_result",
      summary: "aggregate without metadata",
      content: "mean=0.51",
      benchmarkSafety: "aggregate_only",
    });
  } catch {
    aggregateMissingMetadataThrew = true;
  }
  check("memory rejects aggregate_only without metadata.aggregateOnly", aggregateMissingMetadataThrew);

  let secretThrew = false;
  try {
    await mem.remember({
      projectId: "smoke",
      phase: "setup",
      kind: "env_fact",
      summary: "OpenRouter key",
      content: "OPENROUTER_API_KEY=sk-test-1234567890abcdef",
      benchmarkSafety: "safe",
    });
  } catch {
    secretThrew = true;
  }
  check("memory refuses API keys", secretThrew);

  let piiThrew = false;
  try {
    await mem.remember({
      projectId: "smoke",
      phase: "discover",
      kind: "project_fact",
      summary: "founder ssn",
      content: "SSN 123-45-6789",
      benchmarkSafety: "safe",
    });
  } catch {
    piiThrew = true;
  }
  check("memory refuses PII patterns", piiThrew);

  await mem.remember({
    projectId: "smoke",
    phase: "setup",
    kind: "env_fact",
    summary: "redacted local-only provider setup",
    content: "redacted provider setup notes for local operator only",
    benchmarkSafety: "redacted",
    visibility: "local",
  });
  const redactedHits = await mem.search({ projectId: "smoke", query: "redacted provider setup", limit: 5, minScore: 0 });
  check("memory search does not return redacted contents", redactedHits.every((hit) => hit.benchmarkSafety !== "redacted"));

  // ---------------- Graph context: query-first orientation ----------------
  console.log("\nGraphContext (query-first self-orientation):");
  const graphRoot = mkdtempSync(join(tmpdir(), "solo-smoke-graph-"));
  const graphDir = join(graphRoot, "graphify-out");
  mkdirSync(graphDir, { recursive: true });
  writeFileSync(join(graphDir, "GRAPH_REPORT.md"), "# Smoke graph\n\nGod nodes: Composer, Exporter, OfficialScorer\n", "utf8");
  writeFileSync(
    join(graphDir, "graph.json"),
    JSON.stringify({
      nodes: [
        { id: "Composer", community: "ui" },
        { id: "Exporter", community: "ui" },
        { id: "OfficialScorer", community: "eval" },
      ],
      edges: [
        { source: "Composer", target: "Exporter" },
        { source: "Exporter", target: "OfficialScorer" },
      ],
    }),
    "utf8",
  );
  const graphReceipt = inspectGraphContext({ projectRoot: graphRoot });
  check("graph context receipt is ready", graphReceipt.status === "ready", graphReceipt.staleReasons.join(","));
  check("graph context counts nodes and edges", graphReceipt.nodeCount === 3 && graphReceipt.edgeCount === 2);
  const plan = graphQueryPlan("what connects composer to scorer?", graphReceipt);
  check("graph query plan is command-shaped", plan.command.includes("graphify query"));

  // ---------------- External setup gate: finish deterministic work before human credentials ----------------
  console.log("\nExternalSetupGate (no early stop at API-key setup):");
  const incompleteGate = makeExternalSetupGateReceipt({
    goal: "Connect Meshy real 3D generation.",
    provider: "Meshy",
    requiredSecrets: ["MESHY_API_KEY"],
    setupUrls: ["https://www.meshy.ai/api"],
    completedPrework: ["adapter-boundary", "ai-chat-component", "server-side-secret-boundary"],
    resumeCommands: ["npm run build"],
    createdAt: "2026-06-23T00:00:00.000Z",
  });
  const incompleteGateVerdict = verifyExternalSetupGateReceipt(incompleteGate);
  check("credential gate rejects early stop before deterministic prework", incompleteGateVerdict.ok === false && incompleteGateVerdict.errors.some((e) => e.includes("chat-action-protocol")));

  const completeGate = makeExternalSetupGateReceipt({
    goal: "Connect Meshy real 3D generation.",
    provider: "Meshy",
    requiredSecrets: ["MESHY_API_KEY"],
    setupUrls: ["https://www.meshy.ai/api"],
    completedPrework: [...defaultDeterministicPrework],
    resumeCommands: ["vercel env pull .env.local", "npm run build", "npm run test:e2e"],
    createdAt: "2026-06-23T00:00:00.000Z",
  });
  const completeGateVerdict = verifyExternalSetupGateReceipt(completeGate);
  check("credential gate passes only after deterministic prework + resume commands", completeGateVerdict.ok && completeGate.status === "waiting_on_human", completeGateVerdict.errors.join("; "));

  const exposedSecretGate = makeExternalSetupGateReceipt({
    goal: "Connect Meshy real 3D generation.",
    provider: "Meshy",
    requiredSecrets: ["VITE_MESHY_API_KEY"],
    completedPrework: [...defaultDeterministicPrework],
    resumeCommands: ["npm run build"],
  });
  const exposedSecretVerdict = verifyExternalSetupGateReceipt(exposedSecretGate);
  check("credential gate rejects client-exposed provider keys", exposedSecretVerdict.ok === false && exposedSecretVerdict.errors.some((e) => e.includes("server-side only")));

  console.log("\nOpenRouterAgentHosts (optional cheap multi-agent setup):");
  const agentSetup = makeOpenRouterAgentSetupPack({ generatedAt: "2026-06-24T00:00:00.000Z", hostRoot: "D:\\ai-agent-hosts" });
  const agentSetupVerdict = verifyOpenRouterAgentSetupPack(agentSetup);
  check("optional OpenRouter setup verifies", agentSetupVerdict.ok, agentSetupVerdict.errors.join("; "));
  check("model policy selects current cheap paid + coding fallback", agentSetup.environment.SOLO_OPENROUTER_OPENCLAW_MODEL === "deepseek/deepseek-v4-flash" && agentSetup.environment.SOLO_OPENROUTER_HERMES_MODEL === "qwen/qwen3-coder-next");
  check("model policy includes free and multimodal lanes", agentSetup.environment.SOLO_OPENROUTER_FREE_CODE_MODEL === "cohere/north-mini-code:free" && agentSetup.environment.SOLO_OPENROUTER_MULTIMODAL_MODEL === "google/gemini-3.1-flash-lite");
  check("agent setup stays optional", agentSetup.optional === true && agentSetup.safetyRules.some((rule) => rule.includes("optional")));
  check("agent setup does not persist concrete OpenRouter keys", !JSON.stringify(agentSetup).includes("sk-or-") && agentSetup.environment.OPENROUTER_API_KEY.includes("never commit"));
  check("agent setup includes OpenClaw and Hermes conformance commands", agentSetup.verificationCommands.some((cmd) => cmd.includes("openclaw") && cmd.includes("conformance.mjs")) && agentSetup.verificationCommands.some((cmd) => cmd.includes("hermes") && cmd.includes("conformance.mjs")));
  const audit = rankOpenRouterModelsFromCatalog({
    data: [
      {
        id: "expensive/great-code",
        name: "Great Code",
        created: 1780000000,
        description: "agentic coding model",
        context_length: 1048576,
        architecture: { modality: "text->text", input_modalities: ["text"], output_modalities: ["text"] },
        pricing: { prompt: "0.000005", completion: "0.00001" },
        supported_parameters: ["tools", "structured_outputs"],
      },
      {
        id: "cheap/current-code",
        name: "Current Cheap Code",
        created: 1781000000,
        description: "agentic coding model",
        context_length: 262144,
        architecture: { modality: "text->text", input_modalities: ["text"], output_modalities: ["text"] },
        pricing: { prompt: "0.0000001", completion: "0.0000002" },
        supported_parameters: ["tools", "structured_outputs"],
      },
      {
        id: "free/north-mini-code:free",
        name: "North Mini Code free",
        created: 1781700000,
        description: "free agentic coding model",
        context_length: 256000,
        architecture: { modality: "text->text", input_modalities: ["text"], output_modalities: ["text"] },
        pricing: { prompt: "0", completion: "0" },
        supported_parameters: ["tools"],
      },
      {
        id: "google/gemini-flash-lite",
        name: "Gemini Flash Lite",
        created: 1780500000,
        description: "low cost multimodal agent model",
        context_length: 1048576,
        architecture: { modality: "text+image+video->text", input_modalities: ["text", "image", "video"], output_modalities: ["text"] },
        pricing: { prompt: "0.00000025", completion: "0.0000015" },
        supported_parameters: ["tools", "response_format"],
      },
    ],
  }, { generatedAt: "2026-06-24T00:00:00.000Z" });
  check("live catalog audit keeps paid/free/multimodal lanes separate", audit.recommended.paidCode?.id === "cheap/current-code" && audit.recommended.freeCode?.id === "free/north-mini-code:free" && audit.recommended.multimodalUi?.id === "google/gemini-flash-lite");
  check("live catalog audit is marked catalog-only until conformance", audit.warning.includes("Catalog audit only") && audit.warning.includes("conformance"));
  const auditedAgentSetup = makeOpenRouterAgentSetupPack({ generatedAt: "2026-06-24T00:00:00.000Z", hostRoot: "D:\\ai-agent-hosts", modelAudit: audit });
  const auditedAgentSetupVerdict = verifyOpenRouterAgentSetupPack(auditedAgentSetup);
  check("audited OpenRouter setup still verifies", auditedAgentSetupVerdict.ok, auditedAgentSetupVerdict.errors.join("; "));
  check("audited OpenRouter setup exposes catalog recommendations without replacing proved defaults", auditedAgentSetup.environment.SOLO_OPENROUTER_OPENCLAW_MODEL === "deepseek/deepseek-v4-flash" && auditedAgentSetup.environment.SOLO_OPENROUTER_AUDITED_PAID_CODE_MODEL === "cheap/current-code" && auditedAgentSetup.environment.SOLO_OPENROUTER_AUDITED_FREE_CODE_MODEL === "free/north-mini-code:free" && auditedAgentSetup.environment.SOLO_OPENROUTER_AUDITED_MULTIMODAL_MODEL === "google/gemini-flash-lite");

  // ---------------- Agent-ready API: schema + lifecycle + recovery gate ----------------
  console.log("\nAgentReadyApi (tool contracts for model-facing APIs):");
  const writeCellContract = makeAgentReadyToolContract({
    toolName: "write_locked_cell_results",
    purpose: "Write evidence-bearing spreadsheet results after previewing target cells and respecting locks.",
    lifecycle: ["search", "resolve", "preview", "execute", "verify", "recover"],
    requiredArgs: ["ops"],
    inputSchema: {
      type: "object",
      properties: {
        ops: {
          type: "array",
          items: {
            type: "object",
            properties: {
              cellId: { type: "string" },
              value: { type: "string" },
              evidenceRef: { type: "string" },
            },
            required: ["cellId", "value", "evidenceRef"],
          },
        },
      },
      required: ["ops"],
    },
    providerInputSchema: {
      type: "object",
      properties: {
        ops: { type: "array" },
      },
      required: ["ops"],
    },
    outputSchema: {
      type: "object",
      properties: {
        status: { type: "string", enum: ["ok", "pendingApproval", "conflict", "error"] },
        mutationIds: { type: "array", items: { type: "string" } },
        error: { type: "object" },
      },
      required: ["status"],
    },
    useWhen: ["writing evidence-bearing spreadsheet outputs after target cells are resolved"],
    doNotUseWhen: ["the user is actively typing the target cell", "evidence is missing"],
    preconditions: ["read the current cell versions", "collect evidence refs", "preview affected cells"],
    successSignals: ["status is ok or pendingApproval", "mutationIds are returned", "verification read matches expected values"],
    failureModes: [
      { kind: "missing_required_arg", when: "ops is omitted", recoveryPath: "construct ops from resolved target cells and retry once", nextAction: "retry" },
      { kind: "permission_denied", when: "write scope is not allowed", recoveryPath: "ask the human for approval or stop", nextAction: "ask_human" },
      { kind: "cas_conflict", when: "cell version changed", recoveryPath: "re-read target cells and propose a conflict-safe patch", nextAction: "recover" },
      { kind: "provider_timeout", when: "tool call times out", recoveryPath: "verify whether mutation landed before retrying", nextAction: "recover" },
    ],
    costClass: "low",
    latencyClass: "interactive",
    permissionLevel: "write",
    mutates: true,
    approvalRequired: false,
    examples: {
      call: { ops: [{ cellId: "Sheet1!B4", value: "42", evidenceRef: "source:10" }] },
      success: { status: "ok", mutationIds: ["mut_1"] },
      failure: { status: "conflict", error: { kind: "cas_conflict", missingFields: [] } },
    },
  });
  const apiVerdict = verifyAgentReadyToolContract(writeCellContract);
  const contractMd = makeAgentApiContractMarkdown(writeCellContract);
  check("agent-ready API contract verifies", apiVerdict.ok, apiVerdict.errors.join("; "));
  check("agent-api-contract.md names when/not-when/recovery", contractMd.includes("Use When") && contractMd.includes("Do Not Use When") && contractMd.includes("cas_conflict"));

  const missingProviderArg: AgentReadyToolContract = clone(writeCellContract);
  missingProviderArg.providerInputSchema = { type: "object", properties: {}, required: [] };
  const missingProviderArgVerdict = verifyAgentReadyToolContract(missingProviderArg);
  check("agent-ready API gate rejects provider schema arg loss", missingProviderArgVerdict.ok === false && missingProviderArgVerdict.errors.some((e) => e.includes("provider schema")));

  const missingRecovery: AgentReadyToolContract = clone(writeCellContract);
  missingRecovery.failureModes = [];
  const missingRecoveryVerdict = verifyAgentReadyToolContract(missingRecovery);
  check("agent-ready API gate rejects missing recovery paths", missingRecoveryVerdict.ok === false && missingRecoveryVerdict.errors.some((e) => e.includes("failure modes")));

  // ---------------- Research spine: research-backed implementation gate ----------------
  console.log("\nResearchSpine (research-backed decisions + proof target):");
  const researchPack = make3dAgentResearchPack({
    goal: "Fresh founder asks for an AI app that creates 3D models from pictures.",
    generatedAt: "2026-06-23T00:00:00.000Z",
  });
  const researchVerdict = verifyResearchPack(researchPack, { now: new Date("2026-06-23T12:00:00.000Z") });
  check("complete 3D-agent research pack passes", researchVerdict.ok, researchVerdict.errors.join("; "));

  const missingSource = clone<ResearchPack>(researchPack);
  missingSource.sources = missingSource.sources.filter((s) => s.id !== "instantmesh");
  const missingSourceVerdict = verifyResearchPack(missingSource, { now: new Date("2026-06-23T12:00:00.000Z") });
  check("missing source is rejected", missingSourceVerdict.ok === false && missingSourceVerdict.errors.some((e) => e.includes("instantmesh")));

  const staleSource = clone<ResearchPack>(researchPack);
  staleSource.sources[0].verifiedAt = "2020-01-01";
  const staleSourceVerdict = verifyResearchPack(staleSource, { now: new Date("2026-06-23T12:00:00.000Z"), maxSourceAgeDays: 365 });
  check("stale source is rejected", staleSourceVerdict.ok === false && staleSourceVerdict.errors.some((e) => e.includes("stale")));

  const uncitedDecision = clone<ResearchPack>(researchPack);
  uncitedDecision.decisions[0].researchSourceIds = [];
  const uncitedDecisionVerdict = verifyResearchPack(uncitedDecision, { now: new Date("2026-06-23T12:00:00.000Z") });
  check("uncited implementation decision is rejected", uncitedDecisionVerdict.ok === false && uncitedDecisionVerdict.errors.some((e) => e.includes("no researchSourceIds")));

  const unsupportedClaim = clone<ResearchPack>(researchPack);
  unsupportedClaim.claims[1].proofArtifactIds = [];
  unsupportedClaim.claims[1].sourceIds = [];
  const unsupportedClaimVerdict = verifyResearchPack(unsupportedClaim, { now: new Date("2026-06-23T12:00:00.000Z") });
  check("unsupported major capability claim is rejected", unsupportedClaimVerdict.ok === false && unsupportedClaimVerdict.errors.some((e) => e.includes("major capability/result claim")));

  const rubric = top3dComparisonRubric();
  check("top3d comparator has 4 providers and 100 points", rubric.competitors.length === 4 && rubric.totalPoints === 100);

  // ---------------- Design skill bridge: agent-agnostic design intelligence ----------------
  console.log("\nDesignSkillBridge (not Claude Code locked):");
  const designRegistry = designSkillRegistry();
  check("design registry has portable sources", designRegistry.length >= 12 && designRegistry.every((s) => s.agentLocked === false));
  check("design registry includes Codex-compatible skills", designRegistry.some((s) => s.runtimeSupport.includes("codex") && s.id === "frontend-design"));
  check("design registry includes visual/taste/native lanes", ["taste-minimalist-ui", "taste-industrial-brutalist-ui", "frontend-ui-ux", "premium-frontend-ui", "higgsfield-skills", "swiftui-skills"].every((id) => designRegistry.some((s) => s.id === id)));
  const dashboardPlan = recommendDesignSkills({
    surfaceKind: "dashboard",
    stack: "Next.js shadcn Tailwind",
    runtime: "codex",
    usesShadcnMcp: true,
  });
  const dashboardVerdict = verifyDesignSkillPlan(dashboardPlan);
  check("dashboard design plan selects shadcn + UI intelligence", dashboardPlan.selectedSkillIds.includes("shadcn-ui") && dashboardPlan.selectedSkillIds.includes("ui-ux-pro-max"));
  check("dashboard design plan verifies", dashboardVerdict.ok, dashboardVerdict.errors.join("; "));
  const premiumVisualPlan = recommendDesignSkills({
    surfaceKind: "marketing-site",
    stack: "Next.js hero image background video",
    runtime: "codex",
    stylePreset: "premium",
    needsVisualContent: true,
    needsAnimation: true,
  });
  check("premium visual plan selects premium + Higgsfield + GSAP", ["premium-frontend-ui", "higgsfield-skills", "gsap-skills"].every((id) => premiumVisualPlan.selectedSkillIds.includes(id)));
  const mobilePlan = recommendDesignSkills({
    surfaceKind: "mobile-app",
    stack: "Expo React Native SwiftUI",
    runtime: "codex",
    needsMobileNative: true,
    targetPlatform: "ios",
  });
  check("mobile design plan selects Expo/mobile/SwiftUI skills", mobilePlan.selectedSkillIds.includes("mobile-app-ui-design") && mobilePlan.selectedSkillIds.includes("expo-skills") && mobilePlan.selectedSkillIds.includes("swiftui-skills"));
  const badDesignPlan = { ...dashboardPlan, sequence: ["implementation", "design-brief", "browser-verify"] };
  const badDesignVerdict = verifyDesignSkillPlan(badDesignPlan);
  check("design order violation is rejected", badDesignVerdict.ok === false && badDesignVerdict.errors.some((e) => e.includes("before implementation")));
  const full3dDesignFlow = makeDesignFullFlow({
    surfaceKind: "3d-app",
    stack: "Next.js shadcn Three.js hero image",
    runtime: "codex",
    productCategory: "3D asset generation",
    stylePreset: "premium",
    needsAnimation: true,
    needsVisualContent: true,
    usesShadcnMcp: true,
  });
  const full3dDesignVerdict = verifyDesignFullFlow(full3dDesignFlow);
  check("full transcript design flow selects direction/component/industry/motion/visual/proof stages", ["surface-classification", "break-default-direction", "component-registry", "industry-fit-engine", "motion-plan", "visual-content", "implementation-proof"].every((id) => full3dDesignFlow.sequence.includes(id)));
  check("full transcript design flow verifies for 3D app", full3dDesignVerdict.ok, full3dDesignVerdict.errors.join("; "));
  const fullDashboardFlow = makeDesignFullFlow({
    surfaceKind: "dashboard",
    stack: "Next.js shadcn Tailwind",
    runtime: "codex",
    productCategory: "analytics",
    usesShadcnMcp: true,
  });
  check("dashboard full flow includes dashboard arrangement + industry fit", fullDashboardFlow.selectedSkillIds.includes("dashboard-arrangement") && fullDashboardFlow.sequence.includes("dashboard-information-architecture") && fullDashboardFlow.sequence.includes("industry-fit-engine"));
  const fullMobileFlow = makeDesignFullFlow({
    surfaceKind: "mobile-app",
    stack: "Expo SwiftUI React Native",
    runtime: "codex",
    targetPlatform: "ios",
    needsMobileNative: true,
  });
  const fullMobileVerdict = verifyDesignFullFlow(fullMobileFlow);
  check("mobile full flow treats mobile as native, not small web", fullMobileFlow.sequence.includes("mobile-native-rules") && fullMobileFlow.selectedSkillIds.includes("mobile-app-ui-design") && fullMobileFlow.selectedSkillIds.includes("swiftui-skills"));
  check("mobile full flow verifies", fullMobileVerdict.ok, fullMobileVerdict.errors.join("; "));
  const badFullFlow: DesignFullFlowPlan = { ...full3dDesignFlow, sequence: full3dDesignFlow.sequence.filter((id) => id !== "surface-classification") };
  const badFullFlowVerdict = verifyDesignFullFlow(badFullFlow);
  check("full design flow without surface classification is rejected", badFullFlowVerdict.ok === false && badFullFlowVerdict.errors.some((e) => e.includes("surface-classification")));

  const designQualityInput: DesignQualityGateInput = {
    surfaceKind: "3d-app",
    selectedSkillIds: ["frontend-design", "ui-ux-pro-max", "shadcn-ui", "premium-frontend-ui", "gsap-skills"],
    completedCriteria: [...defaultDesignQualityCriteria],
    desktopScreenshotPaths: ["docs/proof/playwright-results/fresh-founder-flow-chromium/fresh-founder-flow.png"],
    mobileScreenshotPaths: ["docs/proof/playwright-results/fresh-founder-flow-mobile/fresh-founder-flow.png"],
    designBriefPath: "docs/proof/design-flow.json",
    componentContractPath: "docs/decisions/implementation-receipts.md",
    interactionProofPaths: ["docs/proof/playwright-report/index.html"],
    accessibilityProofPaths: ["docs/proof/scorecard.md"],
    primarySurface: "workspace-console",
    visualVerdict: "pass",
    qualityBar: "shipping",
  };
  const designQualityReceipt = makeDesignQualityReceipt(designQualityInput);
  const designQualityVerdict = verifyDesignQualityReceipt(designQualityReceipt);
  check("design quality gate passes complete 3D workspace receipt", designQualityVerdict.ok, designQualityVerdict.errors.join("; "));

  const missingVisualReceipt = makeDesignQualityReceipt({
    ...designQualityInput,
    desktopScreenshotPaths: [],
    mobileScreenshotPaths: [],
  });
  const missingVisualVerdict = verifyDesignQualityReceipt(missingVisualReceipt);
  check("design quality gate rejects missing visual screenshots", missingVisualVerdict.ok === false && missingVisualVerdict.errors.some((e) => e.includes("screenshot")));

  const harnessReceipt = makeDesignQualityReceipt({
    ...designQualityInput,
    selectedSkillIds: ["frontend-design", "shadcn-ui"],
    completedCriteria: defaultDesignQualityCriteria.filter((criterion) => criterion !== "industry-fit"),
    primarySurface: "framed-preview-card",
    visualVerdict: "internal-harness",
    qualityBar: "internal",
    notes: ["current UI still reads as an internal test harness"],
  });
  const harnessVerdict = verifyDesignQualityReceipt(harnessReceipt);
  check("design quality gate rejects framed/internal harness UI", harnessVerdict.ok === false && harnessVerdict.errors.some((e) => e.includes("framed preview card")) && harnessVerdict.errors.some((e) => e.includes("internal")));

  // ---------------- gstack bridge: portable operating-review lanes ----------------
  console.log("\ngstackBridge (portable CEO/eng/design/QA/release roles):");
  const gstackRegistry = gstackRoleRegistry();
  check("gstack registry has portable specialist roles", gstackRegistry.length >= 20 && gstackRegistry.every((r) => r.agentLocked === false));
  check("gstack registry covers CEO, eng, QA, security, release", ["plan-ceo-review", "plan-eng-review", "qa-only", "cso", "land-and-deploy"].every((id) => gstackRegistry.some((r) => r.id === id)));
  const discoverGstack = recommendGstackLanes({
    phase: "discover",
    goal: "Fresh founder wants picture-to-3D app from screenshots.",
  });
  check("discover gstack plan requires office-hours + CEO review", discoverGstack.selectedRoleIds.includes("office-hours") && discoverGstack.selectedRoleIds.includes("plan-ceo-review"));
  const buildGstack = recommendGstackLanes({
    phase: "build",
    goal: "Build the 3D app upload/chat/viewer UI.",
    hasUi: true,
    hasSecurityBoundary: true,
    risk: "high",
  });
  const buildGstackVerdict = verifyGstackPlan(buildGstack);
  check("high-risk UI build gstack plan selects eng/design/security/review/guard", ["plan-eng-review", "plan-design-review", "cso", "review", "guard"].every((id) => buildGstack.selectedRoleIds.includes(id)));
  check("high-risk UI build gstack plan verifies", buildGstackVerdict.ok, buildGstackVerdict.errors.join("; "));
  const verifyGstack = recommendGstackLanes({
    phase: "verify",
    goal: "Prove fresh-user 3D app flow on deployed URL.",
    hasUi: true,
    hasDeployment: true,
    hasSecurityBoundary: true,
    needsDevex: true,
  });
  const verifyGstackVerdict = verifyGstackPlan(verifyGstack);
  check("deployed verification gstack plan selects live QA + release + canary", ["qa-only", "browse", "land-and-deploy", "canary"].every((id) => verifyGstack.selectedRoleIds.includes(id)));
  check("deployed verification gstack plan verifies", verifyGstackVerdict.ok, verifyGstackVerdict.errors.join("; "));
  const badGstackPlan: GstackReviewPlan = { ...verifyGstack, selectedRoleIds: verifyGstack.selectedRoleIds.filter((id) => id !== "land-and-deploy") };
  const badGstackVerdict = verifyGstackPlan(badGstackPlan);
  check("deployment proof without land-and-deploy is rejected", badGstackVerdict.ok === false && badGstackVerdict.errors.some((e) => e.includes("land-and-deploy")));

  // ---------------- Fresh-room proof receipts: NodeRoom-compatible latest.json shape ----------------
  console.log("\nFreshRoomProofReceipt (live UI proof receipt compatibility):");
  const proofRoot = mkdtempSync(join(tmpdir(), "solo-smoke-proof-"));
  const touch = (rel: string, body = "proof") => {
    const path = join(proofRoot, rel);
    mkdirSync(join(path, ".."), { recursive: true });
    writeFileSync(path, body, "utf8");
    return rel;
  };
  const freshReceipt: FreshRoomProofReceipt = {
    schemaVersion: 1,
    caseId: "FR-010",
    roomId: "room_fresh",
    command: "npm run test:fresh-room",
    model: "deepseek/deepseek-v4-flash",
    runtimeProfile: "benchmark_completion",
    prompt: "Complete the held-out spreadsheet task.",
    tracePath: touch("trace.zip"),
    videoPath: touch("video.webm"),
    screenshotPaths: [touch("graded.png")],
    exportedFiles: [touch("answer.xlsx")],
    reopenedFiles: [touch("reopened.txt")],
    scorer: { id: "SpreadsheetBench/evaluation.compare_workbooks", official: true, passed: true, resultPath: touch("score.json", "{\"ok\":true}") },
    costUsd: 0.12,
    latencyMs: 42_000,
    tokenUsage: 22_000,
    mutationCount: 8,
    proofSignals: {
      freshRoom: true,
      liveBrowser: true,
      memoryModeFalse: true,
      zeroFabrication: true,
      selfTestPassed: true,
      exportDownloaded: true,
      artifactReopened: true,
    },
    pass: true,
  };
  const freshReceiptVerdict = verifyFreshRoomProofReceipt(freshReceipt, { baseDir: proofRoot });
  check("fresh-room receipt passes with live browser + official scorer proof", freshReceiptVerdict.ok, freshReceiptVerdict.errors.join("; "));
  const noOfficialScorerReceipt: FreshRoomProofReceipt = clone(freshReceipt);
  noOfficialScorerReceipt.scorer.official = false;
  const noOfficialScorerVerdict = verifyFreshRoomProofReceipt(noOfficialScorerReceipt, { baseDir: proofRoot });
  check("fresh-room receipt rejects unofficial scorer", noOfficialScorerVerdict.ok === false && noOfficialScorerVerdict.errors.some((e) => e.includes("official scorer")));
  const noArtifactReopenReceipt: FreshRoomProofReceipt = clone(freshReceipt);
  noArtifactReopenReceipt.proofSignals.artifactReopened = false;
  const noArtifactReopenVerdict = verifyFreshRoomProofReceipt(noArtifactReopenReceipt, { baseDir: proofRoot });
  check("fresh-room receipt rejects missing artifact reopen proof", noArtifactReopenVerdict.ok === false && noArtifactReopenVerdict.errors.some((e) => e.includes("artifactReopened")));

  // ---------------- Build-to-delete: rework ledger ----------------
  console.log("\nReworkLedger (build-to-delete learning preservation):");
  const reworkLedger: ReworkLedger = makeReworkLedger({
    projectId: "smoke",
    entries: [
      {
        id: "empty-provider-tool-schema",
        oldApproach: "Advertise production tools with empty object schemas.",
        whyItSeemedRight: "The backend implementation had validation, so the provider schema looked secondary.",
        failureMode: "Model called tools without required query/sourceArtifactId/ops fields.",
        failureReceiptPath: touch("failures/fr-010-schema-loss.json", "{\"ok\":false}"),
        newApproach: "Generate provider-facing schemas from canonical contracts and test required args.",
        whyItSurvived: "Provider now sees required arguments before tool call generation.",
        proofReceiptPaths: [touch("proofs/provider-schema-parity.json", "{\"ok\":true}")],
        deletedArtifacts: ["empty tool schema fallback"],
        keptArtifacts: ["canonical tool implementation"],
        lesson: "The model only sees the provider contract; backend correctness is not enough.",
      },
    ],
  });
  const reworkVerdict = verifyReworkLedger(reworkLedger, { baseDir: proofRoot });
  check("rework ledger passes complete build-to-delete entry", reworkVerdict.ok, reworkVerdict.errors.join("; "));
  const noDeletionLedger: ReworkLedger = clone(reworkLedger);
  noDeletionLedger.entries[0].deletedArtifacts = [];
  const noDeletionVerdict = verifyReworkLedger(noDeletionLedger, { baseDir: proofRoot });
  check("rework ledger rejects entries that do not delete/deprecate anything", noDeletionVerdict.ok === false && noDeletionVerdict.errors.some((e) => e.includes("deleted")));

  // ---------------- Executable loop runner: phase receipt enforcement ----------------
  console.log("\nLoopRunner (phase receipts and proof-verdict enforcement):");
  const loopReceipt: LoopRunReceipt = makeLoopRunReceipt({
    projectPath: proofRoot,
    goal: "prove a fresh-room 3D app flow",
    createdAt: "2026-06-24T00:00:00.000Z",
  });
  check("loop phase order verifies before iterate", loopPhases.join(" -> ") === "discover -> benchmark -> setup -> build -> adapter -> verify -> iterate");
  const loopFiles: Record<string, string> = {};
  const makeLoopFile = (name: string, body = "ok") => {
    loopFiles[name] = touch(`loop/${name}`, body);
    return loopFiles[name];
  };
  for (const phase of loopReceipt.phases) {
    phase.status = "completed";
    phase.memoryReceiptPath = makeLoopFile(`${phase.phase}-memory.json`, "{\"ok\":true}");
  }
  loopReceipt.phases.find((phase) => phase.phase === "discover")!.artifacts = {
    "graph-context": makeLoopFile("graph-context.json"),
    "research-intake": makeLoopFile("research-intake.json"),
  };
  loopReceipt.phases.find((phase) => phase.phase === "benchmark")!.artifacts = {
    "benchmark-choice": makeLoopFile("benchmark-choice.json"),
    "heldout-manifest": makeLoopFile("heldout-manifest.json"),
  };
  loopReceipt.phases.find((phase) => phase.phase === "setup")!.artifacts = {
    "setup-gate": makeLoopFile("setup-gate.json"),
  };
  loopReceipt.phases.find((phase) => phase.phase === "build")!.artifacts = {
    "agent-api-contract": makeLoopFile("agent-api-contract.md"),
    "design-quality": makeLoopFile("design-quality.json"),
  };
  loopReceipt.phases.find((phase) => phase.phase === "adapter")!.artifacts = {
    "adapter-contract": makeLoopFile("adapter-contract.json"),
    "official-scorer-binding": makeLoopFile("official-scorer-binding.json"),
  };
  loopReceipt.phases.find((phase) => phase.phase === "iterate")!.artifacts = {
    "failure-hypothesis": makeLoopFile("failure-hypothesis.json"),
    "rework-ledger": makeLoopFile("rework-ledger.json"),
  };
  loopReceipt.phases.find((phase) => phase.phase === "verify")!.artifacts = {
    "proof-verdict": makeLoopFile("proof-verdict.json", "{\"ok\":true}"),
    "fresh-room-receipt": makeLoopFile("fresh-room-latest.json"),
  };
  const loopVerdict = verifyLoopRunReceipt(loopReceipt, { baseDir: proofRoot });
  check("loop runner passes only when every phase receipt exists", loopVerdict.ok, loopVerdict.errors.join("; "));
  const noMemoryLoop = clone<LoopRunReceipt>(loopReceipt);
  noMemoryLoop.phases.find((phase) => phase.phase === "build")!.memoryReceiptPath = undefined;
  const noMemoryVerdict = verifyLoopRunReceipt(noMemoryLoop, { baseDir: proofRoot });
  check("loop runner rejects phase completion without memory receipt", noMemoryVerdict.ok === false && noMemoryVerdict.errors.some((e) => e.includes("memoryReceiptPath")));
  const badProofVerdictLoop = clone<LoopRunReceipt>(loopReceipt);
  writeFileSync(join(proofRoot, badProofVerdictLoop.phases.find((phase) => phase.phase === "verify")!.artifacts["proof-verdict"]!), "{\"ok\":false}", "utf8");
  const badProofVerdict = verifyLoopRunReceipt(badProofVerdictLoop, { baseDir: proofRoot });
  check("loop runner refuses done without passing proof-verdict.json", badProofVerdict.ok === false && badProofVerdict.errors.some((e) => e.includes("proof-verdict")));

  // ---------------- RALPH Loop Ledger: resumable milestone state ----------------
  console.log("\nRalphLoopLedger (.solo loop-state + events + receipt gates):");
  const ralphRoot = mkdtempSync(join(tmpdir(), `solo-ralph-${process.pid}-`));
  const ralph = createRalphLedger({
    repoPath: ralphRoot,
    goal: "build agent for this app",
    now: "2026-06-24T00:00:00.000Z",
    budgets: { maxUsd: 5, maxModelCalls: 20 },
  });
  const ralphLedgerPaths = ralphPaths(ralphRoot);
  check("RALPH init writes .solo/loop-state.json", existsSync(ralphLedgerPaths.statePath));
  check("RALPH init writes events.jsonl", existsSync(ralphLedgerPaths.eventsPath));
  check("RALPH init creates milestone receipt dirs", existsSync(join(ralphLedgerPaths.receiptsDir, "P-proof-run")));

  const blockedLiveBuild = startRalphMilestone(ralphRoot, "L");
  check("RALPH start-anywhere blocks when prior receipts are missing", blockedLiveBuild.verification.ok === false && blockedLiveBuild.verification.missing.some((item) => item.includes("A:benchmark-choice")));

  const ralphReceipt = (relative: string, body = "ok") => {
    const abs = join(ralphLedgerPaths.soloDir, relative);
    mkdirSync(dirname(abs), { recursive: true });
    writeFileSync(abs, body, "utf8");
    return relative;
  };
  completeRalphMilestone(ralphRoot, "R", [
    ralphReceipt("receipts/R-reality/capability-spec.json"),
    ralphReceipt("receipts/R-reality/research-spine.json"),
    ralphReceipt("receipts/R-reality/graph-context.json"),
  ]);
  completeRalphMilestone(ralphRoot, "A", [
    ralphReceipt("receipts/A-acceptance-bar/benchmark-choice.json"),
    ralphReceipt("receipts/A-acceptance-bar/rubric.json"),
    ralphReceipt("receipts/A-acceptance-bar/heldout-split-policy.json"),
  ]);
  const liveBuildStart = startRalphMilestone(ralphRoot, "L");
  check("RALPH can start Live Build after R/A receipts exist", liveBuildStart.verification.ok, liveBuildStart.verification.errors.join("; "));

  completeRalphMilestone(ralphRoot, "L", [
    ralphReceipt("receipts/L-live-build/agent-api-contract.json"),
    ralphReceipt("receipts/L-live-build/design-brief.md"),
    ralphReceipt("receipts/L-live-build/build-note.md"),
  ]);
  completeRalphMilestone(ralphRoot, "P", [
    ralphReceipt("receipts/P-proof-run/fresh-room-receipt.json"),
    ralphReceipt("proof-verdict.json", "{\"ok\":false}"),
  ]);
  const badRalphProof = verifyRalphMilestone(ralphRoot, "P");
  check("RALPH proof milestone rejects failing proof-verdict", badRalphProof.ok === false && badRalphProof.errors.some((e) => e.includes("proof-verdict")));
  ralphReceipt("proof-verdict.json", "{\"ok\":true}");
  const goodRalphProof = verifyRalphMilestone(ralphRoot, "P");
  check("RALPH proof milestone accepts passing proof-verdict", goodRalphProof.ok, goodRalphProof.errors.join("; "));

  // ---------------- CLI command center: event bus + dashboard + agent matrix ----------------
  console.log("\nCommandCenter (events, hooks, dashboard):");
  const soloEvent = recordSoloEvent(ralphRoot, {
    event: "tool.post",
    agentHost: "codex",
    milestone: "P",
    phase: "verify",
    status: "ok",
    message: "smoke proof event",
    source: "smoke",
  });
  const soloEvents = readSoloEvents(ralphRoot, 10);
  check("universal SoloEvent appends to .solo/events.jsonl", soloEvent.id.startsWith("evt_") && soloEvents.some((event) => event.id === soloEvent.id));

  const matrix = makeAgentMatrixRows();
  const matrixText = formatAgentMatrix(matrix);
  check("agent matrix includes hook-native and proof-only hosts", ["codex", "claude-code", "windsurf", "generic"].every((id) => matrix.some((row) => row.id === id)) && matrix.some((row) => row.id === "generic" && row.selfReportedCompletionAllowed === false));
  check("agent matrix renders as CLI table", matrixText.includes("host | family") && matrixText.includes("self-report"));

  const codexHookPlan = makeHookInstallPlan("codex", "2026-06-24T00:00:00.000Z");
  check("hook plan writes shared recorder and Codex hook files", codexHookPlan.files.some((file) => file.path === ".solo/bin/record-event") && codexHookPlan.files.some((file) => file.path === ".codex/config.toml"));
  check("hook plan carries no-self-report warning", codexHookPlan.warnings.some((warning) => warning.includes("Generic/no-hooks agents")));

  const dashboard = renderDashboard(ralphRoot, { eventLimit: 8 });
  const dashboardSnapshot = makeDashboardSnapshot(ralphRoot, { eventLimit: 8 });
  check("dashboard renders loop, proof, metrics, and agent hosts", dashboard.includes("SOLO FOUNDER COMMAND CENTER") && dashboard.includes("Proof:") && dashboard.includes("Agent Hosts:"));
  check("dashboard snapshot exposes proof and event metrics", dashboardSnapshot.activeProof.status === "pass" && dashboardSnapshot.metrics.eventCount >= 1);

  const doctor = doctorRalphLoop(ralphRoot);
  check("loop doctor passes complete local command-center layout", doctor.ok && doctor.proofVerdict === "pass", doctor.errors.join("; "));
  const paused = pauseRalphLoop(ralphRoot, { message: "waiting for human provider key", nextAction: "npm run sfn -- setup gate" });
  check("loop pause records resumable blocker", paused.loop.status === "blocked" && paused.loop.milestones[paused.loop.currentMilestone].blockedOn?.nextAction.includes("setup gate") === true);

  // ---------------- SoloControlPlane: durable loop control ----------------
  console.log("\nSoloControlPlane (durable control plane):");
  const controlDb = join(tmpdir(), `solo-smoke-control-${process.pid}-${Date.now()}.db`);
  const control = new SoloControlPlane({ dbUrl: `file:${controlDb}` });
  await control.init();

  const missingContextLoop = await control.startLoop({ projectId: "smoke", goal: "missing context should block", budgetUsd: 1 });
  let missingContextBlocked = false;
  try {
    await control.startPhase(missingContextLoop.loopId, "benchmark");
  } catch {
    missingContextBlocked = true;
  }
  check("post-discover phase requires graph context", missingContextBlocked);

  const trigger = await control.ingestTrigger({
    source: "cron",
    idempotencyKey: "nightly-1",
    projectId: "smoke",
    goal: "run unattended loop",
    budgetUsd: 1,
    payload: { schedule: "nightly" },
  });
  const triggerAgain = await control.ingestTrigger({
    source: "cron",
    idempotencyKey: "nightly-1",
    projectId: "smoke",
    goal: "run unattended loop",
    budgetUsd: 1,
    payload: { schedule: "nightly" },
  });
  check("event trigger is idempotent", trigger.duplicate === false && triggerAgain.duplicate === true && trigger.loopId === triggerAgain.loopId);

  await control.attachContext(trigger.loopId, graphReceipt);
  const discover = await control.startPhase(trigger.loopId, "discover");
  await control.checkpointPhase(discover.phaseRunId, { graphReport: graphReceipt.reportPath });
  await control.completePhase(discover.phaseRunId, { graphReady: true });
  const benchmark = await control.startPhase(trigger.loopId, "benchmark");
  check("phase checkpoint starts after graph context", benchmark.attempt === 1);

  const approval = await control.requestApproval(trigger.loopId, "setup", { command: "pip install -r run/requirements.txt", spendUsd: 0 });
  check("approval request pauses loop", (await control.getLoop(trigger.loopId))?.status === "paused");
  await control.decideApproval(approval.approvalId, { decision: "approve", note: "local install allowed" });
  check("approval decision resumes loop", (await control.getLoop(trigger.loopId))?.status === "queued");

  const spendOk = await control.spend(trigger.loopId, 0.2, "model smoke");
  const trace = await control.recordTraceSpan(trigger.loopId, {
    phase: "iterate",
    name: "held-out clean probe",
    status: "error",
    startedAt: 100,
    endedAt: 175,
    tokens: 1200,
    costUsd: 0.1,
    attrs: { failureCluster: "missing exporter selector" },
  });
  const improve = await control.proposeImprovement({
    loopId: trigger.loopId,
    sourceTraceId: trace.traceId,
    title: "Make live-browser selector contract explicit",
    hypothesis: "The verifier failed because the app adapter guessed selectors.",
    patchHint: "Add selector receipts to the live browser adapter.",
  });
  const spendBlocked = await control.spend(trigger.loopId, 2, "overspend");
  check("budget meter allows in-policy spend", spendOk.allowed === true);
  check("budget meter blocks overspend", spendBlocked.allowed === false && (await control.getLoop(trigger.loopId))?.status === "paused");
  check("trace-sourced improvement is queued", improve.improvementId.startsWith("improve_"));

  const lease = await control.leaseWorktree(trigger.loopId, "reviewer", "D:/tmp/reviewer", "codex/reviewer");
  let duplicateLeaseBlocked = false;
  try {
    await control.leaseWorktree(trigger.loopId, "reviewer", "D:/tmp/reviewer2", "codex/reviewer2");
  } catch {
    duplicateLeaseBlocked = true;
  }
  await control.releaseWorktree(lease.leaseId);
  check("active worktree leases are exclusive per purpose", duplicateLeaseBlocked);

  const resumedControl = new SoloControlPlane({ dbUrl: `file:${controlDb}` });
  await resumedControl.init();
  const resumed = await resumedControl.resumeSummary(trigger.loopId);
  check("control state survives a fresh instance", resumed.loop.context?.status === "ready" && resumed.traceSummary.count === 1 && resumed.improvements.length === 1);

  console.log(`\n=== ${pass} passed, ${fail} failed ===\n`);
  if (fail > 0) process.exit(1);
}

main().catch((err) => {
  console.error(err);
  process.exit(1);
});
