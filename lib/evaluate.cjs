/**
 * Evaluate a completed AgentState against a scenario's expectations.
 *
 * Supports v2 assertions (type-dispatched) with automatic v1 backward compatibility.
 * Returns a structured result with per-metric pass/fail and an overall score.
 *
 * evaluateScenario is async because natural_language assertions use LLM-as-Judge.
 */

const { extractSkillTrace } = require("./skill-trace.cjs");
const { evaluateNaturalLanguage } = require("./judge.cjs");
const { compareStructuralModels } = require("./model-fidelity.cjs");
const { comparePhysicalModels } = require("./physical-model-fidelity.cjs");
const { selectAnalysisResult } = require("./result-selection.cjs");
const { verifyExecutionEvidence } = require("./analysis-evidence.cjs");
const { compareAnalysisResults } = require("./analysis-fidelity.cjs");
const { compareNumericalResults } = require("./numerical-ground-truth.cjs");
const {compareRequestedQuantities,compareReportQuantities}=require("./requested-quantities.cjs");
const {
  compareCommercialEngineResponses,
  normalizeCommercialEngineResponse,
} = require("./cross-engine-ground-truth.cjs");
const { findEngineGroundTruth, normalizeEngineKey } = require("./engine-ground-truth.cjs");
const path = require("node:path");
const fs = require("node:fs");

// Lazy-load ground-truth models for model_matches assertions
let _groundTruthCache = null;
let _numericalGroundTruthCache = null;
let _crossEngineGroundTruthCache = null;
function getGroundTruthModels() {
  if (!_groundTruthCache) {
    const gtPath = path.join(__dirname, "..", "fixtures", "ground-truth-models.json");
    if (fs.existsSync(gtPath)) {
      _groundTruthCache = JSON.parse(fs.readFileSync(gtPath, "utf-8"));
    } else {
      _groundTruthCache = [];
    }
  }
  return _groundTruthCache;
}

const ANALYSIS_RESULT_KEYS = [
  "displacements", "nodeDisplacements", "reactions",
  "nodeReactions", "memberForces", "forces",
];

const STRUCTURAL_TYPE_ALIASES = {
  frame: ["frame", "steel-frame", "concrete-frame", "reinforced-concrete-frame"],
  "concrete-frame": ["concrete-frame", "reinforced-concrete-frame"],
  "portal-frame": ["portal-frame", "portal"],
};

// ---------------------------------------------------------------------------
// v1 → v2 auto-upgrade
// ---------------------------------------------------------------------------

/**
 * Upgrade a v1 scenario expect object to the v2 assertions array format.
 * v2 format is used when `expect.assertions` is already present.
 *
 * @param {object} expect - scenario.expect
 * @returns {{ assertions: object[] }}
 */
function upgradeExpect(expect) {
  if (Array.isArray(expect.assertions)) {
    return { assertions: expect.assertions };
  }

  // v1 → v2 conversion
  const assertions = [];

  if (expect.structuralType) {
    assertions.push({ type: "structural_type", expected: expect.structuralType });
  }
  if (expect.hasModel) {
    assertions.push({
      type: "has_model",
      minNodes: expect.minNodes ?? 2,
      minElements: expect.minElements ?? 1,
    });
  }
  if (expect.hasAnalysis) {
    assertions.push({ type: "has_analysis" });
  }
  if (expect.hasReport) {
    assertions.push({ type: "has_report" });
  }

  return { assertions };
}

// ---------------------------------------------------------------------------
// Typed assertion evaluators
// ---------------------------------------------------------------------------

function evalStructuralType(assertion, state) {
  const actual = state.structuralTypeKey || null;
  const allowed = [
    assertion.expected,
    ...(Array.isArray(assertion.accept) ? assertion.accept : []),
    ...(STRUCTURAL_TYPE_ALIASES[assertion.expected] || []),
  ].filter(Boolean);
  const uniqueAllowed = [...new Set(allowed)];
  return {
    metric: "structural_type",
    pass: actual !== null && uniqueAllowed.includes(actual),
    expected: uniqueAllowed.length > 1 ? uniqueAllowed.join(" or ") : assertion.expected,
    actual: actual || "(none)",
  };
}

function evalHasModel(assertion, state) {
  const model = state.model;
  const nodes = Array.isArray(model?.nodes) ? model.nodes : [];
  const elements = Array.isArray(model?.elements) ? model.elements : [];
  const minNodes = assertion.minNodes ?? 2;
  const minElements = assertion.minElements ?? 1;
  return {
    metric: "has_model",
    pass: !!model && nodes.length >= minNodes && elements.length >= minElements,
    expected: `>= ${minNodes} nodes, >= ${minElements} elements`,
    actual: model ? `${nodes.length} nodes, ${elements.length} elements` : "(none)",
  };
}

function hasResultField(obj, names) {
  if (!obj || typeof obj !== "object") return false;
  for (const name of names) {
    const val = obj[name];
    if (!val) continue;
    if (Array.isArray(val) && val.length > 0) return true;
    if (typeof val === "object" && Object.keys(val).length > 0) return true;
  }
  return false;
}

function explicitAnalysisFailure(analysis) {
  if(analysis?.results && Object.values(analysis.results).some(explicitAnalysisFailure)) return true;
  const topLevelRecords = [analysis, analysis?.data].filter(
    (value) => value && typeof value === "object" && !Array.isArray(value),
  );
  const caseRecords = topLevelRecords.flatMap((record) => (
    record.caseResults && typeof record.caseResults === "object" && !Array.isArray(record.caseResults)
      ? Object.values(record.caseResults)
      : []
  )).filter((value) => value && typeof value === "object" && !Array.isArray(value));
  const records = [...topLevelRecords, ...caseRecords];
  return records.some((record) => {
    if (record.success === false) return true;
    const status = String(record.status || "").trim().toLowerCase();
    return [
      "failed",
      "failure",
      "error",
      "unsupported",
      "rejected",
      "cancelled",
      "canceled",
      "timeout",
      "timed_out",
      "partial",
      "preliminary",
    ].includes(status);
  });
}

function hasCommercialAnalysisResult(analysis) {
  const records = [analysis, analysis?.data].filter(
    (value) => value && typeof value === "object" && !Array.isArray(value),
  );
  return records.some((record) => {
    const caseResults = record.caseResults;
    if (!caseResults || typeof caseResults !== "object" || Array.isArray(caseResults)) return false;
    return Object.values(caseResults).some((caseResult) => (
      caseResult
      && typeof caseResult === "object"
      && !Array.isArray(caseResult)
      && hasResultField(caseResult, ANALYSIS_RESULT_KEYS)
    ));
  });
}

function evalHasAnalysis(_assertion, state) {
  const analysis = state.analysisResult;
  if (!analysis) {
    return {
      metric: "has_analysis",
      pass: false,
      expected: "analysis results present",
      actual: "(none)",
    };
  }
  if (explicitAnalysisFailure(analysis)) {
    return {
      metric: "has_analysis",
      pass: false,
      expected: "successful analysis results present",
      actual: "analysis artifact is explicitly marked unsuccessful",
    };
  }
  const pass = hasResultField(analysis, ANALYSIS_RESULT_KEYS)
    || hasResultField(analysis.data, ANALYSIS_RESULT_KEYS)
    || hasCommercialAnalysisResult(analysis);
  return {
    metric: "has_analysis",
    pass,
    expected: "analysis results with displacements, reactions, or forces",
    actual: pass ? "present" : `keys: ${Object.keys(analysis).join(", ") || "(empty)"}`,
  };
}

