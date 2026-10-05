// Embedder implementation with Transformers.js

import {
  type DataType,
  type DeviceType,
  env,
  ModelRegistry,
  pipeline,
} from '@huggingface/transformers'
import { toError } from '../utils/errors.js'
import { isObjectLike } from '../utils/type-guards.js'
import { EmbeddingError } from './errors.js'
import { type EmbeddingInference, resolveInference } from './inference.js'
import { getInputPrefix, resolveDocumentPrefix } from './prefixes.js'
import type { EmbeddingPipeline, EmbeddingType, PipelineTokenizer } from './types.js'

export { EmbeddingError } from './errors.js'
export type { PipelineTokenizer } from './types.js'

// ============================================
// Type Definitions
// ============================================

/**
 * Embedder configuration
 */
export interface EmbedderConfig {
  /** HuggingFace model path */
  modelPath: string
  /** Batch size */
  batchSize: number
  /** Model cache directory */
  cacheDir: string
  /** Device type */
  device?: string
  /**
   * Quantization dtype, passed through to transformers.js with no allowlist.
   * `undefined` means unset, which `initialize()` resolves to fp32 — the
   * distinction gates failure-path error enrichment, so keep it.
   */
  dtype?: string
  /**
   * Embed document chunks behind a `Title:` line naming their document
   * (default: false). Fallback for models without a native prefix policy.
   */
  titlePrefix?: boolean
  /** Add section paths to chunk embeddings when they fit (default: false). */
  headingPrefix?: boolean
}

interface IndexedEmbeddingInput {
  text: string
  originalIndex: number
  tokenLength: number
}

/** True when the loaded pipeline exposes the call and tokenizer surface used here. */
function isEmbeddingPipeline(value: unknown): value is EmbeddingPipeline {
  return (
    typeof value === 'function' && 'tokenizer' in value && typeof value.tokenizer === 'function'
  )
}

// ============================================
// Token Limit Clamp
// ============================================

/** Above this a reported length is a sentinel, such as `bge-large-zh-v1.5`'s `1e30`. */
const MAX_PLAUSIBLE_TOKENS = 1e6

/**
 * Withheld on the window-only branch, where no tokenizer limit is trustworthy:
 * the RoBERTa family's padding-index offset makes the usable window
 * `max_position_embeddings - 2`.
 */
const RESERVED_POSITIONS = 2

export interface TokenLimitClamp {
  /** The effective token cap, or `null` for degraded mode (no cap, no clamp). */
  tokenLimit: number | null
  /** The pre-clamp tokenizer, for measuring true lengths. */
  measurementTokenizer: PipelineTokenizer | null
}

/** A reported length usable as a limit, or `null` when it is absent or a sentinel. */
function usableTokenLimit(value: unknown): number | null {
  if (typeof value !== 'number' || !Number.isFinite(value)) {
    return null
  }
  return value >= 1 && value <= MAX_PLAUSIBLE_TOKENS ? Math.floor(value) : null
}

function readPositionWindow(candidate: EmbeddingPipeline): number | null {
  return usableTokenLimit(candidate.model?.config?.max_position_embeddings)
}

function resolveEffectiveCap(
  positionWindow: number | null,
  tokenizerLimit: number | null
): number | null {
  if (positionWindow === null) {
    return tokenizerLimit
  }
  if (tokenizerLimit !== null) {
    return Math.min(positionWindow, tokenizerLimit)
  }
  // A window narrower than the reserve cannot yield a positive cap.
  return Math.max(1, positionWindow - RESERVED_POSITIONS)
}

/**
 * Bound the pipeline's tokenization length to the model's position window, by
 * installing a proxy on `candidate`'s tokenizer.
 *
 * The pipeline tokenizes with no `max_length`, which resolves to
 * `model_max_length ?? Infinity` and then to the batch's longest sequence, so a
 * model whose `tokenizer_config.json` omits a real limit sends more positions
 * than it has position embeddings and onnxruntime fails in the
 * position-embedding `Add` node (#202).
 *
 * The measurement tokenizer is captured before the proxy, so measurement
 * reports true lengths. A `Proxy` is used because `model_max_length` is a getter
 * with no setter. An unrecognized shape, or no usable limit, leaves `candidate`
 * untouched.
 */
