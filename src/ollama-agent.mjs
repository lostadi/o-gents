const DEFAULT_ENDPOINT = "http://127.0.0.1:11434";
export const DEFAULT_MODEL = "huihui-spark-vm:32k";

function configuredModelTimeout() {
  const raw = process.env.OVM_MODEL_TIMEOUT_SECONDS;
  if (raw === undefined) return 90_000;
  const seconds = Number(raw);
  if (!/^\d+$/.test(raw) || !Number.isSafeInteger(seconds) || seconds < 1 || seconds > 3600) {
    throw new Error("OVM_MODEL_TIMEOUT_SECONDS must be an integer between 1 and 3600 seconds.");
  }
  return seconds * 1000;
}

function excerpt(value, maximum = 2048) {
  const text = typeof value === "string" ? value : JSON.stringify(value) ?? "";
  if (text.length <= maximum) return text;
  const marker = "\n...[truncated]...\n";
  const head = Math.ceil((maximum - marker.length) / 2);
  return text.slice(0, head) + marker + text.slice(-(maximum - marker.length - head));
}

function compactChecks(checks = []) {
  return checks.slice(0, 8).map((check) => ({ ...check,
    expected: typeof check.expected === "string" ? excerpt(check.expected, 256) : check.expected,
    ...(typeof check.expected === "string" && check.expected.length > 256 ? { expectedTruncated: true } : {}),
  }));
}

function compactReview(review) {
  return review ? { ...review, checks: compactChecks(review.checks) } : null;
}

function compactArtifact(artifact) {
  return artifact.code ? { ...artifact,
    code: { ...artifact.code, contract: { checks: compactChecks(artifact.code.contract.checks) } },
    ...(artifact.peerVerification ? { peerVerification: compactReview(artifact.peerVerification) } : {}),
  } : artifact;
}

function compactAction(action) {
  switch (action.type) {
    case "ostadix": return { type: action.type, mode: action.mode, name: action.name, source: excerpt(action.source, 2048), checks: compactChecks(action.checks) };
    case "review_artifact": return { type: action.type, artifactId: action.artifactId };
    case "read_execution": return { type: action.type, evidenceId: action.evidenceId };
    case "vm": return { type: action.type, command: excerpt(action.command, 1024) };
    case "native": return { type: action.type, operation: action.operation, argsExcerpt: excerpt(action.args, 1024) };
    case "send": return { type: action.type, to: action.to, message: excerpt(action.message, 1024), evidence: action.evidence };
    case "publish": return { type: action.type, path: action.path, name: action.name };
    case "spawn": return { type: action.type, id: action.id, role: excerpt(action.role, 512), mission: excerpt(action.mission, 1024) };
    case "finish": return { type: action.type, summary: excerpt(action.summary, 1024), evidence: action.evidence, assertions: action.assertions };
    case "reply": return { type: action.type, message: excerpt(action.message, 1024), evidence: action.evidence, assertions: action.assertions, revises: action.revises };
    default: return { type: action.type };
  }
}