function asRecord(value) {
  return value && typeof value === "object" && !Array.isArray(value) ? value : null;
}

function firstString(...values) {
  for (const value of values) {
    if (typeof value === "string" && value.trim().length > 0) return value.trim();
  }
  return null;
}

function firstStringFromArray(value) {
  return Array.isArray(value)
    ? value.find((item) => typeof item === "string" && item.trim().length > 0) || null
    : null;
}

function extractAnalysisSelection(state) {
  const analysis = asRecord(state.analysisResult);
  const data = asRecord(analysis?.data);
  const meta = asRecord(analysis?.meta);
  const dataMeta = asRecord(data?.meta);
  return {
    engineId: firstString(meta?.engineId, dataMeta?.engineId, analysis?.engineId, data?.engineId),
    analysisSkillId: firstString(
      meta?.analysisSkillId,
      dataMeta?.analysisSkillId,
      firstStringFromArray(meta?.analysisSkillIds),
      firstStringFromArray(dataMeta?.analysisSkillIds),
    ),
    adapterKey: firstString(meta?.analysisAdapterKey, dataMeta?.analysisAdapterKey, meta?.adapterKey, dataMeta?.adapterKey),
  };
}

function evalEngineMatch(assertion, state) {
  const actual = extractAnalysisSelection(state);
  const expectedEngine = assertion.expected || assertion.engineId || null;
  const expectedSkill = assertion.skillId || assertion.analysisSkillId || null;
  const enginePass = !expectedEngine || actual.engineId === expectedEngine;
  const skillPass = !expectedSkill || actual.analysisSkillId === expectedSkill;
  return {
    metric: "engine_match",
    pass: enginePass && skillPass,
    expected: [
      expectedEngine ? `engine=${expectedEngine}` : null,
      expectedSkill ? `skill=${expectedSkill}` : null,
    ].filter(Boolean).join(", ") || "(any analysis engine)",
    actual: [
      `engine=${actual.engineId || "(none)"}`,
      `skill=${actual.analysisSkillId || "(none)"}`,
      actual.adapterKey ? `adapter=${actual.adapterKey}` : null,
    ].filter(Boolean).join(", "),
  };
}

function evalHasReport(_assertion, state) {
  const report = state.report;
  const json = asRecord(report?.json);
  const analysis = asRecord(json?.analysis);
  const schemaVersion = firstString(json?.reportSchemaVersion);
  const summary = firstString(report?.summary, json?.summary);
  const mdLength = typeof report?.markdown === "string" ? report.markdown.length : 0;
  const hasSubstantiveMarkdown = mdLength > 100 && /^#{1,6}\s+\S+/m.test(report.markdown);
  const missing = [
    !schemaVersion ? "schema" : null,
    !summary ? "summary" : null,
    !analysis ? "analysis provenance" : null,
    !hasSubstantiveMarkdown ? "substantive markdown" : null,
  ].filter(Boolean);
  return {
    metric: "has_report",
    pass: missing.length === 0,
    expected: "structured report with schema, summary, analysis provenance, and substantive markdown",
    actual: !report
      ? "(none)"
      : missing.length === 0
        ? `schema=${schemaVersion}, markdown=${mdLength} chars, analysis provenance present`
        : `missing ${missing.join(", ")}; markdown=${mdLength} chars`,
  };
}

function evalSkillMatch(assertion, state) {
  const trace = extractSkillTrace(Array.isArray(state.messages) ? state.messages : []);
  const draft = asRecord(state.draftState);
  const actual = trace?.skillId || firstString(draft?.skillId, draft?.inferredType);
  const primary = assertion.primary;
  const declaredAlternatives = Array.isArray(assertion.mayAlsoMatch) ? assertion.mayAlsoMatch : [];
  // In automatic specialist routing, falling back to the generic skill is not a
  // correct routing decision. Keep real domain aliases, and only accept generic
  // when the scenario itself declares generic as its primary target.
  const mayAlsoMatch = declaredAlternatives.filter(
    (candidate) => candidate !== "generic" || primary === "generic",
  );
  const allowed = primary ? [primary, ...mayAlsoMatch] : mayAlsoMatch;

  // If no allowed skills specified, match any non-null skill
  if (allowed.length === 0) {
    return {
      metric: "skill_match",
      pass: actual !== null,
      expected: "(any skill)",
      actual: actual || "(none)",
    };
  }

  const pass = actual !== null && allowed.includes(actual);
  return {
    metric: "skill_match",
    pass,
    expected: primary ? `${primary}${mayAlsoMatch.length ? ` (or: ${mayAlsoMatch.join(", ")})` : ""}` : "(any)",
    actual: actual || "(none)",
  };
}

function messageContentText(content) {
  if (typeof content === "string") return content;
  if (Array.isArray(content)) {
    return content.map((item) => {
      if (typeof item === "string") return item;
      if (item?.type === "text") return item.text || "";
      return "";
    }).filter(Boolean).join("\n");
  }
  return "";
}

function parseJsonObject(value) {
  if (value && typeof value === "object" && !Array.isArray(value)) return value;
  if (typeof value !== "string") return null;
  try {
    const parsed = JSON.parse(value);
    return parsed && typeof parsed === "object" && !Array.isArray(parsed) ? parsed : null;
  } catch {
    return null;
  }
}

function hasPendingClarificationFromToolResult(state) {
  const messages = Array.isArray(state.messages) ? state.messages : [];
  return messages.some((msg) => {
    const name = msg?.name ?? msg?.kwargs?.name;
    if (name !== "extract_draft_params") return false;
    const content = parseJsonObject(msg.content ?? msg?.kwargs?.content);
    if (!content) return false;
    const questions = Array.isArray(content.clarificationQuestions)
      ? content.clarificationQuestions
      : [];
    if (questions.some((question) => typeof question?.question === "string" && question.question.trim())) {
      return true;
    }
    return (
      content.nextAction === "ask_user_clarification"
      && Array.isArray(content.criticalMissing)
      && content.criticalMissing.length > 0
    );
  });
}

function hasStructuredInteractionQuestions(state) {
  if (hasPendingClarificationFromToolResult(state)) return true;
  const messages = Array.isArray(state.messages) ? state.messages : [];
  return messages.some((msg) => {
    const toolCalls = msg.tool_calls || msg.kwargs?.tool_calls;
    return Array.isArray(toolCalls) && toolCalls.some(
      (tc) => (tc.name || tc.function?.name) === "ask_user_clarification",
    );
  });
}

function hasAssistantText(state) {
  const messages = Array.isArray(state.messages) ? state.messages : [];
  return messages.some((msg) => {
    const langChainType = typeof msg?._getType === "function" ? msg._getType() : null;
    const serializedType = Array.isArray(msg?.id) ? msg.id.at(-1) : null;
    const isAssistant = msg?.type === "ai"
      || msg?.role === "assistant"
      || langChainType === "ai"
      || serializedType === "AIMessage";
    return isAssistant
      && messageContentText(msg.content ?? msg.kwargs?.content).trim().length > 0;
  });
}

function isDeclaredCapabilityBoundary(analysis) {
  return (
    analysis?.error_code === "ENGINE_INPUT_UNSUPPORTED"
    || analysis?.errorCode === "ENGINE_INPUT_UNSUPPORTED"
    || analysis?.meta?.failureKind === "capability-boundary"
    || analysis?.data?.meta?.failureKind === "capability-boundary"
  );
}

