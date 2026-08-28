// Model registry for the local summarizer, built from the pinned manifest.
// The manifest (models.manifest.json) is the single source of truth shared
// with flake.nix (desktop weight bundling) and scripts/update-model-manifest.mjs
// (regeneration) — nothing here hardcodes a URL or hash.

import manifest from "./models.manifest.json";

export type LlmDevice = "webgpu" | "wasm";

export interface ManifestFile {
    path: string;
    url: string;
    size: number;
    sha256: string;
}

export interface LlmModel {
    id: string;
    label: string;
    repo: string;
    revision: string;
    /** transformers.js dtype key; also names the ONNX file (model_<dtype>.onnx). */
    dtype: string;
    /** Weakest device this model is usable on. "webgpu" bars slow WASM-only
     *  machines from a model that would generate at unusable speed. */
    minDevice: LlmDevice;
    license: string;
    licenseNotice: string;
    licenseUrl: string;
    totalBytes: number;
    files: ManifestFile[];
}

export const MODELS: LlmModel[] = manifest.models;

export const DEFAULT_MODEL_ID = "llama-3.2-1b-instruct";
export const LITE_MODEL_ID = "gemma-3-270m-it";

export const getModel = (id: string): LlmModel | undefined =>
    MODELS.find((model) => model.id === id);

/** A model is usable only once the manifest pins every file's sha256.
 *  Unpinned entries are placeholders awaiting update-model-manifest.mjs. */
export const isPinned = (model: LlmModel): boolean =>
    model.revision !== "" &&
    model.files.length > 0 &&
    model.files.every((file) => file.sha256 !== "");

/** How many external-data shards the ONNX graph references
 *  (onnx/model_<dtype>.onnx_data, _data_1, ...). ONNX Runtime cannot
 *  discover these in a browser — transformers.js must be told to fetch
 *  them, so the count is threaded into the worker's load options. Zero
 *  means the graph is self-contained. */
export const externalDataChunks = (model: LlmModel): number =>
    model.files.filter((file) => file.path.includes(".onnx_data")).length;

/** Models eligible on a device, pinned entries only. */
export const availableModels = (device: LlmDevice): LlmModel[] =>
    MODELS.filter(
        (model) =>
            isPinned(model) && (device === "webgpu" || model.minDevice === "wasm"),
    );

// Weights live in client/public/models/. The dev server serves them from
// the app origin at this path; production desktop builds instead strip them
// from the export (scripts/strip-model-assets.mjs — embedding gigabytes
// breaks rustc) and ship them as Tauri bundle resources read over IPC (see
// engine.ts resolveWeightSource). transformers.js still keys local files as
// `${localModelPath}${repo}/<file>`.
export const LOCAL_MODEL_PATH = "/models/";

/** True when the weights are fetchable from the app's own origin (dev
 *  server, or any hosting that serves public/models). Probes the smallest
 *  manifest file. Production desktop uses the IPC path instead. */
export const hasBundledWeights = async (model: LlmModel): Promise<boolean> => {
    try {
        const response = await fetch(
            `${LOCAL_MODEL_PATH}${model.repo}/config.json`,
            { method: "GET", cache: "no-store" },
        );
        if (!response.ok) {
            return false;
        }
        // GitHub Pages serves an HTML 404 page for some paths with a 200-ish
        // custom setup; require JSON to count as a real bundled config.
        const text = await response.text();
        JSON.parse(text);
        return true;
    } catch {
        return false;
    }
};

// Generation budget. Both candidate models accept far larger windows, but
// the window caps KV-cache memory in the browser and keeps WASM latency
// tolerable. 2,560 (input <= 2,048 after the 512 output reserve) is a WebGPU
// memory bound, not a latency choice: prefill logits are sequence x vocab
// (~0.5 MB per input token on the 1B model), and near-4K prompts drove real
// devices out of GPU memory (webgpu_context "device error(3): Out of
// memory"). The worker enforces this by trimming input to
// contextTokens - MAX_NEW_TOKENS, so no prompt-builder mistake can exceed
// it.
//
// CONTEXT_TOKENS is the floor: every device that ran the model before ran
// it at this window. contextTokensFor raises it only when the adapter's
// reported buffer limit proves there is room for the larger logits tensor.
export const CONTEXT_TOKENS = 2560;
export const MAX_NEW_TOKENS = 512;
/** Ceiling for the adaptive window. Beyond this, prefill latency and the
 *  KV cache grow for little benefit — the prompt builders rarely have more
 *  than ~5K tokens of distinct evidence to offer. */
export const MAX_CONTEXT_TOKENS = 6144;

/** fp32 logit row per input token, from each repo's config.json vocab_size.
 *  Unknown ids get the larger vocab, which only under-sizes the window. */
const LOGIT_BYTES_PER_TOKEN: Record<string, number> = {
    "llama-3.2-1b-instruct": 128256 * 4,
    "gemma-3-270m-it": 262144 * 4,
};
const FALLBACK_LOGIT_BYTES = 262144 * 4;
export const logitBytesPerToken = (model: LlmModel): number =>
    LOGIT_BYTES_PER_TOKEN[model.id] ?? FALLBACK_LOGIT_BYTES;
/** To RAISE the window past the floor, the logits tensor may claim at most
 *  1/3 of the largest allocatable buffer. The rest of the picture (weights
 *  ~1.1 GB, KV cache, activations) shares the same GPU memory, and the
 *  adapter limit is an upper bound on buffer size, not a free-memory
 *  report — near-4K prompts OOMed real devices, so the divisor errs
 *  conservative. Tune here if field results allow. */
