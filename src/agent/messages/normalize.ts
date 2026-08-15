import { feature } from 'bun:bundle'
import type {
  ContentBlock,
  ContentBlockParam,
  RedactedThinkingBlock,
  RedactedThinkingBlockParam,
  TextBlockParam,
  ThinkingBlock,
  ThinkingBlockParam,
  ToolResultBlockParam,
  ToolUseBlock,
  ToolUseBlockParam,
} from '@anthropic-ai/sdk/resources/index.mjs'
import type {
  BetaContentBlock,
  BetaMessage,
  BetaRedactedThinkingBlock,
  BetaThinkingBlock,
} from '@anthropic-ai/sdk/resources/beta/messages/messages.mjs'
import isObject from 'lodash-es/isObject.js'
import last from 'lodash-es/last.js'
import {
  type AnalyticsMetadata_I_VERIFIED_THIS_IS_NOT_CODE_OR_FILEPATHS,
  logEvent,
} from 'src/platform/analytics/index.js'
import { sanitizeToolNameForAnalytics } from 'src/platform/analytics/metadata.js'
import type { AgentId } from 'src/types/ids.js'
import { NO_CONTENT_MESSAGE } from 'src/constants/messages.js'
import {
  checkStatsigFeatureGate_CACHED_MAY_BE_STALE,
} from 'src/platform/analytics/growthbook.js'
import {
  getImageTooLargeErrorMessage,
  getPdfInvalidErrorMessage,
  getPdfPasswordProtectedErrorMessage,
  getPdfTooLargeErrorMessage,
  getRequestTooLargeErrorMessage,
} from 'src/services/api/errors.js'
import {
  findToolByName,
  toolMatchesName,
  type Tools,
} from 'src/Tool.js'
import type {
  AssistantMessage,
  AttachmentMessage,
  Message,
  NormalizedAssistantMessage,
  NormalizedMessage,
  NormalizedUserMessage,
  SystemLocalCommandMessage,
  SystemMessage,
  UserMessage,
} from 'src/types/message.js'
import type { HookAttachment } from 'src/agent/attachments/attachments.js'
import { isAdvisorBlock } from 'src/platform/doctor/advisor.js'
import { isConnectorTextBlock } from 'src/types/connectorText.js'
import { normalizeToolInput, normalizeToolInputForAPI } from 'src/services/api/api.js'
import { logForDebugging } from 'src/shared/debug.js'
import { validateImagesForAPI } from 'src/terminal/image/imageValidation.js'
import { safeParseJSON } from 'src/shared/data/json.js'
import { logError } from 'src/shared/log.js'
import { getAPIProvider } from 'src/utils/model/providers.js'
import { normalizeLegacyToolName } from 'src/services/permissions/permissionRuleParser.js'
import { getStrictToolResultPairing } from 'src/platform/bootstrap/state.js'
import {
  isToolReferenceBlock,
  isToolSearchEnabledOptimistic,
} from 'src/agent/tools/toolSearch.js'
import {
  SYNTHETIC_MODEL,
  SYNTHETIC_TOOL_RESULT_PLACEHOLDER,
} from 'src/agent/messages/constants.js'
import { normalizeAttachmentForAPI } from 'src/agent/messages/attachments.js'
import { createUserMessage } from 'src/agent/messages/factories.js'
import {
  isSystemLocalCommandMessage,
  isToolUseRequestMessage,
  type ToolUseRequestMessage,
} from 'src/agent/messages/predicates.js'
import { deriveShortMessageId, deriveUUID, wrapInSystemReminder } from 'src/agent/messages/text.js'

const TOOL_REFERENCE_TURN_BOUNDARY = 'Tool loaded.'

function isSyntheticApiErrorMessage(
  message: Message,
): message is AssistantMessage & { isApiErrorMessage: true } {
  return (
    message.type === 'assistant' &&
    message.isApiErrorMessage === true &&
    message.message.model === SYNTHETIC_MODEL
  )
}

// Split messages, so each content block gets its own message
export function normalizeMessages(
  messages: AssistantMessage[],
): NormalizedAssistantMessage[]
export function normalizeMessages(
  messages: UserMessage[],
): NormalizedUserMessage[]
export function normalizeMessages(
  messages: (AssistantMessage | UserMessage)[],
): (NormalizedAssistantMessage | NormalizedUserMessage)[]
export function normalizeMessages(messages: Message[]): NormalizedMessage[]
export function normalizeMessages(messages: Message[]): NormalizedMessage[] {
  // isNewChain tracks whether we need to generate new UUIDs for messages when normalizing.
  // When a message has multiple content blocks, we split it into multiple messages,
  // each with a single content block. When this happens, we need to generate new UUIDs
  // for all subsequent messages to maintain proper ordering and prevent duplicate UUIDs.
  // This flag is set to true once we encounter a message with multiple content blocks,
  // and remains true for all subsequent messages in the normalization process.
  let isNewChain = false
  return messages.flatMap(message => {
    switch (message.type) {
      case 'assistant': {
        isNewChain = isNewChain || message.message.content.length > 1
        return message.message.content.map((_, index) => {
          const uuid = isNewChain
            ? deriveUUID(message.uuid, index)
            : message.uuid
          return {
            type: 'assistant' as const,
            timestamp: message.timestamp,
            message: {
              ...message.message,
              content: [_],
              context_management: message.message.context_management ?? null,
            },
            isMeta: message.isMeta,
            isVirtual: message.isVirtual,
            requestId: message.requestId,
            uuid,
            error: message.error,
            isApiErrorMessage: message.isApiErrorMessage,
            advisorModel: message.advisorModel,
          } as NormalizedAssistantMessage
        })
      }
      case 'attachment':
        return [message]
      case 'progress':
        return [message]
      case 'system':
        return [message]
      case 'user': {
        if (typeof message.message.content === 'string') {
          const uuid = isNewChain ? deriveUUID(message.uuid, 0) : message.uuid
          return [
            {
              ...message,
              uuid,
              message: {
                ...message.message,
                content: [{ type: 'text', text: message.message.content }],
              },
            } as NormalizedMessage,
          ]
        }
        isNewChain = isNewChain || message.message.content.length > 1
        let imageIndex = 0
        return message.message.content.map((_, index) => {
          const isImage = _.type === 'image'
          // For image content blocks, extract just the ID for this image
          const imageId =
            isImage && message.imagePasteIds
              ? message.imagePasteIds[imageIndex]
              : undefined
          if (isImage) imageIndex++
          return {
            ...createUserMessage({
              content: [_],
              toolUseResult: message.toolUseResult,
              mcpMeta: message.mcpMeta,
              isMeta: message.isMeta,
              isVisibleInTranscriptOnly: message.isVisibleInTranscriptOnly,
              isVirtual: message.isVirtual,
              timestamp: message.timestamp,
              imagePasteIds: imageId !== undefined ? [imageId] : undefined,
              origin: message.origin,
            }),
            uuid: isNewChain ? deriveUUID(message.uuid, index) : message.uuid,
          } as NormalizedMessage
        })
      }
    }
  })
}

// Re-order, to move result messages to be after their tool use messages
export function reorderMessagesInUI(
  messages: (
    | NormalizedUserMessage
    | NormalizedAssistantMessage
    | AttachmentMessage
    | SystemMessage
  )[],
  syntheticStreamingToolUseMessages: NormalizedAssistantMessage[],
): (
  | NormalizedUserMessage
  | NormalizedAssistantMessage
  | AttachmentMessage
  | SystemMessage
)[] {
  // Maps tool use ID to its related messages
  const toolUseGroups = new Map<
    string,
    {
      toolUse: ToolUseRequestMessage | null
      preHooks: AttachmentMessage[]
      toolResult: NormalizedUserMessage | null
      postHooks: AttachmentMessage[]
    }
  >()

  // First pass: group messages by tool use ID
  for (const message of messages) {
    // Handle tool use messages
    if (isToolUseRequestMessage(message)) {
      const toolUseID = message.message.content[0]?.id
      if (toolUseID) {
        if (!toolUseGroups.has(toolUseID)) {
          toolUseGroups.set(toolUseID, {
            toolUse: null,
            preHooks: [],
            toolResult: null,
            postHooks: [],
          })
        }
        toolUseGroups.get(toolUseID)!.toolUse = message
      }
      continue
    }

    // Handle pre-tool-use hooks
    if (
      isHookAttachmentMessage(message) &&
      message.attachment.hookEvent === 'PreToolUse'
    ) {
      const toolUseID = message.attachment.toolUseID
      if (!toolUseGroups.has(toolUseID)) {
        toolUseGroups.set(toolUseID, {
          toolUse: null,
          preHooks: [],
          toolResult: null,
          postHooks: [],
        })
      }
      toolUseGroups.get(toolUseID)!.preHooks.push(message)
      continue
    }

    // Handle tool results
    if (
      message.type === 'user' &&
      message.message.content[0]?.type === 'tool_result'
    ) {
      const toolUseID = message.message.content[0].tool_use_id
      if (!toolUseGroups.has(toolUseID)) {
        toolUseGroups.set(toolUseID, {
          toolUse: null,
          preHooks: [],
          toolResult: null,
          postHooks: [],
        })
      }
      toolUseGroups.get(toolUseID)!.toolResult = message
      continue
    }

    // Handle post-tool-use hooks
    if (
      isHookAttachmentMessage(message) &&
      message.attachment.hookEvent === 'PostToolUse'
    ) {
      const toolUseID = message.attachment.toolUseID
      if (!toolUseGroups.has(toolUseID)) {
        toolUseGroups.set(toolUseID, {
          toolUse: null,
          preHooks: [],
          toolResult: null,
          postHooks: [],
        })
      }
      toolUseGroups.get(toolUseID)!.postHooks.push(message)
      continue
    }
  }

  // Second pass: reconstruct the message list in the correct order
  const result: (
    | NormalizedUserMessage
    | NormalizedAssistantMessage
    | AttachmentMessage
    | SystemMessage
  )[] = []
  const processedToolUses = new Set<string>()

  for (const message of messages) {
    // Check if this is a tool use
    if (isToolUseRequestMessage(message)) {
      const toolUseID = message.message.content[0]?.id
      if (toolUseID && !processedToolUses.has(toolUseID)) {
        processedToolUses.add(toolUseID)
        const group = toolUseGroups.get(toolUseID)
        if (group && group.toolUse) {
          // Output in order: tool use, pre hooks, tool result, post hooks
          result.push(group.toolUse)
          result.push(...group.preHooks)
          if (group.toolResult) {
            result.push(group.toolResult)
          }
          result.push(...group.postHooks)
        }
      }
      continue
    }

    // Check if this message is part of a tool use group
    if (
      isHookAttachmentMessage(message) &&
      (message.attachment.hookEvent === 'PreToolUse' ||
        message.attachment.hookEvent === 'PostToolUse')
    ) {
      // Skip - already handled in tool use groups
      continue
    }

    if (
      message.type === 'user' &&
      message.message.content[0]?.type === 'tool_result'
    ) {
      // Skip - already handled in tool use groups
      continue
    }

    // Handle api error messages (only keep the last one)
    if (message.type === 'system' && message.subtype === 'api_error') {
      const last = result.at(-1)
      if (last?.type === 'system' && last.subtype === 'api_error') {
        result[result.length - 1] = message
      } else {
        result.push(message)
      }
      continue
    }

    // Add standalone messages
    result.push(message)
  }

  // Add synthetic streaming tool use messages
  for (const message of syntheticStreamingToolUseMessages) {
    result.push(message)
  }

  // Filter to keep only the last api error message
  const last = result.at(-1)
  return result.filter(
    _ => _.type !== 'system' || _.subtype !== 'api_error' || _ === last,
  )
}