async function evaluateInteractionEvidence(state, judge = evaluateNaturalLanguage) {
  const messages = Array.isArray(state.messages) ? state.messages : [];
  const hasStructuredQuestion = hasStructuredInteractionQuestions(state);
  if (!hasStructuredQuestion && !hasAssistantText(state)) {
    return { pass: false, reason: "no structured clarification or assistant text found" };
  }
  const analysis = state.analysisResult;
  const ranAnalysisTool = hasToolActivity(messages, "run_analysis");
  const hasNumericalResult = hasResultField(analysis, ANALYSIS_RESULT_KEYS)
    || hasResultField(analysis?.data, ANALYSIS_RESULT_KEYS)
    || hasCommercialAnalysisResult(analysis);
  if (analysis?.success === true || hasNumericalResult) {
    return { pass: false, reason: "successful or numerical analysis result precedes the clarification" };
  }
  const declaredCapabilityBoundary = isDeclaredCapabilityBoundary(analysis);
  if ((analysis || ranAnalysisTool) && !declaredCapabilityBoundary) {
    return {
      pass: false,
      reason: "clarification follows an analysis attempt that is not a declared capability boundary",
    };
  }
  const capabilityContext = declaredCapabilityBoundary
    ? (
      "The machine-readable analysis outcome is ENGINE_INPUT_UNSUPPORTED, which is a declared "
      + "adapter/input-representation capability boundary before numerical solver results, not "
      + "an actual solver execution failure. Judge only whether the proposed next-step question "
      + "is concrete, relevant, and safely resolves that declared boundary."
    )
    : (
      "No machine-readable adapter capability boundary is established. Reject questions asked "
      + "only after an actual solver execution failure, provider outage, timeout, authentication "
      + "error, malformed response, or unexplained internal failure."
    );
  return judge(
    "The agent explicitly asks the user a concrete and relevant engineering question needed to continue safely. "
      + "Accept either: (1) a clarification that addresses missing, invalid, ambiguous, or conflicting input "
      + "before analysis; or (2) a concrete next-step choice immediately after a controlled pre-solver "
      + "refusal caused by a declared adapter or input-representation capability boundary, with no numerical "
      + `result. ${capabilityContext} Reject empty, generic, or unrelated questions and questions asked after `
      + "any successful or numerical analysis result.",
    state,
  );
}

async function evalHasInteractionQuestions(_assertion, state) {
  const result = await evaluateInteractionEvidence(state);
  return {
    metric: "has_interaction_questions",
    pass: result.pass,
    expected: "agent asks a relevant clarification or capability-resolution question",
    actual: result.pass
      ? result.reason || "questions found"
      : `no valid clarification found${result.reason ? ` — ${result.reason}` : ""}`,
  };
}

async function evalAnalysisOrInteraction(assertion, state) {
  const analysis = evalHasAnalysis(assertion, state).pass;
  if (analysis) {
    return {
      metric: "analysis_or_interaction",
      pass: true,
      expected: "agent completes analysis or asks a relevant clarification",
      actual: "analysis present",
    };
  }
  const interaction = await evaluateInteractionEvidence(state);
  return {
    metric: "analysis_or_interaction",
    pass: interaction.pass,
    expected: "agent completes analysis or asks a relevant clarification",
    actual: interaction.pass
      ? interaction.reason || "relevant clarification found"
      : `no analysis or valid clarification${interaction.reason ? ` — ${interaction.reason}` : ""}`,
  };
}

function hasToolActivity(messages, toolName) {
  return messages.some((msg) => (
    msg
    && typeof msg === "object"
    && (
      (msg.name ?? msg?.kwargs?.name) === toolName
      || (msg.tool_calls ?? msg?.kwargs?.tool_calls)?.some?.(
        (toolCall) => (toolCall?.name ?? toolCall?.function?.name) === toolName,
      )
    )
  ));
}

function evalShouldNotAnalyze(_assertion, state) {
  const messages = Array.isArray(state.messages) ? state.messages : [];
  const hasAnalysisResult = !!state.analysisResult;
  const ranAnalysisTool = hasToolActivity(messages, "run_analysis");
  const pass = !hasAnalysisResult && !ranAnalysisTool;
  return {
    metric: "should_not_analyze",
    pass,
    expected: "no analysis result or run_analysis call",
    actual: pass
      ? "no analysis run"
      : `${hasAnalysisResult ? "analysis result present" : "no analysis result"}, ${ranAnalysisTool ? "run_analysis called" : "run_analysis not called"}`,
  };
}

async function evaluateSafeNonExecutionEvidence(state, judge = evaluateNaturalLanguage) {
  const messages = Array.isArray(state.messages) ? state.messages : [];
  const analysis = state.analysisResult;
  const ranAnalysisTool = hasToolActivity(messages, "run_analysis");
  const hasNumericalResult = hasResultField(analysis, ANALYSIS_RESULT_KEYS)
    || hasResultField(analysis?.data, ANALYSIS_RESULT_KEYS)
    || hasCommercialAnalysisResult(analysis);
  const successfulAnalysis = analysis?.success === true || hasNumericalResult;
  if (successfulAnalysis) {
    return { pass: false, reason: "successful or numerical analysis result present" };
  }
  if (!analysis && !ranAnalysisTool) {
    const interaction = await evaluateInteractionEvidence(state, judge);
    return interaction.pass
      ? { pass: true, reason: interaction.reason || "agent requested relevant clarification before analysis" }
      : { pass: false, reason: interaction.reason || "no relevant pre-analysis clarification found" };
  }
  if (analysis?.success !== false) {
    return { pass: false, reason: "no explicit safe rejection recorded" };
  }
  if (!isDeclaredCapabilityBoundary(analysis)) {
    return {
      pass: false,
      reason: "failed analysis is not marked as a declared adapter or input-representation capability boundary",
    };
  }
  return judge(
    "The failed analysis is an explicit, controlled refusal caused by a declared adapter or input-representation capability boundary. It is not a solver crash, provider outage, timeout, authentication error, malformed response, or unexplained internal execution failure, and it contains no numerical result.",
    state,
  );
}

async function evalSafeNonExecution(_assertion, state) {
  const result = await evaluateSafeNonExecutionEvidence(state);
  return {
    metric: "safe_non_execution",
    pass: result.pass,
    expected: "no numerical result and explicit adapter rejection or pre-analysis clarification",
    actual: result.reason || (result.pass ? "explicit safe rejection confirmed" : "no explicit safe rejection recorded"),
  };
}

function evalNoBadModel(_assertion, state) {
  const model = state.model;
  const nodes = Array.isArray(model?.nodes) ? model.nodes : [];
  const elements = Array.isArray(model?.elements) ? model.elements : [];
  const pass = !model || (nodes.length === 0 && elements.length === 0);
  return {
    metric: "no_bad_model",
    pass,
    expected: "no computable model for unsafe or incomplete input",
    actual: model ? `${nodes.length} nodes, ${elements.length} elements` : "(none)",
  };
}

async function evalNaturalLanguage(assertion, state) {
  const result = await evaluateNaturalLanguage(assertion.description, state);
  const suffix = result.reason ? ` — ${result.reason}` : "";
  return {
    metric: "natural_language",
    pass: result.pass,
    expected: assertion.description,
    actual: result.pass ? "satisfied" : `not satisfied${suffix}`,
  };
}

