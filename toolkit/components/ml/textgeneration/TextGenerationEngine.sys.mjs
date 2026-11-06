/* This Source Code Form is subject to the terms of the Mozilla Public
 * License, v. 2.0. If a copy of the MPL was not distributed with this
 * file, You can obtain one at http://mozilla.org/MPL/2.0/. */

// TextGenerator is a ChromeOnly WebIDL interface (dom/chrome-webidl).
/* global TextGenerator */

/** MLEngine-shaped engine over the HWInference utility process. */

import { XPCOMUtils } from "resource://gre/modules/XPCOMUtils.sys.mjs";

/**
 * @typedef {import("chrome://global/content/ml/EngineProcess.sys.mjs").PipelineOptions} PipelineOptions
 * @typedef {import("chrome://global/content/ml/Utils.sys.mjs").ProgressAndStatusCallbackParams} ProgressAndStatusCallbackParams
 * @typedef {(data: ProgressAndStatusCallbackParams) => void} NotificationsCallback
 * @typedef {{ name: string, when: number }} RunTimestamp
 */

/**
 * PipelineOptions declares its model fields nullable; createEngine() only
 * hands this engine options it has resolved.
 *
 * @typedef {PipelineOptions & {
 *   engineId: string,
 *   taskName: string,
 *   modelId: string,
 *   modelRevision: string,
 *   modelFile: string,
 *   draftModelFile: ?string,
 *   modelHubRootUrl: string,
 *   modelHubUrlTemplate: string,
 * }} ResolvedPipelineOptions
 */

/**
 * The llama.cpp request shape MLEngine consumers send to run().
 *
 * @typedef {object} LlamaRunRequest
 * @property {string | TextGenerationMessage[]} prompt
 * @property {number} [nPredict]
 * @property {number} [minOutputBufferSize]
 * @property {TextGenerationSampler[]} [samplers]
 * @property {object} [jsonSchema] Constrains the output to this JSON schema.
 * @property {number[]} [stopTokens]
 * @property {boolean} [stopOnEndOfGenerationTokens]
 */

/**
 * The chat completion request shape openAIEngine consumers send to run().
 *
 * @typedef {object} ChatCompletionRequest
 * @property {Array<{ role: string, content: unknown, tool_calls?: unknown[] }>} args
 * @property {Record<string, any>} [inferenceParams] temperature, top_p,
 *   max_completion_tokens / max_tokens and response_format apply; `samplers`
 *   is the chain the model is served with, which temperature and top_p
 *   adjust.
 * @property {unknown[]} [tools]
 * @property {string} [token]
 * @property {string} [chatId]
 * @property {object} [streamOptions]
 */

/**
 * @typedef {object} EngineRunResult
 * @property {true} done
 * @property {string} finalOutput
 * @property {true} ok
 * @property {ReturnType<typeof toEngineMetrics>} metrics
 * @property {ReturnType<typeof toEngineResources>} resourcesBefore
 * @property {ReturnType<typeof toEngineResources>} resourcesAfter
 */

const lazy = XPCOMUtils.declareLazy({
  LLAMA_CPP_VERSION:
    "moz-src:///toolkit/components/ml/actors/MLEngineParent.sys.mjs",
  MLEngineParent:
    "moz-src:///toolkit/components/ml/actors/MLEngineParent.sys.mjs",
  MLTelemetry: "chrome://global/content/ml/MLTelemetry.sys.mjs",
  generateUUID: "chrome://global/content/ml/Utils.sys.mjs",
  JSON_GRAMMAR:
    "moz-src:///toolkit/components/ml/textgeneration/JSONSchemaGrammar.sys.mjs",
  jsonSchemaToGrammar:
    "moz-src:///toolkit/components/ml/textgeneration/JSONSchemaGrammar.sys.mjs",
});

/**
 * @param {object} schema
 * @returns {TextGenerationSampler}
 */
function toGrammarSampler(schema) {
  return { type: "grammar", grammar: lazy.jsonSchemaToGrammar(schema) };
}

/**
 * @param {{ type?: string, json_schema?: { schema?: object } }} [responseFormat]
 * @returns {TextGenerationSampler | null}
 */