function compactObservation(observation, { summarizeInventories = false } = {}) {
  if (!observation) return null;
  return {
    round: observation.round,
    evidence: observation.evidence ?? [],
    artifacts: (observation.artifacts ?? []).map(compactArtifact),
    verification: observation.verification ?? null,
    repairs: observation.repairs ?? [],
    ostadix: observation.ostadix ? {
      sourceSha256: observation.ostadix.sourceSha256,
      executionIntentSha256: observation.ostadix.executionIntentSha256,
      mode: observation.ostadix.mode, executed: observation.ostadix.executed,
      checkStatus: observation.ostadix.checkStatus, success: observation.ostadix.success,
      checks: compactChecks(observation.ostadix.checks), exitCode: observation.ostadix.exitCode,
      stdout: excerpt(observation.ostadix.stdout), stderr: excerpt(observation.ostadix.stderr),
      diagnostics: excerpt(observation.ostadix.diagnostics, 2048),
      error: observation.ostadix.error ? excerpt(observation.ostadix.error, 1024) : null,
    } : null,
    peerReview: compactReview(observation.peerReview),
    executionReads: (observation.executionReads ?? []).slice(-2).map((read) => ({
      ...read, source: read.source === null ? null : excerpt(read.source, 2048),
      sourceTruncated: (read.source?.length ?? 0) > 2048,
      checks: compactChecks(read.checks), peerReview: compactReview(read.peerReview),
      actions: read.actions.map(compactAction),
      stdout: { text: excerpt(read.stdout.text), truncated: read.stdout.truncated || read.stdout.text.length > 2048 },
      stderr: { text: excerpt(read.stderr.text, 1024), truncated: read.stderr.truncated || read.stderr.text.length > 1024 },
    })),
    vm: observation.vm ? {
      exitCode: observation.vm.exitCode ?? null,
      error: observation.vm.error ? excerpt(observation.vm.error, 1024) : null,
      output: observation.vm.ostadixCapture ? "Ostadix results appear in ostadix; this VM observation is capture metadata." : excerpt(observation.vm.output ?? ""),
    } : null,
    native: (observation.native ?? []).slice(0, 2).map((result) => ({
      operation: result.operation,
      ...(summarizeInventories && result.operation === "host.runningApps" ? {
        inventorySummary: { count: Array.isArray(result.value) ? result.value.length : null, detail: "Previously observed host application inventory; see its evidence ID. Do not treat application names as file contents." },
      } : { valueExcerpt: excerpt(result.value) }),
    })),
    messages: (observation.messages ?? []).slice(0, 8).map((message) => message.spawned
      ? { spawned: message.spawned }
      : { sent: { to: message.sent?.to, message: excerpt(message.sent?.message, 1024) } }),
    errors: (observation.errors ?? []).slice(0, 8).map((error) => excerpt(error, 1024)),
  };
}

function hasToolObservation(observation) {
  return Boolean(observation && (observation.ostadix || observation.vm || observation.peerReview
    || observation.native?.length || observation.executionReads?.length || observation.evidence?.length));
}

function selectContextEntries(entries = [], limit, required = () => false) {
  const retained = new Set(entries.filter(required));
  for (let index = entries.length - 1; index >= 0 && retained.size < limit; index--) retained.add(entries[index]);
  return entries.filter(entry => retained.has(entry));
}

function contextProjection(agent, context) {
  const previousObservation = compactObservation(agent.lastObservation);
  const lastExecution = !hasToolObservation(agent.lastObservation)
    ? context.lastExecutionObservation ?? context.recentHistory?.findLast(turn => hasToolObservation(turn.observation))?.observation
    : null;
  const lastExecutionObservation = lastExecution ? compactObservation(lastExecution) : null;
  const artifacts = context.availableArtifacts ?? [];
  const focusId = context.pendingCodeReviews?.at(-1)?.id
    ?? previousObservation?.peerReview?.artifactId ?? lastExecutionObservation?.peerReview?.artifactId
    ?? context.recentHistory?.flatMap(turn => turn.actions ?? []).findLast(action => action.type === "review_artifact")?.artifactId;
  const focus = artifacts.find(artifact => artifact.id === focusId)
    ?? artifacts.findLast(artifact => artifact.kind === "ostadix-program" && artifact.producer === agent.id)
    ?? artifacts.findLast(artifact => artifact.kind === "ostadix-program") ?? artifacts.at(-1);
  const focusedReviews = (context.artifactReviews ?? []).filter(review => review.artifactId === focus?.id);
  const focusedReview = focusedReviews.at(-1);
  const evidenceIds = new Set([focus?.code?.executionEvidenceId, focus?.peerVerification?.reviewEvidenceId,
    focusedReview?.executionEvidenceId, focusedReview?.reviewEvidenceId].filter(Boolean));
  for (const observation of [previousObservation, lastExecutionObservation]) {
    for (const evidence of observation?.evidence ?? []) evidenceIds.add(evidence.id);
    for (const read of observation?.executionReads ?? []) if (read.evidence?.id) evidenceIds.add(read.evidence.id);
  }
  const projection = {
    protocol: context.protocol, swarmId: context.swarmId, round: context.round,
    currentInvocationStartRound: context.currentInvocationStartRound ?? 0,
    maximumRounds: context.maximumRounds, maximumAgents: context.maximumAgents,
    mission: context.mission, ...(agent.mission ? { agentMission: agent.mission } : {}),
    identity: { id: agent.id, role: agent.role, parentId: agent.parentId },
    peers: context.peers ?? [], inbox: context.inbox ?? [],
    availableArtifacts: selectContextEntries(artifacts, 8, artifact => artifact === focus).map(compactArtifact),
    availableEvidence: selectContextEntries(context.availableEvidence, 32, evidence => evidenceIds.has(evidence.id)),
    artifactReviews: selectContextEntries(context.artifactReviews, 4, review => review === focusedReview).map(compactReview),
    pendingCodeReviews: context.pendingCodeReviews ?? [],
    sourceBinding: context.sourceBinding ?? null, sourceFacts: (context.sourceFacts ?? []).slice(-32),
    pendingActions: context.pendingActions ?? [], pendingClaims: context.pendingClaims ?? [], repairs: context.repairs ?? [],
    previousObservation, ...(lastExecutionObservation ? { lastExecutionObservation } : {}),
    recentHistory: (context.recentHistory ?? []).slice(-4).map(turn => ({
      round: turn.round, actions: turn.actions.slice(0, 8).map(compactAction),
      observation: compactObservation(turn.observation, { summarizeInventories: true }),
    })),
    ...((context.pendingClaims?.length || agent.lastObservation?.errors?.some(error => error.startsWith("finish deferred: inspect"))) ? {
      reviewNext: {
        instruction: `Your previous commands already ran. Inspect their recorded output; do not repeat them just to answer. If sufficient, return only ${context.interaction === "chat" ? "reply" : "finish"} with the exact prior evidence IDs and assertions. Otherwise request a different diagnostic.`,
        evidenceIds: [...evidenceIds],
      },
    } : {}),
  };
  // Every later reduction works only on this detached projection. Retained
  // receipts, source bytes, predicates and mailbox entries remain untouched.
  return { projection: JSON.parse(JSON.stringify(projection)), focusId: focus?.id, evidenceIds,
    focusedReviewId: focusedReview?.reviewEvidenceId };
}