export function isHookAttachmentMessage(
  message: Message,
): message is AttachmentMessage & { attachment: HookAttachment } {
  return (
    message.type === 'attachment' &&
    (message.attachment.type === 'hook_blocking_error' ||
      message.attachment.type === 'hook_cancelled' ||
      message.attachment.type === 'hook_error_during_execution' ||
      message.attachment.type === 'hook_non_blocking_error' ||
      message.attachment.type === 'hook_success' ||
      message.attachment.type === 'hook_system_message' ||
      message.attachment.type === 'hook_additional_context' ||
      message.attachment.type === 'hook_stopped_continuation')
  )
}

/**
 * Reorders messages so that attachments bubble up until they hit either:
 * - A tool call result (user message with tool_result content)
 * - Any assistant message
 */
export function reorderAttachmentsForAPI(messages: Message[]): Message[] {
  // We build `result` backwards (push) and reverse once at the end — O(N).
  // Using unshift inside the loop would be O(N²).
  const result: Message[] = []
  // Attachments are pushed as we encounter them scanning bottom-up, so
  // this buffer holds them in reverse order (relative to the input array).
  const pendingAttachments: AttachmentMessage[] = []

  // Scan from the bottom up
  for (let i = messages.length - 1; i >= 0; i--) {
    const message = messages[i]!

    if (message.type === 'attachment') {
      // Collect attachment to bubble up
      pendingAttachments.push(message)
    } else {
      // Check if this is a stopping point
      const isStoppingPoint =
        message.type === 'assistant' ||
        (message.type === 'user' &&
          Array.isArray(message.message.content) &&
          message.message.content[0]?.type === 'tool_result')

      if (isStoppingPoint && pendingAttachments.length > 0) {
        // Hit a stopping point — attachments stop here (go after the stopping point).
        // pendingAttachments is already reversed; after the final result.reverse()
        // they will appear in original order right after `message`.
        for (let j = 0; j < pendingAttachments.length; j++) {
          result.push(pendingAttachments[j]!)
        }
        result.push(message)
        pendingAttachments.length = 0
      } else {
        // Regular message
        result.push(message)
      }
    }
  }

  // Any remaining attachments bubble all the way to the top.
  for (let j = 0; j < pendingAttachments.length; j++) {
    result.push(pendingAttachments[j]!)
  }

  result.reverse()
  return result
}

/**
 * Strips tool_reference blocks for tools that no longer exist from tool_result content.
 * This handles the case where a session was saved with MCP tools that are no longer
 * available (e.g., MCP server was disconnected, renamed, or removed).
 * Without this filtering, the API rejects with "Tool reference not found in available tools".
 */
function stripUnavailableToolReferencesFromUserMessage(
  message: UserMessage,
  availableToolNames: Set<string>,
): UserMessage {
  const content = message.message.content
  if (!Array.isArray(content)) {
    return message
  }

  // Check if any tool_reference blocks point to unavailable tools
  const hasUnavailableReference = content.some(
    block =>
      block.type === 'tool_result' &&
      Array.isArray(block.content) &&
      block.content.some(c => {
        if (!isToolReferenceBlock(c)) return false
        const toolName = (c as { tool_name?: string }).tool_name
        return (
          toolName && !availableToolNames.has(normalizeLegacyToolName(toolName))
        )
      }),
  )

  if (!hasUnavailableReference) {
    return message
  }

  return {
    ...message,
    message: {
      ...message.message,
      content: content.map(block => {
        if (block.type !== 'tool_result' || !Array.isArray(block.content)) {
          return block
        }

        // Filter out tool_reference blocks for unavailable tools
        const filteredContent = block.content.filter(c => {
          if (!isToolReferenceBlock(c)) return true
          const rawToolName = (c as { tool_name?: string }).tool_name
          if (!rawToolName) return true
          const toolName = normalizeLegacyToolName(rawToolName)
          const isAvailable = availableToolNames.has(toolName)
          if (!isAvailable) {
            logForDebugging(
              `Filtering out tool_reference for unavailable tool: ${toolName}`,
              { level: 'warn' },
            )
          }
          return isAvailable
        })

        // If all content was filtered out, replace with a placeholder
        if (filteredContent.length === 0) {
          return {
            ...block,
            content: [
              {
                type: 'text' as const,
                text: '[Tool references removed - tools no longer available]',
              },
            ],
          }
        }

        return {
          ...block,
          content: filteredContent,
        }
      }),
    },
  }
}

/**
 * Appends a [id:...] message ID tag to the last text block of a user message.
 * Only mutates the API-bound copy, not the stored message.
 * This lets Claude reference message IDs when calling the snip tool.
 */
function appendMessageTagToUserMessage(message: UserMessage): UserMessage {
  if (message.isMeta) {
    return message
  }

  const tag = `\n[id:${deriveShortMessageId(message.uuid)}]`

  const content = message.message.content

  // Handle string content (most common for simple text input)
  if (typeof content === 'string') {
    return {
      ...message,
      message: {
        ...message.message,
        content: content + tag,
      },
    }
  }

  if (!Array.isArray(content) || content.length === 0) {
    return message
  }

  // Find the last text block
  let lastTextIdx = -1
  for (let i = content.length - 1; i >= 0; i--) {
    if (content[i]!.type === 'text') {
      lastTextIdx = i
      break
    }
  }
  if (lastTextIdx === -1) {
    return message
  }

  const newContent = [...content]
  const textBlock = newContent[lastTextIdx] as TextBlockParam
  newContent[lastTextIdx] = {
    ...textBlock,
    text: textBlock.text + tag,
  }

  return {
    ...message,
    message: {
      ...message.message,
      content: newContent as typeof content,
    },
  }
}

/**
 * Strips tool_reference blocks from tool_result content in a user message.
 * tool_reference blocks are only valid when the tool search beta is enabled.
 * When tool search is disabled, we need to remove these blocks to avoid API errors.
 */
export function stripToolReferenceBlocksFromUserMessage(
  message: UserMessage,
): UserMessage {
  const content = message.message.content
  if (!Array.isArray(content)) {
    return message
  }

  const hasToolReference = content.some(
    block =>
      block.type === 'tool_result' &&
      Array.isArray(block.content) &&
      block.content.some(isToolReferenceBlock),
  )

  if (!hasToolReference) {
    return message
  }

  return {
    ...message,
    message: {
      ...message.message,
      content: content.map(block => {
        if (block.type !== 'tool_result' || !Array.isArray(block.content)) {
          return block
        }

        // Filter out tool_reference blocks from tool_result content
        const filteredContent = block.content.filter(
          c => !isToolReferenceBlock(c),
        )

        // If all content was tool_reference blocks, replace with a placeholder
        if (filteredContent.length === 0) {
          return {
            ...block,
            content: [
              {
                type: 'text' as const,
                text: '[Tool references removed - tool search not enabled]',
              },
            ],
          }
        }

        return {
          ...block,
          content: filteredContent,
        }
      }),
    },
  }
}

/**
 * Strips the 'caller' field from tool_use blocks in an assistant message.
 * The 'caller' field is only valid when the tool search beta is enabled.
 * When tool search is disabled, we need to remove this field to avoid API errors.
 *
 * NOTE: This function only strips the 'caller' field - it does NOT normalize
 * tool inputs (that's done by normalizeToolInputForAPI in normalizeMessagesForAPI).
 * This is intentional: this helper is used for model-specific post-processing
 * AFTER normalizeMessagesForAPI has already run, so inputs are already normalized.
 */
export function stripCallerFieldFromAssistantMessage(
  message: AssistantMessage,
): AssistantMessage {
  const hasCallerField = message.message.content.some(
    block =>
      block.type === 'tool_use' && 'caller' in block && block.caller !== null,
  )

  if (!hasCallerField) {
    return message
  }

  return {
    ...message,
    message: {
      ...message.message,
      content: message.message.content.map(block => {
        if (block.type !== 'tool_use') {
          return block
        }
        // Explicitly construct with only standard API fields
        return {
          type: 'tool_use' as const,
          id: block.id,
          name: block.name,
          input: block.input,
          ...(getAPIProvider() === 'gemini' && (block as any).extra_content ? { extra_content: (block as any).extra_content } : {})
        }
      }),
    },
  }
}

/**
 * Does the content array have a tool_result block whose inner content
 * contains tool_reference (ToolSearch loaded tools)?
 */
function contentHasToolReference(
  content: ReadonlyArray<ContentBlockParam>,
): boolean {
  return content.some(
    block =>
      block.type === 'tool_result' &&
      Array.isArray(block.content) &&
      block.content.some(isToolReferenceBlock),
  )
}

/**
 * Ensure all text content in attachment-origin messages carries the
 * <system-reminder> wrapper. This makes the prefix a reliable discriminator
 * for the post-pass smoosh (smooshSystemReminderSiblings) — no need for every
 * normalizeAttachmentForAPI case to remember to wrap.
 *
 * Idempotent: already-wrapped text is unchanged.
 */
function ensureSystemReminderWrap(msg: UserMessage): UserMessage {
  const content = msg.message.content
  if (typeof content === 'string') {
    if (content.startsWith('<system-reminder>')) return msg
    return {
      ...msg,
      message: { ...msg.message, content: wrapInSystemReminder(content) },
    }
  }
  let changed = false
  const newContent = content.map(b => {
    if (b.type === 'text' && !b.text.startsWith('<system-reminder>')) {
      changed = true
      return { ...b, text: wrapInSystemReminder(b.text) }
    }
    return b
  })
  return changed
    ? { ...msg, message: { ...msg.message, content: newContent } }
    : msg
}

/**
 * Final pass: smoosh any `<system-reminder>`-prefixed text siblings into the
 * last tool_result of the same user message. Catches siblings from:
 * - PreToolUse hook additionalContext (Gap F: attachment between assistant and
 *   tool_result → standalone push → mergeUserMessages → hoist → sibling)
 * - relocateToolReferenceSiblings output (Gap E)
 * - any attachment-origin text that escaped merge-time smoosh
 *
 * Non-system-reminder text (real user input, TOOL_REFERENCE_TURN_BOUNDARY,
 * context-collapse `<collapsed>` summaries) stays untouched — a Human: boundary
 * before actual user input is semantically correct. A/B (sai-20260310-161901,
 * Arm B) confirms: real user input left as sibling + 2 SR-text teachers
 * removed → 0%.
 *
 * Idempotent. Pure function of shape.
 */