function toResponseFormatSampler(responseFormat) {
  switch (responseFormat?.type) {
    case undefined:
    case "text":
      return null;
    case "json_object":
      return { type: "grammar", grammar: lazy.JSON_GRAMMAR };
    case "json_schema": {
      const schema = responseFormat.json_schema?.schema;
      if (!schema) {
        throw new Error(
          "TextGenerationEngine: response_format.json_schema.schema is required"
        );
      }
      return toGrammarSampler(schema);
    }
    default:
      throw new Error(
        `TextGenerationEngine: unsupported response_format "${responseFormat.type}"`
      );
  }
}

/** @param {TextGenerationResourceSnapshot} snapshot */
const toEngineResources = snapshot => ({
  cpuTime: snapshot.cpuTimeMs,
  memory: snapshot.memoryBytes,
});

// LlamaCppPipeline spells the float cache types fp16 and fp32; the
// generator, f16 and f32.
/**
 * @param {string} dtype
 * @returns {TextGenerationKVCacheDtype}
 */
function toKVCacheDtype(dtype) {
  return /** @type {TextGenerationKVCacheDtype} */ (dtype.replace(/^fp/, "f"));
}

/**
 * @param {PipelineOptions} options
 * @returns {TextGeneratorCreateOptions}
 */
function toCreateOptions(options) {
  /** @type {TextGeneratorCreateOptions} */
  const createOptions = {
    contextSize: options.numContext ?? undefined,
    batchSize: options.numBatch ?? undefined,
    ubatchSize: options.numUbatch ?? undefined,
    flashAttn: options.flashAttn ?? undefined,
    featureId: options.featureId ?? "",
    placement: options.device ?? undefined,
  };
  if (options.kvCacheDtype) {
    createOptions.kvCacheDtype = toKVCacheDtype(options.kvCacheDtype);
  }
  if (options.numThreads) {
    createOptions.numThreads = options.numThreads;
  }
  if (options.numThreadsDecoding) {
    createOptions.numThreadsDecoding = options.numThreadsDecoding;
  }
  return createOptions;
}

/**
 * @param {LlamaRunRequest} request
 * @returns {TextGenerationRequest}
 */
function toGenerateRequest(request) {
  let prompt = request.prompt;
  if (!Array.isArray(prompt)) {
    prompt = [{ role: "user", content: String(prompt) }];
  }
  /** @type {TextGenerationRequest} */
  const generateRequest = {
    messages: prompt.map(message => ({
      role: message.role,
      content: message.content,
    })),
  };
  // Leave unset fields absent so TextGenerationRequest defaults apply.
  if (request.nPredict != null) {
    generateRequest.maxTokens = request.nPredict;
  }
  if (request.minOutputBufferSize != null) {
    generateRequest.bufferLength = request.minOutputBufferSize;
  }
  if (request.samplers != null) {
    generateRequest.samplers = request.samplers;
  }
  if (request.jsonSchema) {
    generateRequest.samplers = [
      toGrammarSampler(request.jsonSchema),
      ...(generateRequest.samplers ?? []),
    ];
  }
  if (request.stopTokens != null) {
    generateRequest.stopTokens = request.stopTokens;
  }
  if (request.stopOnEndOfGenerationTokens != null) {
    generateRequest.stopOnEndOfGenerationTokens =
      request.stopOnEndOfGenerationTokens;
  }
  return generateRequest;
}

const CHAT_COMPLETION_ROLES = new Set(["system", "user", "assistant"]);

/**
 * @param {{ temperature?: number, top_p?: number, samplers?: TextGenerationSampler[] }} inferenceParams
 * @returns {TextGenerationSampler[]}
 */
function toSamplers({ temperature, top_p, samplers }) {
  // Chat completion defaults: temperature 1, no nucleus cut; 0 is greedy.
  if (temperature === 0) {
    return [];
  }
  if (!samplers) {
    /** @type {TextGenerationSampler[]} */
    const chain = [];
    if (top_p != null && top_p < 1) {
      chain.push({ type: "top-p", topP: top_p });
    }
    chain.push({ type: "temperature", temp: temperature ?? 1 });
    chain.push({ type: "dist" });
    return chain;
  }
  const chain = samplers.map(sampler => ({ ...sampler }));
  const set = (type, fields, before) => {
    const step = chain.find(sampler => sampler.type === type);
    if (step) {
      Object.assign(step, fields);
      return;
    }
    const index = chain.findIndex(sampler => sampler.type === before);
    chain.splice(index < 0 ? chain.length : index, 0, { type, ...fields });
  };
  if (top_p != null) {
    set("top-p", { topP: top_p }, "temperature");
  }
  if (temperature != null) {
    set("temperature", { temp: temperature }, "dist");
  }
  return chain;
}