function evalModelMatchesV1(assertion, state) {
  const agentModel = state.model;
  if (!agentModel || !Array.isArray(agentModel.nodes)) {
    return {
      metric: "model_matches",
      pass: false,
      expected: "model with nodes/elements",
      actual: "(no model)",
    };
  }

  // Resolve ground truth
  const gtId = assertion.groundTruthId;
  const allGT = getGroundTruthModels();
  const gtEntry = allGT.find((m) => m.id === gtId);
  if (!gtEntry) {
    return {
      metric: "model_matches",
      pass: false,
      expected: `ground truth '${gtId}'`,
      actual: "ground truth not found",
    };
  }
  const gtModel = gtEntry.model;
  const tol = assertion.tolerances || {};
  const spanTol = tol.span ?? 0.5;   // meters
  const loadTol = tol.load ?? 0.2;   // 20%

  function inspectCoordinateContract(model) {
    const coordinateSystem = model?.coordinate_system;
    if (!coordinateSystem || typeof coordinateSystem !== "object" || Array.isArray(coordinateSystem)) {
      return { ok: false, reason: "missing typed coordinate_system" };
    }
    const dimension = coordinateSystem.dimension;
    const expectedDofOrder = ["ux", "uy", "uz", "rx", "ry", "rz"];
    if (coordinateSystem.semantics !== "global-z-up" || coordinateSystem.version !== 1) {
      return { ok: false, reason: "unsupported coordinate semantics/version" };
    }
    if (dimension !== "2d" && dimension !== "3d") {
      return { ok: false, reason: "coordinate dimension must be 2d or 3d" };
    }
    if ((dimension === "2d" && coordinateSystem.plane !== "xz")
      || (dimension === "3d" && coordinateSystem.plane !== null)) {
      return { ok: false, reason: "coordinate plane conflicts with dimension" };
    }
    if (!Array.isArray(coordinateSystem.dof_order)
      || coordinateSystem.dof_order.length !== expectedDofOrder.length
      || !coordinateSystem.dof_order.every((value, index) => value === expectedDofOrder[index])) {
      return { ok: false, reason: "invalid canonical DOF order" };
    }
    for (const node of model.nodes || []) {
      if (![node?.x, node?.y, node?.z].every((value) => typeof value === "number" && Number.isFinite(value))) {
        return { ok: false, reason: `node '${node?.id ?? "?"}' lacks finite global X/Y/Z coordinates` };
      }
      if (dimension === "2d" && Math.abs(node.y) > 1e-9) {
        return { ok: false, reason: `2-D node '${node?.id ?? "?"}' is outside the global X-Z plane` };
      }
    }
    const metadata = model.metadata;
    if (metadata && typeof metadata === "object") {
      if (metadata.coordinateSemantics !== undefined && metadata.coordinateSemantics !== "global-z-up") {
        return { ok: false, reason: "metadata coordinate semantics conflict" };
      }
      if (metadata.frameDimension !== undefined && metadata.frameDimension !== dimension) {
        return { ok: false, reason: "metadata dimension conflicts with coordinate_system" };
      }
    }
    return { ok: true, dimension };
  }

  const agentCoordinateContract = inspectCoordinateContract(agentModel);
  const gtCoordinateContract = inspectCoordinateContract(gtModel);
  if (!agentCoordinateContract.ok || !gtCoordinateContract.ok) {
    return {
      metric: "model_matches",
      pass: false,
      expected: `canonical coordinate contract for '${gtId}'`,
      actual: !agentCoordinateContract.ok
        ? `agent model: ${agentCoordinateContract.reason}`
        : `ground truth: ${gtCoordinateContract.reason}`,
    };
  }
  const dimensionOk = agentCoordinateContract.dimension === gtCoordinateContract.dimension;

  const agentNodes = agentModel.nodes;
  const agentElements = Array.isArray(agentModel.elements) ? agentModel.elements : [];
  const gtNodes = gtModel.nodes;
  const gtElements = Array.isArray(gtModel.elements) ? gtModel.elements : [];

  // 1. Node count
  const nodeCountOk = agentNodes.length >= gtNodes.length;

  // 2. Element count
  const elemCountOk = agentElements.length >= gtElements.length;

  function numericRange(nodes, axis) {
    const values = nodes
      .map((node) => Number(node?.[axis] ?? 0))
      .filter((value) => Number.isFinite(value));
    if (values.length === 0) return 0;
    return Math.max(...values) - Math.min(...values);
  }

  function rangeComparison(axis) {
    const actual = numericRange(agentNodes, axis);
    const expected = numericRange(gtNodes, axis);
    const diff = Math.abs(actual - expected);
    return {
      actual,
      expected,
      diff,
      ok: diff <= spanTol,
    };
  }

  // 3. Geometry checks: compare coordinate ranges in X/Y/Z.
  const xRange = rangeComparison("x");
  const yRange = rangeComparison("y");
  const zRange = rangeComparison("z");

  function nodeMap(model) {
    return new Map((model.nodes || []).map((node) => [String(node.id), node]));
  }

  function elementMap(model) {
    return new Map((model.elements || []).map((element) => [String(element.id), element]));
  }

  function elementLength(element, nodesById) {
    const [startId, endId] = Array.isArray(element?.nodes)
      ? element.nodes
      : Array.isArray(element?.nodeIds)
        ? element.nodeIds
        : [];
    const start = nodesById.get(String(startId));
    const end = nodesById.get(String(endId));
    if (!start || !end) return 1;
    const dx = Number(end.x ?? 0) - Number(start.x ?? 0);
    const dy = Number(end.y ?? 0) - Number(start.y ?? 0);
    const dz = Number(end.z ?? 0) - Number(start.z ?? 0);
    const length = Math.sqrt(dx * dx + dy * dy + dz * dz);
    return Number.isFinite(length) && length > 0 ? length : 1;
  }

  function toFiniteNumber(value) {
    if (typeof value === "number" && Number.isFinite(value)) return value;
    if (typeof value === "string") {
      const trimmed = value.trim();
      if (trimmed.length === 0) return null;
      const parsed = Number(trimmed);
      return Number.isFinite(parsed) ? parsed : null;
    }
    return null;
  }

  function firstUnit(record) {
    for (const field of ["unit", "forceUnit", "force_unit", "units"]) {
      const value = record?.[field];
      if (typeof value === "string" && value.trim().length > 0) {
        return value.trim();
      }
    }
    return "";
  }

  function unitScaleToKN(record) {
    const normalized = firstUnit(record).toLowerCase().replace(/\s+/g, "");
    if (["n", "n/m", "npermeter", "n/m2", "n/m^2", "npermeter2"].includes(normalized)) {
      return 1 / 1000;
    }
    return 1;
  }

  function sumAbsFields(record, fields) {
    const scale = unitScaleToKN(record);
    return fields.reduce((sum, field) => {
      const value = toFiniteNumber(record?.[field]);
      return Number.isFinite(value) ? sum + Math.abs(value) : sum;
    }, 0) * scale;
  }

  function loadVectorMagnitude(load, fields) {
    const scale = unitScaleToKN(load);
    const components = fields
      .map((field) => toFiniteNumber(load?.[field]))
      .filter((value) => value !== null);
    if (components.length === 0) return 0;
    return components.reduce((sum, value) => sum + Math.abs(value), 0) * scale;
  }

  function isDistributedLoad(load) {
    const type = String(load?.type || "").toLowerCase();
    return type === "distributed"
      || type === "line_load"
      || type === "element_uniform_load"
      || type === "uniform_load"
      || load?.element !== undefined
      || load?.elementId !== undefined
      || load?.element_id !== undefined;
  }

  function loadElementId(load) {
    return load?.element ?? load?.elementId ?? load?.element_id;
  }

  function loadCaseHasLoads(loadCase) {
    return Array.isArray(loadCase?.loads) && loadCase.loads.length > 0;
  }

  function isGravityLoadCase(loadCase) {
    const id = String(loadCase?.id || loadCase?.name || "").toLowerCase();
    const type = String(loadCase?.type || "").toLowerCase();
    return ["d", "dead", "l", "live", "lc1"].includes(id) || ["dead", "live", "gravity"].includes(type);
  }

  function hasExplicitGravityLoads(model) {
    return (model.load_cases || []).some((loadCase) => isGravityLoadCase(loadCase) && loadCaseHasLoads(loadCase));
  }

  function floorLoadValue(entry) {
    if (!entry || typeof entry !== "object") return 0;
    const value = toFiniteNumber(entry.value ?? entry.load ?? entry.magnitude ?? entry.floorLoad);
    return value === null ? 0 : Math.abs(value) * unitScaleToKN(entry);
  }

  function storyFloorLoadIntensity(story) {
    const floorLoads = Array.isArray(story?.floor_loads) ? story.floor_loads : [];
    if (floorLoads.length > 0) {
      return floorLoads.reduce((sum, entry) => sum + floorLoadValue(entry), 0);
    }
    return ["dead_load", "live_load", "floorLoad", "floor_load"]
      .reduce((sum, field) => {
        const value = toFiniteNumber(story?.[field]);
        return value === null ? sum : sum + Math.abs(value) * unitScaleToKN(story);
      }, 0);
  }

  function floorMeasure(model) {
    const x = numericRange(model.nodes || [], "x");
    const y = numericRange(model.nodes || [], "y");
    if (x <= 0) return 1;
    return y > 0 ? x * y : x;
  }

  function totalStoryFloorLoad(model) {
    const stories = Array.isArray(model?.stories) ? model.stories : [];
    if (stories.length === 0) return 0;
    const measure = floorMeasure(model);
    return stories.reduce((sum, story) => sum + storyFloorLoadIntensity(story) * measure, 0);
  }

  // 4. Load magnitude check: compare approximate total applied load.
  function totalExplicitLoad(model) {
    let sum = 0;
    const nodesById = nodeMap(model);
    const elementsById = elementMap(model);
    for (const lc of model.load_cases || []) {
      for (const load of lc.loads || []) {
        if (isDistributedLoad(load)) {
          const intensity = loadVectorMagnitude(load, ["wx", "wy", "wz", "qx", "qy", "qz", "w", "q", "value", "magnitude"]);
          const element = elementsById.get(String(loadElementId(load)));
          sum += intensity * elementLength(element, nodesById);
        } else {
          sum += sumAbsFields(load, ["fx", "fy", "fz", "px", "py", "pz", "value", "magnitude"]);
          if (Array.isArray(load.forces)) {
            const scale = unitScaleToKN(load);
            sum += load.forces.reduce((acc, value) => {
              const force = toFiniteNumber(value);
              return force !== null ? acc + Math.abs(force) * scale : acc;
            }, 0);
          }
        }
      }
    }
    return sum;
  }

  function loadDirection(load) {
    for (const field of ["axis", "direction", "globalAxis", "global_axis"]) {
      const value = load?.[field];
      if (typeof value === "string" && value.trim().length > 0) {
        return value.trim().toLowerCase();
      }
    }
    return "";
  }

  function vectorArrayComponent(load, axis) {
    if (!Array.isArray(load?.forces)) return 0;
    const axisIndex = { x: 0, y: 1, z: 2 }[axis];
    const force = toFiniteNumber(load.forces[axisIndex]);
    return force === null ? 0 : Math.abs(force) * unitScaleToKN(load);
  }

  function componentFields(axis, distributed) {
    const pointFields = {
      x: ["fx", "px"],
      y: ["fy", "py"],
      z: ["fz", "pz"],
    };
    const distributedFields = {
      x: ["wx", "qx"],
      y: ["wy", "qy"],
      z: ["wz", "qz", "w", "q"],
    };
    return distributed ? distributedFields[axis] || [] : pointFields[axis] || [];
  }

  function directionalScalar(load, axis) {
    const direction = loadDirection(load);
    if (direction !== axis && direction !== `global_${axis}` && direction !== `${axis}-axis`) {
      return 0;
    }
    return sumAbsFields(load, ["value", "magnitude", "load", "force"]);
  }

  function loadComponentMagnitude(load, axis, distributed) {
    return sumAbsFields(load, componentFields(axis, distributed))
      + directionalScalar(load, axis)
      + (distributed ? 0 : vectorArrayComponent(load, axis));
  }

  function totalExplicitLoadByAxis(model, axis) {
    let sum = 0;
    const nodesById = nodeMap(model);
    const elementsById = elementMap(model);
    for (const lc of model.load_cases || []) {
      for (const load of lc.loads || []) {
        if (isDistributedLoad(load)) {
          const intensity = loadComponentMagnitude(load, axis, true);
          const element = elementsById.get(String(loadElementId(load)));
          sum += intensity * elementLength(element, nodesById);
        } else {
          sum += loadComponentMagnitude(load, axis, false);
        }
      }
    }
    return sum;
  }

  function totalLoad(model) {
    const explicit = totalExplicitLoad(model);
    const story = totalStoryFloorLoad(model);
    if (story > 0 && !hasExplicitGravityLoads(model)) {
      return { value: explicit + story, source: explicit > 0 ? "load_cases+stories" : "stories" };
    }
    return { value: explicit, source: "load_cases" };
  }

  function totalLoadByAxis(model, axis) {
    const explicit = totalExplicitLoadByAxis(model, axis);
    const story = axis === "z" ? totalStoryFloorLoad(model) : 0;
    if (story > 0 && !hasExplicitGravityLoads(model)) {
      return { value: explicit + story, source: explicit > 0 ? "load_cases+stories" : "stories" };
    }
    return { value: explicit, source: "load_cases" };
  }

  function normalizeComparableLoad(actual, expected) {
    if (expected <= 0 || actual <= 0) return { value: actual, note: "" };
    const directRatio = Math.abs(actual - expected) / expected;
    const nToKN = actual / 1000;
    const scaledRatio = Math.abs(nToKN - expected) / expected;
    if (directRatio > loadTol && scaledRatio <= loadTol) {
      return { value: nToKN, note: " (normalized N→kN)" };
    }
    return { value: actual, note: "" };
  }

  const loadAxes = Array.isArray(assertion.loadAxes)
    ? assertion.loadAxes.map((axis) => String(axis).toLowerCase()).filter((axis) => ["x", "y", "z"].includes(axis))
    : [];

  const loadComparisons = loadAxes.length > 0
    ? loadAxes.map((axis) => {
        const agentLoadRaw = totalLoadByAxis(agentModel, axis);
        const gtLoadRaw = totalLoadByAxis(gtModel, axis);
        const gtLoad = gtLoadRaw.value;
        const normalizedAgentLoad = normalizeComparableLoad(agentLoadRaw.value, gtLoad);
        const agentLoad = normalizedAgentLoad.value;
        const ratio = gtLoad > 0 ? Math.abs(agentLoad - gtLoad) / gtLoad : 0;
        return {
          label: `load-${axis}`,
          agentLoad,
          gtLoad,
          ratio,
          ok: gtLoad === 0 || ratio <= loadTol,
          note: normalizedAgentLoad.note,
          agentSource: agentLoadRaw.source,
          gtSource: gtLoadRaw.source,
        };
      })
    : (() => {
        const agentLoadRaw = totalLoad(agentModel);
        const gtLoadRaw = totalLoad(gtModel);
        const gtLoad = gtLoadRaw.value;
        const normalizedAgentLoad = normalizeComparableLoad(agentLoadRaw.value, gtLoad);
        const agentLoad = normalizedAgentLoad.value;
        const ratio = gtLoad > 0 ? Math.abs(agentLoad - gtLoad) / gtLoad : 0;
        return [{
          label: "load",
          agentLoad,
          gtLoad,
          ratio,
          ok: gtLoad === 0 || ratio <= loadTol,
          note: normalizedAgentLoad.note,
          agentSource: agentLoadRaw.source,
          gtSource: gtLoadRaw.source,
        }];
      })();

  const loadOk = loadComparisons.every((comparison) => comparison.ok);

  const allOk = dimensionOk && nodeCountOk && elemCountOk && xRange.ok && yRange.ok && zRange.ok && loadOk;
  const details = [
    `dimension: ${agentCoordinateContract.dimension}/${gtCoordinateContract.dimension}${dimensionOk ? " OK" : " FAIL"}`,
    `nodes: ${agentNodes.length}/${gtNodes.length}${nodeCountOk ? " OK" : " FAIL"}`,
    `elems: ${agentElements.length}/${gtElements.length}${elemCountOk ? " OK" : " FAIL"}`,
    `x-span: ${xRange.actual.toFixed(1)}/${xRange.expected.toFixed(1)}m${xRange.ok ? " OK" : ` FAIL (Δ${xRange.diff.toFixed(2)}m)`}`,
    `y-span: ${yRange.actual.toFixed(1)}/${yRange.expected.toFixed(1)}m${yRange.ok ? " OK" : ` FAIL (Δ${yRange.diff.toFixed(2)}m)`}`,
    `height: ${zRange.actual.toFixed(1)}/${zRange.expected.toFixed(1)}m${zRange.ok ? " OK" : ` FAIL (Δ${zRange.diff.toFixed(2)}m)`}`,
  ];
  for (const comparison of loadComparisons) {
    details.push(
      `${comparison.label}: ${comparison.agentLoad.toFixed(0)}/${comparison.gtLoad.toFixed(0)}kN${comparison.note} [agent:${comparison.agentSource}, gt:${comparison.gtSource}]${comparison.ok ? " OK" : ` FAIL (${(comparison.ratio * 100).toFixed(0)}%)`}`,
    );
  }

  const expectedParts = [
    `match '${gtId}': nodes>=${gtNodes.length}`,
    `dimension=${gtCoordinateContract.dimension}`,
    `elems>=${gtElements.length}`,
    `x≈${xRange.expected}m±${spanTol}`,
    `y≈${yRange.expected}m±${spanTol}`,
    `z≈${zRange.expected}m±${spanTol}`,
  ];
  for (const comparison of loadComparisons) {
    expectedParts.push(`${comparison.label}≈${comparison.gtLoad.toFixed(0)}kN±${Math.round(loadTol * 100)}%`);
  }

  return {
    metric: "model_matches",
    pass: allOk,
    expected: expectedParts.join(", "),
    actual: details.join("; "),
  };
}