function smooshSystemReminderSiblings(
  messages: (UserMessage | AssistantMessage)[],
): (UserMessage | AssistantMessage)[] {
  return messages.map(msg => {
    if (msg.type !== 'user') return msg
    const content = msg.message.content
    if (!Array.isArray(content)) return msg

    const hasToolResult = content.some(b => b.type === 'tool_result')
    if (!hasToolResult) return msg

    const srText: TextBlockParam[] = []
    const kept: ContentBlockParam[] = []
    for (const b of content) {
      if (b.type === 'text' && b.text.startsWith('<system-reminder>')) {
        srText.push(b)
      } else {
        kept.push(b)
      }
    }
    if (srText.length === 0) return msg

    // Smoosh into the LAST tool_result (positionally adjacent in rendered prompt)
    const lastTrIdx = kept.findLastIndex(b => b.type === 'tool_result')
    const lastTr = kept[lastTrIdx] as ToolResultBlockParam
    const smooshed = smooshIntoToolResult(lastTr, srText)
    if (smooshed === null) return msg // tool_ref constraint — leave alone

    const newContent = [
      ...kept.slice(0, lastTrIdx),
      smooshed,
      ...kept.slice(lastTrIdx + 1),
    ]
    return {
      ...msg,
      message: { ...msg.message, content: newContent },
    }
  })
}

/**
 * Strip non-text blocks from is_error tool_results — the API rejects the
 * combination with "all content must be type text if is_error is true".
 *
 * Read-side guard for transcripts persisted before smooshIntoToolResult
 * learned to filter on is_error. Without this a resumed session with one
 * of these 400s on every call and can't be recovered by /fork. Adjacent
 * text left behind by a stripped image is re-merged.
 */
function sanitizeErrorToolResultContent(
  messages: (UserMessage | AssistantMessage)[],
): (UserMessage | AssistantMessage)[] {
  return messages.map(msg => {
    if (msg.type !== 'user') return msg
    const content = msg.message.content
    if (!Array.isArray(content)) return msg

    let changed = false
    const newContent = content.map(b => {
      if (b.type !== 'tool_result' || !b.is_error) return b
      const trContent = b.content
      if (!Array.isArray(trContent)) return b
      if (trContent.every(c => c.type === 'text')) return b
      changed = true
      const texts = trContent.filter(c => c.type === 'text').map(c => c.text)
      const textOnly: TextBlockParam[] =
        texts.length > 0 ? [{ type: 'text', text: texts.join('\n\n') }] : []
      return { ...b, content: textOnly }
    })
    if (!changed) return msg
    return { ...msg, message: { ...msg.message, content: newContent } }
  })
}

/**
 * Move text-block siblings off user messages that contain tool_reference.
 *
 * When a tool_result contains tool_reference, the server expands it to a
 * functions block. Any text siblings appended to that same user message
 * (auto-memory, skill reminders, etc.) create a second human-turn segment
 * right after the functions-close tag — an anomalous pattern the model
 * imprints on. At a later tool-results tail, the model completes the
 * pattern and emits the stop sequence. See #21049 for mechanism and
 * five-arm dose-response.
 *
 * The fix: find the next user message with tool_result content but NO
 * tool_reference, and move the text siblings there. Pure transformation —
 * no state, no side effects. The target message's existing siblings (if any)
 * are preserved; moved blocks append.
 *
 * If no valid target exists (tool_reference message is at/near the tail),
 * siblings stay in place. That's safe: a tail ending in a human turn (with
 * siblings) gets an Assistant: cue before generation; only a tail ending
 * in bare tool output (no siblings) lacks the cue.
 *
 * Idempotent: after moving, the source has no text siblings; second pass
 * finds nothing to move.
 */
function relocateToolReferenceSiblings(
  messages: (UserMessage | AssistantMessage)[],
): (UserMessage | AssistantMessage)[] {
  const result = [...messages]

  for (let i = 0; i < result.length; i++) {
    const msg = result[i]!
    if (msg.type !== 'user') continue
    const content = msg.message.content
    if (!Array.isArray(content)) continue
    if (!contentHasToolReference(content)) continue

    const textSiblings = content.filter(b => b.type === 'text')
    if (textSiblings.length === 0) continue

    // Find the next user message with tool_result but no tool_reference.
    // Skip tool_reference-containing targets — moving there would just
    // recreate the problem one position later.
    let targetIdx = -1
    for (let j = i + 1; j < result.length; j++) {
      const cand = result[j]!
      if (cand.type !== 'user') continue
      const cc = cand.message.content
      if (!Array.isArray(cc)) continue
      if (!cc.some(b => b.type === 'tool_result')) continue
      if (contentHasToolReference(cc)) continue
      targetIdx = j
      break
    }

    if (targetIdx === -1) continue // No valid target; leave in place.

    // Strip text from source, append to target.
    result[i] = {
      ...msg,
      message: {
        ...msg.message,
        content: content.filter(b => b.type !== 'text'),
      },
    }
    const target = result[targetIdx] as UserMessage
    result[targetIdx] = {
      ...target,
      message: {
        ...target.message,
        content: [
          ...(target.message.content as ContentBlockParam[]),
          ...textSiblings,
        ],
      },
    }
  }

  return result
}