/**
 * @param {ChatCompletionRequest} request
 * @returns {TextGenerationRequest}
 */
function toGenerateRequestFromChatCompletion(request) {
  if (request.tools?.length) {
    throw new Error("TextGenerationEngine: tools are not supported");
  }
  const messages = request.args.map(message => {
    if (message.tool_calls?.length) {
      throw new Error("TextGenerationEngine: tool calls are not supported");
    }
    if (!CHAT_COMPLETION_ROLES.has(message.role)) {
      throw new Error(
        `TextGenerationEngine: unsupported message role "${message.role}"`
      );
    }
    if (typeof message.content !== "string") {
      throw new Error("TextGenerationEngine: message content must be a string");
    }
    return {
      role: /** @type {TextGenerationRole} */ (message.role),
      content: message.content,
    };
  });
  const params = request.inferenceParams ?? {};
  const samplers = toSamplers(params);
  const grammar = toResponseFormatSampler(params.response_format);
  if (grammar) {
    samplers.unshift(grammar);
  }
  /** @type {TextGenerationRequest} */
  const generateRequest = { messages, samplers };
  // Chat completions generate until the model stops; the generator clamps
  // the budget to its context.
  generateRequest.maxTokens =
    params.max_completion_tokens ?? params.max_tokens ?? 0xffffffff;
  return generateRequest;
}

/**
 * @param {LlamaRunRequest | ChatCompletionRequest} request
 * @returns {TextGenerationRequest}
 */
function toAnyGenerateRequest(request) {
  return "args" in request
    ? toGenerateRequestFromChatCompletion(request)
    : toGenerateRequest(request);
}

/**
 * @param {TextGenerationResult} result
 * @param {RunTimestamp[]} runTimestamps
 */
function toEngineMetrics(result, runTimestamps) {
  const { usage } = result;
  const outputTokens = usage.generatedTokens;
  const decodingTime = usage.timings.decodeMs;
  return {
    runTimestamps,
    inputTokens: usage.promptTokens,
    inputCharacters: usage.promptCharacters,
    outputTokens,
    inferenceTime: usage.timings.prefillMs + decodingTime,
    decodingTime,
    timeToFirstToken: usage.timings.prefillMs,
    tokensPerSecond: decodingTime
      ? outputTokens / (decodingTime / 1000)
      : undefined,
    timePerOutputToken: outputTokens ? decodingTime / outputTokens : undefined,
  };
}

/** Async-iterable sink that the delta callback pushes into. */
class ChunkQueue {
  /** @type {string[]} */
  #pending = [];
  #closed = false;
  /** @type {((value?: unknown) => void) | null} */
  #wakeUp = null;

  /** @param {string} text */
  push(text) {
    this.#pending.push(text);
    this.#wakeUp?.();
  }

  close() {
    this.#closed = true;
    this.#wakeUp?.();
  }

  async *[Symbol.asyncIterator]() {
    while (!this.#closed || this.#pending.length) {
      if (!this.#pending.length) {
        await new Promise(resolve => {
          this.#wakeUp = resolve;
        });
        this.#wakeUp = null;
        continue;
      }
      yield this.#pending.shift();
    }
  }
}

/** What recordEngineRun reports about a streamed run. */
class StreamStats {
  firstChunkAt = 0;
  lastChunkAt = 0;
  chunkCount = 0;
  characterCount = 0;
  streaming = false;

  constructor() {
    this.beforeRun = ChromeUtils.now();
  }

  /** @param {string} text */
  onChunk(text) {
    this.lastChunkAt = ChromeUtils.now();
    if (!this.firstChunkAt) {
      this.firstChunkAt = this.lastChunkAt;
    }
    this.chunkCount += 1;
    this.characterCount += text.length;
  }

  /** @param {EngineRunResult} result */
  metrics(result) {
    return {
      tokenCount: result.metrics.outputTokens,
      characterCount: this.characterCount,
      timeToFirstChunk: this.firstChunkAt
        ? this.firstChunkAt - this.beforeRun
        : null,
      averageChunkTime:
        this.chunkCount > 1
          ? (this.lastChunkAt - this.firstChunkAt) / (this.chunkCount - 1)
          : null,
    };
  }
}