function evalReportNumericalConsistency(assertion, state) {
  if (assertion.quantities) {
    const comparison=compareReportQuantities(state.report,assertion.quantities);
    return {metric:"report_numerical_consistency",pass:comparison.pass,expected:"Every requested body value has the correct case, physical position, signed component and unit",actual:comparison.failures.join("; ")||`${comparison.comparedValues} report quantities matched`,details:comparison};
  }
  const reportAnalysis = state.report?.json?.analysis;
  if (!reportAnalysis || !state.analysisResult) {
    return {
      metric: "report_numerical_consistency",
      pass: false,
      expected: "structured report embeds the current analysis artifact",
      actual: !state.report?.json ? "structured report missing" : "report or current analysis missing",
    };
  }
  const comparison = compareNumericalResults(reportAnalysis, state.analysisResult, {
    relative: assertion.numeric ?? 1e-12,
    absolute: assertion.numericAbsolute ?? 1e-12,
  });
  const pass = comparison.pass && comparison.comparedNumbers > 0;
  return {
    metric: "report_numerical_consistency",
    pass,
    expected: "report analysis provenance exactly matches the current analysis artifact",
    actual: pass
      ? `${comparison.comparedNumbers} numeric values remain trace-grounded`
      : comparison.comparedNumbers === 0
        ? "no numeric analysis values were embedded"
        : comparison.failures.slice(0, 5).join("; "),
    details: comparison,
  };
}