export function normalizeMessagesForAPI(
  messages: Message[],
  tools: Tools = [],
): (UserMessage | AssistantMessage)[] {
  // Build set of available tool names for filtering unavailable tool references
  const availableToolNames = new Set(tools.map(t => t.name))

  // First, reorder attachments to bubble up until they hit a tool result or assistant message
  // Then strip virtual messages — they're display-only (e.g. REPL inner tool
  // calls) and must never reach the API.
  const reorderedMessages = reorderAttachmentsForAPI(messages).filter(
    m => !((m.type === 'user' || m.type === 'assistant') && m.isVirtual),
  )

  // Build a map from error text → which block types to strip from the preceding user message.
  const errorToBlockTypes: Record<string, Set<string>> = {
    [getPdfTooLargeErrorMessage()]: new Set(['document']),
    [getPdfPasswordProtectedErrorMessage()]: new Set(['document']),
    [getPdfInvalidErrorMessage()]: new Set(['document']),
    [getImageTooLargeErrorMessage()]: new Set(['image']),
    [getRequestTooLargeErrorMessage()]: new Set(['document', 'image']),
  }

  // Walk the reordered messages to build a targeted strip map:
  // userMessageUUID → set of block types to strip from that message.
  const stripTargets = new Map<string, Set<string>>()
  for (let i = 0; i < reorderedMessages.length; i++) {
    const msg = reorderedMessages[i]!
    if (!isSyntheticApiErrorMessage(msg)) {
      continue
    }
    // Determine which error this is
    const errorText =
      Array.isArray(msg.message.content) &&
      msg.message.content[0]?.type === 'text'
        ? msg.message.content[0].text
        : undefined
    if (!errorText) {
      continue
    }
    const blockTypesToStrip = errorToBlockTypes[errorText]
    if (!blockTypesToStrip) {
      continue
    }
    // Walk backward to find the nearest preceding isMeta user message
    for (let j = i - 1; j >= 0; j--) {
      const candidate = reorderedMessages[j]!
      if (candidate.type === 'user' && candidate.isMeta) {
        const existing = stripTargets.get(candidate.uuid)
        if (existing) {
          for (const t of blockTypesToStrip) {
            existing.add(t)
          }
        } else {
          stripTargets.set(candidate.uuid, new Set(blockTypesToStrip))
        }
        break
      }
      // Skip over other synthetic error messages or non-meta messages
      if (isSyntheticApiErrorMessage(candidate)) {
        continue
      }
      // Stop if we hit an assistant message or non-meta user message
      break
    }
  }

  const result: (UserMessage | AssistantMessage)[] = []
  reorderedMessages
    .filter(
      (
        _,
      ): _ is
        | UserMessage
        | AssistantMessage
        | AttachmentMessage
        | SystemLocalCommandMessage => {
        if (
          _.type === 'progress' ||
          (_.type === 'system' && !isSystemLocalCommandMessage(_)) ||
          isSyntheticApiErrorMessage(_)
        ) {
          return false
        }
        return true
      },
    )
    .forEach(message => {
      switch (message.type) {
        case 'system': {
          // local_command system messages need to be included as user messages
          // so the model can reference previous command output in later turns
          const userMsg = createUserMessage({
            content: message.content,
            uuid: message.uuid,
            timestamp: message.timestamp,
          })
          const lastMessage = last(result)
          if (lastMessage?.type === 'user') {
            result[result.length - 1] = mergeUserMessages(lastMessage, userMsg)
            return
          }
          result.push(userMsg)
          return
        }
        case 'user': {
          // Merge consecutive user messages because Bedrock doesn't support
          // multiple user messages in a row; 1P API does and merges them
          // into a single user turn

          // When tool search is NOT enabled, strip all tool_reference blocks from
          // tool_result content, as these are only valid with the tool search beta.
          // When tool search IS enabled, strip only tool_reference blocks for
          // tools that no longer exist (e.g., MCP server was disconnected).
          let normalizedMessage = message
          if (!isToolSearchEnabledOptimistic()) {
            normalizedMessage = stripToolReferenceBlocksFromUserMessage(message)
          } else {
            normalizedMessage = stripUnavailableToolReferencesFromUserMessage(
              message,
              availableToolNames,
            )
          }

          // Strip document/image blocks from the specific meta user message that
          // preceded a PDF/image/request-too-large error, to prevent re-sending
          // the problematic content on every subsequent API call.
          const typesToStrip = stripTargets.get(normalizedMessage.uuid)
          if (typesToStrip && normalizedMessage.isMeta) {
            const content = normalizedMessage.message.content
            if (Array.isArray(content)) {
              const filtered = content.filter(
                block => !typesToStrip.has(block.type),
              )
              if (filtered.length === 0) {
                // All content blocks were stripped; skip this message entirely
                return
              }
              if (filtered.length < content.length) {
                normalizedMessage = {
                  ...normalizedMessage,
                  message: {
                    ...normalizedMessage.message,
                    content: filtered,
                  },
                }
              }
            }
          }

          // Server renders tool_reference expansion as <functions>...</functions>
          // (same tags as the system prompt's tool block). When this is at the
          // prompt tail, capybara models sample the stop sequence at ~10% (A/B:
          // 21/200 vs 0/200 on v3-prod). A sibling text block inserts a clean
          // "\n\nHuman: ..." turn boundary. Injected here (API-prep) rather than
          // stored in the message so it never renders in the REPL, and is
          // auto-skipped when strip* above removes all tool_reference content.
          // Must be a sibling, NOT inside tool_result.content — mixing text with
          // tool_reference inside the block is a server ValueError.
          // Idempotent: query.ts calls this per-tool-result; the output flows
          // back through here via claude.ts on the next API request. The first
          // pass's sibling gets a \n[id:xxx] suffix from appendMessageTag below,
          // so startsWith matches both bare and tagged forms.
          //
          // Gated OFF when tengu_toolref_defer_j8m is active — that gate
          // enables relocateToolReferenceSiblings in post-processing below,
          // which moves existing siblings to a later non-ref message instead
          // of adding one here. This injection is itself one of the patterns
          // that gets relocated, so skipping it saves a scan. When gate is
          // off, this is the fallback (same as pre-#21049 main).
          if (
            !checkStatsigFeatureGate_CACHED_MAY_BE_STALE(
              'tengu_toolref_defer_j8m',
            )
          ) {
            const contentAfterStrip = normalizedMessage.message.content
            if (
              Array.isArray(contentAfterStrip) &&
              !contentAfterStrip.some(
                b =>
                  b.type === 'text' &&
                  b.text.startsWith(TOOL_REFERENCE_TURN_BOUNDARY),
              ) &&
              contentHasToolReference(contentAfterStrip)
            ) {
              normalizedMessage = {
                ...normalizedMessage,
                message: {
                  ...normalizedMessage.message,
                  content: [
                    ...contentAfterStrip,
                    { type: 'text', text: TOOL_REFERENCE_TURN_BOUNDARY },
                  ],
                },
              }
            }
          }

          // If the last message is also a user message, merge them
          const lastMessage = last(result)
          if (lastMessage?.type === 'user') {
            result[result.length - 1] = mergeUserMessages(
              lastMessage,
              normalizedMessage,
            )
            return
          }

          // Otherwise, add the message normally
          result.push(normalizedMessage)
          return
        }
        case 'assistant': {
          // Normalize tool inputs for API (strip fields like plan from ExitPlanModeV2)
          // When tool search is NOT enabled, we must strip tool_search-specific fields
          // like 'caller' from tool_use blocks, as these are only valid with the
          // tool search beta header
          const toolSearchEnabled = isToolSearchEnabledOptimistic()
          const normalizedMessage: AssistantMessage = {
            ...message,
            message: {
              ...message.message,
              content: message.message.content.map(block => {
                if (block.type === 'tool_use') {
                  const tool = tools.find(t => toolMatchesName(t, block.name))
                  const normalizedInput = tool
                    ? normalizeToolInputForAPI(
                        tool,
                        block.input as Record<string, unknown>,
                      )
                    : block.input
                  const canonicalName = tool?.name ?? block.name

                  // When tool search is enabled, preserve all fields including 'caller'
                  if (toolSearchEnabled) {
                    const { extra_content, ...restBlock } = block as any
                    return {
                      ...restBlock,
                      name: canonicalName,
                      input: normalizedInput,
                      ...(getAPIProvider() === 'gemini' && extra_content ? { extra_content } : {})
                    }
                  }

                  // When tool search is NOT enabled, explicitly construct tool_use
                  // block with only standard API fields to avoid sending fields like
                  // 'caller' that may be stored in sessions from tool search runs
                    return {
                    type: 'tool_use' as const,
                    id: block.id,
                    name: canonicalName,
                    input: normalizedInput,
                    ...(getAPIProvider() === 'gemini' && (block as any).extra_content ? { extra_content: (block as any).extra_content } : {})
                  }
                }
                return block
              }),
            },
          }

          // Find a previous assistant message with the same message ID and merge.
          // Walk backwards, skipping tool results and different-ID assistants,
          // since concurrent agents (teammates) can interleave streaming content
          // blocks from multiple API responses with different message IDs.
          for (let i = result.length - 1; i >= 0; i--) {
            const msg = result[i]!

            if (msg.type !== 'assistant' && !isToolResultMessage(msg)) {
              break
            }

            if (msg.type === 'assistant') {
              if (msg.message.id === normalizedMessage.message.id) {
                result[i] = mergeAssistantMessages(msg, normalizedMessage)
                return
              }
              continue
            }
          }

          result.push(normalizedMessage)
          return
        }
        case 'attachment': {
          const rawAttachmentMessage = normalizeAttachmentForAPI(
            message.attachment,
          )
          const attachmentMessage = checkStatsigFeatureGate_CACHED_MAY_BE_STALE(
            'tengu_chair_sermon',
          )
            ? rawAttachmentMessage.map(ensureSystemReminderWrap)
            : rawAttachmentMessage

          // If the last message is also a user message, merge them
          const lastMessage = last(result)
          if (lastMessage?.type === 'user') {
            result[result.length - 1] = attachmentMessage.reduce(
              (p, c) => mergeUserMessagesAndToolResults(p, c),
              lastMessage,
            )
            return
          }

          result.push(...attachmentMessage)
          return
        }
      }
    })

  // Relocate text siblings off tool_reference messages — prevents the
  // anomalous two-consecutive-human-turns pattern that teaches the model
  // to emit the stop sequence after tool results. See #21049.
  // Runs after merge (siblings are in place) and before ID tagging (so
  // tags reflect final positions). When gate is OFF, this is a noop and
  // the TOOL_REFERENCE_TURN_BOUNDARY injection above serves as fallback.
  const relocated = checkStatsigFeatureGate_CACHED_MAY_BE_STALE(
    'tengu_toolref_defer_j8m',
  )
    ? relocateToolReferenceSiblings(result)
    : result

  // Filter orphaned thinking-only assistant messages (likely introduced by
  // compaction slicing away intervening messages between a failed streaming
  // response and its retry). Without this, consecutive assistant messages with
  // mismatched thinking block signatures cause API 400 errors.
  const withFilteredOrphans = filterOrphanedThinkingOnlyMessages(relocated)

  // Order matters: strip trailing thinking first, THEN filter whitespace-only
  // messages. The reverse order has a bug: a message like [text("\n\n"), thinking("...")]
  // survives the whitespace filter (has a non-text block), then thinking stripping
  // removes the thinking block, leaving [text("\n\n")] — which the API rejects.
  //
  // These multi-pass normalizations are inherently fragile — each pass can create
  // conditions a prior pass was meant to handle. Consider unifying into a single
  // pass that cleans content, then validates in one shot.
  const withFilteredThinking =
    filterTrailingThinkingFromLastAssistant(withFilteredOrphans)
  const withFilteredWhitespace =
    filterWhitespaceOnlyAssistantMessages(withFilteredThinking)
  const withNonEmpty = ensureNonEmptyAssistantContent(withFilteredWhitespace)

  // filterOrphanedThinkingOnlyMessages doesn't merge adjacent users (whitespace
  // filter does, but only when IT fires). Merge here so smoosh can fold the
  // SR-text sibling that hoistToolResults produces. The smoosh itself folds
  // <system-reminder>-prefixed text siblings into the adjacent tool_result.
  // Gated together: the merge exists solely to feed the smoosh; running it
  // ungated changes VCR fixture hashes for @-mention scenarios (adjacent
  // [prompt, attachment] users) without any benefit when the smoosh is off.
  const smooshed = checkStatsigFeatureGate_CACHED_MAY_BE_STALE(
    'tengu_chair_sermon',
  )
    ? smooshSystemReminderSiblings(mergeAdjacentUserMessages(withNonEmpty))
    : withNonEmpty

  // Unconditional — catches transcripts persisted before smooshIntoToolResult
  // learned to filter on is_error. Without this a resumed session with an
  // image-in-error tool_result 400s forever.
  const sanitized = sanitizeErrorToolResultContent(smooshed)

  // Append message ID tags for snip tool visibility (after all merging,
  // so tags always match the surviving message's messageId field).
  // Skip in test mode — tags change message content hashes, breaking
  // VCR fixture lookup. Gate must match SnipTool.isEnabled() — don't
  // inject [id:] tags when the tool isn't available (confuses the model
  // and wastes tokens on every non-meta user message for every ant).
  if (feature('HISTORY_SNIP') && process.env.NODE_ENV !== 'test') {
    const { isSnipRuntimeEnabled } =
      // eslint-disable-next-line @typescript-eslint/no-require-imports
      require('src/agent/compact/snipCompact.js') as typeof import('src/agent/compact/snipCompact.js')
    if (isSnipRuntimeEnabled()) {
      for (let i = 0; i < sanitized.length; i++) {
        if (sanitized[i]!.type === 'user') {
          sanitized[i] = appendMessageTagToUserMessage(
            sanitized[i] as UserMessage,
          )
        }
      }
    }
  }

  // Validate all images are within API size limits before sending
  validateImagesForAPI(sanitized)

  return sanitized
}

export function mergeUserMessagesAndToolResults(
  a: UserMessage,
  b: UserMessage,
): UserMessage {
  const lastContent = normalizeUserTextContent(a.message.content)
  const currentContent = normalizeUserTextContent(b.message.content)
  return {
    ...a,
    message: {
      ...a.message,
      content: hoistToolResults(
        mergeUserContentBlocks(lastContent, currentContent),
      ),
    },
  }
}

export function mergeAssistantMessages(
  a: AssistantMessage,
  b: AssistantMessage,
): AssistantMessage {
  return {
    ...a,
    message: {
      ...a.message,
      content: [...a.message.content, ...b.message.content],
    },
  }
}

function isToolResultMessage(msg: Message): boolean {
  if (msg.type !== 'user') {
    return false
  }
  const content = msg.message.content
  if (typeof content === 'string') return false
  return content.some(block => block.type === 'tool_result')
}

export function mergeUserMessages(a: UserMessage, b: UserMessage): UserMessage {
  const lastContent = normalizeUserTextContent(a.message.content)
  const currentContent = normalizeUserTextContent(b.message.content)
  if (feature('HISTORY_SNIP')) {
    // A merged message is only meta if ALL merged messages are meta. If any
    // operand is real user content, the result must not be flagged isMeta
    // (so [id:] tags get injected and it's treated as user-visible content).
    // Gated behind the full runtime check because changing isMeta semantics
    // affects downstream callers (e.g., VCR fixture hashing in SDK harness
    // tests), so this must only fire when snip is actually enabled — not
    // for all ants.
    const { isSnipRuntimeEnabled } =
      // eslint-disable-next-line @typescript-eslint/no-require-imports
      require('src/agent/compact/snipCompact.js') as typeof import('src/agent/compact/snipCompact.js')
    if (isSnipRuntimeEnabled()) {
      return {
        ...a,
        isMeta: a.isMeta && b.isMeta ? (true as const) : undefined,
        uuid: a.isMeta ? b.uuid : a.uuid,
        message: {
          ...a.message,
          content: hoistToolResults(
            joinTextAtSeam(lastContent, currentContent),
          ),
        },
      }
    }
  }
  return {
    ...a,
    // Preserve the non-meta message's uuid so [id:] tags (derived from uuid)
    // stay stable across API calls (meta messages like system context get fresh uuids each call)
    uuid: a.isMeta ? b.uuid : a.uuid,
    message: {
      ...a.message,
      content: hoistToolResults(joinTextAtSeam(lastContent, currentContent)),
    },
  }
}