export class TextGenerationEngine {
  /** @type {string} */
  engineId;
  /** @type {ResolvedPipelineOptions} */
  pipelineOptions;
  /** @type {"uninitialized" | "ready" | "closed"} */
  engineStatus = "uninitialized";

  /** The model id, as consumers of a chat completion engine read it. */
  get model() {
    return this.pipelineOptions.modelId;
  }

  /** Id of the device that loaded the model, see HWInferenceDevice. */
  get device() {
    return this.#generator?.device ?? null;
  }
  /** @type {NotificationsCallback | null} */
  notificationsCallback = null;
  /** @type {InstanceType<typeof lazy.MLTelemetry>} */
  telemetry;

  /** @type {TextGenerator | null} */
  #generator = null;
  /** @type {HWInferenceDeviceKind | null} */
  #deviceKind = null;
  /** @type {RunTimestamp[]} */
  #initTimestamps = [];
  #inFlight = false;

  /** @param {PipelineOptions} pipelineOptions */
  static shouldRoute(pipelineOptions) {
    if (!Services.prefs.getBoolPref("browser.ml.llama.hwInference", false)) {
      return false;
    }
    return pipelineOptions.backend === "llama.cpp";
  }

  /**
   * @param {PipelineOptions} pipelineOptions
   * @param {NotificationsCallback | null} [notificationsCallback]
   * @param {AbortSignal} [abortSignal]
   */
  static async create(
    pipelineOptions,
    notificationsCallback = null,
    abortSignal = undefined
  ) {
    const start = ChromeUtils.now();
    const engine = new TextGenerationEngine(
      pipelineOptions,
      notificationsCallback
    );
    const { engineId } = engine;
    try {
      await engine.#initialize(abortSignal);
      engine.telemetry.recordEngineCreationSuccessFlow({
        engineId,
        duration: ChromeUtils.now() - start,
        deviceKind: engine.#deviceKind,
      });
    } catch (error) {
      engine.telemetry.recordEngineCreationFailure({
        modelId: pipelineOptions.modelId,
        featureId: pipelineOptions.featureId,
        taskName: pipelineOptions.taskName,
        engineId,
        error,
      });
      throw error;
    }
    return engine;
  }

  /**
   * @param {PipelineOptions} pipelineOptions
   * @param {NotificationsCallback | null} notificationsCallback
   */
  constructor(pipelineOptions, notificationsCallback) {
    this.pipelineOptions = /** @type {ResolvedPipelineOptions} */ (
      pipelineOptions
    );
    this.engineId = this.pipelineOptions.engineId;
    this.notificationsCallback = notificationsCallback;
    this.telemetry = new lazy.MLTelemetry({
      featureId: pipelineOptions.featureId,
      flowId: pipelineOptions.flowId,
      hostProcess: "hwinference",
    });
  }