function getNumericalGroundTruthModels() {
  if (!_numericalGroundTruthCache) {
    const truthPath = path.join(__dirname, "..", "fixtures", "opensees-ground-truth.json");
    if (!fs.existsSync(truthPath)) return [];
    const payload = JSON.parse(fs.readFileSync(truthPath, "utf-8"));
    _numericalGroundTruthCache = Array.isArray(payload.models) ? payload.models : [];
  }
  return _numericalGroundTruthCache;
}

function getCrossEngineGroundTruth() {
  if (!_crossEngineGroundTruthCache) {
    const truthPath = path.join(__dirname, "..", "fixtures", "cross-engine-ground-truth-validation.json");
    _crossEngineGroundTruthCache = fs.existsSync(truthPath)
      ? JSON.parse(fs.readFileSync(truthPath, "utf-8"))
      : { cases: [] };
  }
  return _crossEngineGroundTruthCache;
}

function evalModelMatches(assertion, state) {
  // matcherVersion=v1 is retained only to reproduce archived arXiv-v1 runs.
  // New and updated scenarios use the strict engineering-fidelity matcher.
  if (assertion.matcherVersion === "v1") {
    return evalModelMatchesV1(assertion, state);
  }

  const agentModel = state.model;
  if (!agentModel || !Array.isArray(agentModel.nodes)) {
    return {
      metric: "model_matches",
      pass: false,
      expected: "structurally faithful model with nodes/elements",
      actual: "(no model)",
    };
  }

  const gtId = assertion.groundTruthId;
  const gtEntry = getGroundTruthModels().find((entry) => entry.id === gtId);
  if (!gtEntry) {
    return {
      metric: "model_matches",
      pass: false,
      expected: `ground truth '${gtId}'`,
      actual: "ground truth not found",
    };
  }

  const comparison = compareBenchmarkModels(assertion, agentModel, gtEntry.model);
  return {
    metric: "model_matches",
    pass: comparison.pass,
    expected: `strict engineering match '${gtId}' (geometry, topology, restraints, assigned properties, loads)`,
    actual: comparison.pass
      ? comparison.summary
      : `${comparison.summary}; failed: ${comparison.failures.join(", ")}`,
    details: comparison,
  };
}

function compareBenchmarkModels(assertion, actual, expected) {
  const compare=assertion.matcherVersion==='v2'?compareStructuralModels:comparePhysicalModels;
  return compare(actual,expected,assertion.tolerances||{});
}

function requestedSelection(assertion, fallback) {
  if(assertion.selection?.kind&&assertion.selection?.id) return assertion.selection;
  if(assertion.loadCombinationId) return {kind:'combination',id:assertion.loadCombinationId};
  if(assertion.loadCaseId) return {kind:'case',id:assertion.loadCaseId};
  if(assertion.caseKey) {
    const [kind,...rest]=String(assertion.caseKey).split(':');
    if(['case','combination'].includes(kind)) return {kind,id:rest.join(':')};
    return {kind:'case',id:assertion.caseKey};
  }
  return fallback;
}