function mergeAdjacentUserMessages(
  msgs: (UserMessage | AssistantMessage)[],
): (UserMessage | AssistantMessage)[] {
  const out: (UserMessage | AssistantMessage)[] = []
  for (const m of msgs) {
    const prev = out.at(-1)
    if (m.type === 'user' && prev?.type === 'user') {
      out[out.length - 1] = mergeUserMessages(prev, m) // lvalue — can't use .at()
    } else {
      out.push(m)
    }
  }
  return out
}

/**
 * In thecontent[] list on a UserMessage, tool_result blocks much come first
 * to avoid "tool result must follow tool use" API errors.
 */
function hoistToolResults(content: ContentBlockParam[]): ContentBlockParam[] {
  const toolResults: ContentBlockParam[] = []
  const otherBlocks: ContentBlockParam[] = []

  for (const block of content) {
    if (block.type === 'tool_result') {
      toolResults.push(block)
    } else {
      otherBlocks.push(block)
    }
  }

  return [...toolResults, ...otherBlocks]
}

function normalizeUserTextContent(
  a: string | ContentBlockParam[],
): ContentBlockParam[] {
  if (typeof a === 'string') {
    return [{ type: 'text', text: a }]
  }
  return a
}

/**
 * Concatenate two content block arrays, appending `\n` to a's last text block
 * when the seam is text-text. The API concatenates adjacent text blocks in a
 * user message without a separator, so two queued prompts `"2 + 2"` +
 * `"3 + 3"` would otherwise reach the model as `"2 + 23 + 3"`.
 *
 * Blocks stay separate; the `\n` goes on a's side so no block's startsWith
 * changes — smooshSystemReminderSiblings classifies via
 * `startsWith('<system-reminder>')`, and prepending to b would break that
 * when b is an SR-wrapped attachment.
 */
function joinTextAtSeam(
  a: ContentBlockParam[],
  b: ContentBlockParam[],
): ContentBlockParam[] {
  const lastA = a.at(-1)
  const firstB = b[0]
  if (lastA?.type === 'text' && firstB?.type === 'text') {
    return [...a.slice(0, -1), { ...lastA, text: lastA.text + '\n' }, ...b]
  }
  return [...a, ...b]
}

type ToolResultContentItem = Extract<
  ToolResultBlockParam['content'],
  readonly unknown[]
>[number]

/**
 * Fold content blocks into a tool_result's content. Returns the updated
 * tool_result, or `null` if smoosh is impossible (tool_reference constraint).
 *
 * Valid block types inside tool_result.content per SDK: text, image,
 * search_result, document. All of these smoosh. tool_reference (beta) cannot
 * mix with other types — server ValueError — so we bail with null.
 *
 * - string/undefined content + all-text blocks → string (preserve legacy shape)
 * - array content with tool_reference → null
 * - otherwise → array, with adjacent text merged (notebook.ts idiom)
 */
function smooshIntoToolResult(
  tr: ToolResultBlockParam,
  blocks: ContentBlockParam[],
): ToolResultBlockParam | null {
  if (blocks.length === 0) return tr

  const existing = tr.content
  if (Array.isArray(existing) && existing.some(isToolReferenceBlock)) {
    return null
  }

  // API constraint: is_error tool_results must contain only text blocks.
  // Queued-command siblings can carry images (pasted screenshot) — smooshing
  // those into an error result produces a transcript that 400s on every
  // subsequent call and can't be recovered by /fork. The image isn't lost:
  // it arrives as a proper user turn anyway.
  if (tr.is_error) {
    blocks = blocks.filter(b => b.type === 'text')
    if (blocks.length === 0) return tr
  }

  const allText = blocks.every(b => b.type === 'text')

  // Preserve string shape when existing was string/undefined and all incoming
  // blocks are text — this is the common case (hook reminders into Bash/Read
  // results) and matches the legacy smoosh output shape.
  if (allText && (existing === undefined || typeof existing === 'string')) {
    const joined = [
      (existing ?? '').trim(),
      ...blocks.map(b => (b as TextBlockParam).text.trim()),
    ]
      .filter(Boolean)
      .join('\n\n')
    return { ...tr, content: joined }
  }

  // General case: normalize to array, concat, merge adjacent text
  const base: ToolResultContentItem[] =
    existing === undefined
      ? []
      : typeof existing === 'string'
        ? existing.trim()
          ? [{ type: 'text', text: existing.trim() }]
          : []
        : [...existing]

  const merged: ToolResultContentItem[] = []
  for (const b of [...base, ...blocks]) {
    if (b.type === 'text') {
      const t = b.text.trim()
      if (!t) continue
      const prev = merged.at(-1)
      if (prev?.type === 'text') {
        merged[merged.length - 1] = { ...prev, text: `${prev.text}\n\n${t}` } // lvalue
      } else {
        merged.push({ type: 'text', text: t })
      }
    } else {
      // image / search_result / document — pass through
      merged.push(b as ToolResultContentItem)
    }
  }

  return { ...tr, content: merged }
}

export function mergeUserContentBlocks(
  a: ContentBlockParam[],
  b: ContentBlockParam[],
): ContentBlockParam[] {
  // See https://anthropic.slack.com/archives/C06FE2FP0Q2/p1747586370117479 and
  // https://anthropic.slack.com/archives/C0AHK9P0129/p1773159663856279:
  // any sibling after tool_result renders as </function_results>\n\nHuman:<...>
  // on the wire. Repeated mid-conversation, this teaches capy to emit Human: at
  // a bare tail → 3-token empty end_turn. A/B (sai-20260310-161901) validated:
  // smoosh into tool_result.content → 92% → 0%.
  const lastBlock = last(a)
  if (lastBlock?.type !== 'tool_result') {
    return [...a, ...b]
  }

  if (!checkStatsigFeatureGate_CACHED_MAY_BE_STALE('tengu_chair_sermon')) {
    // Legacy (ungated) smoosh: only string-content tool_result + all-text
    // siblings → joined string. Matches pre-universal-smoosh behavior on main.
    // The precondition guarantees smooshIntoToolResult hits its string path
    // (no tool_reference bail, string output shape preserved).
    if (
      typeof lastBlock.content === 'string' &&
      b.every(x => x.type === 'text')
    ) {
      const copy = a.slice()
      copy[copy.length - 1] = smooshIntoToolResult(lastBlock, b)!
      return copy
    }
    return [...a, ...b]
  }

  // Universal smoosh (gated): fold all non-tool_result block types (text,
  // image, document, search_result) into tool_result.content. tool_result
  // blocks stay as siblings (hoisted later by hoistToolResults).
  const toSmoosh = b.filter(x => x.type !== 'tool_result')
  const toolResults = b.filter(x => x.type === 'tool_result')
  if (toSmoosh.length === 0) {
    return [...a, ...b]
  }

  const smooshed = smooshIntoToolResult(lastBlock, toSmoosh)
  if (smooshed === null) {
    // tool_reference constraint — fall back to siblings
    return [...a, ...b]
  }

  return [...a.slice(0, -1), smooshed, ...toolResults]
}

// Sometimes the API returns empty messages (eg. "\n\n"). We need to filter these out,
// otherwise they will give an API error when we send them to the API next time we call query().
export function normalizeContentFromAPI(
  contentBlocks: BetaMessage['content'],
  tools: Tools,
  agentId?: AgentId,
): BetaMessage['content'] {
  if (!contentBlocks) {
    return []
  }
  return contentBlocks.map(contentBlock => {
    switch (contentBlock.type) {
      case 'tool_use': {
        if (
          typeof contentBlock.input !== 'string' &&
          !isObject(contentBlock.input)
        ) {
          // we stream tool use inputs as strings, but when we fall back, they're objects
          throw new Error('Tool use input must be a string or object')
        }

        // With fine-grained streaming on, we are getting a stringied JSON back from the API.
        // The API has strange behaviour, where it returns nested stringified JSONs, and so
        // we need to recursively parse these. If the top-level value returned from the API is
        // an empty string, this should become an empty object (nested values should be empty string).
        // TODO: This needs patching as recursive fields can still be stringified
        let normalizedInput: unknown
        if (typeof contentBlock.input === 'string') {
          const parsed = safeParseJSON(contentBlock.input)
          if (parsed === null && contentBlock.input.length > 0) {
            // TET/FC-v3 diagnostic: the streamed tool input JSON failed to
            // parse. We fall back to {} which means downstream validation
            // sees empty input. The raw prefix goes to debug log only — no
            // PII-tagged proto column exists for it yet.
            logEvent('tengu_tool_input_json_parse_fail', {
              toolName: sanitizeToolNameForAnalytics(contentBlock.name),
              inputLen: contentBlock.input.length,
            })
          }
          normalizedInput = parsed ?? {}
        } else {
          normalizedInput = contentBlock.input
        }

        // Then apply tool-specific corrections
        if (typeof normalizedInput === 'object' && normalizedInput !== null) {
          const tool = findToolByName(tools, contentBlock.name)
          if (tool) {
            try {
              normalizedInput = normalizeToolInput(
                tool,
                normalizedInput as { [key: string]: unknown },
                agentId,
              )
            } catch (error) {
              logError(new Error('Error normalizing tool input: ' + error))
              // Keep the original input if normalization fails
            }
          }
        }

        return {
          ...contentBlock,
          input: normalizedInput,
        }
      }
      case 'text':
        if (contentBlock.text.trim().length === 0) {
          logEvent('tengu_model_whitespace_response', {
            length: contentBlock.text.length,
          })
        }
        // Return the block as-is to preserve exact content for prompt caching.
        // Empty text blocks are handled at the display layer and must not be
        // altered here.
        return contentBlock
      case 'code_execution_tool_result':
      case 'mcp_tool_use':
      case 'mcp_tool_result':
      case 'container_upload':
        // Beta-specific content blocks - pass through as-is
        return contentBlock
      case 'server_tool_use':
        if (typeof contentBlock.input === 'string') {
          return {
            ...contentBlock,
            input: (safeParseJSON(contentBlock.input) ?? {}) as {
              [key: string]: unknown
            },
          }
        }
        return contentBlock
      default:
        return contentBlock
    }
  })
}