export function installTokenLimitClamp(candidate: unknown): TokenLimitClamp {
  if (!isEmbeddingPipeline(candidate)) {
    return { tokenLimit: null, measurementTokenizer: null }
  }

  const measurementTokenizer = candidate.tokenizer
  const tokenizerLimit = usableTokenLimit(measurementTokenizer.model_max_length)
  const tokenLimit = resolveEffectiveCap(readPositionWindow(candidate), tokenizerLimit)
  if (tokenLimit === null) {
    return { tokenLimit: null, measurementTokenizer }
  }

  candidate.tokenizer = new Proxy(measurementTokenizer, {
    apply(target, thisArg, args: unknown[]) {
      const [input, options] = args
      const clamped = {
        ...(isObjectLike(options) ? options : {}),
        max_length: tokenLimit,
        truncation: true,
      }
      return Reflect.apply(target, thisArg, [input, clamped])
    },
  })

  return { tokenLimit, measurementTokenizer }
}

/** True when every entry exposes the numeric `length` the batching math reads. */
function isTokenLengthArray(value: unknown): value is { length: number }[] {
  return (
    Array.isArray(value) &&
    value.every(
      (entry) =>
        typeof entry === 'object' &&
        entry !== null &&
        'length' in entry &&
        typeof entry.length === 'number'
    )
  )
}

// Keep estimated padding waste below one-third of dense self-attention work.
const MAX_PADDING_AMPLIFICATION = 1.5

function estimatePaddingAmplification(inputs: IndexedEmbeddingInput[]): number {
  let maxTokenLength = 0
  let individualWork = 0
  for (const input of inputs) {
    maxTokenLength = Math.max(maxTokenLength, input.tokenLength)
    individualWork += input.tokenLength ** 2
  }
  return (inputs.length * maxTokenLength ** 2) / individualWork
}

function deferBatchOutliers(inputs: IndexedEmbeddingInput[]): {
  batch: IndexedEmbeddingInput[]
  deferred: IndexedEmbeddingInput[]
} {
  const batch = [...inputs]
  const deferred: IndexedEmbeddingInput[] = []

  while (batch.length > 1) {
    if (estimatePaddingAmplification(batch) <= MAX_PADDING_AMPLIFICATION) {
      break
    }

    let longestIndex = 0
    let longestTokens = batch[0]?.tokenLength ?? 0
    for (let index = 1; index < batch.length; index++) {
      const tokenLength = batch[index]?.tokenLength ?? 0
      if (tokenLength > longestTokens) {
        longestIndex = index
        longestTokens = tokenLength
      }
    }

    const longest = batch[longestIndex]
    if (longest === undefined) {
      break
    }
    deferred.push(longest)
    batch.splice(longestIndex, 1)
  }

  return { batch, deferred }
}

// ============================================
// Embedder Class
// ============================================

/** Transformers.js wrapper: lazily loaded model, batched embedding. */
export class Embedder {
  // Using unknown to avoid TS2590 (union type too complex with @types/jsdom)
  private model: unknown = null
  private initPromise: Promise<void> | null = null
  /** The resolved cap, or `null` before initialization and in degraded mode. */
  private tokenLimit: number | null = null
  /** The pre-clamp tokenizer, so measurement never reports clamped lengths. */
  private measurementTokenizer: PipelineTokenizer | null = null
  /**
   * One-shot flags, per instance: each state belongs to this embedder's model.
   * They survive `dispose()`; re-initialization is not new information.
   */
  private truncationWarned: boolean = false
  private degradedModeWarned: boolean = false
  private readonly config: EmbedderConfig
  private readonly inference: EmbeddingInference

  constructor(config: EmbedderConfig) {
    this.config = config
    this.inference = resolveInference(config.modelPath)
  }

  get headingPrefix(): boolean {
    return this.config.headingPrefix ?? false
  }