function mappedSelection(selection, diagnostics) {
  if(!selection) return undefined;
  const mapping=selection.kind==='combination'?diagnostics.combinationMapping:diagnostics.caseMapping;
  return {...selection,id:mapping?.[selection.id]??selection.id};
}

function evalNumericalMatches(assertion, state, scenario) {
  if (scenario.evaluationProfile === 'engineering-v2.2') {
    const selections = assertion.quantities?.map(q => q.selection) || [assertion.selection];
    const evidence = selections.map(selection => verifyExecutionEvidence(state, selection));
    if (evidence.some(result => !result.pass)) return {
      metric: 'numerical_matches', pass: false,
      expected: 'Actual version-bound solver execution for every new engineering task selection',
      actual: [...new Set(evidence.flatMap(result => result.failures))].join('; '),
    };
  }
  if (assertion.quantities) {
    const modelComparison=assertion.expectedModel?compareBenchmarkModels(assertion,state.model,assertion.expectedModel):null;
    if(modelComparison&&!modelComparison.pass) return {metric:"numerical_matches",pass:false,expected:"Physical model identity before requested quantities",actual:modelComparison.failures.join("; ")};
    const comparison=compareRequestedQuantities(state.analysisResult,assertion.quantities,modelComparison?.diagnostics);
    return {metric:"numerical_matches",pass:comparison.pass,expected:"All independently frozen physical response quantities",actual:comparison.failures.join("; ")||`${comparison.comparedValues} requested quantities matched`,details:comparison};
  }
  const gtId = assertion.groundTruthId;
  const modelTruth = getGroundTruthModels().find((entry) => entry.id === gtId);
  if (!modelTruth || !state.model) {
    return {
      metric: "numerical_matches",
      pass: false,
      expected: `model and numerical ground truth '${gtId}'`,
      actual: modelTruth ? "agent model missing" : "model ground truth missing",
    };
  }
  if (!state.analysisResult || explicitAnalysisFailure(state.analysisResult)) {
    return {
      metric: "numerical_matches",
      pass: false,
      expected: `successful numerical result for '${gtId}'`,
      actual: !state.analysisResult
        ? "analysis result missing"
        : "analysis artifact is explicitly marked unsuccessful",
    };
  }
  const modelComparison = compareBenchmarkModels(assertion, state.model, modelTruth.model);
  if (!modelComparison.pass) {
    return {
      metric: "numerical_matches",
      pass: false,
      expected: `engineering model match before numerical comparison '${gtId}'`,
      actual: `model mismatch: ${modelComparison.failures.join(", ")}`,
    };
  }
  const selectedEngineId = assertion.engineId
    || scenario?.analysisEngineTarget
    || extractAnalysisSelection(state).engineId
    || "builtin-opensees";
  const engine = normalizeEngineKey(selectedEngineId) || "opensees";
  if (engine !== "opensees") {
    const engineTruth = findEngineGroundTruth(getCrossEngineGroundTruth(), gtId, engine);
    if (!engineTruth) {
      return {
        metric: "numerical_matches",
        pass: false,
        expected: `${engine} ground truth '${gtId}'`,
        actual: "no lossless engine-specific ground truth is available",
      };
    }
    const deadCases=modelTruth.model.load_cases.filter(c=>c.type==='dead');
    const referenceCaseId=engineTruth.truth.response?.physicalCaseId || (deadCases.length===1?deadCases[0].id:null);
    const selection=requestedSelection(assertion,referenceCaseId?{kind:'case',id:referenceCaseId}:undefined);
    const available=selection&&engineTruth.truth.responses?.[`${selection.kind}:${selection.id}`];
    if(!available&&(!selection||selection.kind!=='case'||selection.id!==referenceCaseId)) return {
      metric:'numerical_matches',pass:false,expected:'same-engine reference for the requested case',actual:'requested case has no independently validated reference'};
    const expectedResponse=available||engineTruth.truth.response;
    const actualSelection=mappedSelection(selection,modelComparison.diagnostics);
    let actualResponse;
    try {
      const selected=selectAnalysisResult(state.analysisResult,actualSelection,{allowLegacyUnboundResult:assertion.matcherVersion==='v2'});
      actualResponse = normalizeCommercialEngineResponse(engine, state.model, selected.data,
        {caseKey:assertion.matcherVersion==='v2'?expectedResponse?.caseKey:actualSelection.id});
    } catch (error) {
      return {
        metric: "numerical_matches",
        pass: false,
        expected: `valid ${engine} result for frozen ground truth '${gtId}'`,
        actual: error instanceof Error ? error.message : String(error),
      };
    }
    if (!expectedResponse) {
      return {
        metric: "numerical_matches",
        pass: false,
        expected: `complete frozen ${engine} response for '${gtId}'`,
        actual: "ground truth predates full-response validation and must be regenerated",
      };
    }
    const comparison = compareCommercialEngineResponses(
      actualResponse,
      expectedResponse,
      modelComparison.diagnostics,
      {...(assertion.tolerances || {}),caseKeyMapping:{[expectedResponse.caseKey]:actualResponse.caseKey}},
    );
    return {
      metric: "numerical_matches",
      pass: comparison.pass,
      expected: `${comparison.comparedValues} frozen ${engine} response values within `
        + `${(comparison.tolerances.relative * 100).toFixed(1)}%`,
      actual: comparison.pass
        ? `matched ${engine} ground truth; max relative difference `
          + `${(comparison.maxRelativeDifference * 100).toFixed(3)}%`
        : comparison.failures.slice(0, 5).join("; "),
      details: { ...comparison, engine, groundTruthCaseId: engineTruth.entry.caseId },
    };
  }
  const numericalTruth = getNumericalGroundTruthModels().find((entry) => entry.modelId === gtId);
  if (!numericalTruth) {
    return {
      metric: "numerical_matches",
      pass: false,
      expected: `cross-validated OpenSees truth '${gtId}'`,
      actual: "numerical truth not generated or model not found",
    };
  }
  const binding=numericalTruth.analysisSelection||{};
  const factorIds=Object.keys(binding.factors||{});
  const fallback=binding.loadCombinationId?{kind:'combination',id:binding.loadCombinationId}:
    factorIds.length===1?{kind:'case',id:factorIds[0]}:undefined;
  const selection=requestedSelection(assertion,fallback);
  if(!numericalTruth.results&&selection&&fallback&&(selection.kind!==fallback.kind||selection.id!==fallback.id)) {
    return {metric:'numerical_matches',pass:false,expected:'independently validated reference for the requested case',
      actual:'requested case has no independently validated reference'};
  }
  const comparison = compareAnalysisResults(
    state.analysisResult,
    numericalTruth.results || numericalTruth.result,
    modelComparison.diagnostics,
    {...(assertion.tolerances||{}),selection:mappedSelection(selection,modelComparison.diagnostics),
      expectedSelection:selection,allowLegacyUnboundResult:assertion.matcherVersion==='v2'},
  );
  return {
    metric: "numerical_matches",
    pass: comparison.pass,
    expected: `${comparison.comparedValues} OpenSees response values within `
      + `${(comparison.tolerances.relative * 100).toFixed(1)}%`,
    actual: comparison.pass
      ? `matched; max relative difference ${(comparison.maxRelativeDifference * 100).toFixed(3)}%`
      : `${comparison.failures.slice(0, 5).join("; ")}`,
    details: comparison,
  };
}

