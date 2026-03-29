/**
 * Eval Task Definitions — Loaded from eval-config.json
 */

import { dirname, join, resolve } from "path";
import { fileURLToPath } from "url";
import { existsSync } from "fs";

// Project root = three levels up from eval/src/eval/
const __dirname = dirname(fileURLToPath(import.meta.url));
const PROJECT_ROOT = resolve(__dirname, "../../..");

// ─── Scorer helpers ──────────────────────────────────────────────────────────

/** Score 100 if ALL keywords appear in output (case-insensitive), else 0. */
export function keywords(...words: string[]): Scorer {
  return output => {
    const lower = output.toLowerCase();
    const matched = words.filter(w => lower.includes(w.toLowerCase()));
    return Math.round((matched.length / words.length) * 100);
  };
}

/** Score 100 if pattern matches output, else 0. */
export function regex(pattern: RegExp): Scorer {
  return output => (pattern.test(output) ? 100 : 0);
}

/** Score = average of all scorers. */
export function allOf(...scorers: Scorer[]): Scorer {
  return output => {
    const scores = scorers.map(s => s(output));
    return Math.round(scores.reduce((a, b) => a + b, 0) / scores.length);
  };
}

/** Score = max of any scorer (passes if any one passes). */
export function anyOf(...scorers: Scorer[]): Scorer {
  return output => Math.max(...scorers.map(s => s(output)));
}

/** Score 100 if file exists at path (relative to project root), else 0. */
export function fileExists(filePath: string): Scorer {
  return _output => {
    const absolutePath = resolve(PROJECT_ROOT, filePath);
    return existsSync(absolutePath) ? 100 : 0;
  };
}

export type Scorer = (output: string) => number; // 0–100

export type JsonScorer = {
  type: "keywords" | "regex" | "allOf" | "anyOf" | "fileExists";
  params: any;
};

export function parseScorer(json: JsonScorer): Scorer {
  switch (json.type) {
    case "keywords":
      return keywords(...json.params.words);
    case "regex":
      return regex(new RegExp(json.params.pattern));
    case "allOf":
      return allOf(...json.params.scorers.map(parseScorer));
    case "anyOf":
      return anyOf(...json.params.scorers.map(parseScorer));
    case "fileExists":
      return fileExists(json.params.path);
    default:
      throw new Error(`Unknown scorer type: ${json.type}`);
  }
}

// ─── Types ───────────────────────────────────────────────────────────────────

export const DEFAULT_MODEL = "github-copilot/claude-sonnet-4.5";

export interface EvalTask {
  id: string;
  name: string;
  category: "browser" | "coding" | "data-extraction" | "navigation" | "form";
  /** Full prompt sent to `opencode run` */
  prompt: string;
  /** Optional model override (e.g. "google/antigravity-gemini-3-flash") */
  model?: string;
  /** Time limit in seconds (default 120) */
  timeoutSeconds?: number;
  /** Fast keyword/regex scorer — always runs, 0–100 */
  scorer: Scorer;
  /**
   * If true, also run LLM-as-judge after the keyword scorer.
   * The judge receives the full agent output text + screenshot (if available).
   * Final score = average of keyword score and judge score.
   */
  llmJudge?: boolean;
  /**
   * Filename the agent is instructed to save a screenshot to.
   * Passed to the LLM judge so it can open and inspect the image.
   * Example: "eval-screenshot.png"
   */
  screenshotPath?: string;
  /**
   * Optional human baseline step count for this task.
   * Used by the judge engine to compute an overhead ratio comparison.
   * Set in eval-config.json as a placeholder; populate with real data later.
   */
  humanBaselineSteps?: number;
  /**
   * Files the agent must produce, relative to project root.
   * These paths are injected into the agent prompt so the agent knows
   * exactly where and with what name to save its outputs.
   * Example: ["outputs/sales_data_audited.xlsx"]
   */
  outputFiles?: string[];
  /**
   * Input files the task depends on, relative to project root.
   * Injected into the agent prompt so the agent knows which files to read.
   * Example: ["uploads/sales_data.xlsx"]
   */
  inputFiles?: string[];
  /**
   * Path to a pre-authored reference answer file, relative to project root.
   * Passed to the judge as a path so it can open and verify against it.
   * Example: "eval/answers/EVAL_FM_001_answer.json"
   */
  expectedOutputFile?: string;
}

// ─── Loading from JSON ───────────────────────────────────────────────────────

export interface EvalConfig {
  /** Human-readable domain name, used as the sub-folder under the model directory */
  name: string;
  defaultModel: string;
  tasks: Array<{
    id: string;
    name: string;
    category: string;
    prompt: string;
    timeoutSeconds?: number;
    scorer: JsonScorer;
    llmJudge?: boolean;
    screenshotPath?: string;
    model?: string; // Optional per-task override
    /**
     * Human baseline steps placeholder. Populate to enable overhead ratio
     * comparisons in efficiency analysis. Leave undefined to skip.
     */
    humanBaselineSteps?: number;
    /** Files the agent must produce, relative to project root. */
    outputFiles?: string[];
    /** Input files the task depends on, relative to project root. */
    inputFiles?: string[];
    /** Path to a pre-authored reference answer file, relative to project root. */
    expectedOutputFile?: string;
  }>;
}

let loadedTasks: EvalTask[] | null = null;
let loadedDefaultModel: string | null = null;
let loadedConfigName: string | null = null;

export async function loadEvalConfig(
  configPath?: string
): Promise<{ name: string; defaultModel: string; tasks: EvalTask[] }> {
  // If a specific path is given, bypass the module-level cache
  if (!configPath && loadedTasks && loadedDefaultModel && loadedConfigName)
    return { name: loadedConfigName, defaultModel: loadedDefaultModel, tasks: loadedTasks };

  // Resolve config path: explicit arg, or default next to run-eval.ts (eval/)
  // Default: eval/tasks/eval-config.json (two levels up from eval/src/eval/, then into tasks/)
  const resolvedPath = configPath ?? join(__dirname, "..", "..", "tasks", "eval-config.json");
  const configText = await Bun.file(resolvedPath).text();
  const config: EvalConfig = JSON.parse(configText);

  const tasks: EvalTask[] = config.tasks.map(t => ({
    id: t.id,
    name: t.name,
    category: t.category as any,
    prompt: t.prompt,
    model: t.model || config.defaultModel,
    timeoutSeconds: t.timeoutSeconds,
    scorer: parseScorer(t.scorer),
    llmJudge: t.llmJudge,
    screenshotPath: t.screenshotPath,
    humanBaselineSteps: t.humanBaselineSteps,
    outputFiles: t.outputFiles,
    inputFiles: t.inputFiles,
    expectedOutputFile: t.expectedOutputFile,
  }));

  if (!configPath) {
    // Cache only the default config load
    loadedTasks = tasks;
    loadedDefaultModel = config.defaultModel;
    loadedConfigName = config.name;
  }

  return { name: config.name, defaultModel: config.defaultModel, tasks };
}

// ─── Registry ─────────────────────────────────────────────────────────────────

export const ALL_TASKS: EvalTask[] = []; // Placeholder, use getAllTasks()
export async function getAllTasks(configPath?: string): Promise<EvalTask[]> {
  const { tasks } = await loadEvalConfig(configPath);
  return tasks;
}

export async function getTaskById(id: string, configPath?: string): Promise<EvalTask | undefined> {
  const tasks = await getAllTasks(configPath);
  return tasks.find(t => t.id === id);
}