  /** Retrieval document header; callers add it once, after semantic chunking. */
  async getDocumentPrefix(title?: string | null): Promise<string> {
    return resolveDocumentPrefix(
      this.config.modelPath,
      this.config.titlePrefix ?? false,
      title,
      async () => ({
        cap: await this.getTokenLimit(),
        countTokens: (texts) => this.countTokens(texts),
      })
    )
  }

  /**
   * Release resources held by the Embedder pipeline
   */
  async dispose(): Promise<void> {
    const model: unknown = this.model
    const dispose = isObjectLike(model) ? model['dispose'] : undefined
    if (typeof dispose === 'function') {
      try {
        await dispose.call(model)
      } catch (error) {
        console.error('Error disposing embedder model:', error)
      }
    }
    this.model = null
    this.initPromise = null
    this.tokenLimit = null
    this.measurementTokenizer = null
  }

  /**
   * Initialize Transformers.js model
   */
  async initialize(): Promise<void> {
    // Skip if already initialized
    if (this.model) {
      return
    }

    // Set cache directory BEFORE creating pipeline
    env.cacheDir = this.config.cacheDir
    if (process.env['HF_ENDPOINT']) {
      env.remoteHost = process.env['HF_ENDPOINT']
    }

    // No fallback — if the requested device fails, init throws.
    const device = this.config.device || 'cpu'

    console.error(`Embedder: Setting cache directory to "${this.config.cacheDir}"`)
    console.error(`Embedder: Loading model "${this.config.modelPath}" on device "${device}"...`)

    try {
      this.model = await pipeline('feature-extraction', this.config.modelPath, {
        // The sole fp32 default literal. Both values pass through
        // un-allowlisted (see `resolveDevice`) into a closed literal union.
        // biome-ignore lint/nursery/noUnsafeTypeAssertion: un-allowlisted passthrough to a closed literal union
        dtype: (this.config.dtype ?? 'fp32') as DataType,
        // biome-ignore lint/nursery/noUnsafeTypeAssertion: un-allowlisted passthrough to a closed literal union
        device: device as DeviceType,
      })
      const clamp = installTokenLimitClamp(this.model)
      this.tokenLimit = clamp.tokenLimit
      this.measurementTokenizer = clamp.measurementTokenizer
      console.error(`Embedder: Model loaded successfully (device=${device})`)
    } catch (error) {
      const nativeError = toError(error)

      // Only enrich when RAG_DTYPE was explicitly set (unset is `undefined` per
      // TD-5). Enrichment never runs on the happy path and never on the unset
      // path, so normal operation adds zero network. Always re-throw — an
      // unavailable dtype fails loud, never silently downgrades (TD-2).
      const message = await this.enrichDtypeFailureMessage(nativeError.message)
      throw new EmbeddingError(message, { cause: nativeError })
    }
  }

  /**
   * Best-effort failure-path enrichment for an explicit `RAG_DTYPE`: name the
   * dtypes the model does provide when the requested one is absent.
   *
   * The enumeration is a Hub network call in its own try/catch, so an
   * air-gapped run degrades to a generic dtype-aware message instead of
   * surfacing a confusing secondary error. Never throws, and never converts
   * the load failure into a fallback — the caller always re-throws.
   */
  private async enrichDtypeFailureMessage(nativeMessage: string): Promise<string> {
    const requestedDtype = this.config.dtype
    if (requestedDtype === undefined) {
      return nativeMessage
    }

    try {
      const availableDtypes = await ModelRegistry.get_available_dtypes(this.config.modelPath)
      if (availableDtypes.includes(requestedDtype)) {
        // The requested dtype exists for this model, so the load failed for some
        // other reason — keep the native message, don't misattribute it to dtype.
        return nativeMessage
      }
      return `Model "${this.config.modelPath}" provides dtypes [${availableDtypes.join(', ')}]; requested dtype "${requestedDtype}" is unavailable. Set RAG_DTYPE to one of the available dtypes, or leave it unset for the fp32 default.`
    } catch {
      // Enumeration unavailable (e.g. offline). Degrade to a generic clear,
      // dtype-aware message — no secondary error, still re-thrown by the caller.
      return `Failed to load model "${this.config.modelPath}" with requested dtype "${requestedDtype}". The model may not provide this dtype, and the available-dtype list could not be retrieved. Set RAG_DTYPE to a dtype the model provides, or leave it unset for the fp32 default. (${nativeMessage})`
    }
  }