  /** @param {AbortSignal} [abortSignal] */
  async #initialize(abortSignal) {
    abortSignal?.throwIfAborted();
    const options = this.pipelineOptions;
    this.#initTimestamps = [
      { name: "initializationStart", when: ChromeUtils.now() },
    ];

    const hub = await lazy.MLEngineParent.createModelHub({
      rootUrl: options.modelHubRootUrl,
      urlTemplate: options.modelHubUrlTemplate,
    });
    const sessionId = lazy.generateUUID();
    const fetchFile = async file => {
      const [blob] = await hub.getModelFileAsBlob({
        engineId: options.engineId,
        taskName: options.taskName,
        model: options.modelId,
        revision: options.modelRevision,
        file,
        modelHubRootUrl: options.modelHubRootUrl,
        modelHubUrlTemplate: options.modelHubUrlTemplate,
        progressCallback: this.notificationsCallback,
        abortSignal,
        featureId: options.featureId ?? options.engineId,
        sessionId,
      });
      return blob;
    };
    let modelBlob;
    let draftBlob;
    try {
      modelBlob = await fetchFile(options.modelFile);
      if (options.draftModelFile) {
        draftBlob = await fetchFile(options.draftModelFile);
      }
    } finally {
      await hub.notifyModelDownloadComplete({
        engineId: options.engineId,
        model: options.modelId,
        revision: options.modelRevision,
        featureId: options.featureId ?? options.engineId,
        sessionId,
      });
    }

    const createOptions = toCreateOptions(options);
    if (draftBlob) {
      createOptions.draftModel = draftBlob;
    }
    this.#generator = await TextGenerator.create(modelBlob, createOptions);
    this.#deviceKind = this.#generator.deviceKind;
    this.pipelineOptions.backend = "llama.cpp";
    this.#initTimestamps.push({
      name: "initializationEnd",
      when: ChromeUtils.now(),
    });
    this.engineStatus = "ready";
  }

  #runnableGenerator() {
    if (this.engineStatus !== "ready" || !this.#generator) {
      throw new Error("TextGenerationEngine: engine is not ready");
    }
    if (this.#inFlight) {
      throw new Error("A generation is already in progress");
    }
    return this.#generator;
  }

  /**
   * @param {LlamaRunRequest | ChatCompletionRequest} request
   * @param {(text: string) => void} [onDelta]
   * @returns {Promise<EngineRunResult>}
   */
  async #execute(request, onDelta) {
    const generator = this.#runnableGenerator();
    const generateRequest = toAnyGenerateRequest(request);
    this.#inFlight = true;
    try {
      const runStart = ChromeUtils.now();
      generator.clear();
      const result = await generator.generate(generateRequest, onDelta);
      const runEnd = ChromeUtils.now();
      return {
        done: true,
        finalOutput: result.content,
        ok: true,
        metrics: toEngineMetrics(result, [
          ...this.#initTimestamps,
          { name: "runStart", when: runStart },
          { name: "runEnd", when: runEnd },
        ]),
        resourcesBefore: toEngineResources(result.resources.before),
        resourcesAfter: toEngineResources(result.resources.after),
      };
    } finally {
      this.#inFlight = false;
    }
  }

  /**
   * @param {StreamStats} stats
   * @param {EngineRunResult} result
   */
  #recordRun(stats, result) {
    this.telemetry.recordRunInferenceSuccessFlow(this.engineId, result.metrics);
    this.telemetry.recordEngineRun({
      beforeRun: stats.beforeRun,
      resourcesBefore: result.resourcesBefore,
      resourcesAfter: result.resourcesAfter,
      engineId: this.engineId,
      modelId: this.pipelineOptions.modelId,
      backend: this.pipelineOptions.backend,
      backendSourceRevision: lazy.LLAMA_CPP_VERSION,
      deviceKind: this.#deviceKind,
      ...(stats.streaming ? stats.metrics(result) : {}),
    });
  }

  /** @param {LlamaRunRequest | ChatCompletionRequest} request */
  async run(request) {
    const stats = new StreamStats();
    try {
      const result = await this.#execute(request);
      this.#recordRun(stats, result);
      return result;
    } catch (error) {
      this.telemetry.recordRunInferenceFailure(error);
      throw error;
    }
  }

  /** @param {LlamaRunRequest | ChatCompletionRequest} request */
  async *runWithGenerator(request) {
    const stats = new StreamStats();
    stats.streaming = true;
    const queue = new ChunkQueue();
    /** @type {Promise<EngineRunResult> | null} */
    let completion = null;
    let settled = false;
    try {
      completion = this.#execute(request, text => {
        stats.onChunk(text);
        queue.push(text);
      });
      // Keeps the rejection handled; the await below rethrows it.
      completion.catch(() => {});
      const close = () => queue.close();
      completion.then(close, close);

      for await (const text of queue) {
        yield { text, tokens: [], isPrompt: false };
      }

      const result = await completion;
      // Link Preview keys its final flush on an empty terminal chunk.
      yield { text: "", tokens: [], isPrompt: false };

      this.#recordRun(stats, result);
      settled = true;
      return result;
    } catch (error) {
      settled = true;
      this.telemetry.recordRunInferenceFailure(error);
      throw error;
    } finally {
      // Breaking out of a `for await` loop returns this generator mid-decode.
      if (!settled) {
        this.cancel();
        const result = await completion?.catch(() => null);
        if (result) {
          this.#recordRun(stats, result);
        }
      }
    }
  }

  /** Stops the generation; the run settles and the generator stays usable. */
  cancel() {
    this.#generator?.cancel();
  }

  async terminate() {
    if (this.#generator) {
      this.#generator.terminate();
      this.#generator = null;
    }
    this.engineStatus = "closed";
  }
}