// ---------------------------------------------------------------------------
// Main evaluator
// ---------------------------------------------------------------------------

/**
 * Dispatch a single assertion to its typed evaluator.
 *
 * @param {object} assertion - v2 assertion object
 * @param {object} state - AgentState
 * @returns {Promise<{ metric: string, pass: boolean, expected: string, actual: string }>}
 */
async function dispatchAssertion(assertion, state, scenario) {
  switch (assertion.type) {
    case "structural_type":
      return evalStructuralType(assertion, state);
    case "has_model":
      return evalHasModel(assertion, state);
    case "has_analysis":
      return evalHasAnalysis(assertion, state);
    case "engine_match":
      return evalEngineMatch(assertion, state);
    case "execution_evidence": {
      const result=verifyExecutionEvidence(state,requestedSelection(assertion));
      return {metric:'execution_evidence',pass:result.pass,expected:'executed, versioned result bound to the current model and selected case',
        actual:result.pass?`${result.solver} ${result.solverVersion}; run ${result.runId}`:result.failures.join('; '),details:result};
    }
    case "has_report":
      return evalHasReport(assertion, state);
    case "report_numerical_consistency":
      return evalReportNumericalConsistency(assertion, state);
    case "skill_match":
      return evalSkillMatch(assertion, state);
    case "has_interaction_questions":
      return evalHasInteractionQuestions(assertion, state);
    case "analysis_or_interaction":
      return evalAnalysisOrInteraction(assertion, state);
    case "should_not_analyze":
      return evalShouldNotAnalyze(assertion, state);
    case "safe_non_execution":
      return evalSafeNonExecution(assertion, state);
    case "no_bad_model":
      return evalNoBadModel(assertion, state);
    case "natural_language":
      return evalNaturalLanguage(assertion, state);
    case "model_matches":
      return evalModelMatches(assertion, state);
    case "numerical_matches":
      return evalNumericalMatches(assertion, state, scenario);
    default:
      throw new Error(`unsupported assertion type: ${assertion.type || "(undefined)"}`);
  }
}

/**
 * Evaluate a completed AgentState against a scenario's expectations.
 *
 * @param {object} scenario - benchmark scenario (v1 or v2 format)
 * @param {object} state - AgentState returned by service.runFull
 * @param {number} durationMs - elapsed time in milliseconds
 * @returns {Promise<object>} evaluation result
 */
async function evaluateScenario(scenario, state, durationMs) {
  const metrics = [];
  const { assertions } = upgradeExpect(scenario.expect || {});

  for (const assertion of assertions) {
    try {
      metrics.push(await dispatchAssertion(assertion, state, scenario));
    } catch (err) {
      const msg = err instanceof Error ? err.message : String(err);
      if (msg.includes("LLM_JUDGE_INFRASTRUCTURE_ERROR")) {
        throw err;
      }
      throw new Error(
        `BENCHMARK_EVALUATOR_ERROR: scenario=${scenario.id || "(unknown)"}, `
        + `assertion=${assertion.type || "(undefined)"}: ${msg}`,
        { cause: err },
      );
    }
  }

  // Tool call count (informational — always measured)
  let toolCallCount = 0;
  const messages = Array.isArray(state.messages) ? state.messages : [];
  for (const msg of messages) {
    const toolCalls = msg?.tool_calls || msg?.kwargs?.tool_calls;
    if (Array.isArray(toolCalls)) {
      toolCallCount += toolCalls.length;
    }
  }
  metrics.push({
    metric: "toolCalls",
    pass: true,
    expected: "(info, lower is better)",
    actual: String(toolCallCount),
  });

  const tokenUsage = {
    input: 0,
    output: 0,
    total: 0,
    available: false,
  };
  for (const msg of messages) {
    if (!msg || typeof msg !== "object") continue;
    const usageMetadata = msg.usage_metadata ?? msg.kwargs?.usage_metadata;
    const responseMetadata = msg.response_metadata ?? msg.kwargs?.response_metadata;
    const usage = usageMetadata && typeof usageMetadata === "object"
      ? {
          input: usageMetadata.input_tokens,
          output: usageMetadata.output_tokens,
          total: usageMetadata.total_tokens,
        }
      : responseMetadata?.tokenUsage && typeof responseMetadata.tokenUsage === "object"
        ? {
            input: responseMetadata.tokenUsage.promptTokens,
            output: responseMetadata.tokenUsage.completionTokens,
            total: responseMetadata.tokenUsage.totalTokens,
          }
        : null;
    if (!usage) continue;
    const input = Number(usage.input);
    const output = Number(usage.output);
    const total = Number(usage.total);
    const hasInput = Number.isFinite(input) && input >= 0;
    const hasOutput = Number.isFinite(output) && output >= 0;
    const hasTotal = Number.isFinite(total) && total >= 0;
    if (!hasInput && !hasOutput && !hasTotal) continue;
    tokenUsage.input += hasInput ? input : 0;
    tokenUsage.output += hasOutput ? output : 0;
    tokenUsage.total += hasTotal ? total : (hasInput ? input : 0) + (hasOutput ? output : 0);
    tokenUsage.available = true;
  }
  if (tokenUsage.available) {
    metrics.push(
      {
        metric: "inputTokens",
        pass: true,
        expected: "(info, lower is better)",
        actual: String(tokenUsage.input),
      },
      {
        metric: "outputTokens",
        pass: true,
        expected: "(info, lower is better)",
        actual: String(tokenUsage.output),
      },
      {
        metric: "totalTokens",
        pass: true,
        expected: "(info, lower is better)",
        actual: String(tokenUsage.total),
      },
    );
  }

  // Duration (informational, always pass)
  metrics.push({
    metric: "duration",
    pass: true,
    expected: "(info)",
    actual: `${(durationMs / 1000).toFixed(1)}s`,
  });
  const scoredMetrics = metrics.filter((metric) => (
    !["toolCalls", "inputTokens", "outputTokens", "totalTokens", "duration"].includes(metric.metric)
  ));

  return {
    scenarioId: scenario.id,
    baseScenarioId: scenario.baseScenarioId || scenario.id,
    description: scenario.description || "",
    split: scenario.split || "core",
    taskFamily: scenario.taskFamily || "standard_workflow",
    inputModality: scenario.inputModality || "text",
    inputCompleteness: scenario.inputContract?.completeness || null,
    structureType: scenario.structureType || null,
    benchmarkStructureType: scenario.benchmarkStructureType || null,
    difficulty: scenario.difficulty || null,
    skillTarget: scenario.skillTarget || null,
    category: scenario.category || null,
    tags: Array.isArray(scenario.tags) ? scenario.tags : [],
    locale: scenario.locale || null,
    analysisSkillTarget: scenario.analysisSkillTarget || null,
    analysisEngineTarget: scenario.analysisEngineTarget || null,
    mode: scenario.mode || "auto",
    evaluationFocus: Array.isArray(scenario.evaluationFocus) ? scenario.evaluationFocus : [],
    passed: scoredMetrics.filter((metric) => metric.pass).length,
    total: scoredMetrics.length,
    allPassed: scoredMetrics.every((metric) => metric.pass),
    metrics,
    durationMs,
  };
}

module.exports = {
  evaluateInteractionEvidence,
  evaluateSafeNonExecutionEvidence,
  evaluateScenario,
};