  /**
   * Ensure model is initialized (lazy initialization)
   * This method is called automatically by embed() and embedBatch()
   */
  private async ensureInitialized(): Promise<void> {
    // Already initialized
    if (this.model) {
      return
    }

    // Initialization already in progress, wait for it
    if (this.initPromise !== null) {
      await this.initPromise
      return
    }

    console.error(
      'Embedder: First use detected. Initializing model (downloading ~90MB, may take 1-2 minutes)...'
    )

    this.initPromise = this.initialize().catch((error) => {
      // Clear initPromise on failure to allow retry on the next call.
      this.initPromise = null
      throw error
    })

    await this.initPromise
  }

  /**
   * The effective token cap, or `null` when none could be resolved.
   *
   * Self-initializing: the value exists only after the model loads, and a
   * caller may need it before the first embedding.
   */
  async getTokenLimit(): Promise<number | null> {
    await this.ensureInitialized()
    if (this.tokenLimit === null) {
      this.warnDegradedMode()
    }
    return this.tokenLimit
  }

  /**
   * Report once that no cap was resolved. Warning here rather than in
   * `initialize()` covers every consumer, which all read the cap through
   * {@link getTokenLimit}.
   */
  private warnDegradedMode(): void {
    if (this.degradedModeWarned) {
      return
    }
    this.degradedModeWarned = true
    console.error(
      `Embedder: no position-window token limit could be resolved for model "${this.config.modelPath}". Inputs are not length-guarded and oversized input may fail at inference.`
    )
  }

  /**
   * The lengths batch planning runs on: `min(trueLength, cap)`, the length the
   * clamped pipeline actually feeds the model. Warns once when a true length
   * exceeds the cap.
   */
  private async planTokenLengths(texts: string[]): Promise<number[]> {
    const tokenLimit = await this.getTokenLimit()
    const trueLengths = await this.countTokens(texts)
    if (tokenLimit === null) {
      return trueLengths
    }

    let longestObserved = 0
    for (const length of trueLengths) {
      longestObserved = Math.max(longestObserved, length)
    }
    if (longestObserved > tokenLimit && !this.truncationWarned) {
      this.truncationWarned = true
      console.error(
        `Embedder: input exceeds the model token limit of ${tokenLimit} tokens (longest input measured ${longestObserved} tokens). Text past the limit is truncated before embedding.`
      )
    }
    return trueLengths.map((length) => Math.min(length, tokenLimit))
  }

  /**
   * The true token length of each text, in input order. Tokenization only, no
   * inference.
   *
   * Measured with `truncation: false` through the pre-clamp tokenizer, so a
   * length above {@link getTokenLimit} means inference will truncate. Throws
   * when no such tokenizer was captured, rather than returning a length
   * measured through an unknown surface.
   */
  async countTokens(texts: string[], type?: EmbeddingType): Promise<number[]> {
    if (texts.length === 0) {
      return []
    }

    await this.ensureInitialized()

    const tokenizer = this.measurementTokenizer
    if (tokenizer === null) {
      throw new EmbeddingError('Embedder tokenizer is unavailable for measurement')
    }

    const prefix = getInputPrefix(this.config.modelPath, type)
    const tokenized = tokenizer(prefix ? texts.map((text) => prefix + text) : texts, {
      padding: false,
      truncation: false,
      return_tensor: false,
    })
    const inputIds = tokenized?.input_ids
    if (!isTokenLengthArray(inputIds) || inputIds.length !== texts.length) {
      throw new EmbeddingError('Unexpected embedder tokenizer output shape')
    }
    return inputIds.map((ids) => ids.length)
  }

