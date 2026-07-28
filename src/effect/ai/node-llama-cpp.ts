import {Effect, Layer, Path} from 'effect';
import {fromPromiseInterruptible} from '../errors.js';
import {SystemInfo} from '../system.js';
import {
  EmbeddingFailed,
  GenerationFailed,
  InferenceInterrupted,
  InsufficientMemory,
  ModelLoadFailed,
  ModelNotInstalled,
  NativeRuntimeUnavailable,
  RerankingFailed,
  InvalidModelOutput,
  UnsupportedNativeRuntime,
} from './errors.js';
import {
  LlamaCppEngine,
  type LlamaCppEngineShape,
  type LlamaEmbeddingSession,
  type LlamaGenerationSession,
  type LlamaRankingSession,
  type LocalModelLoadOptions,
} from './llama-cpp-engine.js';

interface NativeEmbedding {
  readonly vector: readonly number[];
}

interface NativeEmbeddingContext {
  readonly disposed: boolean;
  readonly dispose: () => Promise<void>;
  readonly getEmbeddingFor: (input: string) => Promise<NativeEmbedding>;
}

interface NativeRankingContext {
  readonly disposed: boolean;
  readonly dispose: () => Promise<void>;
  readonly rankAll: (query: string, documents: string[]) => Promise<number[]>;
}

interface NativeModel {
  readonly disposed: boolean;
  readonly dispose: () => Promise<void>;
  readonly createEmbeddingContext: (options: {
    readonly contextSize?: number;
    readonly createSignal: AbortSignal;
    readonly ignoreMemorySafetyChecks: false;
    readonly threads: number;
  }) => Promise<NativeEmbeddingContext>;
  readonly createRankingContext: (options: {
    readonly contextSize?: number;
    readonly createSignal: AbortSignal;
    readonly ignoreMemorySafetyChecks: false;
    readonly threads: number;
  }) => Promise<NativeRankingContext>;
  readonly createContext?: (options: {
    readonly contextSize?: number;
    readonly createSignal: AbortSignal;
    readonly ignoreMemorySafetyChecks: false;
    readonly sequences: 1;
    readonly threads: number;
  }) => Promise<NativeGenerationContext>;
  readonly detokenize: (tokens: readonly number[], specialTokens?: boolean, lastTokens?: readonly number[]) => string;
  readonly tokenize: (text: string, specialTokens?: boolean, options?: 'trimLeadingSpace') => readonly number[];
}

interface NativeGenerationContext {
  readonly disposed: boolean;
  readonly dispose: () => Promise<void>;
  readonly getSequence: () => unknown;
}

interface NativeGrammar {
  readonly parse: (json: string) => unknown;
}

interface NativeChatSession {
  readonly dispose: (options?: {readonly disposeSequence?: boolean}) => void;
  readonly disposed: boolean;
  readonly prompt: (
    prompt: string,
    options: {
      readonly grammar: NativeGrammar;
      readonly maxTokens: number;
      readonly seed?: number;
      readonly signal: AbortSignal;
      readonly temperature: 0;
    },
  ) => Promise<string>;
}

interface NativeLlama {
  readonly buildType: 'localBuild' | 'prebuilt';
  readonly cpuMathCores: number;
  readonly disposed: boolean;
  readonly gpu: string | false;
  readonly dispose: () => Promise<void>;
  readonly loadModel: (options: {
    readonly ignoreMemorySafetyChecks: false;
    readonly loadSignal: AbortSignal;
    readonly modelPath: string;
  }) => Promise<NativeModel>;
  readonly createGrammarForJsonSchema?: (schema: Readonly<Record<string, unknown>>) => Promise<NativeGrammar>;
}

interface NodeLlamaCppModule {
  readonly LlamaChatSession?: new (options: {
    readonly contextSequence: unknown;
    readonly systemPrompt?: string;
  }) => NativeChatSession;
  readonly getLlama: (options: {
    readonly build: 'never';
    readonly logLevel: 'error';
    readonly progressLogs: false;
    readonly skipDownload: true;
    readonly usePrebuiltBinaries: true;
  }) => Promise<NativeLlama>;
}