export function filterUnresolvedToolUses(messages: Message[]): Message[] {
  // Collect all tool_use IDs and tool_result IDs directly from message content blocks.
  // This avoids calling normalizeMessages() which generates new UUIDs — if those
  // normalized messages were returned and later recorded to the transcript JSONL,
  // the UUID dedup would not catch them, causing exponential transcript growth on
  // every session resume.
  const toolUseIds = new Set<string>()
  const toolResultIds = new Set<string>()

  for (const msg of messages) {
    if (msg.type !== 'user' && msg.type !== 'assistant') continue
    const content = msg.message.content
    if (!Array.isArray(content)) continue
    for (const block of content) {
      if (block.type === 'tool_use') {
        toolUseIds.add(block.id)
      }
      if (block.type === 'tool_result') {
        toolResultIds.add(block.tool_use_id)
      }
    }
  }

  const unresolvedIds = new Set(
    [...toolUseIds].filter(id => !toolResultIds.has(id)),
  )

  if (unresolvedIds.size === 0) {
    return messages
  }

  // Filter out assistant messages whose tool_use blocks are all unresolved
  return messages.filter(msg => {
    if (msg.type !== 'assistant') return true
    const content = msg.message.content
    if (!Array.isArray(content)) return true
    const toolUseBlockIds: string[] = []
    for (const b of content) {
      if (b.type === 'tool_use') {
        toolUseBlockIds.push(b.id)
      }
    }
    if (toolUseBlockIds.length === 0) return true
    // Remove message only if ALL its tool_use blocks are unresolved
    return !toolUseBlockIds.every(id => unresolvedIds.has(id))
  })
}

type ThinkingBlockType =
  | ThinkingBlock
  | RedactedThinkingBlock
  | ThinkingBlockParam
  | RedactedThinkingBlockParam
  | BetaThinkingBlock
  | BetaRedactedThinkingBlock

function isThinkingBlock(
  block: ContentBlockParam | ContentBlock | BetaContentBlock,
): block is ThinkingBlockType {
  return block.type === 'thinking' || block.type === 'redacted_thinking'
}

/**
 * Filter trailing thinking blocks from the last message if it's an assistant message.
 * The API doesn't allow assistant messages to end with thinking/redacted_thinking blocks.
 */
function filterTrailingThinkingFromLastAssistant(
  messages: (UserMessage | AssistantMessage)[],
): (UserMessage | AssistantMessage)[] {
  const lastMessage = messages.at(-1)
  if (!lastMessage || lastMessage.type !== 'assistant') {
    // Last message is not assistant, nothing to filter
    return messages
  }

  const content = lastMessage.message.content
  const lastBlock = content.at(-1)
  if (!lastBlock || !isThinkingBlock(lastBlock)) {
    return messages
  }

  // Find last non-thinking block
  let lastValidIndex = content.length - 1
  while (lastValidIndex >= 0) {
    const block = content[lastValidIndex]
    if (!block || !isThinkingBlock(block)) {
      break
    }
    lastValidIndex--
  }

  logEvent('tengu_filtered_trailing_thinking_block', {
    messageUUID:
      lastMessage.uuid as AnalyticsMetadata_I_VERIFIED_THIS_IS_NOT_CODE_OR_FILEPATHS,
    blocksRemoved: content.length - lastValidIndex - 1,
    remainingBlocks: lastValidIndex + 1,
  })

  // Insert placeholder if all blocks were thinking
  const filteredContent =
    lastValidIndex < 0
      ? [{ type: 'text' as const, text: '[No message content]', citations: [] }]
      : content.slice(0, lastValidIndex + 1)

  const result = [...messages]
  result[messages.length - 1] = {
    ...lastMessage,
    message: {
      ...lastMessage.message,
      content: filteredContent,
    },
  }
  return result
}

/**
 * Check if an assistant message has only whitespace-only text content blocks.
 * Returns true if all content blocks are text blocks with only whitespace.
 * Returns false if there are any non-text blocks (like tool_use) or text with actual content.
 */
function hasOnlyWhitespaceTextContent(
  content: Array<{ type: string; text?: string }>,
): boolean {
  if (content.length === 0) {
    return false
  }

  for (const block of content) {
    // If there's any non-text block (tool_use, thinking, etc.), the message is valid
    if (block.type !== 'text') {
      return false
    }
    // If there's a text block with non-whitespace content, the message is valid
    if (block.text !== undefined && block.text.trim() !== '') {
      return false
    }
  }

  // All blocks are text blocks with only whitespace
  return true
}

/**
 * Filter out assistant messages with only whitespace-only text content.
 *
 * The API requires "text content blocks must contain non-whitespace text".
 * This can happen when the model outputs whitespace (like "\n\n") before a thinking block,
 * but the user cancels mid-stream, leaving only the whitespace text.
 *
 * This function removes such messages entirely rather than keeping a placeholder,
 * since whitespace-only content has no semantic value.
 *
 * Also used by conversationRecovery to filter these from the main state during session resume.
 */
export function filterWhitespaceOnlyAssistantMessages(
  messages: (UserMessage | AssistantMessage)[],
): (UserMessage | AssistantMessage)[]
export function filterWhitespaceOnlyAssistantMessages(
  messages: Message[],
): Message[]
export function filterWhitespaceOnlyAssistantMessages(
  messages: Message[],
): Message[] {
  let hasChanges = false

  const filtered = messages.filter(message => {
    if (message.type !== 'assistant') {
      return true
    }

    const content = message.message.content
    // Keep messages with empty arrays (handled elsewhere) or that have real content
    if (!Array.isArray(content) || content.length === 0) {
      return true
    }

    if (hasOnlyWhitespaceTextContent(content)) {
      hasChanges = true
      logEvent('tengu_filtered_whitespace_only_assistant', {
        messageUUID:
          message.uuid as AnalyticsMetadata_I_VERIFIED_THIS_IS_NOT_CODE_OR_FILEPATHS,
      })
      return false
    }

    return true
  })

  if (!hasChanges) {
    return messages
  }

  // Removing assistant messages may leave adjacent user messages that need
  // merging (the API requires alternating user/assistant roles).
  const merged: Message[] = []
  for (const message of filtered) {
    const prev = merged.at(-1)
    if (message.type === 'user' && prev?.type === 'user') {
      merged[merged.length - 1] = mergeUserMessages(prev, message) // lvalue
    } else {
      merged.push(message)
    }
  }
  return merged
}

/**
 * Ensure all non-final assistant messages have non-empty content.
 *
 * The API requires "all messages must have non-empty content except for the
 * optional final assistant message". This can happen when the model returns
 * an empty content array.
 *
 * For non-final assistant messages with empty content, we insert a placeholder.
 * The final assistant message is left as-is since it's allowed to be empty (for prefill).
 *
 * Note: Whitespace-only text content is handled separately by filterWhitespaceOnlyAssistantMessages.
 */
function ensureNonEmptyAssistantContent(
  messages: (UserMessage | AssistantMessage)[],
): (UserMessage | AssistantMessage)[] {
  if (messages.length === 0) {
    return messages
  }

  let hasChanges = false
  const result = messages.map((message, index) => {
    // Skip non-assistant messages
    if (message.type !== 'assistant') {
      return message
    }

    // Skip the final message (allowed to be empty for prefill)
    if (index === messages.length - 1) {
      return message
    }

    // Check if content is empty
    const content = message.message.content
    if (Array.isArray(content) && content.length === 0) {
      hasChanges = true
      logEvent('tengu_fixed_empty_assistant_content', {
        messageUUID:
          message.uuid as AnalyticsMetadata_I_VERIFIED_THIS_IS_NOT_CODE_OR_FILEPATHS,
        messageIndex: index,
      })

      return {
        ...message,
        message: {
          ...message.message,
          content: [
            { type: 'text' as const, text: NO_CONTENT_MESSAGE, citations: [] },
          ],
        },
      }
    }

    return message
  })

  return hasChanges ? result : messages
}

/**
 * Filter orphaned thinking-only assistant messages.
 *
 * During streaming, each content block is yielded as a separate message with the same
 * message.id. When messages are loaded for resume, interleaved user messages or attachments
 * can prevent proper merging by message.id, leaving orphaned assistant messages that contain
 * only thinking blocks. These cause "thinking blocks cannot be modified" API errors.
 *
 * A thinking-only message is "orphaned" if there is NO other assistant message with the
 * same message.id that contains non-thinking content (text, tool_use, etc). If such a
 * message exists, the thinking block will be merged with it in normalizeMessagesForAPI().
 */
export function filterOrphanedThinkingOnlyMessages(
  messages: (UserMessage | AssistantMessage)[],
): (UserMessage | AssistantMessage)[]
export function filterOrphanedThinkingOnlyMessages(
  messages: Message[],
): Message[]
export function filterOrphanedThinkingOnlyMessages(
  messages: Message[],
): Message[] {
  // First pass: collect message.ids that have non-thinking content
  // These will be merged later in normalizeMessagesForAPI()
  const messageIdsWithNonThinkingContent = new Set<string>()
  for (const msg of messages) {
    if (msg.type !== 'assistant') continue

    const content = msg.message.content
    if (!Array.isArray(content)) continue

    const hasNonThinking = content.some(
      block => block.type !== 'thinking' && block.type !== 'redacted_thinking',
    )
    if (hasNonThinking && msg.message.id) {
      messageIdsWithNonThinkingContent.add(msg.message.id)
    }
  }

  // Second pass: filter out thinking-only messages that are truly orphaned
  const filtered = messages.filter(msg => {
    if (msg.type !== 'assistant') {
      return true
    }

    const content = msg.message.content
    if (!Array.isArray(content) || content.length === 0) {
      return true
    }

    // Check if ALL content blocks are thinking blocks
    const allThinking = content.every(
      block => block.type === 'thinking' || block.type === 'redacted_thinking',
    )

    if (!allThinking) {
      return true // Has non-thinking content, keep it
    }

    // It's thinking-only. Keep it if there's another message with same id
    // that has non-thinking content (they'll be merged later)
    if (
      msg.message.id &&
      messageIdsWithNonThinkingContent.has(msg.message.id)
    ) {
      return true
    }

    // Truly orphaned - no other message with same id has content to merge with
    logEvent('tengu_filtered_orphaned_thinking_message', {
      messageUUID:
        msg.uuid as AnalyticsMetadata_I_VERIFIED_THIS_IS_NOT_CODE_OR_FILEPATHS,
      messageId: msg.message
        .id as AnalyticsMetadata_I_VERIFIED_THIS_IS_NOT_CODE_OR_FILEPATHS,
      blockCount: content.length,
    })
    return false
  })

  return filtered
}

/**
 * Strip signature-bearing blocks (thinking, redacted_thinking, connector_text)
 * from all assistant messages. Their signatures are bound to the API key that
 * generated them; after a credential change (e.g. /login) they're invalid and
 * the API rejects them with a 400.
 */