function limitContextDetails(value, maximum) {
  if (!value || typeof value !== "object") return;
  // Never truncate an identity, digest, mission, path, status or assertion ID.
  // These fields are excerpts already, or human-readable payloads that may be
  // excerpted with a visible marker. JSON is serialized only after projection.
  const excerptFields = new Set(["source", "stdout", "stderr", "diagnostics", "error", "output", "text",
    "valueExcerpt", "argsExcerpt", "command", "message", "summary", "rationale", "detail", "scope", "instruction"]);
  for (const [key, entry] of Object.entries(value)) {
    if (key === "expected" && typeof entry === "string" && entry.length > Math.min(maximum, 128)) {
      value[key] = excerpt(entry, Math.min(maximum, 128)); value.expectedTruncated = true;
    } else if (typeof entry === "string" && excerptFields.has(key) && entry.length > maximum) {
      value[key] = excerpt(entry, maximum);
      if (key === "source") value.sourceTruncated = true;
      if (key === "text") value.truncated = true;
    } else if (key === "errors" && Array.isArray(entry)) value[key] = entry.map(error => excerpt(error, maximum));
    else if (entry && typeof entry === "object") limitContextDetails(entry, maximum);
  }
}

function evidenceSummary(record) {
  const keys = ["id", "producer", "round", "kind", "sourceSha256", "executed", "checkStatus", "exitCode", "status", "allowedAssertions"];
  return Object.fromEntries(keys.filter(key => record[key] !== undefined).map(key => [key, record[key]]));
}

function minimizeContextDetails(value) {
  if (!value || typeof value !== "object") return;
  for (const [key, entry] of Object.entries(value)) {
    if (key === "checks" && Array.isArray(entry)) {
      value[key] = [];
      value.checksSummary = { count: entry.length, passed: entry.filter(check => check.passed === true).length,
        failed: entry.filter(check => check.passed === false).length, predicateTextOmitted: true };
    } else if (key === "evidence" && Array.isArray(entry)) value[key] = entry.map(evidenceSummary);
    else if (key === "actions" && Array.isArray(entry)) value[key] = entry.map(action => ({
      type: action.type, ...(action.mode ? { mode: action.mode } : {}), ...(action.name ? { name: action.name } : {}),
      ...(action.evidenceId ? { evidenceId: action.evidenceId } : {}), ...(action.artifactId ? { artifactId: action.artifactId } : {}),
      detailsOmitted: true,
    }));
    else if (entry && typeof entry === "object") minimizeContextDetails(entry);
  }
}