const EMBEDDING_CONTEXT_TOKEN_RESERVE = 16;
const EMBEDDING_WINDOW_OVERLAP_TOKENS = 32;

export interface NodeLlamaCppLayerOptions {
  readonly loadModule?: () => Promise<NodeLlamaCppModule>;
}

const loadInstalledNodeLlamaCpp = async (moduleSpecifier: string = 'node-llama-cpp'): Promise<NodeLlamaCppModule> =>
  (await import(moduleSpecifier)) as unknown as NodeLlamaCppModule;

export function nodeLlamaCppEngineLayer(options: {
  readonly loadModule: () => Promise<NodeLlamaCppModule>;
}): Layer.Layer<LlamaCppEngine, NativeRuntimeUnavailable | UnsupportedNativeRuntime>;
export function nodeLlamaCppEngineLayer(
  options?: NodeLlamaCppLayerOptions,
): Layer.Layer<LlamaCppEngine, NativeRuntimeUnavailable | UnsupportedNativeRuntime, Path.Path | SystemInfo>;
export function nodeLlamaCppEngineLayer(options: NodeLlamaCppLayerOptions = {}) {
  return Layer.effect(
    LlamaCppEngine,
    Effect.gen(function* () {
      let loadModule = options.loadModule;
      if (!loadModule) {
        const path = yield* Path.Path;
        const system = yield* SystemInfo;
        let moduleSpecifier = 'node-llama-cpp';
        if (typeof THREADNOTE_STANDALONE !== 'undefined' && THREADNOTE_STANDALONE) {
          const nativeModuleUrl = yield* path
            .toFileUrl(path.join(path.dirname(system.executablePath), 'runtime', 'node-llama-cpp.js'))
            .pipe(
              Effect.mapError(
                cause =>
                  new NativeRuntimeUnavailable({
                    cause,
                    message: 'Could not resolve the bundled node-llama-cpp runtime.',
                  }),
              ),
            );
          moduleSpecifier = nativeModuleUrl.href;
        }
        loadModule = () => loadInstalledNodeLlamaCpp(moduleSpecifier);
      }
      const module = yield* fromPromiseInterruptible(
        () => loadModule(),
        cause =>
          new NativeRuntimeUnavailable({
            cause,
            message: `Could not load the node-llama-cpp runtime: ${errorMessage(cause)}`,
          }),
      );
      const llama = yield* Effect.acquireRelease(
        fromPromiseInterruptible(
          () =>
            module.getLlama({
              build: 'never',
              logLevel: 'error',
              progressLogs: false,
              skipDownload: true,
              usePrebuiltBinaries: true,
            }),
          cause =>
            isNoBinaryFound(cause)
              ? new UnsupportedNativeRuntime({
                  cause,
                  message:
                    'No compatible prebuilt node-llama-cpp binary is available. Threadnote will not compile llama.cpp automatically.',
                })
              : new NativeRuntimeUnavailable({
                  cause,
                  message: `Could not initialize node-llama-cpp: ${errorMessage(cause)}`,
                }),
        ),
        native => disposeIgnoringFailure(native),
      );
      return LlamaCppEngine.of(makeEngine(llama, module));
    }),
  );
}

function nativeInferenceThreads(llama: NativeLlama): number {
  return Math.max(1, llama.cpuMathCores);
}