export function stripSignatureBlocks(messages: Message[]): Message[] {
  let changed = false
  const result = messages.map(msg => {
    if (msg.type !== 'assistant') return msg

    const content = msg.message.content
    if (!Array.isArray(content)) return msg

    const filtered = content.filter(block => {
      if (isThinkingBlock(block)) return false
      if (feature('CONNECTOR_TEXT')) {
        if (isConnectorTextBlock(block)) return false
      }
      return true
    })
    if (filtered.length === content.length) return msg

    // Strip to [] even for thinking-only messages. Streaming yields each
    // content block as a separate same-id AssistantMessage (claude.ts:2150),
    // so a thinking-only singleton here is usually a split sibling that
    // mergeAssistantMessages (2232) rejoins with its text/tool_use partner.
    // If we returned the original message, the stale signature would survive
    // the merge. Empty content is absorbed by merge; true orphans are handled
    // by the empty-content placeholder path in normalizeMessagesForAPI.

    changed = true
    return {
      ...msg,
      message: { ...msg.message, content: filtered },
    } as typeof msg
  })

  return changed ? result : messages
}

/**
 * Defensive validation: ensure tool_use/tool_result pairing is correct.
 *
 * Handles both directions:
 * - Forward: inserts synthetic error tool_result blocks for tool_use blocks missing results
 * - Reverse: strips orphaned tool_result blocks referencing non-existent tool_use blocks
 *
 * Logs when this activates to help identify the root cause.
 *
 * Strict mode: when getStrictToolResultPairing() is true (HFI opts in at
 * startup), any mismatch throws instead of repairing. For training-data
 * collection, a model response conditioned on synthetic placeholders is
 * tainted — fail the trajectory rather than waste labeler time on a turn
 * that will be rejected at submission anyway.
 */
export function ensureToolResultPairing(
  messages: (UserMessage | AssistantMessage)[],
): (UserMessage | AssistantMessage)[] {
  const result: (UserMessage | AssistantMessage)[] = []
  let repaired = false

  // Cross-message tool_use ID tracking. The per-message seenToolUseIds below
  // only caught duplicates within a single assistant's content array (the
  // normalizeMessagesForAPI-merged case). When two assistants with DIFFERENT
  // message.id carry the same tool_use ID — e.g. orphan handler re-pushed an
  // assistant already present in mutableMessages with a fresh message.id, or
  // normalizeMessagesForAPI's backward walk broke on an intervening user
  // message — the dup lived in separate result entries and the API rejected
  // with "tool_use ids must be unique", deadlocking the session (CC-1212).
  const allSeenToolUseIds = new Set<string>()

  for (let i = 0; i < messages.length; i++) {
    const msg = messages[i]!

    if (msg.type !== 'assistant') {
      // A user message with tool_result blocks but NO preceding assistant
      // message in the output has orphaned tool_results. The assistant
      // lookahead below only validates assistant→user adjacency; it never
      // sees user messages at index 0 or user messages preceded by another
      // user. This happens on resume when the transcript starts mid-turn
      // (e.g. messages[0] is a tool_result whose assistant pair was dropped
      // by earlier compaction — API rejects with "messages.0.content:
      // unexpected tool_use_id").
      if (
        msg.type === 'user' &&
        Array.isArray(msg.message.content) &&
        result.at(-1)?.type !== 'assistant'
      ) {
        const stripped = msg.message.content.filter(
          block =>
            !(
              typeof block === 'object' &&
              'type' in block &&
              block.type === 'tool_result'
            ),
        )
        if (stripped.length !== msg.message.content.length) {
          repaired = true
          // If stripping emptied the message and nothing has been pushed yet,
          // keep a placeholder so the payload still starts with a user
          // message (normalizeMessagesForAPI runs before us, so messages[1]
          // is an assistant — dropping messages[0] entirely would yield a
          // payload starting with assistant, a different 400).
          const content =
            stripped.length > 0
              ? stripped
              : result.length === 0
                ? [
                    {
                      type: 'text' as const,
                      text: '[Orphaned tool result removed due to conversation resume]',
                    },
                  ]
                : null
          if (content !== null) {
            result.push({
              ...msg,
              message: { ...msg.message, content },
            })
          }
          continue
        }
      }
      result.push(msg)
      continue
    }

    // Collect server-side tool result IDs (*_tool_result blocks have tool_use_id).
    const serverResultIds = new Set<string>()
    for (const c of msg.message.content) {
      if ('tool_use_id' in c && typeof c.tool_use_id === 'string') {
        serverResultIds.add(c.tool_use_id)
      }
    }

    // Dedupe tool_use blocks by ID. Checks against the cross-message
    // allSeenToolUseIds Set so a duplicate in a LATER assistant (different
    // message.id, not merged by normalizeMessagesForAPI) is also stripped.
    // The per-message seenToolUseIds tracks only THIS assistant's surviving
    // IDs — the orphan/missing-result detection below needs a per-message
    // view, not the cumulative one.
    //
    // Also strip orphaned server-side tool use blocks (server_tool_use,
    // mcp_tool_use) whose result blocks live in the SAME assistant message.
    // If the stream was interrupted before the result arrived, the use block
    // has no matching *_tool_result and the API rejects with e.g. "advisor
    // tool use without corresponding advisor_tool_result".
    const seenToolUseIds = new Set<string>()
    const finalContent = msg.message.content.filter(block => {
      if (block.type === 'tool_use') {
        if (allSeenToolUseIds.has(block.id)) {
          repaired = true
          return false
        }
        allSeenToolUseIds.add(block.id)
        seenToolUseIds.add(block.id)
      }
      if (
        (block.type === 'server_tool_use' || block.type === 'mcp_tool_use') &&
        !serverResultIds.has((block as { id: string }).id)
      ) {
        repaired = true
        return false
      }
      return true
    })

    const assistantContentChanged =
      finalContent.length !== msg.message.content.length

    // If stripping orphaned server tool uses empties the content array,
    // insert a placeholder so the API doesn't reject empty assistant content.
    if (finalContent.length === 0) {
      finalContent.push({
        type: 'text' as const,
        text: '[Tool use interrupted]',
        citations: [],
      })
    }

    const assistantMsg = assistantContentChanged
      ? {
          ...msg,
          message: { ...msg.message, content: finalContent },
        }
      : msg

    result.push(assistantMsg)

    // Collect tool_use IDs from this assistant message
    const toolUseIds = [...seenToolUseIds]

    // Check the next message for matching tool_results. Also track duplicate
    // tool_result blocks (same tool_use_id appearing twice) — for transcripts
    // corrupted before Fix 1 shipped, the orphan handler ran to completion
    // multiple times, producing [asst(X), user(tr_X), asst(X), user(tr_X)] which
    // normalizeMessagesForAPI merges to [asst([X,X]), user([tr_X,tr_X])]. The
    // tool_use dedup above strips the second X; without also stripping the
    // second tr_X, the API rejects with a duplicate-tool_result 400 and the
    // session stays stuck.
    const nextMsg = messages[i + 1]
    const existingToolResultIds = new Set<string>()
    let hasDuplicateToolResults = false

    if (nextMsg?.type === 'user') {
      const content = nextMsg.message.content
      if (Array.isArray(content)) {
        for (const block of content) {
          if (
            typeof block === 'object' &&
            'type' in block &&
            block.type === 'tool_result'
          ) {
            const trId = (block as ToolResultBlockParam).tool_use_id
            if (existingToolResultIds.has(trId)) {
              hasDuplicateToolResults = true
            }
            existingToolResultIds.add(trId)
          }
        }
      }
    }

    // Find missing tool_result IDs (forward direction: tool_use without tool_result)
    const toolUseIdSet = new Set(toolUseIds)
    const missingIds = toolUseIds.filter(id => !existingToolResultIds.has(id))

    // Find orphaned tool_result IDs (reverse direction: tool_result without tool_use)
    const orphanedIds = [...existingToolResultIds].filter(
      id => !toolUseIdSet.has(id),
    )

    if (
      missingIds.length === 0 &&
      orphanedIds.length === 0 &&
      !hasDuplicateToolResults
    ) {
      continue
    }

    repaired = true

    // Build synthetic error tool_result blocks for missing IDs
    const syntheticBlocks: ToolResultBlockParam[] = missingIds.map(id => ({
      type: 'tool_result' as const,
      tool_use_id: id,
      content: SYNTHETIC_TOOL_RESULT_PLACEHOLDER,
      is_error: true,
    }))

    if (nextMsg?.type === 'user') {
      // Next message is already a user message - patch it
      let content: (ContentBlockParam | ContentBlock)[] = Array.isArray(
        nextMsg.message.content,
      )
        ? nextMsg.message.content
        : [{ type: 'text' as const, text: nextMsg.message.content }]

      // Strip orphaned tool_results and dedupe duplicate tool_result IDs
      if (orphanedIds.length > 0 || hasDuplicateToolResults) {
        const orphanedSet = new Set(orphanedIds)
        const seenTrIds = new Set<string>()
        content = content.filter(block => {
          if (
            typeof block === 'object' &&
            'type' in block &&
            block.type === 'tool_result'
          ) {
            const trId = (block as ToolResultBlockParam).tool_use_id
            if (orphanedSet.has(trId)) return false
            if (seenTrIds.has(trId)) return false
            seenTrIds.add(trId)
          }
          return true
        })
      }

      const patchedContent = [...syntheticBlocks, ...content]

      // If content is now empty after stripping orphans, skip the user message
      if (patchedContent.length > 0) {
        const patchedNext: UserMessage = {
          ...nextMsg,
          message: {
            ...nextMsg.message,
            content: patchedContent,
          },
        }
        i++
        // Prepending synthetics to existing content can produce a
        // [tool_result, text] sibling the smoosh inside normalize never saw
        // (pairing runs after normalize). Re-smoosh just this one message.
        result.push(
          checkStatsigFeatureGate_CACHED_MAY_BE_STALE('tengu_chair_sermon')
            ? smooshSystemReminderSiblings([patchedNext])[0]!
            : patchedNext,
        )
      } else {
        // Content is empty after stripping orphaned tool_results. We still
        // need a user message here to maintain role alternation — otherwise
        // the assistant placeholder we just pushed would be immediately
        // followed by the NEXT assistant message, which the API rejects with
        // a role-alternation 400 (not the duplicate-id 400 we handle).
        i++
        result.push(
          createUserMessage({
            content: NO_CONTENT_MESSAGE,
            isMeta: true,
          }),
        )
      }
    } else {
      // No user message follows - insert a synthetic user message (only if missing IDs)
      if (syntheticBlocks.length > 0) {
        result.push(
          createUserMessage({
            content: syntheticBlocks,
            isMeta: true,
          }),
        )
      }
    }
  }

  if (repaired) {
    // Capture diagnostic info to help identify root cause
    const messageTypes = messages.map((m, idx) => {
      if (m.type === 'assistant') {
        const toolUses = m.message.content
          .filter(b => b.type === 'tool_use')
          .map(b => (b as ToolUseBlock | ToolUseBlockParam).id)
        const serverToolUses = m.message.content
          .filter(
            b => b.type === 'server_tool_use' || b.type === 'mcp_tool_use',
          )
          .map(b => (b as { id: string }).id)
        const parts = [
          `id=${m.message.id}`,
          `tool_uses=[${toolUses.join(',')}]`,
        ]
        if (serverToolUses.length > 0) {
          parts.push(`server_tool_uses=[${serverToolUses.join(',')}]`)
        }
        return `[${idx}] assistant(${parts.join(', ')})`
      }
      if (m.type === 'user' && Array.isArray(m.message.content)) {
        const toolResults = m.message.content
          .filter(
            b =>
              typeof b === 'object' && 'type' in b && b.type === 'tool_result',
          )
          .map(b => (b as ToolResultBlockParam).tool_use_id)
        if (toolResults.length > 0) {
          return `[${idx}] user(tool_results=[${toolResults.join(',')}])`
        }
      }
      return `[${idx}] ${m.type}`
    })

    if (getStrictToolResultPairing()) {
      throw new Error(
        `ensureToolResultPairing: tool_use/tool_result pairing mismatch detected (strict mode). ` +
          `Refusing to repair — would inject synthetic placeholders into model context. ` +
          `Message structure: ${messageTypes.join('; ')}. See inc-4977.`,
      )
    }

    logEvent('tengu_tool_result_pairing_repaired', {
      messageCount: messages.length,
      repairedMessageCount: result.length,
      messageTypes: messageTypes.join(
        '; ',
      ) as AnalyticsMetadata_I_VERIFIED_THIS_IS_NOT_CODE_OR_FILEPATHS,
    })
    logError(
      new Error(
        `ensureToolResultPairing: repaired missing tool_result blocks (${messages.length} -> ${result.length} messages). Message structure: ${messageTypes.join('; ')}`,
      ),
    )
  }

  return result
}