function essentialReview(review) {
  if (!review) return null;
  return { artifactId: review.artifactId, producer: review.producer, reviewer: review.reviewer,
    round: review.round, status: review.status, executionEvidenceId: review.executionEvidenceId,
    reviewEvidenceId: review.reviewEvidenceId, checksSummary: review.checksSummary };
}

function essentialObservation(observation) {
  if (!observation) return null;
  const evidence = (observation.evidence ?? []).map(evidenceSummary);
  return { round: observation.round, evidence, ostadix: observation.ostadix, peerReview: essentialReview(observation.peerReview),
    // The raw capture receipt has already been replaced by the O outcome.
    ...(observation.ostadix ? {} : { vm: observation.vm }),
    native: observation.native, errors: observation.errors.slice(-2),
    executionReads: observation.executionReads.slice(-1).map(read => ({
      evidence: evidenceSummary(read.evidence), source: read.source, sourceTruncated: read.sourceTruncated,
      stdout: read.stdout, stderr: read.stderr, exitCode: read.exitCode, checksSummary: read.checksSummary,
      independentVerification: false, peerReview: essentialReview(read.peerReview), actions: read.actions,
    })),
    detailsOmitted: true,
  };
}

function budgetContext(agent, context, maximum, { retry = false } = {}) {
  const { projection, focusId, evidenceIds, focusedReviewId } = contextProjection(agent, context);
  const collections = ["recentHistory", "inbox", "availableEvidence", "availableArtifacts", "artifactReviews", "pendingCodeReviews",
    "sourceFacts", "pendingActions", "pendingClaims", "repairs", "peers"];
  const availableCounts = Object.fromEntries(collections.map(key => [key, context[key]?.length ?? 0]));
  const serialize = level => {
    const omitted = Object.fromEntries(collections.filter(key => availableCounts[key] > (projection[key]?.length ?? 0))
      .map(key => [key, availableCounts[key] - projection[key].length]));
    projection.contextOmissions = {
      userCharacterBudget: maximum, reductionLevel: level, omitted,
      detail: "This is a bounded view, not complete history. Full records remain retained; omitted or excerpted content is not new evidence.",
      ...(level > 0 ? { payloadExcerptsReduced: true } : {}), ...(level === 3 ? { predicateTextOmitted: true } : {}),
      ...(retry ? { reason: "server-context-overflow-retry" } : {}),
    };
    return JSON.stringify(projection);
  };
  let serialized = serialize(0);
  if (serialized.length <= maximum) return serialized;

  // Remove repeated and older context before reducing the current results.
  projection.recentHistory = projection.recentHistory.slice(-1);
  projection.inbox = projection.inbox.slice(-2);
  projection.availableEvidence = selectContextEntries(projection.availableEvidence, 4, record => evidenceIds.has(record.id));
  projection.availableArtifacts = selectContextEntries(projection.availableArtifacts, 2, artifact => artifact.id === focusId);
  projection.artifactReviews = selectContextEntries(projection.artifactReviews, 1, review => review.reviewEvidenceId === focusedReviewId);
  projection.sourceFacts = projection.sourceFacts.slice(-2);
  projection.repairs = projection.repairs.slice(-2);
  for (const key of ["pendingActions", "pendingClaims"]) projection[key] = projection[key].slice(-2);
  for (const key of collections) limitContextDetails(projection[key], 384);
  serialized = serialize(1);
  if (serialized.length <= maximum) return serialized;

  projection.recentHistory = [];
  projection.inbox = projection.inbox.slice(-1);
  projection.availableEvidence = projection.availableEvidence.filter(record => evidenceIds.has(record.id)).map(evidenceSummary);
  projection.availableArtifacts = projection.availableArtifacts.filter(artifact => artifact.id === focusId);
  projection.artifactReviews = projection.artifactReviews.filter(review => review.reviewEvidenceId === focusedReviewId);
  projection.pendingCodeReviews = selectContextEntries(projection.pendingCodeReviews, 1, artifact => artifact.id === focusId);
  projection.sourceFacts = projection.sourceFacts.slice(-1);
  projection.repairs = [];
  projection.peers = projection.peers.map(peer => ({ id: peer.id, finished: peer.finished }));
  for (const key of ["pendingActions", "pendingClaims"]) projection[key] = projection[key].slice(-1);
  // Keep both the current API error and the last real result, with their
  // original rounds and identities. An error must not erase completed work.
  for (const key of [...collections, "previousObservation", "lastExecutionObservation"]) limitContextDetails(projection[key], 256);
  serialized = serialize(2);
  if (serialized.length <= maximum) return serialized;

  for (const key of [...collections, "previousObservation", "lastExecutionObservation"]) {
    limitContextDetails(projection[key], 128); minimizeContextDetails(projection[key]);
  }
  projection.previousObservation = essentialObservation(projection.previousObservation);
  if (projection.lastExecutionObservation) projection.lastExecutionObservation = essentialObservation(projection.lastExecutionObservation);
  projection.availableArtifacts = projection.availableArtifacts.map(artifact => ({ id: artifact.id, kind: artifact.kind,
    name: artifact.name, producer: artifact.producer, round: artifact.round, sha256: artifact.sha256,
    ...(artifact.code ? { code: { executionEvidenceId: artifact.code.executionEvidenceId,
      contract: { checksSummary: artifact.code.contract.checksSummary } } } : {}),
    peerVerification: artifact.peerVerification ? { status: artifact.peerVerification.status,
      reviewEvidenceId: artifact.peerVerification.reviewEvidenceId } : null, detailsOmitted: true,
  }));
  projection.artifactReviews = projection.artifactReviews.map(essentialReview);
  // Keep each exact evidence record once; the observation itself is the source
  // for repeated inventory entries, including allowed assertion kinds.
  const observedIds = new Set([projection.previousObservation, projection.lastExecutionObservation].flatMap(observation => [
    ...(observation?.evidence ?? []).map(record => record.id), ...(observation?.executionReads ?? []).map(read => read.evidence.id),
  ]));
  projection.availableEvidence = projection.availableEvidence.filter(record => !observedIds.has(record.id));
  serialized = serialize(3);
  if (serialized.length <= maximum) return serialized;
  throw new Error(`Ollama context budget cannot fit essential mission, identity and retained result references (${serialized.length} characters; budget ${maximum}). Shorten the mission or agent mission, reduce active work, or explicitly choose a model/context with more capacity. No inference request or tool action was dispatched for this projection.`);
}