function makeEngine(llama: NativeLlama, module: NodeLlamaCppModule): LlamaCppEngineShape {
  return {
    diagnostics: {
      backend: llama.gpu === false ? 'cpu' : llama.gpu,
      buildType: llama.buildType,
      cpuMathCores: llama.cpuMathCores,
    },
    loadEmbeddingSession: options =>
      Effect.gen(function* () {
        const model = yield* acquireModel(llama, options);
        const context = yield* Effect.acquireRelease(
          fromPromiseInterruptible(
            signal =>
              model.createEmbeddingContext({
                contextSize: options.contextSize,
                createSignal: signal,
                ignoreMemorySafetyChecks: false,
                threads: nativeInferenceThreads(llama),
              }),
            cause => modelLoadError(options, cause, 'embedding context'),
          ),
          native => disposeIgnoringFailure(native),
        );
        return embeddingSession(options, model, context);
      }),
    loadGenerationSession: options =>
      Effect.gen(function* () {
        const model = yield* acquireModel(llama, options);
        if (!model.createContext || !llama.createGrammarForJsonSchema || !module.LlamaChatSession) {
          return yield* new ModelLoadFailed({
            cause: new Error('Installed node-llama-cpp runtime does not expose structured generation APIs.'),
            message: `Could not load structured generation for ${options.modelId}.`,
            modelId: options.modelId,
          });
        }
        return generationSession(options, model, llama, module.LlamaChatSession);
      }),
    loadRankingSession: options =>
      Effect.gen(function* () {
        const model = yield* acquireModel(llama, options);
        const context = yield* Effect.acquireRelease(
          fromPromiseInterruptible(
            signal =>
              model.createRankingContext({
                contextSize: options.contextSize,
                createSignal: signal,
                ignoreMemorySafetyChecks: false,
                threads: nativeInferenceThreads(llama),
              }),
            cause => modelLoadError(options, cause, 'ranking context'),
          ),
          native => disposeIgnoringFailure(native),
        );
        return rankingSession(options, context);
      }),
  };
}

function generationSession(
  options: LocalModelLoadOptions,
  model: NativeModel,
  llama: NativeLlama,
  ChatSession: NonNullable<NodeLlamaCppModule['LlamaChatSession']>,
): LlamaGenerationSession {
  return {
    generate: request =>
      Effect.scoped(
        Effect.gen(function* () {
          const createContext = model.createContext;
          const createGrammar = llama.createGrammarForJsonSchema;
          if (!createContext || !createGrammar) {
            return yield* new GenerationFailed({
              cause: new Error('Structured generation APIs became unavailable.'),
              message: `Structured generation with ${options.modelId} is unavailable.`,
              modelId: options.modelId,
            });
          }
          const context = yield* Effect.acquireRelease(
            fromPromiseInterruptible(
              signal =>
                createContext.call(model, {
                  contextSize: options.contextSize,
                  createSignal: signal,
                  ignoreMemorySafetyChecks: false,
                  sequences: 1,
                  threads: nativeInferenceThreads(llama),
                }),
              cause => modelLoadError(options, cause, 'generation context'),
            ),
            native => disposeIgnoringFailure(native),
          ).pipe(
            Effect.mapError(
              cause =>
                new GenerationFailed({
                  cause,
                  message: `Could not create a generation context for ${options.modelId}: ${errorMessage(cause)}`,
                  modelId: options.modelId,
                }),
            ),
          );
          const grammar = yield* fromPromiseInterruptible(
            () => createGrammar.call(llama, request.jsonSchema),
            cause =>
              new GenerationFailed({
                cause,
                message: `Could not create JSON grammar for ${options.modelId}.`,
                modelId: options.modelId,
              }),
          );
          const session = yield* Effect.acquireRelease(
            Effect.sync(
              () =>
                new ChatSession({
                  contextSequence: context.getSequence(),
                  systemPrompt: request.system,
                }),
            ),
            native => Effect.sync(() => native.dispose({disposeSequence: false})),
          );
          const output = yield* fromPromiseInterruptible(
            signal =>
              session.prompt(request.prompt, {
                grammar,
                maxTokens: request.maxTokens,
                seed: request.seed,
                signal,
                temperature: 0,
              }),
            cause =>
              isAbortError(cause)
                ? new InferenceInterrupted({
                    message: `Generation with ${options.modelId} was interrupted.`,
                    modelId: options.modelId,
                    operation: 'generate',
                  })
                : new GenerationFailed({
                    cause,
                    message: `Generation with ${options.modelId} failed: ${errorMessage(cause)}`,
                    modelId: options.modelId,
                  }),
          );
          return yield* Effect.try({
            try: () => grammar.parse(output),
            catch: () =>
              new InvalidModelOutput({
                message: `Generation model ${options.modelId} returned output that did not match its JSON schema.`,
                modelId: options.modelId,
              }),
          });
        }),
      ),
    modelId: options.modelId,
  };
}