  /**
   * Single-text embedding; the vector dimension depends on the model.
   * Optional type prepares raw query/similarity input; omitted type accepts prepared text.
   *
   * Delegates to {@link embedBatch} so this path shares its clamp, measurement
   * and warning rather than reaching the pipeline unguarded.
   */
  async embed(text: string, type?: EmbeddingType): Promise<number[]> {
    const embeddings = await this.embedBatch([text], type)
    const embedding = embeddings[0]
    if (embedding === undefined) {
      throw new EmbeddingError('Missing embedder batch output row')
    }
    return embedding
  }

  /**
   * Batched embedding; the vector dimension depends on the model.
   * Optional type prepares raw query/similarity input; omitted type accepts prepared text.
   */
  async embedBatch(texts: string[], type?: EmbeddingType): Promise<number[][]> {
    // Nothing to embed → skip model init entirely.
    if (texts.length === 0) {
      return []
    }

    if (texts.some((text) => text.length === 0)) {
      throw new EmbeddingError('Cannot generate embedding for empty text')
    }

    const prefix = getInputPrefix(this.config.modelPath, type)
    if (prefix) {
      texts = texts.map((text) => prefix + text)
    }
    // Lazy initialization: initialize on first use if not already initialized
    await this.ensureInitialized()

    try {
      // True batched inference: the pipeline takes an array and returns one
      // [batchLen, dim] tensor per forward pass. Calling it once per text via
      // Promise.all made `batchSize` meaningless, since onnxruntime inference
      // is not parallelized that way. Mean-pooling honors the attention mask,
      // so per-row vectors match the single-text result.
      if (!isEmbeddingPipeline(this.model)) {
        throw new EmbeddingError('Embedder pipeline is not callable')
      }
      const modelCall = this.model
      // One measurement per call, so planning and truncation reporting cannot
      // disagree about a length.
      const plannedLengths = await this.planTokenLengths(texts)
      const embeddings: (number[] | undefined)[] = Array.from({ length: texts.length })
      const deferred: IndexedEmbeddingInput[] = []

      const embedInputs = async (inputs: IndexedEmbeddingInput[]): Promise<void> => {
        const output = await this.inference(
          modelCall,
          inputs.map((input) => input.text)
        )

        // Validate the output shape before slicing so a runtime/model contract
        // change surfaces as a clear error rather than silently wrong vectors.
        const dims = output?.dims
        const dim = Array.isArray(dims) ? dims[dims.length - 1] : undefined
        const data = output?.data
        if (
          !(data instanceof Float32Array) ||
          typeof dim !== 'number' ||
          dim <= 0 ||
          data.length !== inputs.length * dim
        ) {
          throw new EmbeddingError('Unexpected embedder batch output shape')
        }

        for (const [row, input] of inputs.entries()) {
          embeddings[input.originalIndex] = Array.from(data.subarray(row * dim, (row + 1) * dim))
        }
      }

      for (let i = 0; i < texts.length; i += this.config.batchSize) {
        const batchTexts = texts.slice(i, i + this.config.batchSize)
        const indexedInputs = batchTexts.map((text, batchIndex) => {
          const originalIndex = i + batchIndex
          const tokenLength = plannedLengths[originalIndex]
          if (tokenLength === undefined) {
            throw new EmbeddingError('Unexpected embedder tokenizer output shape')
          }
          return { text, originalIndex, tokenLength }
        })
        const selected = deferBatchOutliers(indexedInputs)
        deferred.push(...selected.deferred)
        await embedInputs(selected.batch)
      }

      for (const input of deferred) {
        await embedInputs([input])
      }

      const complete = embeddings.filter(
        (embedding): embedding is number[] => embedding !== undefined
      )
      if (complete.length !== embeddings.length) {
        throw new EmbeddingError('Missing embedder batch output row')
      }
      return complete
    } catch (error) {
      if (error instanceof EmbeddingError) {
        throw error
      }
      throw new EmbeddingError(`Failed to generate batch embeddings: ${toError(error).message}`, {
        cause: toError(error),
      })
    }
  }
}