function contextCharacterBudget(contextTokens, system) {
  if (!Number.isSafeInteger(contextTokens) || contextTokens < 1) throw new Error("OVM_SWARM_CONTEXT must be a positive integer token capacity.");
  // Estimate the English system instructions at four characters per token and
  // the mixed JSON payload at three, leaving the configured 2048-token response
  // and message overhead. The actual model
  // tokenizer may differ; a specific server overflow permits one tighter retry.
  const available = contextTokens - Math.ceil(system.length / 4) - 2048 - 256;
  const maximum = Math.min(8000, Math.floor(available * 3));
  if (maximum < 512) throw new Error(`Ollama context capacity ${contextTokens} is too small for the system instructions and response reserve. Explicitly configure a larger supported OVM_SWARM_CONTEXT; no inference request was dispatched.`);
  return maximum;
}

function isContextOverflow(status, body) {
  return status === 400 && /exceed_context_size_error|(?:request|prompt|input)[\s\S]{0,100}exceeds? (?:the )?(?:available |maximum )?context|context (?:length|window|size) (?:is )?(?:exceeded|too small)/i.test(body);
}

function systemPrompt(nativeOperations, { interactive = false } = {}) {
  const capabilities = nativeOperations.length
    ? nativeOperations.map((item) => `- ${item.name}: args=${JSON.stringify(item.argsSchema ?? { minItems: item.minimumArguments ?? 0, maxItems: item.maximumArguments ?? 0 })}; ${item.description ?? item.evidence}; access=${item.access}`).join("\n")
    : "- none on this host";
  return `You are a gent: one autonomous agent with its own persistent Linux microVM in an o-gents swarm. Ostadix is your structured execution and checking interface. You also have a bounded host capability broker and mailboxes to peer gents.

Each decision is one phase: request new VM/native/artifact work, OR report/finish
using results that already exist. Never combine finish or a result report with new work.
Work requests and explicitly unverified hypotheses can accompany new work.
The following actions are a catalogue of choices, not a sequence to repeat.
Return exactly one JSON object with this shape:
{
  "rationale": "brief decision explanation",
  "actions": [
    {"type":"vm","command":"a Linux shell program","reason":"why"},
    {"type":"ostadix","name":"sum","mode":"run","source":"python^(\\n__oval_result__ = 1 + 1\\n)_python","checks":[{"kind":"stdout_contains","expected":"[number] 2"}]},
    {"type":"read_execution","evidenceId":"shared-execution-id"},
    {"type":"review_artifact","artifactId":"ostadix:published-contract-digest"},
    {"type":"send","kind":"request or hypothesis or report","to":"peer-id or all","message":"claim or request","evidence":["prior-observation-id"]},
    {"type":"inspect_source","path":"/root/.bash_history"},
    {"type":"publish","path":"/root/deliverable.txt","name":"deliverable"},
    {"type":"native","operation":"catalog name","args":[]},
    {"type":"spawn","id":"child-id","role":"specialty","mission":"bounded subtask"},
    {"type":"finish","summary":"your assessment","evidence":["prior-observation-id"],"assertions":[{"evidenceId":"prior-observation-id","kind":"stdout_contains","expected":"expected observed content"}]}${interactive ? ',\n    {"type":"reply","message":"answer for the user","evidence":["prior-observation-id"],"assertions":[]}' : ''}
  ]
}

Use at most one guest action (vm, ostadix, review_artifact, publish, or inspect_source), two native actions, and eight total actions in a round. VM commands run only inside your private guest. Messages arrive to peers on their next round. Use spawn only for a separable subtask when the current agent count is below maximumAgents; all peers plus you count toward that cap. Follow agentMission for your assigned part of the global mission. VM and native results arrive in previousObservation on your next turn; recentHistory pairs your recent actions with their observed results. Review that history before deciding, and avoid repeating already successful actions unless new evidence requires it. lastExecutionObservation retains the latest real tool result when previousObservation contains only a reasoning/API error; its original round still applies. contextOmissions describes a bounded view, not the full history. Excerpts marked [truncated] or expectedOmitted are incomplete; do not infer omitted results or rerun completed work merely because older context is omitted. Do not claim a result or finish in the same turn that requests it. Once prior observations support completion, return a finish action without requesting new VM or native evidence. For Python work, prefer available standard-library tools such as unittest; check availability before assuming pytest or other application packages. The prepared guest includes Ostadix (O, o, olangc), ostadix-mcp, o-node, and major language runtimes. NAT internet access is enabled by default. Distribution can be auto, local, or required. Auto attempts the shared VM mesh but keeps local execution available if it fails; local skips the mesh. Inspect /run/ovm/ready or ovm-peer status before assuming mesh availability. When the mesh is ready, ovm-peer list shows registered guest identities. NAT may reach host-accessible Tailscale destinations; verify each destination rather than assuming reachability. Use ovm-peer status PEER to check a running peer, and ovm-peer run PEER FILE.O for native Ostadix remote execution with automatic pairing. A listed peer may be stopped; VM peers are available only while their commands are running in the same round. An explicit isolated launch disables networking. Do not wrap JSON in markdown.

Evidence and artifact rules:
- Prefer ostadix for code work: author a small .O program using real nesting syntax, request mode check to inspect structure without running, then mode run with explicit expected stdout checks. Source text is preserved exactly. The controller invokes native O checks, reads backend diagnostics, obtains an execution-intent digest, and executes with native source/intent binding inside your VM. A parse result is not behavioral proof; skipped backend checks remain visible. Missing runtime support is an error, never a passing check.
- For a simple program use source "python^(\\n__oval_result__ = 1 + 1\\n)_python" and a stdout_contains check for "[number] 2". Native O output includes its value type and trailing newline: the exact JSON string for this example is "[number] 2\\n". Preserve that newline in stdout_equals. Run mode requires at least one meaningful stdout_equals or stdout_contains check. Put language-specific assertions/tests inside the program for stronger checks; choose the expected result before execution and do not weaken it merely to make a failure pass.
- A successful run automatically publishes the exact O source as an immutable code artifact with its declared check contract. You do not need a separate publish action for that source. Each artifact has an ostadix: ID, sha256, code.executionEvidenceId, and peerVerification. The producer's own passing checks leave it awaiting-peer-review. Predicate excerpts marked expectedTruncated are incomplete; review_artifact always uses the full unchanged contract from the artifact store.
- Read a peer's published execution with read_execution using code.executionEvidenceId. This exposes source, recorded actions, output, checks and original producer; truncation is explicit. A read or a repeated assertion is not an independent execution.
- A different gent must use review_artifact with the exact artifact ID to rerun its unchanged source and checks in that gent's own VM. Self-review is refused. Review requests arrive automatically through the mailbox. If needed, spawn a distinct reviewer within maximumAgents. For artifact IDs and execution IDs, copy the exact values from availableArtifacts; never invent a plausible ID. Keep the same program name for a corrected revision; only the latest revision of each produced program must pass peer review before finish. Do not finish early while peers still need your review.
- Use ostadix_checks_passed with expected true against the :ostadix evidence ID for a run's declared checks. Use peer_review_passed with expected true against the :peer-review evidence ID for independently rerun checks. Both are limited to the recorded predicates; peer agreement does not prove the whole mission. Static-check and capture metadata cannot satisfy execution assertions. Ordinary chat and exploratory vm commands remain available without requiring a peer.
- Every tool observation has controller-issued evidence IDs. Cite the exact prior ID when reporting or finishing. Peer messages are claims, not independent verification; repeating a cited result preserves its original producer.
- currentInvocationStartRound marks the saved history before this user request began. Observations with a greater round number already happened for this request. If the requested command succeeded in one of those rounds, review it and answer; do not execute it again merely because the mission asks to run a command.
- A report or finish alongside new VM/native/publish work needs later review. Work requests and explicit hypotheses may travel immediately with kind request or hypothesis; they remain unverified. Pending claims preserve your proposed report for amendment. Use send.revises with its pending claim ID when you have reviewed the observation. Never change a success claim into a work request just to bypass evidence checks.
- VM plus publish is repaired: the VM runs first, publication is queued against its observed success. Inspect structured repairs and pendingActions; do not keep resubmitting the same rejected sequence. Additional VM actions are dropped rather than run without a new decision.
- Exit zero proves only that the command returned zero. Output MISSING, an empty file, or a status-only success notice does not establish a deliverable. Verify actual content and use stdout_equals or stdout_contains assertions on its observation. exit_code assertions are allowed but check only the exit code. Native host.appForFile returns an application association, not file contents; never use it as content evidence.
- Each VM has a separate filesystem. A peer's /root/file is not your /root/file. Publish actual file bytes with a publish action on its own round, after producing the file. Files up to 256 KiB can be published; the family artifact budget is 64 files and 2 MiB. Peers then inspect availableArtifacts.guestPath under the read-only /ovm/artifacts mount. Check its SHA-256 and contents. Publishing records bytes and provenance, not semantic correctness.
- Your own VM files already persist between rounds and chat messages. Publish only to share an artifact with peers or explicitly deliver its bytes; publication is unnecessary merely to save a file. An artifact-capture observation contains receipt metadata, not the file contents or the earlier command's stdout. Use artifact_sha256 with its digest, or cite the original kind vm evidence for stdout_contains/stdout_equals/exit_code. Do not attach a stdout assertion to an artifact-capture ID.
- Preserve source order and provenance when transforming records. Do not invent missing timestamps, history, or outcomes. Distinguish guest history from host history; request or identify the intended source. Lossless parsing, inferred procedure, and tested reproduction are separate achievements. State unresolved gaps instead of substituting fabricated evidence.
- A finish requires at least one explicit passing assertion against prior evidence. Prose alone cannot close an agent. Assertion kinds: stdout_contains, stdout_equals, exit_code (VM or executed Ostadix); ostadix_checks_passed and peer_review_passed (expected true); native_value_equals (exact native value); artifact_sha256 (captured artifact digest); source_kind (source_present/source_absent/source_unreadable/source_not_regular). Every assertion needs evidenceId and expected. Passed assertions establish only those checks, not the whole mission.
- For exit_code, expected is a JSON number, for example {"evidenceId":"prior-vm-id","kind":"exit_code","expected":0}. For stdout checks, expected is the exact observed string or substring, including significant whitespace.
- Inspect sourceBinding before deriving data. inspect_source produces a durable source fact. A source_absent fact is an observed negative result for that VM/path/round, not an empty slot to fill with invented history. Reuse it or identify a new source; recheck the same path only after a later action could have changed it. A guest path and a host Terminal history are different sources.
${interactive ? '- This is a VM-enabled conversation. Use reply, not finish, to answer the user and wait for their next message. Reply does not mark the task verified or finish the agent. For execution requests, run the VM action first, then reply using the actual result. Cite the exact kind vm evidence ID for command output; add a stdout_contains assertion if reporting a specific observed value. For conceptual questions you may reply without tools, clearly as an explanation. Do not claim you executed something without an observation. Use reply.revises with the pending reply ID when reviewing a previously proposed answer.' : ''}

Native capabilities available to this swarm:
${capabilities}`;
}