function acquireModel(llama: NativeLlama, options: LocalModelLoadOptions) {
  return Effect.acquireRelease(
    fromPromiseInterruptible(
      signal =>
        llama.loadModel({
          ignoreMemorySafetyChecks: false,
          loadSignal: signal,
          modelPath: options.modelPath,
        }),
      cause => modelLoadError(options, cause, 'model'),
    ),
    model => disposeIgnoringFailure(model),
  );
}

function embeddingSession(
  options: LocalModelLoadOptions & {readonly dimensions: number},
  model: NativeModel,
  context: NativeEmbeddingContext,
): LlamaEmbeddingSession {
  return {
    dimensions: options.dimensions,
    embedMany: inputs =>
      fromPromiseInterruptible(
        signal => {
          const disposeOnAbort = () => {
            void context.dispose();
          };
          signal.addEventListener('abort', disposeOnAbort, {once: true});
          return embedInputsSequentially(model, context, inputs, options.contextSize).finally(() => {
            signal.removeEventListener('abort', disposeOnAbort);
          });
        },
        cause =>
          isAbortError(cause)
            ? new InferenceInterrupted({
                message: `Embedding with ${options.modelId} was interrupted.`,
                modelId: options.modelId,
                operation: 'embed',
              })
            : new EmbeddingFailed({
                cause,
                message: `Embedding with ${options.modelId} failed: ${errorMessage(cause)}`,
                modelId: options.modelId,
              }),
      ).pipe(
        Effect.flatMap(embeddings => {
          const vectors = embeddings.map(embedding => embedding.vector);
          const invalid = vectors.find(
            vector => vector.length !== options.dimensions || vector.some(component => !Number.isFinite(component)),
          );
          return invalid
            ? Effect.fail(
                new EmbeddingFailed({
                  cause: invalid,
                  message: `Embedding model ${options.modelId} returned an invalid vector; expected ${options.dimensions} finite dimensions.`,
                  modelId: options.modelId,
                }),
              )
            : Effect.succeed(vectors);
        }),
      ),
    modelId: options.modelId,
  };
}

async function embeddingForInput(
  model: NativeModel,
  context: NativeEmbeddingContext,
  input: string,
  contextSize: number | undefined,
): Promise<NativeEmbedding> {
  const windows = embeddingInputWindows(model, input, contextSize);
  if (windows.length === 1) {
    return context.getEmbeddingFor(windows[0]!.text);
  }
  const embeddings: NativeEmbedding[] = [];
  for (const window of windows) {
    embeddings.push(await context.getEmbeddingFor(window.text));
  }
  const dimensions = embeddings[0]?.vector.length ?? 0;
  const pooled = new Array<number>(dimensions).fill(0);
  let totalWeight = 0;
  for (const [index, embedding] of embeddings.entries()) {
    const weight = windows[index]!.weight;
    totalWeight += weight;
    for (let dimension = 0; dimension < dimensions; dimension += 1) {
      pooled[dimension] += (embedding.vector[dimension] ?? 0) * weight;
    }
  }
  if (totalWeight > 0) {
    for (let dimension = 0; dimension < dimensions; dimension += 1) {
      pooled[dimension] /= totalWeight;
    }
  }
  const magnitude = Math.sqrt(pooled.reduce((sum, value) => sum + value * value, 0));
  return {vector: magnitude > 0 ? pooled.map(value => value / magnitude) : pooled};
}

async function embedInputsSequentially(
  model: NativeModel,
  context: NativeEmbeddingContext,
  inputs: readonly string[],
  contextSize: number | undefined,
): Promise<readonly NativeEmbedding[]> {
  const embeddings: NativeEmbedding[] = [];
  for (const input of inputs) {
    embeddings.push(await embeddingForInput(model, context, input, contextSize));
  }
  return embeddings;
}