const RAISE_HEADROOM_DIVISOR = 3;
/** To KEEP the floor, its logits must fit in 1/2 of the limit; adapters
 *  below that shrink to what 1/2 allows. Half, not a third, because the
 *  floor has field history: it ran on adapters whose limit gave its logits
 *  2x headroom. A 1 GiB adapter proved the need to shrink at all — its
 *  ~1002 MiB floor logits OOMed against a 1024 MiB max buffer. */
const SHRINK_HEADROOM_DIVISOR = 2;
/** Window below which the prompts stop working: 1,048 tokens of fixed
 *  overhead plus the 512 output reserve leave under ~500 tokens of
 *  evidence. usableDevice treats WebGPU windows below this as unusable
 *  rather than reviewing evidence it cannot see. */
export const MIN_CONTEXT_TOKENS = 2048;

const roundWindow = (inputTokens: number): number =>
    Math.floor((inputTokens + MAX_NEW_TOKENS) / 128) * 128;

/** Context window for this model on this device, in either direction from
 *  the floor. WASM (and adapters that report no limits) stay at the
 *  CONTEXT_TOKENS floor — the WASM path is latency-bound and 32-bit, so a
 *  larger window only buys slower prompts. On WebGPU the window grows with
 *  the adapter's buffer limit, or shrinks below the floor when the limit
 *  proves the floor cannot fit. The result can be under
 *  MIN_CONTEXT_TOKENS — callers gate through usableDevice. */
export const contextTokensFor = (
    model: LlmModel,
    capabilities: { device: LlmDevice; maxBufferBytes?: number },
): number => {
    if (capabilities.device !== "webgpu" || !capabilities.maxBufferBytes) {
        return CONTEXT_TOKENS;
    }
    const perToken = logitBytesPerToken(model);
    const raised = roundWindow(
        Math.floor(
            capabilities.maxBufferBytes / RAISE_HEADROOM_DIVISOR / perToken,
        ),
    );
    if (raised >= CONTEXT_TOKENS) {
        return Math.min(MAX_CONTEXT_TOKENS, raised);
    }
    const floorLogitBytes = (CONTEXT_TOKENS - MAX_NEW_TOKENS) * perToken;
    if (
        floorLogitBytes <=
        capabilities.maxBufferBytes / SHRINK_HEADROOM_DIVISOR
    ) {
        return CONTEXT_TOKENS;
    }
    return roundWindow(
        Math.floor(
            capabilities.maxBufferBytes / SHRINK_HEADROOM_DIVISOR / perToken,
        ),
    );
};

/** The device this model can run on here, or null when it cannot run at
 *  all. WebGPU counts only when its window still fits a working prompt;
 *  models that allow WASM fall back to it (CPU memory, no GPU buffer
 *  limits), and WebGPU-only models report unusable. The engine and the UI
 *  gates share this so they agree. */
export const usableDevice = (
    model: LlmModel,
    capabilities: { device: LlmDevice; maxBufferBytes?: number },
): LlmDevice | null => {
    if (
        capabilities.device === "webgpu" &&
        contextTokensFor(model, capabilities) >= MIN_CONTEXT_TOKENS
    ) {
        return "webgpu";
    }
    return model.minDevice === "wasm" ? "wasm" : null;
};

/** The model this device will actually run: the user's selection when it
 *  is pinned and usable here, else the pinned lite model. Null when
 *  neither fits — only then do the AI features hide. The stored preference
 *  is never rewritten, so a later session on stronger hardware honors it
 *  again. Every feature gate and load path must resolve through this, or
 *  a device that cannot run the selected model loses the feature instead
 *  of falling back. */
export const resolveUsableModel = (
    selectedId: string,
    capabilities: { device: LlmDevice; maxBufferBytes?: number },
): LlmModel | null => {
    for (const id of [selectedId, LITE_MODEL_ID]) {
        const model = getModel(id);
        if (model && isPinned(model) && usableDevice(model, capabilities)) {
            return model;
        }
    }
    return null;
};
/** Output budget for the draft narrative. The model writes ~120 words of
 *  prose (the app appends gaps and sources itself); a short leash also cuts
 *  the meta-openers and summary paragraphs the 1B model pads with when it
 *  has room. */
export const DRAFT_MAX_NEW_TOKENS = 300;
/** Conservative chars-per-token estimate for budget math done outside the
 *  tokenizer; the worker re-checks with the real tokenizer and trims. */
export const CHARS_PER_TOKEN = 4;
/** Fixed prompt overhead around the evidence excerpts: instructions ~250,
 *  control and objectives ~600, and review findings ~200. */
const PROMPT_OVERHEAD_TOKENS = 1048;
/** Token budget for evidence excerpts: what the input budget of the given
 *  window leaves after PROMPT_OVERHEAD_TOKENS. At the floor window this is
 *  1,000 tokens (~3 excerpts); an adaptive window raises it token for
 *  token. The pinned verified-quote chunks go in first, so the
 *  proven-relevant material is what survives the cut. */
export const evidenceCharBudget = (contextTokens: number): number =>
    (contextTokens - MAX_NEW_TOKENS - PROMPT_OVERHEAD_TOKENS) *
    CHARS_PER_TOKEN;
export const EVIDENCE_CHAR_BUDGET = evidenceCharBudget(CONTEXT_TOKENS);