/**
 * Strip advisor blocks from messages. The API rejects server_tool_use blocks
 * with name "advisor" unless the advisor beta header is present.
 */
export function stripAdvisorBlocks(
  messages: (UserMessage | AssistantMessage)[],
): (UserMessage | AssistantMessage)[] {
  let changed = false
  const result = messages.map(msg => {
    if (msg.type !== 'assistant') return msg
    const content = msg.message.content
    const filtered = content.filter(b => !isAdvisorBlock(b))
    if (filtered.length === content.length) return msg
    changed = true
    if (
      filtered.length === 0 ||
      filtered.every(
        b =>
          b.type === 'thinking' ||
          b.type === 'redacted_thinking' ||
          (b.type === 'text' && (!b.text || !b.text.trim())),
      )
    ) {
      filtered.push({
        type: 'text' as const,
        text: '[Advisor response]',
        citations: [],
      })
    }
    return { ...msg, message: { ...msg.message, content: filtered } }
  })
  return changed ? result : messages
}

/**
 * Index of the last REAL user message — one carrying non-tool_result content
 * (a typed prompt, queued command, attachment). Messages after it belong to
 * the assistant turn currently in flight. tool_result-only user messages are
 * loop plumbing, not turn boundaries.
 */
function lastRealUserMessageIndex(
  messages: (UserMessage | AssistantMessage)[],
): number {
  for (let i = messages.length - 1; i >= 0; i--) {
    const m = messages[i]
    if (m?.type !== 'user') continue
    const c = m.message.content
    if (typeof c === 'string') return i
    // A message carrying ANY tool_result is loop plumbing even when text
    // siblings ride along (deferred-tool "Tool loaded." notices, collapsed
    // context summaries, system reminders) — treating those as boundaries
    // would advance the boundary INTO the in-flight tool loop and re-expose
    // the turn-initial signed thinking to stripping. Only a user message
    // with zero tool_results is a real turn boundary.
    if (
      Array.isArray(c) &&
      !(c as Array<{ type?: string }>).some(b => b?.type === 'tool_result')
    ) {
      return i
    }
  }
  return -1
}

/**
 * Strip `thinking` blocks from assistant messages outside the keep window:
 * only the last `keepRecentTurns` ASSISTANT messages keep their thinking.
 *
 * The window is position-based over assistant messages, NOT count-based over
 * thinking-bearing ones. Count-based had a pathology with sporadic thinking:
 * when the model thinks on only a few early turns, exactly keepRecentTurns of
 * them remain "the most recent thinking turns" forever, never strip, and sit
 * as a pending byte-mutation near the head of the conversation — pinning the
 * clip-frontier cache marker there for the rest of the session (see
 * docs/tech/cache/clip-frontier-breakpoint.md). Position-based, old thinking
 * ages out after keepRecentTurns assistant turns whether or not the model
 * thought again since.
 *
 * `redacted_thinking` blocks are never stripped — the API requires them to be
 * echoed back verbatim and stripping them causes a 400.
 *
 * Used across all providers to keep token estimation accurate and prevent
 * premature auto-compact from inflated local message arrays.
 */
export function stripOldThinkingBlocks(
  messages: (UserMessage | AssistantMessage)[],
  keepRecentTurns: number,
): (UserMessage | AssistantMessage)[] {
  const assistantIndices: number[] = []
  for (let i = 0; i < messages.length; i++) {
    if (messages[i]?.type === 'assistant') assistantIndices.push(i)
  }
  const keepSet = new Set(
    keepRecentTurns > 0 ? assistantIndices.slice(-keepRecentTurns) : [],
  )
  // Never strip the assistant turn currently in flight: a tool loop appends
  // thinking-less continuation messages that advance the positional window,
  // and stripping the turn-initial signed thinking mid-loop risks the API's
  // "thinking blocks cannot be modified" 400 (recovered only via the costly
  // stripThinkingFromHistory retry) and drops reasoning_content continuity
  // on shim providers. keepRecentTurns=0 (the retry path) bypasses this on
  // purpose — it must strip everything.
  const currentTurnStart =
    keepRecentTurns > 0 ? lastRealUserMessageIndex(messages) : -1

  const stripSet = new Set<number>()
  for (const i of assistantIndices) {
    if (keepSet.has(i)) continue
    if (currentTurnStart !== -1 && i > currentTurnStart) continue
    if (keepRecentTurns > 0 && currentTurnStart === -1) continue
    const content = (messages[i] as AssistantMessage).message.content
    if (content.some((b: BetaContentBlock) => b.type === 'thinking')) {
      stripSet.add(i)
    }
  }
  if (stripSet.size === 0) return messages

  let changed = false
  const result = messages.map((msg, i) => {
    if (!stripSet.has(i) || msg.type !== 'assistant') return msg

    // Filter out only `thinking` blocks; leave `redacted_thinking` untouched.
    const filtered = msg.message.content.filter(
      (b: BetaContentBlock) => b.type !== 'thinking',
    )

    // If the message becomes empty or thinking-only after stripping, insert a
    // placeholder so the API never receives an empty assistant turn.
    const hasNonThinking = filtered.some(
      (b: BetaContentBlock) =>
        b.type !== 'thinking' && b.type !== 'redacted_thinking',
    )
    if (!hasNonThinking) {
      filtered.push({ type: 'text' as const, text: '[thinking omitted]', citations: [] })
    }

    changed = true
    return {
      ...msg,
      message: { ...msg.message, content: filtered },
    } as typeof msg
  })

  return changed ? result : messages
}

/**
 * Strip narration `text` blocks from old assistant messages, keeping only the
 * most recent `keepRecentTurns` assistant messages that mix text with a tool
 * call intact.
 *
 * Narration = a `text` block in an assistant turn that ALSO contains a
 * `tool_use` block (the model talked while working). A `text` block in a turn
 * with no `tool_use` is the final answer and is never stripped. Turns with a
 * `tool_use` never become empty after dropping their text, so no placeholder is
 * needed (unlike stripOldThinkingBlocks).
 *
 * Used across all providers to keep the inter-tool-call narration out of the
 * cached prefix — it never participates in cache_write or recurring input.
 *
 * Skips turns that also contain `thinking` / `redacted_thinking` blocks.
 * Stripping `text` from such a turn shifts the indices of the remaining
 * blocks, which invalidates the position chain that the server requires for
 * signed thinking blocks. The API then 400s with "thinking or
 * redacted_thinking blocks in the latest assistant message cannot be
 * modified." (Diagnosed on Opus 4.8 + adaptive thinking — see bench failures
 * in scripts/bench/results/serial-read-nudge-ab-...14-28-52-454Z.md.)
 */
export function stripOldNarrationBlocks(
  messages: (UserMessage | AssistantMessage)[],
  keepRecentTurns: number,
): (UserMessage | AssistantMessage)[] {
  // Position-based keep window over ASSISTANT messages, mirroring
  // stripOldThinkingBlocks: narration survives only in the last
  // keepRecentTurns assistant turns. Count-based ("last N narration-bearing
  // turns") had the same sporadic-narration pathology — old narration turns
  // that never aged out kept a pending mutation alive near the head of the
  // conversation and pinned the clip-frontier cache marker.
  const assistantIndices: number[] = []
  for (let i = 0; i < messages.length; i++) {
    if (messages[i]?.type === 'assistant') assistantIndices.push(i)
  }
  const keepSet = new Set(
    keepRecentTurns > 0 ? assistantIndices.slice(-keepRecentTurns) : [],
  )
  // Never strip the in-flight turn (see stripOldThinkingBlocks): tool-only
  // iterations advance the positional window, and stripping the model's own
  // just-written plan text mid-task both loses working context and creates
  // a per-iteration byte mutation near the tail (cache churn) under the
  // default profile, where no clip frontier caps the marker.
  const currentTurnStart =
    keepRecentTurns > 0 ? lastRealUserMessageIndex(messages) : -1

  // Narration = text mixed with tool_use AND no thinking blocks (stripping
  // text from a thinking-bearing turn shifts block indices and invalidates
  // the signed-thinking position chain).
  const stripSet = new Set<number>()
  for (const i of assistantIndices) {
    if (keepSet.has(i)) continue
    if (currentTurnStart !== -1 && i > currentTurnStart) continue
    if (keepRecentTurns > 0 && currentTurnStart === -1) continue
    const content = (messages[i] as AssistantMessage).message.content
    const hasText = content.some((b: BetaContentBlock) => b.type === 'text')
    const hasToolUse = content.some(
      (b: BetaContentBlock) => b.type === 'tool_use',
    )
    const hasThinking = content.some(
      (b: BetaContentBlock) =>
        b.type === 'thinking' || b.type === 'redacted_thinking',
    )
    if (hasText && hasToolUse && !hasThinking) {
      stripSet.add(i)
    }
  }
  if (stripSet.size === 0) return messages

  let changed = false
  const result = messages.map((msg, i) => {
    if (!stripSet.has(i) || msg.type !== 'assistant') return msg

    // Drop only `text` blocks; the tool_use (and anything else) stays. The turn
    // keeps its tool_use, so it can never become empty.
    const filtered = msg.message.content.filter(
      (b: BetaContentBlock) => b.type !== 'text',
    )

    changed = true
    return {
      ...msg,
      message: { ...msg.message, content: filtered },
    } as typeof msg
  })

  return changed ? result : messages
}