function embeddingInputWindows(
  model: NativeModel,
  input: string,
  contextSize: number | undefined,
): readonly {readonly text: string; readonly weight: number}[] {
  if (contextSize === undefined || contextSize <= EMBEDDING_CONTEXT_TOKEN_RESERVE + 1) {
    return [{text: input, weight: 1}];
  }
  const maximumTokens = contextSize - EMBEDDING_CONTEXT_TOKEN_RESERVE;
  const tokens = model.tokenize(input, false);
  if (tokens.length <= maximumTokens) {
    return [{text: input, weight: Math.max(1, tokens.length)}];
  }
  const overlapTokens = Math.min(EMBEDDING_WINDOW_OVERLAP_TOKENS, Math.max(1, Math.floor(maximumTokens / 8)));
  const windows: Array<{readonly text: string; readonly weight: number}> = [];
  for (let start = 0; start < tokens.length;) {
    const end = Math.min(tokens.length, start + maximumTokens);
    const windowTokens = tokens.slice(start, end);
    const text = model.detokenize(windowTokens, false);
    if (text.length > 0) {
      windows.push({text, weight: windowTokens.length});
    }
    if (end >= tokens.length) break;
    start = end - overlapTokens;
  }
  return windows.length > 0 ? windows : [{text: input, weight: 1}];
}

function rankingSession(options: LocalModelLoadOptions, context: NativeRankingContext): LlamaRankingSession {
  return {
    modelId: options.modelId,
    rank: (query, documents) =>
      fromPromiseInterruptible(
        signal => {
          const disposeOnAbort = () => {
            void context.dispose();
          };
          signal.addEventListener('abort', disposeOnAbort, {once: true});
          return context.rankAll(query, [...documents]).finally(() => {
            signal.removeEventListener('abort', disposeOnAbort);
          });
        },
        cause =>
          isAbortError(cause)
            ? new InferenceInterrupted({
                message: `Reranking with ${options.modelId} was interrupted.`,
                modelId: options.modelId,
                operation: 'rerank',
              })
            : new RerankingFailed({
                cause,
                message: `Reranking with ${options.modelId} failed: ${errorMessage(cause)}`,
                modelId: options.modelId,
              }),
      ).pipe(
        Effect.flatMap(scores =>
          scores.length !== documents.length || scores.some(score => !Number.isFinite(score))
            ? Effect.fail(
                new RerankingFailed({
                  cause: scores,
                  message: `Reranker ${options.modelId} returned ${scores.length} invalid scores for ${documents.length} documents.`,
                  modelId: options.modelId,
                }),
              )
            : Effect.succeed(scores),
        ),
      ),
  };
}

function modelLoadError(options: LocalModelLoadOptions, cause: unknown, resource: string) {
  if (isMissingFile(cause)) {
    return new ModelNotInstalled({
      message: `Model ${options.modelId} is not installed.`,
      modelId: options.modelId,
      path: options.modelPath,
    });
  }
  if (isInsufficientMemory(cause)) {
    return new InsufficientMemory({
      cause,
      message: `There is not enough memory to load the ${resource} for ${options.modelId}.`,
      modelId: options.modelId,
    });
  }
  return new ModelLoadFailed({
    cause,
    message: `Could not load the ${resource} for ${options.modelId}: ${errorMessage(cause)}`,
    modelId: options.modelId,
  });
}

function disposeIgnoringFailure(resource: {readonly disposed: boolean; readonly dispose: () => Promise<void>}) {
  return resource.disposed
    ? Effect.void
    : fromPromiseInterruptible(
        () => resource.dispose(),
        () => undefined,
      ).pipe(Effect.ignore);
}

function errorMessage(cause: unknown): string {
  return cause instanceof Error ? cause.message : String(cause);
}

function errorName(cause: unknown): string | undefined {
  if (cause instanceof Error) {
    return cause.name && cause.name !== 'Error' ? cause.name : cause.constructor.name;
  }
  return typeof cause === 'object' && cause !== null && 'name' in cause ? String(cause.name) : undefined;
}

function isAbortError(cause: unknown): boolean {
  return errorName(cause) === 'AbortError';
}

function isInsufficientMemory(cause: unknown): boolean {
  return errorName(cause) === 'InsufficientMemoryError';
}

function isMissingFile(cause: unknown): boolean {
  return (
    errorName(cause) === 'ENOENT' ||
    (typeof cause === 'object' && cause !== null && 'code' in cause && cause.code === 'ENOENT')
  );
}

function isNoBinaryFound(cause: unknown): boolean {
  return errorName(cause) === 'NoBinaryFoundError';
}