export class OllamaAgentClient {
  constructor({
    endpoint = process.env.OVM_OLLAMA_URL ?? DEFAULT_ENDPOINT,
    model = process.env.OVM_SWARM_MODEL ?? DEFAULT_MODEL,
    timeoutMilliseconds = configuredModelTimeout(),
    contextTokens = Number.parseInt(process.env.OVM_SWARM_CONTEXT ?? "8192", 10),
    fetchImpl = globalThis.fetch,
  } = {}) {
    this.endpoint = endpoint.replace(/\/$/, "");
    this.model = model;
    this.timeoutMilliseconds = timeoutMilliseconds;
    this.contextTokens = contextTokens;
    this.fetchImpl = fetchImpl;
  }

  async decide(agent, context) {
    const controller = new AbortController();
    const timer = setTimeout(() => controller.abort(new Error("Ollama decision timed out")), this.timeoutMilliseconds);
    try {
      const system = systemPrompt(context.nativeOperations, { interactive: context.interaction === "chat" });
      const maximum = contextCharacterBudget(this.contextTokens, system);
      let user = budgetContext(agent, context, maximum);
      let body, retries = 0;
      for (;;) {
        const response = await this.fetchImpl(`${this.endpoint}/api/chat`, {
          method: "POST",
          headers: { "content-type": "application/json" },
          body: JSON.stringify({
            model: this.model, stream: false, format: "json", think: false, keep_alive: "10m",
            options: { temperature: 0.2, num_ctx: this.contextTokens, num_predict: 2048 },
            messages: [{ role: "system", content: system }, { role: "user", content: user }],
          }),
          signal: controller.signal,
        });
        body = await response.text();
        if (response.ok) break;
        if (retries === 0 && isContextOverflow(response.status, body)) {
          // This is a rejected reasoning request: no model decision, VM action
          // or publication has occurred. Retry once with less context, never
          // replay tools or silently increase the configured context window.
          user = budgetContext(agent, context, Math.min(Math.floor(maximum / 2), user.length - 256), { retry: true });
          retries++;
          continue;
        }
        throw new Error(`Ollama ${response.status}: ${body.slice(0, 2048)}`);
      }
      const parsed = JSON.parse(body);
      const content = parsed.message?.content ?? parsed.response;
      if (typeof content !== "string" || content.trim().length === 0) {
        throw new Error(`Ollama response did not contain an agent decision (done_reason=${parsed.done_reason ?? "unknown"})`);
      }
      return { model: parsed.model ?? this.model, content, metrics: {
        doneReason: parsed.done_reason ?? null,
        totalDuration: parsed.total_duration ?? null,
        promptTokens: parsed.prompt_eval_count ?? null,
        outputTokens: parsed.eval_count ?? null,
        contextCharacters: user.length, contextRetries: retries,
      } };
    } finally {
      clearTimeout(timer);
    }
  }
}
