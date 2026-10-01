/**
 * AgentSession - Core abstraction for agent lifecycle and session management.
 *
 * This class is shared between all run modes (interactive, print, rpc).
 * It encapsulates:
 * - Agent state access
 * - Event subscription with automatic session persistence
 * - Model and thinking level management
 * - Compaction (manual and auto)
 * - Bash execution
 * - Session switching and branching
 *
 * Modes use this class and add their own I/O layer on top.
 */

import { AsyncLocalStorage } from "node:async_hooks";
import * as fs from "node:fs";
import * as os from "node:os";
import * as path from "node:path";
import { scheduler } from "node:timers/promises";
import { isPromise } from "node:util/types";
import {
	type AfterToolCallContext,
	type AfterToolCallResult,
	type Agent,
	AgentBusyError,
	type AgentEvent,
	type AgentMessage,
	type AgentState,
	type AgentTool,
	type AgentToolCall,
	type AgentToolContext,
	type AgentToolResult,
	type AgentTurnEndContext,
	AppendOnlyContextManager,
	type AsideMessage,
	assistantSnapshotOrigin,
	type BeforeToolCallContext,
	type BeforeToolCallResult,
	EventLoopKeepalive,
	type QueuedMessagePreparation,
	resolveTelemetry,
	type StreamFn,
	TERMINAL_TOOL_RESULT_ABORT_REASON,
	type ThinkingLevel,
	type ToolChoiceDirective,
} from "@oh-my-pi/pi-agent-core";
import {
	type CompactionPreparation,
	type CompactionResult,
	calculatePromptTokens,
	collectEntriesForBranchSummary,
	generateBranchSummary,
	type ShakeConfig,
} from "@oh-my-pi/pi-agent-core/compaction";
import type {
	AnthropicFallbackCreditHandle,
	AssistantMessage,
	CodexCompactionContext,
	Context,
	ImageContent,
	Judge,
	Message,
	MessageAttribution,
	Model,
	OAuthAccountIdentity,
	ProviderResponseMetadata,
	ProviderSessionState,
	ResetCreditAccountStatus,
	ResetCreditRedeemOutcome,
	ResetCreditTarget,
	ServiceTier,
	ServiceTierByFamily,
	ServiceTierFamily,
	SimpleStreamOptions,
	TextContent,
	ToolCall,
	ToolChoice,
	ToolResultMessage,
	UsageReport,
	UserMessage,
} from "@oh-my-pi/pi-ai";
import { type Effort, resolveApiKeyOnce, serviceTierFamily, streamSimple } from "@oh-my-pi/pi-ai";
import * as AIError from "@oh-my-pi/pi-ai/error";
import { resetOpenAICodexHistoryAfterCompaction } from "@oh-my-pi/pi-ai/providers/openai-codex-responses";
import { withCredentialRedaction } from "@oh-my-pi/pi-ai/providers/transform-messages";
import { toolWireSchema } from "@oh-my-pi/pi-ai/utils/schema";
import { supportsOutputTokenLimit } from "@oh-my-pi/pi-catalog/compat/output-limits";
import { requiresNativeTools, requiresToolFreeHistoryForToolOptOut } from "@oh-my-pi/pi-catalog/compat/tools";
import { preferredDialect } from "@oh-my-pi/pi-catalog/identity";
import { modelsAreEqual } from "@oh-my-pi/pi-catalog/models";
import { type EditStore, PowerAssertion, type PowerAssertionOptions } from "@oh-my-pi/pi-natives";
import {
	$env,
	escapeXmlText,
	formatDuration,
	getAgentDbPath,
	isEnoent,
	isBunTestRuntime,
	isInteractiveHost,
	isRecord,
	logger,
	postmortem,
	prompt,
	Snowflake,
	stringProperty,
	untilAborted,
	toError,
	withTimeout,
	withFileLock,
} from "@oh-my-pi/pi-utils";
import type { AdvisorConfig } from "@oh-my-pi/pi-tui/overlays/advisor-config";
import { formatUsageResetWindow } from "@oh-my-pi/pi-tui/overlays/usage-display";
import { type AdvisorSupervisionPipelineReport, loadAdvisorTranscriptCosts } from "../advisor";
import { ASYNC_JOB_MANAGER_SHUTDOWN_REASON, type AsyncJob, AsyncJobManager } from "../async";
import { reset as resetCapabilities } from "../capability";
import type { EffectiveExtensionRoots } from "../capability/types";
import { shouldEnableAppendOnlyContext } from "../config/append-only-context-mode";
import type { ModelRegistry } from "../config/model-registry";
import {
	DEFAULT_PREWALK_TARGET,
	getModelMatchPreferences,
	type ResolvedModelRoleValue,
	resolveCliModel,
} from "../config/model-resolver";
import { expandPromptTemplate, type PromptTemplate } from "../config/prompt-templates";
import { buildServiceTierByFamily, isServiceTierForFamily, serviceTierSettingToTier } from "../config/service-tier";
import { combine, type SettingsScope } from "../config/registry";
import type { Settings } from "../config/settings";
import { RawSseDebugBuffer } from "@oh-my-pi/pi-tui/apps/debug/raw-sse-buffer";
import { getEditStore } from "../edit/store";
import { releaseCompletionHandles } from "../eval/completion-bridge";
import { releaseJudgmentBatches } from "../eval/judgment-batch-bridge";
import type { EvalPreludeDefinition } from "../eval/preludes";
import type { PythonResult } from "../eval/py/executor";
import { formatEvalStateContext } from "../eval/state";
import { WorkPoolRegistry } from "../task/workpool";
import type { BashPtyOptions, BashResult } from "../exec/bash-executor";
import type { TtsrManager } from "../export/ttsr";
import type { LoadedCustomCommand } from "../extensibility/custom-commands";
import type { CustomTool } from "../extensibility/custom-tools/types";
import type {
	ExtensionCommandContext,
	ExtensionRunner,
	ExtensionUIContext,
	MessageEndEvent,
	MessageStartEvent,
	MessageUpdateEvent,
	PreparedExtension,
	SessionBeforeBranchResult,
	SessionBeforeSwitchResult,
	SessionBeforeTreeResult,
	SessionStopEventResult,
	ToolExecutionEndEvent,
	ToolExecutionStartEvent,
	ToolExecutionUpdateEvent,
	ToolInfo,
	TreePreparation,
	TurnEndEvent,
	TurnStartEvent,
} from "../extensibility/extensions";
import { emitSessionShutdownEvent, TOP_LEVEL_AGENT } from "../extensibility/extensions";
import { ManagedTimers } from "../extensibility/extensions/managed-timers";
import { createExtensionModelQuery } from "../extensibility/extensions/model-api";
import type { CompactOptions, ContextUsage } from "../extensibility/extensions/types";
import type { HookCommandContext } from "../extensibility/hooks/types";
import type { TaskResultAuthorityValidator } from "../extensibility/shared-events";
import type { CustomCommandContext } from "../extensibility/custom-commands/types";
import { SkillDescriptionCatalog } from "../extensibility/skill-descriptions";
import type { Skill, SkillWarning } from "../extensibility/skills";
import { expandSlashCommand, type FileSlashCommand, loadSlashCommands } from "../extensibility/slash-commands";
import { normalizeToolEventInput, resolveToolEventInput } from "../extensibility/tool-event-input";
import { GoalRuntime } from "../goals/runtime";
import type { GoalModeState } from "../goals/state";
import type { HindsightSessionState } from "../hindsight/state";
import { InternalUrlRouter, type LocalProtocolOptions } from "../internal-urls";
import { hasNativeJudge, journalJudgmentUsage, resolveJudge, sharedJudgmentCache } from "../judgment";
import type { IrcMessage } from "@oh-my-pi/pi-tui/tools/irc";
import type { DaemonCompletionNotification } from "../launch/protocol";
import { shutdownMnemopiEmbedClient } from "../mnemopi/embed-client";
import { getMnemopiSessionState, type MnemopiSessionState, setMnemopiSessionState } from "../mnemopi/state";
import { MAGIC_KEYWORDS, type MagicKeywordContext, type MagicKeywordId } from "../modes/magic-keywords";
import { containsMagicKeyword } from "@oh-my-pi/pi-tui/prompt/magic-keywords";
import { theme } from "@oh-my-pi/pi-tui/theme";
import { parseTurnBudget } from "../modes/turn-budget";
import { computeNonMessageTokens } from "@oh-my-pi/pi-tui/status-line/context-usage";
import { type PlanApprovalDetails, resolveApprovedPlan } from "../plan-mode/approved-plan";
import { listPlanFiles, readPlanFile, resolvePlanFilePath } from "../plan-mode/plan-files";
import { loadOverallPlanReference } from "../plan-mode/plan-handoff";
import type { PlanModeState } from "../plan-mode/state";
import goalModeContextPrompt from "../prompts/goals/goal-mode-context.md" with { type: "text" };
import goalTodoContextPrompt from "../prompts/goals/goal-todo-context.md" with { type: "text" };
import anthropicUsageWrapUpPrompt from "../prompts/system/anthropic-usage-wrap-up.md" with { type: "text" };
import autoContinuePrompt from "../prompts/system/auto-continue.md" with { type: "text" };
import checkpointActiveNoticeTemplate from "../prompts/system/checkpoint-active-notice.md" with { type: "text" };
import interruptedThinkingTemplate from "../prompts/system/interrupted-thinking.md" with { type: "text" };
import planModeActivePrompt from "../prompts/system/plan-mode-active.md" with { type: "text" };
import planModeReferencePrompt from "../prompts/system/plan-mode-reference.md" with { type: "text" };
import planModeToolDecisionReminderPrompt from "../prompts/system/plan-mode-tool-decision-reminder.md" with { type: "text" };
import rewindReportTemplate from "../prompts/system/rewind-report.md" with { type: "text" };
import sessionStopBlockedPrompt from "../prompts/system/session-stop-blocked.md" with { type: "text" };
import sideChannelNoToolsReminder from "../prompts/system/side-channel-no-tools.md" with { type: "text" };
import skillfulNoticePrompt from "../prompts/system/skillful-notice.md" with { type: "text" };
import vibeModeActivePrompt from "../prompts/system/vibe-mode-active.md" with { type: "text" };
import { AgentLifecycleManager } from "../registry/agent-lifecycle";
import { type AgentRef, AgentRegistry, getAgentTombstonePath } from "../registry/agent-registry";
import {
	deobfuscateAgentMessages,
	deobfuscateAssistantContent,
	deobfuscateSessionContext,
	deobfuscateToolArguments,
	obfuscateProviderContext,
} from "../secrets/message-transform";
import type { SecretObfuscator } from "../secrets/obfuscator";
import type { InstructionPrepDegradation } from "../system-prompt";
import {
	type BoundTaskDriverControls,
	buildTaskReadContinuationRecord,
	claimTaskReadContinuation,
	classifyTaskChildContinuation,
	effectiveTaskArguments,
	hasTaskReadContinuationMarkers,
	initializationContract,
	isTaskReadTextContent,
	type NativePlainReadProvenance,
	type NativeTaskResultReadyCheckpoint,
	type NativeTaskResultReadyV1,
	type OriginalTaskCompletionCapture,
	type PersistedTaskBindingV1,
	type PersistedTaskCallRef,
	type PersistedTaskResultRef,
	PROMPT_PREPARATION,
	type PromptPreparationRecordV1,
	preparedEntryIds,
	readPreparationRecord,
	readTaskBinding,
	TASK_NATIVE_RESULT_READY,
	TASK_READ_CONTINUATION_READY,
	TASK_READ_CONTINUATION_STARTED,
	TASK_RESULT_PROCESSING_PROTOCOL,
	TASK_RESULT_PROCESSING_STARTED,
	TASK_RUN_BINDING,
	type TaskCallCapture,
	type TaskReadContinuationCheckpoint,
	type TaskReadContinuationClaim,
	type TaskReadRequestFence,
	type TaskRecoveryContract,
	type TaskResultProcessingGate,
	type TaskResultProcessingRef,
	type TaskResultProcessingStartedV1,
	taskRecoveryHash,
	taskResultRecoveryState,
	taskRuntimeContract,
	validateTaskReadContinuationPrefix,
} from "../task/recovery";
import { cfgSecretsEnabled } from "../secrets/settings";
import { releaseSharpshooterSession } from "../sharpshooter/backend";
import { flushSharpshooterExtraction } from "../sharpshooter/extract";
import { toolReadsSkillUris } from "../system-prompt";
import {
	AUTO_THINKING,
	type ConfiguredThinkingLevel,
	parseConfiguredThinkingLevel,
	shouldDisableReasoning,
	toReasoningEffort,
} from "@oh-my-pi/pi-tui/thinking";
import { isLowSignalTitleInput } from "../tiny/text";
import { shutdownTinyTitleClient } from "../tiny/title-client";
import type { ImageAttachmentEntry, ToolSession } from "../tools";
import { resolveApproval } from "../tools/approval";
import { type AskToolDetails } from "@oh-my-pi/pi-tui/tools/ask";
import { type AskToolInput, recoverAskQuestions } from "../tools/ask";
import {
	armIdleCloseForOwner,
	cancelIdleCloseForOwner,
	freezeTabsForOwner,
	releaseIdleTabsForOwner,
	releaseTabsForOwner,
} from "../tools/browser/tab-supervisor";
import type { CheckpointState, CompletedRewindState } from "../tools/checkpoint";
import { releaseComputerSessionsForOwner } from "../tools/computer/supervisor";
import { nativePlainReadProvenance } from "../tools/read";
import { isAutoQaEnabled } from "../tools/report-tool-issue";
import {
	buildResolveReminderMessage,
	isPreviewResolutionToolCall,
	isProposeToolCall,
	type PlanProposalHandler,
	writeDeviceDispatch,
} from "../tools/resolve";
import { PROPOSE_DEVICE_NAME } from "@oh-my-pi/pi-tui/tools/resolve";
import { supportsExternalThinking } from "../tools/think";
import type { TodoPhase } from "@oh-my-pi/pi-tui/tools/todo";
import { ToolError } from "@oh-my-pi/pi-tui/tools/tool-errors";
import type { WorkPoolYieldItem } from "../task/workpool-yield";
import type { AgentDefinition } from "../task/types";
import type { ModelMention } from "@oh-my-pi/pi-tui/prompt/model-mention-syntax";
import { ModelMentionRegistry } from "./model-mentions";
import { parseCommandArgs } from "../utils/command-args";
import type { EditMode } from "@oh-my-pi/pi-tui/tools/edit";
import { resolveFileDisplayMode } from "../utils/file-display-mode";
import { extractFileMentions, generateFileMentionMessages } from "../utils/file-mentions";
import { normalizeModelContextImages } from "../utils/image-loading";
import { TokenRateMeter } from "../utils/token-rate";
import { resumeCommand } from "../utils/resume-command";
import { generateSessionTitle } from "../utils/title-generator";
import { buildNamedToolChoice, isToolChoiceActive } from "../utils/tool-choice";
import type { VibeModeState } from "../vibe/state";
import type { AgentSessionEvent, AgentSessionEventListener } from "./agent-session-events";
import type {
	AgentSessionConfig,
	AgentSessionDisposeOptions,
	AsyncJobSnapshot,
	CommandMetadataChangedListener,
	ContextUsageBreakdown,
	DispatchAuthorityValidation,
	DroppedPrompt,
	EphemeralTurnOptions,
	EphemeralTurnResult,
	FollowUpOptions,
	FreshSessionResult,
	HandoffResult,
	ModelCycleResult,
	PersistedTurnContinuationRequest,
	PersistedTurnContinuationResult,
	PersistedTurnRefusal,
	Prewalk,
	PromptOptions,
	ResetSessionContextResult,
	ResolvedRoleModel,
	RestoredQueuedMessage,
	RoleModelCycle,
	RoleModelCycleResult,
	SendUserMessageOptions,
	SessionHandoffOptions,
	SessionOAuthAccountList,
	SessionStats,
	SteerOptions,
	UsageFallbackConfirmer,
} from "./agent-session-types";
import { writeArtifact } from "./artifacts";
import { renderAttachmentSourceNotice } from "./attachment-source-notice";
import { formatArtifactErrorNotice, type OutputMeta, stripOutputNotice } from "@oh-my-pi/pi-tui/tools/output-meta";
import { truncateMiddle } from "@oh-my-pi/pi-tui/tools/streaming-output";
import {
	ASYNC_INLINE_RESULT_MAX_CHARS,
	ASYNC_PREVIEW_MAX_CHARS,
	ASYNC_PREVIEW_TAIL_CHARS,
	ASYNC_RESULT_MESSAGE_TYPE,
	type AsyncResultEntry,
	buildAsyncResultBatchMessage,
} from "./async-job-delivery";
import { BashRunner, type BashRunnerHost } from "./bash-runner";
import {
	checkpointStartedAtFromEntry,
	completedRewindFromEntry,
	isSuccessfulCheckpointEntry,
	semanticToolResult,
} from "./checkpoint-entries";
import type { ClientBridge } from "./client-bridge";
import { type ClaudeResetAction, type ClaudeResetPlan, planClaudeResetRedemptions } from "./claude-auto-reset";
import {
	type CodexAutoRedeemCoordinator,
	type CodexResetAction,
	type CodexResetPlan,
	type CodexResetTrigger,
	type ResetRecoveryResult,
	ATTEMPT_COOLDOWN_MS,
	resetAccountLockKey,
	defaultCodexAutoRedeemCoordinator,
	isTerminalRedeemOutcome,
	overlayLiveResetCredits,
	planCodexResetRedemptions,
	REDEEM_RETRY_DEFER_MS,
	SWEEP_MIN_INTERVAL_MS,
	shouldEvaluateCodexAutoRedeem,
	shouldPromptCodexAutoRedeem,
} from "./codex-auto-reset";
import { recordCredentialPin, seedCredentialPins } from "./credential-pin";
import { EvalRunner, type EvalRunnerHost } from "./eval-runner";
import {
	collectPendingToolCalls,
	createInterruptedTurnAbortMessage,
	describePendingToolCalls,
	SESSION_EXIT_CUSTOM_TYPE,
	type SessionExitData,
	summarizeToolArguments,
	TOOL_EXECUTION_START_CUSTOM_TYPE,
	type ToolExecutionStartData,
} from "./exit-diagnostics";
import {
	buildExtensionDeliveryBatchMessage,
	EXTENSION_DELIVERY_MESSAGE_TYPE,
	type ExtensionDeliveryEntry,
} from "./extension-delivery";
import { IrcBridge, type IrcBridgeHost } from "./irc-bridge";
import {
	buildLaunchCompletionBatchMessage,
	isLaunchCompletionOwner,
	LAUNCH_COMPLETION_MESSAGE_TYPE,
	type LaunchCompletionEntry,
} from "./launch-completion";
import {
	type BashExecutionMessage,
	buildReplanTitleContext,
	CHECKPOINT_ACTIVE_REMINDER_TYPE,
	type CustomMessage,
	type CustomMessagePayload,
	convertToLlm,
	createCustomMessage,
	dedupeEphemeralReply,
	demoteInterruptedThinking,
	didSessionMessagesChange,
	type FileMentionMessage,
	type HookMessage,
	INTERRUPTED_THINKING_MESSAGE_TYPE,
	type InterruptedThinkingDetails,
	isEmptyErrorTurn,
	isTitleContextReply,
	isUserInterruptAbort,
	isUserInvokedSkillPrompt,
	logProviderTurnError,
	normalizeCustomMessagePayload,
	type PythonExecutionMessage,
	SILENT_ABORT_MARKER,
	SKILL_PROMPT_MESSAGE_TYPE,
	sanitizeAssistantForReparentedHistory,
	USER_INTERRUPT_LABEL,
	VIBE_MODE_CONTEXT_MESSAGE_TYPE,
} from "./messages";
import { ModelControls, type ModelControlsHost } from "./model-controls";
import {
	isPrewalkPlanNudge,
	PrewalkCoordinator,
	type PrewalkCoordinatorHost,
	type PrewalkRestartResult,
} from "./prewalk";
import {
	isAdvisorCard,
	isDisplayableQueuedMessage,
	isHiddenUserCompanion,
	isUserAuthoredQueuedMessage,
	isUserQueuedMessage,
	queueChipText,
	toRestoredQueuedMessage,
} from "./queued-messages";
import type { ServingModel } from "./retry-fallback-chains";
import {
	type AdvisorStats,
	type AdvisorStatusOverviewEntry,
	SessionAdvisors,
	type SessionAdvisorsHost,
} from "./session-advisors";
import type { BuildSessionContextOptions, SessionContext } from "./session-context";
import { getRestorableSessionModels, isTranscriptEntry } from "./session-context";
import type { CacheWarmer, CacheWarmingMode, CacheWarmingStatus } from "./cache-warmer";
import { isUserRequestEntry, transcriptEntryMessage, userTurnDraft } from "@oh-my-pi/pi-tui/chat/transcript-entry";
import { formatSessionDumpText } from "./session-dump-format";
import type { BranchSummaryEntry, NewSessionOptions } from "./session-entries";
import { SessionHandoff, type SessionHandoffHost } from "./session-handoff";
import { loadSessionFile } from "./session-loader";
import {
	COMPACTION_CHECK_NONE,
	createCodexCompactionContext as createMaintenanceCodexCompactionContext,
	SessionMaintenance,
	type SessionMaintenanceHost,
} from "./session-maintenance";
import { cleanupEmptyMoveSession, copySessionArtifacts, type SessionManager } from "./session-manager";
import { SessionMemory, type SessionMemoryHost } from "./session-memory";
import { buildSessionMetadata } from "./session-metadata";
import { SessionProviderBoundary, type SessionProviderBoundaryHost } from "./session-provider-boundary";
import { SessionStatsTracker, type SessionStatsTrackerHost } from "./session-stats";
import { SessionTools, type SessionToolsHost } from "./session-tools";
import { resolveOpenAIWebsocketPreference } from "./settings-stream-fn";
import type { ShakeMode, ShakeResult } from "./shake-types";
import { skillPromptTitleInput } from "@oh-my-pi/pi-tui/chat/skill-title-input";
import { ToolChoiceQueue } from "./tool-choice-queue";
import { planTurnPersistence, sameMessageContent, sessionMessagePersistenceKey } from "./turn-persistence";
import { TurnRecovery, type TurnRecoveryHost } from "./turn-recovery";
import { YieldQueue } from "./yield-queue";

export * from "./agent-session-events";
export * from "./agent-session-types";
export type { AdvisorStats, AdvisorStatusOverviewEntry, PerAdvisorStat } from "./session-advisors";

const SESSION_STOP_CONTINUATION_CAP = 8;

import { LoopGuards, type StreamGuardsHost, StreamingEditGuard } from "./stream-guards";
import { TodoTracker, type TodoTrackerHost } from "./todo-tracker";
import { TtsrCoordinator, type TtsrCoordinatorHost } from "./ttsr-coordinator";

import { cfgAdvisorEnabled, cfgAdvisorMaxNotesPerUpdate } from "../advisor/settings";
import { cfgBrowserEnabled, cfgBrowserFreezeOnTurnEnd, cfgBrowserIdleCloseSec } from "../tools/browser/settings";
import {
	cfgClaudeResets,
	cfgClaudeResetsAutoRedeem,
	cfgCodeModeInputs,
	cfgCodexResets,
	cfgCodexResetsAutoRedeem,
	cfgDefaultThinkingLevel,
	cfgExternalThinking,
	cfgPowerSleepPrevention,
	cfgPrewalkEnabled,
	cfgProviderAppendOnlyContext,
	cfgProvidersCacheWarming,
	cfgProvidersCacheRetention,
	cfgProvidersAntigravityEndpoint,
	cfgRetryUsageAwareFallback,
	cfgSampling,
	cfgSkillful,
	cfgTierAdvisor,
	cfgTierAnthropic,
	cfgTierGoogle,
	cfgTierOpenai,
	cfgProvidersAnthropicSlowMode,
} from "./settings";
import { type AnthropicSlowModeController, anthropicSlowModeLanes } from "./anthropic-slow-mode";
import { cfgInterruptMode } from "../modes/settings";
import { cfgFollowUpMode } from "../modes/settings";
import { cfgSteeringMode } from "../modes/settings";
import { cfgDisabledProviders, cfgModelRoles } from "../config/model-settings";
import { cfgEvalToolsEnabled } from "../eval/settings";
import { cfgExtensions, type SkillsSettings } from "../extensibility/settings";
import {
	cfgImagesAutoResize,
	cfgMagicKeyword,
	cfgMagicKeywordsEnabled,
	cfgThemeDark,
	cfgThemeLight,
} from "../modes/settings";
import {
	cfgTaskAgentAdvisor,
	cfgTaskAgentModelOverrides,
	cfgTaskAgentPrewalk,
	cfgTaskBatch,
	cfgTaskDisabledAgents,
	cfgTaskIsolationEnabled,
	cfgTaskMaxRecursionDepth,
	cfgTaskPrewalk,
} from "../task/settings";
import {
	cfgBranchSummaryReserveTokens,
	cfgExtendedContext,
	cfgWorkspaceAdditionalDirectories,
} from "./context-settings";
import { cfgTitleRefreshOnReplan } from "../goals/settings";
import {
	cfgAsyncEnabled,
	cfgComputerEnabled,
	cfgRatchetEnabled,
	cfgDevAutoqa,
	cfgDevAutoqaConsent,
	cfgTodoEnabled,
	cfgToolsApproval,
	cfgToolsApprovalMode,
} from "../tools/settings";
import { cfgTtsrJudge } from "../export/ttsr-settings";

/** Advisor settings whose edit toggles or rebuilds a running advisor. */
const cfgAdvisorRuntimeInputs = combine({
	enabled: cfgAdvisorEnabled,
	maxNotesPerUpdate: cfgAdvisorMaxNotesPerUpdate,
	tier: cfgTierAdvisor,
});
/** Settings behind the session's extra workspace roots and the auto-QA prompt note. */
const cfgWorkspacePromptInputs = combine({
	additionalDirectories: cfgWorkspaceAdditionalDirectories,
	autoqa: cfgDevAutoqa,
	autoqaConsent: cfgDevAutoqaConsent,
});

const PLAN_MODE_REMINDER_MAX = 3;
const POST_PROMPT_DRAIN_TIMEOUT_MS = 5_000;
const AGENT_START_POLICY_MAX_ATTEMPTS = 3;
/** Vision descriptions gate admission; stay under the RPC clients' 30 s request timeout. */
const IMAGE_DESCRIPTION_ADMISSION_TIMEOUT_MS = 20_000;

/** A failed preparation, not a provider failure: the ordinary input can still be restored. */
class AgentStartPolicyChangedError extends Error {
	constructor() {
		super("System prompt changed repeatedly during before_agent_start; original input was not delivered.");
		this.name = "AgentStartPolicyChangedError";
	}
}

/**
 * Rejection from {@link AgentSession.prompt} with `throwOnDrop: true` when the
 * prompt was dropped before reaching the agent (an abort, session transition,
 * or usage preflight denial won the race with turn setup). The prompt was not
 * persisted, so resubmitting it is safe. Headless drivers use this to retry.
 */
export class PromptDroppedError extends Error {
	constructor() {
		super("Prompt dropped before provider dispatch.");
		this.name = "PromptDroppedError";
	}
}

const EXPERIMENTAL_CONTEXT_REQUIRED_TOOLS: Record<string, true> = {
	context_notes: true,
	new_context: true,
	read: true,
	grep: true,
};

/** Internal marker for hook messages queued through the agent loop */
// ============================================================================
// Constants
// ============================================================================

const noOpUIContext: ExtensionUIContext = {
	select: async (_title, _options, _dialogOptions) => undefined,
	confirm: async (_title, _message, _dialogOptions) => false,
	input: async (_title, _placeholder, _dialogOptions) => undefined,
	notify: () => {},
	onTerminalInput: () => () => {},
	setStatus: () => {},
	setWorkingMessage: () => {},
	setWidget: () => {},
	setTitle: () => {},
	custom: async () => undefined as never,
	setEditorText: () => {},
	pasteToEditor: () => {},
	getEditorText: () => "",
	editor: async () => undefined,
	addAutocompleteProvider: () => {},
	get theme() {
		return theme;
	},
	getAllThemes: () => Promise.resolve([]),
	getTheme: () => Promise.resolve(undefined),
	setTheme: _theme => Promise.resolve({ success: false, error: "UI not available" }),
	setFooter: () => {},
	setHeader: () => {},
	setEditorComponent: () => {},
	getToolsExpanded: () => false,
	setToolsExpanded: () => {},
};

// ============================================================================
// AgentSession Class
// ============================================================================

type MessageEndPersistenceSlot = {
	readonly promise: Promise<void>;
	persist: (persistMessage: () => void | Promise<void>) => Promise<void>;
	release: () => void;
};
type AgentEndEvent = Extract<AgentEvent, { type: "agent_end" }>;

/** How a settle describes what happens next; see {@link AgentSession} `#settleAgentEnd`. */
type AgentEndSettleOptions = { willContinue?: boolean; awaitingAsyncWork?: boolean };

type PostPromptSkipReason = "aborted" | "stale-generation";

type AgentContinueSkipReason =
	| PostPromptSkipReason
	| "session-unavailable"
	| "should-continue-false"
	| "post-restore-unavailable";

type ScheduledAgentContinueOptions = {
	source: string;
	delayMs?: number;
	generation?: number;
	shouldContinue?: () => boolean;
	onSkip?: (reason: AgentContinueSkipReason) => void;
	onError?: (error: unknown) => void;
};

type ScheduledAgentContinueRequest = {
	schedulerToken: number;
	options: ScheduledAgentContinueOptions;
};

type AgentContinueOutcome =
	| { status: "completed" }
	| { status: "skipped"; reason: AgentContinueSkipReason }
	| { status: "failed"; error: unknown };

/**
 * Reported by `#dispatchPrompt` to `prompt()`: whether the prompt took the
 * session — a turn dispatched or queued, or the agent already owning one.
 * Distinct from the public return value, which stays `true` for a dropped
 * prompt. A dispatch that `agent.prompt` rejects started no turn and claims
 * nothing.
 */
type PromptDispatchOutcome = { sessionClaimed: boolean };

type ActiveAgentContinue = {
	schedulerToken: number;
	source: string;
	coalescedSources: Set<string>;
	promise: Promise<AgentContinueOutcome>;
};

type SessionTitleSource = "auto" | "user";
type SessionNameTrigger = "replan";
type SetSessionNameWithTrigger = (
	name: string,
	source?: SessionTitleSource,
	trigger?: SessionNameTrigger,
) => Promise<boolean>;

const kPersistedSessionEntryId = Symbol("persistedSessionEntryId");
type PersistedAssistantMessage = AssistantMessage & {
	[kPersistedSessionEntryId]?: string;
};
class PersistedContinuationError extends Error {
	constructor(
		readonly code: PersistedTurnRefusal["code"],
		message: string,
	) {
		super(message);
	}
}
interface OriginalTaskResultAttempt {
	bootstrapLeaf: string | null;
	bootstrapFile: string | undefined;
	bootstrapCwd: string;
	events: Promise<void>;
	projectedAssistant?: AssistantMessage;
	delivered?: boolean;
	committedResult?: AgentMessage;
	capture: TaskCallAuthorityCapture;
	gate: TaskResultProcessingGate;
	durable: Promise<void>;
	resolveDurable(): void;
	rejectDurable(error: unknown): void;
	failure?: unknown;
	scope?: ParentTaskRecoveryScope;
	ready?: NativeTaskResultReadyCheckpoint;
	processing?: Promise<void>;
}
interface BoundTaskCall {
	authority?: TaskCallAuthorityCapture;
	binding?: PersistedTaskBindingV1;
	original?: OriginalTaskResultAttempt;
}
interface TaskReadRevivalPreparation {
	ref: AgentRef;
	ready: TaskReadContinuationCheckpoint;
	manager?: SessionManager;
	pending?: Promise<void>;
	claim?: TaskReadContinuationClaim;
	expectedLeaf: string;
}
interface ParentTaskRecoveryScope {
	readPreparation?: TaskReadRevivalPreparation;
	original?: OriginalTaskResultAttempt;
	validateCompletion?: () => Promise<() => void>;
	assertCompletionFiles?: () => void;
	completion?: TaskResultProcessingRef;
	completedChildRef?: AgentRef;
	advanceExpectedLeaf(entryId: string): void;
	loadedPolicyHash: string;
	phase: "child" | "parent";
	resultEntryId?: string;
	parentRuntime?: TaskRecoveryContract["runtime"];
	parentTools?: Array<{ tool: AgentTool; execute: AgentTool["execute"] }>;
	validatePolicy?: () => Promise<void>;
	binding: PersistedTaskBindingV1;
	signal: AbortSignal;
	generation: number;
	revoked?: string;
	child?: AgentSession;
	ref?: AgentRef;
	validateAuthority(): Promise<void>;
	assertOwnership(): void;
	releaseChild?: () => void;
}
interface TaskReadCandidate {
	assistant: AssistantMessage;
	toolCallId: string;
	disqualified?: boolean;
	arguments?: { path: string };
	native?: NativePlainReadProvenance;
	nativeResultSha256?: string;
	turnEnd: Promise<void>;
	resolveTurnEnd(): void;
	turnEndSeen: boolean;
	request?: object;
	responsePending?: boolean;
	responseGateActive?: boolean;
	responseEvents?: Promise<void>;
	ready?: TaskReadContinuationCheckpoint;
	claim?: TaskReadContinuationClaim;
	claiming?: Promise<void>;
	expectedLeaf?: string;
}
interface ChildTaskRecoveryScope {
	read?: TaskReadCandidate;
	readFailure?: string;
	readProtocolEntered?: boolean;
	initialBatch?: PromptPreparationBatch;
	initialLeaf?: string;
	initialMessages?: readonly AgentMessage[];
	initialMessagesHash?: string;
	initialDispatch?: "armed" | "dispatched";
	preparationReady?: Promise<void>;
	resolvePreparation?: () => void;
	context: AsyncLocalStorage<object>;
	assertNativeCompletion?: () => void;
	loadedPolicyHash: string;
	generation: number;
	anchorEntryId?: string;
	tools?: Array<{ tool: AgentTool; execute: AgentTool["execute"] }>;
	parent: ParentTaskRecoveryScope;
	token: object;
	driverActive: boolean;
}
interface TaskCallAuthorityCapture {
	assistant: AssistantMessage;
	origin: PromptPreparationBatch;
	sessionId: string;
	generation: number;
	toolCallId: string;
	validate: TaskResultAuthorityValidator;
	signal?: AbortSignal;
}
interface PromptPreparationBatch {
	id: string;
	sessionId: string;
	generation: number;
	anchor?: AgentMessage;
	anchorEntryId?: string;
	taskBindingId?: string;
	members: Map<AgentMessage, string | undefined>;
	complete: boolean;
}

/**
 * Clone one top-level notification field without ever returning an object owned
 * by the live session. Most values take the lossless structured-clone path. If
 * a third-party metadata object contains functions or other unsupported values,
 * JSON sanitization drops those values; a cyclic/non-JSON value finally degrades
 * to a descriptive string rather than retaining a shared mutable reference.
 */
function cloneMessageEndNotificationField(value: unknown): unknown {
	try {
		return structuredClone(value);
	} catch {}
	try {
		const json = JSON.stringify(value);
		if (json !== undefined) return JSON.parse(json) as unknown;
	} catch {}
	return String(value);
}

/** Build a detached, notification-only snapshot of an AgentMessage. */
function cloneMessageEndNotification(message: AgentMessage): AgentMessage {
	const snapshot: Record<PropertyKey, unknown> = {};
	for (const key of Reflect.ownKeys(message)) {
		const descriptor = Object.getOwnPropertyDescriptor(message, key);
		if (!descriptor?.enumerable) continue;
		snapshot[key] = cloneMessageEndNotificationField(Reflect.get(message, key));
	}
	return snapshot as unknown as AgentMessage;
}

const INTERRUPTED_THINKING_MIN_CHARS = 60;
const SESSION_CWD_CHANGE_REJECTED = Symbol("sessionCwdChangeRejected");

/**
 * Translate a `power.sleepPrevention` mode into `PowerAssertion.start` options,
 * or `undefined` when the mode asks for no assertion at all.
 */
export function powerAssertionOptions(mode: "off" | "idle" | "display" | "system"): PowerAssertionOptions | undefined {
	if (mode === "off") return undefined;
	return {
		reason: "omp agent session",
		idle: true,
		display: mode === "display" || mode === "system",
		system: mode === "system",
		user: mode === "system",
	};
}

export class AgentSession implements SettingsScope {
	readonly agent: Agent;
	readonly sessionManager: SessionManager;
	readonly settings: Settings;
	/** Session-start policy, independent of the selected project memory backend. */
	readonly memoryEnabled: boolean;
	/** Entries of tools mounted under `xd://`; empty when virtual devices are unmounted. */
	getXdevToolEntries: () => Array<{ name: string; summary: string }>;
	readonly yieldQueue: YieldQueue;
	editStore?: EditStore;

	/** Materializes this session's live extension-root policy per discovery call. */
	readonly #extensionRoots: () => EffectiveExtensionRoots;

	/**
	 * Session-local extension roots for post-startup rediscovery. Subagents may
	 * inherit the owning session's provider so recursive task discovery preserves
	 * explicit roots, mode, configured roots, and provenance.
	 */
	get effectiveExtensionRoots(): EffectiveExtensionRoots {
		return this.#extensionRoots();
	}

	/** Parent-imported extension factories, forwarded to session forks (`/tan`) to rebind runtime providers. */
	readonly #preparedExtensions: readonly PreparedExtension[] | undefined;

	/**
	 * Session-independent imported extension factories safe to rebind in child
	 * sessions. A `/tan` fork forwards these as `preloadedPreparedExtensions`
	 * so the child re-registers the parent's runtime providers.
	 */
	get preparedExtensions(): readonly PreparedExtension[] | undefined {
		return this.#preparedExtensions;
	}

	/** Source paths of the parent's loaded extensions; forwarded to `/tan` forks as the prepared-extension fallback. */
	readonly #extensionPaths: readonly string[] | undefined;

	/** Source paths of loaded extensions, forwarded to child sessions when prepared factories are unavailable. */
	get extensionPaths(): readonly string[] | undefined {
		return this.#extensionPaths;
	}

	#powerAssertion: PowerAssertion | undefined;

	readonly configWarnings: string[] = [];
	/** Construction skipped fallback-chain validation; {@link validateRetryFallbackChains} still owes it. */
	#fallbackChainValidationDeferred = false;

	readonly #models: ModelControls;
	readonly #tools: SessionTools;
	readonly #prewalk: PrewalkCoordinator;

	readonly #providerBoundary: SessionProviderBoundary;
	#promptTemplates: PromptTemplate[];
	#slashCommands: FileSlashCommand[];
	/** Tail of the serialized {@link refreshSkillsAndCommands} chain. */
	#skillsAndCommandsRefresh: Promise<void> = Promise.resolve();
	/**
	 * Raw text the caller originally submitted for a queued plain `role: "user"`
	 * message — before slash/custom-command rewriting, prompt-template expansion,
	 * or `^model` mention substitution. Recorded by `#queueUserMessage`, the same
	 * point `#queueCustomMessage` stamps `__queueChipText` for skill invocations;
	 * a side map (not a message field) because `UserMessage` has no free-form
	 * details slot to carry it, and it must never reach the model or persisted
	 * session content. `removeQueuedMessage` matches against it so an RPC client
	 * removing by the exact text it submitted can find its own transformed queued
	 * entry without unsafely replaying a (possibly side-effecting) slash/custom
	 * command.
	 */
	readonly #queuedMessageRawText = new WeakMap<AgentMessage, string>();

	// Event subscription state
	#unsubscribeAgent?: () => void;
	#unsubscribeQueueChange?: () => void;
	#cancelExitRecorder?: () => void;
	#cancelFatalRecoveryHint?: () => void;
	#exitRecorded = false;
	/** Last observed `workspace.additionalDirectories`, diffed on change to add/remove only settings-seeded roots. */
	#settingsWorkspaceDirectories: readonly string[] = [];
	/** Last observed auto-QA gate; the system prompt advertises `xd://report_issue` only while it holds. */
	#autoQaEnabled = false;
	/** Teardowns registered via {@link addDisposer} (including settings listeners bound to this session); drained on dispose. */
	#disposers: Array<() => void> = [];
	/** Last (enable, providerId) tuple resolved by `#syncAppendOnlyContext` — used to skip no-op invalidations. */
	#lastAppendOnlyResolution?: { enable: boolean; providerId: string | undefined };
	#eventListeners: AgentSessionEventListener[] = [];
	#activeToolExecutionUpdates = new Map<string, Extract<AgentSessionEvent, { type: "tool_execution_update" }>>();
	#runStateListeners = new Set<(state: "running" | "idle") => void>();
	/** The last `agent_end` that {@link #settleAgentEnd} published; a failed maintenance pass settles any other. */
	#settledAgentEnd: AgentEndEvent | undefined;
	#commandMetadataChangedListeners: CommandMetadataChangedListener[] = [];
	#sessionChangeCallbacks = new Set<() => void>();
	#observedSessionId: string | undefined;

	/** Messages queued to be included with the next user prompt as context ("asides"). */
	#pendingNextTurnMessages: CustomMessage[] = [];
	/**
	 * Dispatch-time authority checks for hidden next-turn messages (S2.5). Keyed by
	 * the exact queued object identity so a queued batch's validator survives the
	 * drain, restore, and before-model-call paths. A validator is honored only for
	 * a hidden `deliverAs: "nextTurn"` + `triggerTurn: true` message.
	 */
	#hiddenNextTurnDispatchValidators = new WeakMap<CustomMessage, DispatchAuthorityValidation>();
	#scheduledHiddenNextTurnGeneration: number | undefined = undefined;
	#queuedMessageDrainScheduled = false;
	/** A single model-only notebook reminder queued for the current prompt generation. */
	#experimentalContextNotesReminder: { prompt: string; generation: number } | undefined;
	#planModeState: PlanModeState | undefined;
	#vibeModeState: VibeModeState | undefined;
	#goalModeState: GoalModeState | undefined;
	#goalRuntime: GoalRuntime;
	readonly #advisors: SessionAdvisors;
	/** Resolves once the resume-time advisor spend backfill settles. */
	#advisorCostRestore: Promise<void> = Promise.resolve();
	#goalTurnCounter = 0;
	#planReferenceSent = false;
	#planReferencePath = "local://PLAN.md";
	#clientBridge: ClientBridge | undefined;
	#allowAcpAgentInitiatedTurns = false;
	/** Session file created by this session's `/move`; removed on dispose if it stayed empty. */
	#movedFromEmptySessionFile?: string;

	readonly #maintenance: SessionMaintenance;

	// Branch summarization state
	#branchSummaryAbortController: AbortController | undefined = undefined;

	readonly #handoff: SessionHandoff;

	// Retry state
	readonly #recovery: TurnRecovery;
	#textOutputCommitted = true;
	#planModeReminderCount = 0;
	#planModeReminderAwaitingProgress = false;
	readonly #todo: TodoTracker;
	readonly #modelMentions: ModelMentionRegistry;
	#workPoolYieldItems: readonly WorkPoolYieldItem[] = [];
	/** Item set matching the last successfully rebuilt provider prompt. The base
	 *  prompt starts consistent with the empty set; every later value is a
	 *  snapshot taken after a prompt rebuild resolves. Rollback restores this —
	 *  never the merely requested previous set, which may belong to a transition
	 *  that itself failed. Never mutated in place; replaced wholesale. */
	#lastPublishedWorkPoolYieldItems: readonly WorkPoolYieldItem[] = [];
	/** Serialized tail of pooled-turn yield contract transitions; never rejects. */
	#workPoolYieldTransition: Promise<void> = Promise.resolve();
	#replanTitleRefreshInFlight: Promise<void> | undefined = undefined;
	/** Resolved TITLE_SYSTEM.md override applied to every automatic session-title
	 *  generation path. Refresh via {@link AgentSession.setTitleSystemPrompt} when
	 *  the session cwd changes. */
	#titleSystemPrompt: string | undefined;
	/** Task recursion depth (0 = main/top-level, >0 = subagent). Mirrors ToolSession.taskDepth. */
	#taskDepth = 0;
	#titleGenerationInFlightFor: string | undefined;
	/** First-message auto-title that may be retried from conversation context.
	 *  Once the title model declines the message (greeting-like or too ambiguous,
	 *  e.g. a pasted image plus "help") AND the assistant has replied, the title is
	 *  regenerated once from the recent user/assistant/thinking turns. */
	#deferredTitle: { sessionId: string; declined: boolean; replied: boolean } | undefined;
	#titleProviderSessionId: string | undefined;
	#titleProviderParentSessionId: string | undefined;
	/** Host hook invoked when a typed user prompt is dropped before dispatch;
	 *  see {@link setPromptDropped}. */
	#promptDropped: ((prompt: DroppedPrompt) => void) | undefined;
	#titleGenerationAbortController = new AbortController();
	#toolChoiceQueue = new ToolChoiceQueue();

	readonly #bash: BashRunner;

	readonly #eval: EvalRunner;
	readonly #evalToolSession: ToolSession | undefined;
	/**
	 * AsyncJobManager owned by this session (top-level only). Subagents leave
	 * this undefined and **MUST NOT** dispose the global instance on teardown.
	 */
	readonly #ownedAsyncJobManager: AsyncJobManager | undefined;
	/**
	 * AsyncJobManager scoped to this session for introspection/cancellation.
	 *
	 * This differs from `#ownedAsyncJobManager`: subagents can inherit a parent
	 * manager for their own owner id, while secondary top-level sessions are left
	 * undefined to avoid reading the primary's jobs.
	 */
	readonly #asyncJobManager: AsyncJobManager | undefined;
	/** Clears this session's owner delivery sink registration; set when a manager + agent id exist. */
	#unregisterAsyncDeliverySink: (() => void) | undefined;
	/**
	 * Async-delivery generation, bumped on every session transition that evicts
	 * this owner's jobs (see {@link AgentSession.#cancelOwnAsyncJobs}). Stamped
	 * onto each queued async-result follow-up so a delivery formatted or drained
	 * across a `/new` is dropped regardless of job-id reuse.
	 */
	#asyncDeliveryEpoch = 0;

	readonly #irc: IrcBridge;
	#ircWakeTurnObserver:
		| ((records: AgentMessage[]) => ((error?: unknown) => void | Promise<void>) | undefined)
		| undefined;
	// Agent identity (registry id) used for IRC routing and job ownership.
	#agentId: string | undefined;
	#agentKind: "main" | "sub" = "main";
	#scoutAllowedBySpawnPolicy = true;
	#providerSessionId: string | undefined;
	#freshProviderSessionId: string | undefined;
	#inheritedProviderPromptCacheKey: string | undefined;
	#autolearnCaptureAbortController: AbortController | undefined;
	#autolearnCaptureTask: Promise<void> | undefined;
	#isDisposed = false;
	#modelDiscoveryAbortController = new AbortController();
	/** Process-wide by default (double-spend safety across sessions); injectable for tests. */
	#resetCoordinator: CodexAutoRedeemCoordinator;
	/** Each turn stream may adopt a peer's confirmed reset once, not retry on it indefinitely. */
	#adoptedResetMarkers = new Map<string, number>();
	// Extension system
	#extensionRunner: ExtensionRunner | undefined = undefined;
	#getEvalPreludes: (() => readonly EvalPreludeDefinition[]) | undefined;
	#reconcileBrowserMcpFilter: AgentSessionConfig["reconcileBrowserMcpFilter"];
	#skillDescriptions: SkillDescriptionCatalog;
	#promptSkillsSource: readonly Skill[] | undefined;
	#promptSkills: readonly Skill[] = [];
	/**
	 * Backs `ctx.setInterval`/`setTimeout`/`clearTimer` for the runner-less
	 * command-context fallback (SDK embeddings with no extension runner). Lazily
	 * created; cleared on dispose alongside the runner's own timers (#5664).
	 */
	#fallbackExtensionTimers: ManagedTimers | undefined = undefined;
	#turnIndex = 0;
	#messageEndPersistenceTail: Promise<void> = Promise.resolve();
	#pendingMessageEndPersistence = new Map<string, Promise<void>>();
	#persistedMessageKeys: { anchor: string; keys: Set<string> } | undefined;

	// Custom commands (TypeScript slash commands)
	#customCommands: LoadedCustomCommand[] = [];
	/** MCP prompt commands (updated dynamically when prompts are loaded) */
	#mcpPromptCommands: LoadedCustomCommand[] = [];

	// Model registry for API key resolution
	#modelRegistry: ModelRegistry;
	#usageFallbackConfirmer: UsageFallbackConfirmer | undefined;
	#usagePreflightAbortControllers = new Set<AbortController>();
	/** In-flight vision descriptions that gate prompt admission; abort() cancels them. */
	#imageDescriptionAbortControllers = new Set<AbortController>();
	#queuedMessageDrainBlocked = false;
	#modeExitDrainSuppressionDepth = 0;
	#usagePreflightReadyForNextModelCall = false;
	#usagePreflightReadyModel: Model | undefined;
	#detachUsageBeforeQueueDequeue: (() => void) | undefined;
	#detachUsageBeforeModelCall: (() => void) | undefined;
	/** Claude account lane (`cred:<id>`/`key:<hash>`) that served the latest Anthropic request. */
	#anthropicSlowModeLane: string | undefined;
	/** `<lane>#<window>` of the wrap-up window this session already told the model about. */
	#anthropicWrapUpHinted: string | undefined;

	#transformContext: (messages: AgentMessage[], signal?: AbortSignal) => AgentMessage[] | Promise<AgentMessage[]>;
	#onPayload: SimpleStreamOptions["onPayload"] | undefined;
	#onResponse: SimpleStreamOptions["onResponse"] | undefined;
	/**
	 * Providers/models (`${provider}/${id}`) whose runtime context window has
	 * already been re-probed after their first successful inference this session,
	 * so a lazy-load local model (LM Studio JIT, llama.cpp cold start) is
	 * refreshed exactly once rather than on every response (#9001).
	 */
	#lazyContextRefreshed = new Set<string>();
	#onSseEvent: SimpleStreamOptions["onSseEvent"] | undefined;
	#sideStreamFn: StreamFn;
	#convertToLlm: (messages: AgentMessage[]) => Message[] | Promise<Message[]>;
	#disconnectOwnedMcpManager: (() => Promise<void>) | undefined;

	readonly #ttsr: TtsrCoordinator;
	readonly #stats: SessionStatsTracker;

	/** One-shot flag for expected internal plan-mode aborts. Approval actions may
	 *  abort the post-approval continuation before compaction, execution, or
	 *  manual refinement. Consumed inside `#handleAgentEvent` for the matching
	 *  `message_end` + `stopReason: "aborted"`; callers clear it in `finally` so
	 *  it cannot leak into later unrelated aborts. */
	#planInternalAbortPending = false;
	#pendingAbortErrorId?: number;

	#postPromptTasks = new Set<Promise<unknown>>();
	#postPromptTasksPromise: Promise<void> | undefined = undefined;
	#postPromptTasksResolve: (() => void) | undefined = undefined;
	#postPromptTasksAbortController = new AbortController();
	/**
	 * Cancels the current turn's pre-dispatch setup (memory-backend auto-recall and
	 * other awaited preparation in {@link #prepareAgentStart}) when {@link abort} runs.
	 * Bumping {@link #promptGeneration} only makes the cooperative `isCurrent()` checks
	 * return false; a blocking network recall cannot observe that until it resolves, so
	 * Esc would otherwise stall for the full recall timeout (issue #12668).
	 */
	#promptSetupAbortController: AbortController | undefined;
	#activeAgentContinue: ActiveAgentContinue | undefined;
	#agentContinueSchedulerToken = 0;

	readonly #streamingEditGuard: StreamingEditGuard;
	readonly #loopGuards: LoopGuards;
	#promptInFlightCount = 0;
	#abortInProgress = false;
	/** Submissions accepted by prompt()/promptCustomMessage()/sendCustomMessage() that have not
	 *  yet dispatched a turn, queued, or bailed. Preprocessing (manual-compaction wait, slash
	 *  commands, image normalization, vision description) runs before #promptInFlightCount is
	 *  incremented, so `isStreaming` alone cannot tell a host that a submission is admitted. */
	#admittedSubmissionCount = 0;
	#admittedSubmissionsSettled: PromiseWithResolvers<void> | undefined;
	// Wire-level agent_end emission deferred until #promptInFlightCount drops to 0.
	// Internal extension hooks and post-emit work (auto-retry, auto-compaction, todo
	// checks in #handleAgentEvent) still fire on the original schedule — only the
	// `#emit(event)` that reaches external subscribers (rpc-mode stdout, ACP bridge,
	// Cursor exec, TUI listeners) is held back. Without this, a client that resumes
	// on `agent_end` can fire its next `prompt` before #promptWithMessage's finally
	#promptGeneration = 0;
	#persistedTurnRequest: (PersistedTurnContinuationRequest & { generation: number }) | undefined;
	#recoverSynchronousTask: AgentSessionConfig["recoverSynchronousTask"];
	#validateSynchronousTaskPolicy: AgentSessionConfig["validateSynchronousTaskPolicy"];
	#assertSynchronousTaskPolicy: AgentSessionConfig["assertSynchronousTaskPolicy"];
	#activeTaskRecovery: ParentTaskRecoveryScope | undefined;
	#childTaskRecovery: ChildTaskRecoveryScope | undefined;
	#taskRecoveryOwner = new AsyncLocalStorage<object>();
	#taskControlPermit: "prompt" | "abort" | undefined;
	// abort() can finish in a message_end listener before queued settle work runs.
	#activeAgentPromptGeneration = this.#promptGeneration;
	/** Bumped by newSession()/switchSession() at the same point they clear the pending IRC/aside
	 *  queue (restored on a rolled-back switchSession()). A message-queueing call that spans an
	 *  await (image normalization, vision description) captures this before the await and checks
	 *  it again right before enqueueing into IrcBridge, so a record started for the outgoing
	 *  session cannot land in a different session's queue after the transition. Deliberately
	 *  distinct from #promptGeneration, which also changes on a plain abort() — asides must still
	 *  enqueue and fold/resume normally across an in-session interrupt, only a session identity
	 *  change should drop them. */
	#sessionGeneration = 0;
	/** Settles when switchSession commits or restores its previous generation on rollback.
	 *  newSession never rolls its generation back, so it does not delay stale aside/SDK calls. */
	#sessionGenerationSettled: Promise<void> | undefined;
	/** Readiness barrier for the outermost session/transcript transition, including all
	 *  hooks and rollback reconciliation, independently of when its generation settles. */
	#sessionTransitionSettled: Promise<void> | undefined;
	#resolveSessionTransition: (() => void) | undefined;
	#sessionTransitionDepth = 0;
	/** Each using declaration disposes one depth, so nested transitions reuse this token. */
	readonly #sessionTransitionScope: Disposable = {
		[Symbol.dispose]: () => {
			if (--this.#sessionTransitionDepth !== 0) return;
			const resolve = this.#resolveSessionTransition;
			this.#sessionTransitionSettled = undefined;
			this.#resolveSessionTransition = undefined;
			resolve?.();
		},
	};
	#promptSequence = 0;
	#promptPreparationByMessage = new WeakMap<AgentMessage, PromptPreparationBatch>();
	#persistedEntryByMessage = new WeakMap<AgentMessage, string>();
	#activePromptPreparation: PromptPreparationBatch | undefined;
	#boundTaskCalls = new Map<string, BoundTaskCall>();
	#taskCallAuthorities = new WeakMap<AssistantMessage, Map<string, TaskCallAuthorityCapture>>();
	#taskResultByMessage = new WeakMap<AgentMessage, PersistedTaskResultRef>();
	#taskResultCommitScopes = new WeakMap<AgentMessage, ParentTaskRecoveryScope>();
	#approvedTaskResultCommits = new WeakSet<AgentMessage>();
	#skippedPostTurnSpeculationCompletion: Promise<void> | undefined;
	#pendingAgentEndEmit: AgentSessionEvent | undefined;
	#inFlightSettledCallbacks: Array<() => void | Promise<void>> = [];
	#sessionStopContinuationCount = 0;
	#sessionStopHookActive = false;
	#obfuscator: SecretObfuscator | undefined;
	/** Last `skillful` value applied to this session; dedupes {@link setSkillful} and its setting watch. */
	#skillfulApplied = false;
	#checkpointState: CheckpointState | undefined = undefined;
	#pendingRewindReport: string | undefined = undefined;
	#lastCompletedRewind: CompletedRewindState | undefined = undefined;
	#rewoundToolResultIds = new Set<string>();
	#lastSuccessfulYieldToolCallId: string | undefined = undefined;
	/**
	 * Sticky across an in-flight prompt run: a successful `yield` makes the run
	 * terminal for execution purposes, so any trailing empty/aborted assistant
	 * stop must NOT trigger empty-stop/unexpected-stop/compaction continuations.
	 * Cleared before every new prompt turn so the next turn evaluates cleanly.
	 */
	#yieldTerminationPending = false;
	#synchronouslyTerminatedYieldToolCallIds = new Set<string>();
	#providerSessionState = new Map<string, ProviderSessionState>();
	readonly #cacheWarmer: CacheWarmer | undefined;
	#hindsightSessionState: HindsightSessionState | undefined = undefined;
	readonly #memory: SessionMemory;
	readonly rawSseDebugBuffer: RawSseDebugBuffer;

	#resetPromptMaintenanceState(): void {
		this.#recovery.resetForNewPrompt();
		this.#maintenance.resetForNewPrompt();
		this.#yieldTerminationPending = false;
	}

	#acquirePowerAssertion(): void {
		if (isBunTestRuntime()) return;
		if (this.#powerAssertion) return;
		const options = powerAssertionOptions(cfgPowerSleepPrevention.get(this.settings));
		if (!options) return;
		try {
			this.#powerAssertion = PowerAssertion.start(options);
		} catch (error) {
			logger.warn("Failed to acquire power assertion", { error: String(error) });
		}
	}

	#releasePowerAssertion(): void {
		const assertion = this.#powerAssertion;
		this.#powerAssertion = undefined;
		if (!assertion) return;
		try {
			assertion.stop();
		} catch (error) {
			logger.warn("Failed to release power assertion", { error: String(error) });
		}
	}

	#beginInFlight(): void {
		this.#promptInFlightCount++;
		if (this.#promptInFlightCount === 1) {
			this.#acquirePowerAssertion();
		}
	}

	#endInFlight(onSettled?: () => void | Promise<void>): void {
		if (onSettled) this.#inFlightSettledCallbacks.push(onSettled);
		this.#promptInFlightCount = Math.max(0, this.#promptInFlightCount - 1);
		if (this.#promptInFlightCount !== 0) return;
		this.yieldQueue.requestIdleFlush();
		this.#releasePowerAssertion();
		this.#flushPendingAgentEnd();
		if (this.#inFlightSettledCallbacks.length === 0) {
			this.#drainStrandedQueuedMessages();
			return;
		}
		void this.#flushInFlightSettledCallbacks().finally(() => this.#drainStrandedQueuedMessages());
	}

	async #flushInFlightSettledCallbacks(): Promise<void> {
		const callbacks = this.#inFlightSettledCallbacks;
		this.#inFlightSettledCallbacks = [];
		for (const callback of callbacks) {
			try {
				await callback();
			} catch (error) {
				logger.warn("In-flight settle callback failed", { error: String(error) });
			}
		}
	}

	/** A steer/follow-up can land after the agent loop's final queue poll, or
	 *  after an abort stops an auto-continued queued turn. In both cases the
	 *  agent-core queue still owns the message, but no loop is left to poll it.
	 *  Runs whenever the session settles; the guard makes it a no-op when the
	 *  queue was consumed normally or a new turn already started. */
	#drainStrandedQueuedMessages(): void {
		if (this.#abortInProgress) return;
		// Session transitions (newSession/`/new`, compact, model-switch, session-switch,
		// dispose) call #disconnectFromAgent() BEFORE `await abort()`, so abort's own
		// finally lands here with no listener attached. Auto-resuming now would snapshot
		// the still-old context (the transition hasn't reached agent.reset() yet), start a
		// stale provider turn that races the reset, and — once reconnected — append its
		// output to the fresh session (issue #5800). A disconnected session never owns the
		// queue: the transition does. newSession/switchSession drop the queue (reset /
		// clearAllQueues), so nothing survives; compaction preserves it and re-drains itself
		// after #reconnectToAgent (see compact()'s finally); an explicit prompt flushes it
		// in every case.
		if (this.#unsubscribeAgent === undefined) return;
		// A concern steered into a resumed streaming run after a user interrupt can
		// strand at the turn tail (steered past the loop's final boundary poll). While
		// that interrupt's suppression is still in effect, reclaim such advisor steers
		// as visible advice once idle — mirroring abort's #extractQueuedAdvisorCards —
		// so they neither auto-resume the run the user stopped (a non-empty steer queue
		// otherwise bypasses the latch in #canAutoContinueForFollowUp) nor linger to
		// flush at the next prompt. Real user steers/follow-ups are left untouched.
		if (this.#advisors.autoResumeSuppressed && !this.isStreaming) {
			for (const card of this.#extractQueuedAdvisorCards()) {
				this.#preserveAdvisorCard(card);
			}
		}
		this.#scheduleQueuedMessageDrain();
		this.#resumeStrandedIrcAsides();
	}

	/** IRC records that arrive after the loop's final aside poll — or while an abort skipped that
	 *  poll — land in pending IRC queues with no loop left to drain them; the queued-message drain's
	 *  gate (agent.hasQueuedMessages()) does not count peer IRC interrupts. Once idle, wake a turn so
	 *  the agent responds to the peer. Skip only when a queued steer/follow-up will itself drive a
	 *  resume turn whose aside poll already consumes these (no double-wake). */
	#resumeStrandedIrcAsides(): void {
		if (this.#modeExitDrainSuppressionDepth > 0 || this.#isDisposed || this.isStreaming || !this.#irc.hasPending()) {
			return;
		}
		// A pooled yield contract means a pool turn owns this worker (installed,
		// dispatching, or dispatch-imminent). Waking here would either emit keyed
		// yields against its items or re-queue into the deferral path forever, so
		// leave the records pending until the contract clears.
		if (this.#workPoolYieldItems.length > 0) {
			return;
		}
		// Session transitions call #disconnectFromAgent() BEFORE `await abort()`, and only bump
		// #sessionGeneration/clear the IRC queue several awaits later once they reach agent.reset().
		// A normalization await that resolves in that gap sees an unchanged generation and an idle,
		// non-streaming session, so without this guard it would wake/fold into the still-old context
		// and race the transition's own reset — same rationale as #drainStrandedQueuedMessages.
		if (this.#unsubscribeAgent === undefined) return;
		if (this.#canAutoContinueForFollowUp() && this.agent.hasQueuedMessages()) return;
		// Parked wake records resume alongside ordinary stranded asides; they were
		// already decided wake-intended at deferral time.
		const records = [...this.#irc.drainDeferredWakes(), ...this.#irc.drainPending()];
		if (this.#planModeState?.enabled) {
			// Plan mode: fold stranded IRC asides into context without waking an
			// autonomous turn. Convergence to ask/resolve stays user-driven.
			this.#foldStrandedIrcAsidesIntoContext(records);
			return;
		}
		if (this.#advisors.autoResumeSuppressed) {
			// A user interrupt is still in effect (clearQueue({ forInterrupt: true }) already
			// dropped these same records from the agent-core queues to keep the run the user
			// stopped from auto-resuming). Only a real peer IRC message justifies waking a fresh
			// turn here; extension/user asides fold into context like the plan-mode branch above,
			// staying user-driven until the next deliberate prompt.
			const wake: AgentMessage[] = [];
			const fold: AgentMessage[] = [];
			for (const record of records) {
				if (record.role === "custom" && record.customType === "irc:incoming") wake.push(record);
				else fold.push(record);
			}
			this.#foldStrandedIrcAsidesIntoContext(fold);
			if (wake.length > 0) this.#wakeForIrc(wake);
			return;
		}
		this.#wakeForIrc(records);
	}

	/** Persist stranded IRC/extension asides into context without starting a turn — shared by the
	 *  plan-mode branch and the post-interrupt fold branch of #resumeStrandedIrcAsides. All records
	 *  (custom and non-custom alike) route through emitExternalEvent so message_end both appends to
	 *  context and notifies event listeners — #persistMessageEnd handles custom-role persistence
	 *  (sessionManager.appendCustomMessageEntry) from that event, and a displayable custom aside that
	 *  went stranded mid-stream gets the message_end its sender's rebuild-skip decision expects
	 *  (extension-ui-controller's #applyCustomMessageDisplay), matching IrcBridge.flushPending(). */
	#foldStrandedIrcAsidesIntoContext(records: AgentMessage[]): void {
		for (const record of records) {
			this.agent.emitExternalEvent({ type: "message_start", message: record });
			this.agent.emitExternalEvent({ type: "message_end", message: record });
		}
	}

	/** Re-validates a #sessionGeneration snapshot captured before an aside/SDK call's await.
	 *  A mismatch alone does not mean the record's source session is gone —
	 *  switchSession() restores the exact prior generation on rollback — so wait out any in-flight
	 *  generation change (#sessionGenerationSettled) and recheck rather than discarding immediately.
	 *  Returns true when the caller should drop its record (no in-flight transition to wait for, or
	 *  the generation is still different once one settles); false once the generation matches again. */
	async #sessionGenerationChanged(sessionGeneration: number): Promise<boolean> {
		while (this.#sessionGeneration !== sessionGeneration) {
			const settled = this.#sessionGenerationSettled;
			if (!settled) return true;
			await settled;
		}
		return false;
	}

	/** Fire-and-forget wake turn for incoming IRC — idle delivery and stranded-aside resume both
	 *  route here. Wrapped in #beginInFlight/#endInFlight so the turn is tracked and its settle
	 *  re-drains anything that stranded during it. A user interrupt may have intentionally left a
	 *  follow-up queued behind an invalid tail (seam #5); the wake turn's loop would otherwise drain
	 *  it, so park the follow-up queue across the wake and restore it after. It stays queued post-wake
	 *  because #canAutoContinueForFollowUp suppresses follow-up auto-resume while a user interrupt is
	 *  in effect, even though the wake left a provider-valid tail. */
	#wakeForIrc(records: AgentMessage[]): void {
		if (this.#modeExitDrainSuppressionDepth > 0) {
			this.#irc.queueAside(records);
			return;
		}
		// Park only a *blocked* follow-up (one a user interrupt is intentionally holding); an
		// already-resumable follow-up can ride the wake turn normally without reordering.
		const parkedFollowUps =
			this.agent.peekSteeringQueue().length === 0 &&
			this.agent.peekFollowUpQueue().length > 0 &&
			!this.#canAutoContinueForFollowUp()
				? [...this.agent.peekFollowUpQueue()]
				: [];
		const parkedQueueDrainBlocked = parkedFollowUps.length > 0 && this.#queuedMessageDrainBlocked;
		if (parkedFollowUps.length > 0) {
			this.agent.replaceQueues([...this.agent.peekSteeringQueue()], []);
			if (parkedQueueDrainBlocked) this.#queuedMessageDrainBlocked = false;
		}
		// The wake observer is attached only once prompt ownership is won below: a
		// deferred wake runs no turn, so observing it would capture the next
		// turn's yield/output and relay it as this wake's reply.
		let finishObservation: ((error?: unknown) => void | Promise<void>) | undefined;
		this.#resetPromptMaintenanceState();
		// Capture the generation before the wake so its post-prompt recovery wait
		// bails the instant an abort (which bumps #promptGeneration) supersedes
		// this wake — otherwise the wait would follow a successor turn (a queued
		// follow-up or another stranded IRC wake started by abort cleanup),
		// delaying finishObservation and mis-attributing the successor's RPC
		// progress to this now-dead wake monitor.
		const generation = this.#promptGeneration;
		this.#beginInFlight();
		let turnError: unknown;
		// A pooled-turn yield transition (item-set mutation + prompt rebuild) may be
		// in flight when the wake lands. Starting the turn on the stale prompt would
		// advertise one yield schema while the runtime enforces the other, so join
		// the transition before building the turn from a consistent contract.
		void this.whenWorkPoolYieldSettled()
			.then(() => {
				// Synchronous ownership check, atomic with the dispatch below:
				// agent.prompt() claims streaming with no await in between, and the
				// yield contract above mutates synchronously, so no install can
				// interleave here.
				if (this.#workPoolYieldItems.length > 0) {
					// A pooled turn owns this worker (installed, running, or
					// dispatch-imminent): park wake-intended records where pooled
					// turns cannot flush them, for a monitored wake after clearing.
					// Flushing them as ordinary asides would feed them to the batch
					// with no observer to reply to the sender.
					this.#irc.queueDeferredWake(records);
					logger.debug("IRC wake turn parked while pooled");
					return;
				}
				if (this.agent.state.isStreaming) {
					this.#irc.queueAside(records);
					logger.debug("IRC wake turn deferred behind the running turn");
					return;
				}
				try {
					finishObservation = this.#ircWakeTurnObserver?.(records);
				} catch (error) {
					logger.warn("IRC wake turn observer failed to start", { error: String(error) });
				}
				return this.agent.prompt(records);
			})
			.catch(error => {
				if (error instanceof AgentBusyError) {
					// Lost the prompt race after passing the checks above: an
					// ordinary running turn takes these as asides, but a pooled
					// turn must not flush them, so park them instead.
					if (this.#workPoolYieldItems.length > 0) {
						this.#irc.queueDeferredWake(records);
						logger.debug("IRC wake turn parked while pooled");
					} else {
						this.#irc.queueAside(records);
						logger.debug("IRC wake turn deferred behind the running turn");
					}
					return;
				}
				turnError = error;
				logger.warn("IRC wake turn failed", { error: String(error) });
			})
			.finally(async () => {
				try {
					await this.#waitForPostPromptRecovery(generation);
				} catch (error) {
					turnError ??= error;
					logger.warn("IRC wake turn recovery failed", { error: String(error) });
				}
				if (parkedFollowUps.length > 0) {
					this.agent.replaceQueues(
						[...this.agent.peekSteeringQueue()],
						[...parkedFollowUps, ...this.agent.peekFollowUpQueue()],
					);
					this.#queuedMessageDrainBlocked ||= parkedQueueDrainBlocked;
				}
				this.#endInFlight(async () => {
					try {
						await finishObservation?.(turnError);
					} catch (error) {
						logger.warn("IRC wake turn observer failed to finish", { error: String(error) });
					}
				});
			});
	}

	/** Remove advisor concern/blocker cards from the agent-core steer/follow-up
	 *  queues and return them. Used on a deliberate user interrupt so the post-abort
	 *  stranded-message drain cannot auto-resume the run on an advisor card that was
	 *  steered in just before the user stopped; real user follow-ups stay queued.
	 *  Synchronous and await-free so it runs before the abort path polls the queue. */
	#extractQueuedAdvisorCards(): CustomMessage[] {
		const steering = this.agent.peekSteeringQueue();
		const followUp = this.agent.peekFollowUpQueue();
		const cards = [...steering, ...followUp].filter(isAdvisorCard);
		if (cards.length === 0) return [];
		this.agent.replaceQueues(
			steering.filter(m => !isAdvisorCard(m)),
			followUp.filter(m => !isAdvisorCard(m)),
		);
		this.#reconcileQueuedMessageDrain();
		return cards;
	}

	/** Record a suppressed advisor concern as visible, persisted advice without
	 *  triggering a turn. When the agent is idle (the normal post-interrupt case,
	 *  including the post-prompt unwind window where the core loop has ended), emit
	 *  message_start/message_end like #flushPendingIrcAsides so #handleAgentEvent
	 *  renders it live (TUI/ACP) and persists it as a CustomMessageEntry. Only while
	 *  an abort is still tearing a live turn down do we park it hidden, so abort's
	 *  settle step replays it once idle — never appended into a live streamMessage. */
	#preserveAdvisorCard(card: CustomMessage): void {
		if (this.#abortInProgress && this.isStreaming) {
			this.#pendingNextTurnMessages.push(card);
			return;
		}
		this.agent.emitExternalEvent({ type: "message_start", message: card });
		this.agent.emitExternalEvent({ type: "message_end", message: card });
	}

	#resetInFlight(): void {
		this.#promptInFlightCount = 0;
		this.yieldQueue.requestIdleFlush();
		this.#releasePowerAssertion();
		this.#flushPendingAgentEnd();
		if (this.#inFlightSettledCallbacks.length === 0) {
			this.#drainStrandedQueuedMessages();
			return;
		}
		void this.#flushInFlightSettledCallbacks().finally(() => this.#drainStrandedQueuedMessages());
	}

	#flushPendingAgentEnd(): void {
		const pending = this.#pendingAgentEndEmit;
		if (!pending) return;
		this.#pendingAgentEndEmit = undefined;
		if (pending.type !== "agent_end" || pending.isTerminal === false) {
			this.#emit(pending);
			return;
		}

		// `agent_end` is deferred until the prompt count reaches zero, but it is
		// emitted immediately before the settle drain schedules work that arrived
		// after the loop's final queue/aside poll. Such a tail arrival is a real
		// continuation, not a terminal stop: mark this end non-terminal so
		// subscribers wait through the queued steer/follow-up or stranded IRC wake.
		const canDrain =
			!this.#abortInProgress && this.#unsubscribeAgent !== undefined && this.#modeExitDrainSuppressionDepth === 0;
		const queuedContinuation =
			canDrain &&
			!this.#queuedMessageDrainBlocked &&
			this.#canAutoContinueForFollowUp() &&
			this.agent.hasQueuedMessages();
		const ircContinuation = canDrain && !this.#isDisposed && !this.#planModeState?.enabled && this.#irc.hasPending();
		this.#emit(queuedContinuation || ircContinuation ? { ...pending, isTerminal: false } : pending);
	}

	/**
	 * Arm prewalk outside the normal startup path so an explicit slash command starts immediately.
	 */
	armPrewalk(target: Model, thinkingLevel?: ConfiguredThinkingLevel): boolean {
		return this.#prewalk.arm(target, thinkingLevel);
	}

	/** Restore a planning model and re-arm prewalk without partially applying a rejected restart. */
	restartPrewalk(
		source: Model,
		sourceThinkingLevel: ConfiguredThinkingLevel | undefined,
		target: Model,
		targetThinkingLevel: ConfiguredThinkingLevel | undefined,
	): Promise<PrewalkRestartResult> {
		return this.#prewalk.restart(source, sourceThinkingLevel, target, targetThinkingLevel);
	}

	/** Validate the active plan artifact and shape an `xd://propose` result for review-mode hosts. */
	async preparePlanForReview(title: string): Promise<AgentToolResult<PlanApprovalDetails>> {
		const state = this.getPlanModeState();
		if (!state?.enabled) {
			throw new ToolError("Plan mode is not active.");
		}
		const { planFilePath, title: resolvedTitle } = await resolveApprovedPlan({
			suppliedTitle: title,
			statePlanFilePath: state.planFilePath,
			readPlan: url => this.#readPlanFile(url),
			listPlanFiles: () => this.#listPlanFiles(),
		});
		return {
			content: [{ type: "text", text: "Plan ready for review." }],
			details: { planFilePath, title: resolvedTitle, planExists: true },
		};
	}

	async #readPlanFile(planFilePath: string): Promise<string | null> {
		return readPlanFile(planFilePath, {
			localProtocolOptions: this.#localProtocolOptions(),
			cwd: this.sessionManager.getCwd(),
		});
	}

	/** `local://` URLs of plan files in the session-local root, newest first —
	 *  a fallback for `resolveApprovedPlan` when the agent dropped `extra.title`. */
	async #listPlanFiles(): Promise<string[]> {
		return listPlanFiles({ localProtocolOptions: this.#localProtocolOptions() });
	}

	#codeModeState: { namespacesInfo?: unknown };
	#getApiKey?: Agent["getApiKey"];
	#getInstructionPrepDegradations?: () => readonly InstructionPrepDegradation[];

	/** Live generation tok/s for the working row; fed by this session's own streamed deltas. */
	readonly tokenRate: TokenRateMeter;

	constructor(config: AgentSessionConfig) {
		this.agent = config.agent;
		this.#getApiKey = this.agent.getApiKey;
		this.#getInstructionPrepDegradations = config.getInstructionPrepDegradations;
		this.tokenRate = new TokenRateMeter(text => this.agent.tokenizer.countTokens(text));
		this.#reseedTokenRate();
		this.agent.setQueuedMessageGrouping(
			(previous, next) =>
				isHiddenUserCompanion(previous) && (isHiddenUserCompanion(next) || isUserQueuedMessage(next)),
		);
		this.#codeModeState = config.codeModeState ?? {};
		this.sessionManager = config.sessionManager;
		this.settings = config.settings;
		this.#skillDescriptions = config.skillDescriptions ?? new SkillDescriptionCatalog();
		this.memoryEnabled = config.memoryEnabled ?? true;
		this.#modelRegistry = config.modelRegistry;
		this.#extensionRoots =
			config.extensionRoots ??
			(() => ({
				explicit: config.additionalExtensionPaths ?? [],
				mode: config.disableExtensionDiscovery ? "explicit-only" : "merge",
				configured: cfgExtensions.get(this.settings),
				configuredLevel: this.settings.extensionsSourceLevel(),
			}));
		this.#preparedExtensions = config.preparedExtensions;
		this.#extensionPaths = config.extensionPaths;
		this.#resetCoordinator = config.codexResetCoordinator ?? defaultCodexAutoRedeemCoordinator;
		const bashHost: BashRunnerHost = {
			agent: this.agent,
			sessionManager: this.sessionManager,
			settings: this.settings,
			extensionRunner: () => this.#extensionRunner,
			isStreaming: () => this.isStreaming,
		};
		this.#bash = new BashRunner(bashHost);
		// Power assertions are taken per turn (see #beginInFlight); nothing acquired here.
		const evalHost: EvalRunnerHost = {
			agent: this.agent,
			sessionManager: this.sessionManager,
			settings: this.settings,
			evalToolSession: config.evalToolSession,
			extensionRunner: () => this.#extensionRunner,
			isStreaming: () => this.isStreaming,
			appendSessionMessage: message => {
				this.agent.appendMessage(message);
				this.sessionManager.appendMessage(message);
			},
		};
		this.#eval = new EvalRunner(evalHost, {
			kernelOwnerId: config.evalKernelOwnerId ?? `agent-session:${Snowflake.next()}`,
		});
		this.#evalToolSession = config.evalToolSession;
		const initialEvalStateContext = this.#buildEvalStateContextMessage();
		if (initialEvalStateContext) this.agent.appendMessage(initialEvalStateContext);
		const ircHost: IrcBridgeHost = {
			agent: this.agent,
			sessionManager: this.sessionManager,
			isDisposed: () => this.#isDisposed,
			isStreaming: () => this.isStreaming,
			planModeEnabled: () => this.#planModeState?.enabled === true,
			emitSessionEvent: event => this.#emitSessionEvent(event),
			wakeForIrc: records => this.#wakeForIrc(records),
		};
		this.#irc = new IrcBridge(ircHost);
		const prewalkHost: PrewalkCoordinatorHost = {
			agent: this.agent,
			sessionManager: this.sessionManager,
			settings: this.settings,
			model: () => this.model,
			configuredThinkingLevel: () => this.configuredThinkingLevel(),
			emitNotice: (level, message, source) => this.emitNotice(level, message, source),
			setModelTemporary: (model, thinkingLevel, options) => this.setModelTemporary(model, thinkingLevel, options),
			setActiveToolsByName: names => this.setActiveToolsByName(names),
			restoreNonMCPToolPresentation: (nonMCPToolNames, nonMCPMountedToolNames) =>
				this.restoreNonMCPToolPresentation(nonMCPToolNames, nonMCPMountedToolNames),
			getActiveToolNames: () => this.getActiveToolNames(),
			getEnabledToolNames: () => this.getEnabledToolNames(),
			getMountedXdevToolNames: () => this.getMountedXdevToolNames(),
			hasBuiltInTool: name => this.hasBuiltInTool(name),
			getPlanModeState: () => this.getPlanModeState(),
			setPlanModeState: state => this.setPlanModeState(state),
			getPlanReferencePath: () => this.getPlanReferencePath(),
			setPlanProposalHandler: handler => this.setPlanProposalHandler(handler),
			waitForSessionMessagePersistence: message => this.#waitForSessionMessagePersistence(message),
			localProtocolOptions: () => this.#localProtocolOptions(),
		};
		this.#prewalk = new PrewalkCoordinator(prewalkHost, {
			prewalk: config.prewalk,
			planYolo: config.planYolo,
		});
		const todoHost: TodoTrackerHost = {
			agent: this.agent,
			sessionManager: this.sessionManager,
			settings: this.settings,
			model: () => this.model,
			agentKind: () => this.#agentKind,
			emitSessionEvent: event => this.#emitSessionEvent(event),
			scheduleAgentContinue: options => this.#scheduleAgentContinue(options),
			promptGeneration: () => this.#promptGeneration,
			hasPendingAsyncWake: () => this.#hasPendingAsyncWake(),
			getActiveToolNames: () => this.getActiveToolNames(),
			getEnabledToolNames: () => this.getEnabledToolNames(),
			toolRegistry: () => this.#tools.registry,
			planModeEnabled: () => this.#planModeState?.enabled === true,
			prewalkWillHandoff: () => this.#prewalk.willHandoff,
			consumeLastServedToolChoiceLabel: () => this.#toolChoiceQueue.consumeLastServedLabel(),
		};
		this.#todo = new TodoTracker(todoHost);
		this.#modelMentions = new ModelMentionRegistry({
			sessionManager: this.sessionManager,
			modelRegistry: this.#modelRegistry,
			scopedModels: () => this.scopedModels.map(s => s.model),
			inheritedAgents: config.inheritedSessionAgents,
		});
		this.#ownedAsyncJobManager = config.ownedAsyncJobManager;
		this.#asyncJobManager = config.asyncJobManager ?? config.ownedAsyncJobManager;
		const modelControlsHost: ModelControlsHost = {
			agent: this.agent,
			settings: this.settings,
			modelRegistry: this.#modelRegistry,
			sessionManager: this.sessionManager,
			providerSessionState: this.#providerSessionState,
			model: () => this.model,
			sessionId: () => this.sessionId,
			promptGeneration: () => this.#promptGeneration,
			resolveActiveEditMode: () => this.#tools.resolveActiveEditMode(),
			syncAfterModelChange: previousEditMode => this.#tools.syncAfterModelChange(previousEditMode),
			setModelWithProviderSessionReset: model => this.#setModelWithProviderSessionReset(model),
			clearActiveRetryFallback: () => this.#recovery.clearActiveRetryFallback(),
			clearInheritedProviderPromptCacheKey: () => this.#clearInheritedProviderPromptCacheKey(),
			magicKeywordEnabled: keyword => this.#magicKeywordEnabled(keyword),
			emit: event => this.#emit(event),
			emitSessionEvent: event => this.#emitSessionEvent(event),
			emitNotice: (level, message, source) => this.emitNotice(level, message, source),
		};
		this.#models = new ModelControls(modelControlsHost, {
			scopedModels: config.scopedModels,
			thinkingLevel: config.thinkingLevel,
			thinkingLevelCeiling: config.thinkingLevelCeiling,
			serviceTierByFamily: config.serviceTierByFamily,
		});

		this.#promptTemplates = config.promptTemplates ?? [];
		this.#slashCommands = config.slashCommands ?? [];
		this.#extensionRunner = config.extensionRunner;
		this.#extensionRunner?.setTaskResultProcessingGate(id => this.getTaskResultProcessingGate(id));
		this.agent.addBeforeModelCall(async () => {
			for (const bound of this.#boundTaskCalls.values()) {
				if (bound.original) await bound.original.durable;
			}
		});
		this.agent.addBeforeQueuedMessageDequeueHook(() => {
			if (!this.agent.hasQueuedMessages()) return;
			const original = [...this.#boundTaskCalls.values()].find(bound => bound.original)?.original;
			if (original) {
				const error = new Error("Queued owner input must wait for original task result cleanup");
				this.#failOriginalTaskAttempt(original, error);
				throw error;
			}
		});
		this.#cacheWarmer = config.cacheWarmer;
		if (config.cacheWarmer) {
			const warmer = config.cacheWarmer;
			warmer.onWarmed = (message, extensionOverride) => this.#recordCacheWarmUsage(message, extensionOverride);
			warmer.onRefreshStart = refresh => void this.#emitSessionEvent({ type: "cache_warming_start", ...refresh });
			warmer.onRefreshEnd = refresh => void this.#emitSessionEvent({ type: "cache_warming_end", ...refresh });
			this.subscribeRunState(state => {
				if (state === "idle") warmer.onAgentSettled();
			});
			cfgProvidersCacheWarming.listen(this, () => warmer.onModeChanged());
		}
		this.#getEvalPreludes = config.getEvalPreludes;
		this.#reconcileBrowserMcpFilter = config.reconcileBrowserMcpFilter;
		this.#customCommands = config.customCommands ?? [];
		const recoveryHost: TurnRecoveryHost = {
			agent: this.agent,
			sessionManager: this.sessionManager,
			settings: this.settings,
			modelRegistry: this.#modelRegistry,
			configWarnings: this.configWarnings,
			model: () => this.model,
			contextFitsModel: (model, excludedMessage) => this.#maintenance.contextFitsModel(model, excludedMessage),
			textOutputCommitted: () => this.#textOutputCommitted,
			thinkingLevel: () => this.thinkingLevel,
			configuredThinkingLevel: () => this.configuredThinkingLevel(),
			setThinkingLevel: level => this.setThinkingLevel(level),
			thinkingLevelCeiling: () => this.#models.thinkingLevelCeiling,
			isDisposed: () => this.#isDisposed,
			isStreaming: () => this.isStreaming,
			isCompacting: () => this.isCompacting,
			abortInProgress: () => this.#abortInProgress,
			streamingEditAbortTriggered: () => this.#streamingEditGuard.abortTriggered,
			promptGeneration: () => this.#promptGeneration,
			promptSequence: () => this.#promptSequence,
			sessionId: () => this.sessionId,
			emitSessionEvent: event => this.#emitSessionEvent(event),
			scheduleAgentContinue: options => this.#scheduleAgentContinue(options),
			waitForSessionMessagePersistence: message => this.#waitForSessionMessagePersistence(message),
			appendSessionMessage: message => this.#appendSessionMessage(message),
			persistedAssistantEntryId: message => (message as PersistedAssistantMessage)[kPersistedSessionEntryId],
			sessionMessageAlreadyPersisted: message => this.#sessionMessageAlreadyPersisted(message),
			setModelWithProviderSessionReset: model => this.#setModelWithProviderSessionReset(model),
			resolveActiveEditMode: () => this.#tools.resolveActiveEditMode(),
			syncAfterModelChange: previousEditMode => this.#tools.syncAfterModelChange(previousEditMode),
			resetCurrentResponsesProviderSession: reason => this.#resetCurrentResponsesProviderSession(reason),
			maybeAutoRedeemReset: activeBlockUnblockAtMs => this.#maybeAutoRedeemReset(activeBlockUnblockAtMs),
			runAutoCompaction: (reason, willRetry, deferred, allowDefer, options) =>
				this.#maintenance.runAutoCompaction(reason, willRetry, deferred, allowDefer, options),
			shakeForRequestBodyReadTimeout: generation => this.#maintenance.shakeForRequestBodyReadTimeout(generation),
			withBashBranchTransition: operation => this.#bash.withBranchTransition(operation),
		};
		this.#fallbackChainValidationDeferred = config.deferRetryFallbackValidation === true;
		this.#recovery = new TurnRecovery(recoveryHost, {
			initialRetryFallback: config.initialRetryFallback,
			deferFallbackChainValidation: this.#fallbackChainValidationDeferred,
		});
		this.#detachUsageBeforeQueueDequeue = this.agent.addBeforeQueuedMessageDequeueHook(async signal => {
			if (
				!cfgRetryUsageAwareFallback.get(this.settings) ||
				(this.#usagePreflightReadyForNextModelCall && this.#usagePreflightReadyModel === this.model)
			) {
				return;
			}
			if (!(await this.#runQueuedUsageAwarePreflight(signal))) {
				signal?.throwIfAborted();
				throw new DOMException("Usage preflight cancelled", "AbortError");
			}
		});
		this.agent.prepareQueuedMessages = this.#prepareQueuedUserMessages;
		this.#detachUsageBeforeModelCall = this.agent.addBeforeModelCallHook(async signal => {
			if (!cfgRetryUsageAwareFallback.get(this.settings)) return;
			if (this.#usagePreflightReadyForNextModelCall) {
				const checkedModel = this.#usagePreflightReadyModel;
				this.#usagePreflightReadyForNextModelCall = false;
				this.#usagePreflightReadyModel = undefined;
				if (checkedModel === this.model) return;
			}
			if (!(await this.#runUsageAwarePreflight(signal))) {
				signal?.throwIfAborted();
				throw new DOMException("Usage preflight cancelled", "AbortError");
			}
		});
		const statsHost: SessionStatsTrackerHost = {
			session: this,
			agent: this.agent,
			sessionManager: this.sessionManager,
			modelRegistry: this.#modelRegistry,
			model: () => this.model,
			sessionId: () => this.sessionId,
		};
		this.#stats = new SessionStatsTracker(statsHost);
		const memoryHost: SessionMemoryHost = {
			agent: this.agent,
			settings: this.settings,
			modelRegistry: this.#modelRegistry,
			isDisposed: () => this.#isDisposed,
			cwd: () => this.sessionManager.getCwd(),
			addDisposer: dispose => this.addDisposer(dispose),
			emitNotice: (level, message, source) => this.emitNotice(level, message, source),
			memoryBackendSession: () => this,
			getHindsightSessionState: () => this.getHindsightSessionState(),
			setHindsightSessionState: state => this.setHindsightSessionState(state),
			getMnemopiSessionState: () => this.getMnemopiSessionState(),
			takeMnemopiSessionState: () => setMnemopiSessionState(this, undefined),
			setBaseSystemPrompt: prompt => {
				this.#tools.setBaseSystemPrompt(prompt);
				this.agent.setSystemPrompt(prompt);
			},
			refreshBaseSystemPrompt: () => this.#tools.refreshBaseSystemPrompt(),
			replaceMemoryTools: tools => this.#tools.replaceMemoryTools(tools),
		};
		this.#memory = new SessionMemory(memoryHost, {
			memoryEnabled: this.memoryEnabled,
			memoryAgentDir: config.memoryAgentDir,
			memoryTaskDepth: config.memoryTaskDepth,
			createMemoryTools: config.createMemoryTools,
		});
		this.#taskDepth = config.memoryTaskDepth ?? 0;
		// Resolve the wire service-tier per request so the Fireworks Priority
		// toggle scopes priority to Fireworks alone, without mutating the shared
		// session `serviceTier` that drives `/fast` and OpenAI/Anthropic priority.
		this.agent.serviceTierResolver = model => this.#models.effectiveServiceTier(model);
		this.#titleSystemPrompt = config.titleSystemPrompt;
		this.#transformContext = config.transformContext ?? (messages => messages);
		this.#sideStreamFn = config.sideStreamFn ?? streamSimple;
		this.#onPayload = config.onPayload;
		this.rawSseDebugBuffer = config.rawSseDebugBuffer ?? new RawSseDebugBuffer();
		// Avoid wrapping in an `async` closure when no user callback is configured: the
		// outer await on `#onResponse` (provider-response.ts) tolerates a sync void return,
		// and skipping the wrapper drops a per-event `newPromiseCapability` allocation that
		// shows up as ~3.5% self time in streaming profiles.
		const configuredOnResponse = config.onResponse;
		this.#onResponse = configuredOnResponse
			? async (response, model, signal) => {
					this.rawSseDebugBuffer.recordResponse(response, model);
					this.#stats.ingestProviderUsageHeaders(response, model);
					await this.#maybeRefreshLazyLocalContext(response, model);
					await configuredOnResponse(response, model, signal);
				}
			: (response, model) => {
					this.rawSseDebugBuffer.recordResponse(response, model);
					this.#stats.ingestProviderUsageHeaders(response, model);
					// Returns void (no allocation) unless a one-time lazy-model
					// refresh is actually due, preserving the sync fast path.
					return this.#maybeRefreshLazyLocalContext(response, model);
				};
		const configuredOnSseEvent = config.onSseEvent;
		this.#onSseEvent = configuredOnSseEvent
			? (event, model) => {
					this.rawSseDebugBuffer.recordEvent(event, model);
					configuredOnSseEvent(event, model);
				}
			: (event, model) => {
					this.rawSseDebugBuffer.recordEvent(event, model);
				};
		this.agent.setProviderResponseInterceptor(this.#onResponse);
		this.agent.setRawSseEventInterceptor(this.#onSseEvent);
		this.agent.setOnTurnEnd(async (messages, signal, context) => {
			if (signal?.aborted) return;
			const rewindReport = this.#extractRewindReport(messages);
			if (rewindReport) {
				this.#pendingRewindReport = undefined;
				await this.#applyRewind(rewindReport, messages, context);
			}
			this.#loopGuards.recordTurn(messages, context);
			await this.#prewalk.advanceAtTurnEnd(messages, context);
			if (context?.willContinue) this.#steerAnthropicWrapUp();
			await this.#advisors.onPrimaryTurnEnd(messages, context?.willContinue, signal);
			await this.#maintenance.maintainContextMidRun(messages, signal, context);
		});
		this.yieldQueue = new YieldQueue({
			isStreaming: () => this.isStreaming,
			injectIdle: async messages => {
				const first = messages[0];
				if (!first) return;
				this.#beginInFlight();
				try {
					await this.agent.prompt(messages.length === 1 ? first : messages);
				} finally {
					this.#endInFlight();
				}
			},
			scheduleIdleFlush: run => {
				const keepalive = new EventLoopKeepalive();
				try {
					this.#schedulePostPromptTask(
						async () => {
							try {
								await run();
							} finally {
								keepalive[Symbol.dispose]();
							}
						},
						{
							delayMs: 1,
							onSkip: () => {
								keepalive[Symbol.dispose]();
								this.yieldQueue.cancelIdleFlushScheduling();
							},
						},
					);
				} catch (error) {
					keepalive[Symbol.dispose]();
					throw error;
				}
			},
		});
		this.yieldQueue.register<LaunchCompletionEntry>(LAUNCH_COMPLETION_MESSAGE_TYPE, {
			isStale: entry =>
				this.#isDisposed || !isLaunchCompletionOwner(entry.owner, this.sessionManager.getSessionId()),
			build: buildLaunchCompletionBatchMessage,
		});
		// Receipt-backed extension deliveries (OMP-51): resolve only on injection,
		// and only into the session that enqueued them — a switch makes them stale.
		this.yieldQueue.register<ExtensionDeliveryEntry>(EXTENSION_DELIVERY_MESSAGE_TYPE, {
			isStale: entry =>
				this.#isDisposed || (entry.owner !== undefined && entry.owner !== this.sessionManager.getSessionId()),
			build: buildExtensionDeliveryBatchMessage,
		});
		// Background-job completions / late diagnostics are pulled into the run at
		// each step boundary as non-interrupting asides. Peer IRCs share the aside
		// injection boundary, but also expose a non-consuming interrupt peek so
		// `wait` can return early before the boundary drains them.
		this.agent.hasIrcInterrupts = () => this.#irc.hasInterrupts();
		// Completion notices (finished background jobs, exited supervised
		// processes) queue here for the same boundary; peeking them lets a
		// `wait` return early rather than miss a queued completion.
		this.agent.hasBackgroundCompletions = () =>
			this.yieldQueue.has(LAUNCH_COMPLETION_MESSAGE_TYPE) || this.yieldQueue.has(ASYNC_RESULT_MESSAGE_TYPE);
		this.agent.setAsideMessageProvider(() => {
			const thunks: AsideMessage[] = this.#irc.drainPending().map(record => () => record);
			thunks.push(...this.yieldQueue.drainLazy());
			// Mid-run todo reconciliation — evaluated at injection time so a turn
			// that flips a todo just before this poll suppresses the nudge.
			thunks.push(() => this.#todo.takeMidRunNudge());
			const contextNotesReminder = this.#experimentalContextNotesReminder;
			if (contextNotesReminder) {
				this.#experimentalContextNotesReminder = undefined;
				if (contextNotesReminder.generation === this.#promptGeneration) {
					thunks.push(() => ({
						role: "custom",
						customType: "experimental-context-notes-reminder",
						content: contextNotesReminder.prompt,
						display: false,
						timestamp: Date.now(),
					}));
				}
			}
			return thunks;
		});
		this.#convertToLlm = config.convertToLlm ?? convertToLlm;
		this.getXdevToolEntries = config.getXdevToolEntries ?? (() => []);
		const sessionToolsHost: SessionToolsHost = {
			agent: this.agent,
			sessionManager: this.sessionManager,
			settings: this.settings,
			effectiveExtensionRoots: () => this.effectiveExtensionRoots,
			modelRegistry: this.#modelRegistry,
			extensionRunner: () => this.#extensionRunner,
			clientBridge: () => this.#clientBridge,
			agentKind: () => this.#agentKind,
			isDisposed: () => this.#isDisposed,
			isStreaming: () => this.isStreaming,
			queuedMessageCount: () => this.queuedMessageCount,
			planModeEnabled: () => this.#planModeState?.enabled === true,
			model: () => this.model,
			setCodeModeNamespacesInfo: info => {
				this.#codeModeState.namespacesInfo = info;
			},
			memoryBackendSession: () => this,
			clearInheritedProviderPromptCacheKey: () => this.#clearInheritedProviderPromptCacheKey(),
			clearMemoryPromotionSnapshot: () => this.#memory.clearPromotionSnapshot(),
			captureMemoryPromotionSnapshot: prompt => this.#memory.capturePromotionSnapshot(prompt),
			emitNotice: (level, message, source) => this.emitNotice(level, message, source),
			notifyCommandMetadataChanged: () => this.#notifyCommandMetadataChanged(),
			localProtocolOptions: () => this.#localProtocolOptions(),
			evalPreludes: () => this.getEvalPreludes(),
			sessionAgents: () => this.getSessionAgents(),
		};
		this.#tools = new SessionTools(sessionToolsHost, {
			autoApprove: config.autoApprove,
			toolRegistry: config.toolRegistry,
			createVibeTools: config.createVibeTools,
			createThinkTool: config.createThinkTool,
			builtInToolNames: config.builtInToolNames,
			mcpManagerToolNames: config.mcpManagerToolNames,
			presentationPinnedToolNames: config.presentationPinnedToolNames,
			ensureWriteRegistered: config.ensureWriteRegistered,
			isDeviceOnlyWrite: config.isDeviceOnlyWrite,
			setDeviceOnlyWrite: config.setDeviceOnlyWrite,
			setPendingFullWriteDescription: config.setPendingFullWriteDescription,
			ensureGoalRegistered: config.ensureGoalRegistered,
			reconcileSettingsGatedTools: config.reconcileSettingsGatedTools,
			rebuildSystemPrompt: config.rebuildSystemPrompt,
			getMcpServerInstructions: config.getMcpServerInstructions,
			xdev: config.xdev,
			setActiveToolNames: config.setActiveToolNames,
			baseSystemPrompt: this.agent.state.systemPrompt,
			skills: config.skills,
			skillWarnings: config.skillWarnings,
			skillsSettings: config.skillsSettings,
			skillsReloadable: config.skillsReloadable,
		});
		this.#disconnectOwnedMcpManager = config.disconnectOwnedMcpManager;
		const ttsrHost: TtsrCoordinatorHost = {
			emitNotice: (level, message, source) => this.emitNotice(level, message, source),
			agent: this.agent,
			sessionManager: this.sessionManager,
			settings: this.settings,
			emitSessionEvent: event => this.#emitSessionEvent(event),
			schedulePostPromptTask: (task, options) => this.#schedulePostPromptTask(task, options),
			scheduleAgentContinue: options => this.#scheduleAgentContinue(options),
			promptGeneration: () => this.#promptGeneration,
			ruleJudge: () => this.ruleJudge(),
			deliverRuleWarning: (content, ruleNames) => this.#deliverRuleWarning(content, ruleNames),
			sessionGeneration: () => this.#sessionGeneration,
		};
		this.#ttsr = new TtsrCoordinator(ttsrHost, config.ttsrManager);
		this.#extensionRunner?.setToolCallPreflight?.({
			before: (toolCallId, tool, args) => this.#ttsr.beforeBridgedToolCall(toolCallId, tool, args),
			after: (toolCallId, result, context) => this.#ttsr.afterBridgedToolCall(toolCallId, result, context),
			cancel: toolCallId => this.#ttsr.cancelBridgedToolCall(toolCallId),
		});
		this.agent.setOnBeforeYield(() => this.#ttsr.settleJudgments());
		this.#obfuscator = config.obfuscator;
		this.#recoverSynchronousTask = config.recoverSynchronousTask;
		this.#validateSynchronousTaskPolicy = config.validateSynchronousTaskPolicy;
		this.#assertSynchronousTaskPolicy = config.assertSynchronousTaskPolicy;
		const providerBoundaryHost: SessionProviderBoundaryHost = {
			agent: this.agent,
			sessionManager: this.sessionManager,
			settings: this.settings,
			modelRegistry: this.#modelRegistry,
			model: () => this.model,
			sessionId: () => this.sessionId,
			localProtocolOptions: () => this.#localProtocolOptions(),
			transformContext: (messages, signal) => this.#transformContext(messages, signal),
			convertToLlm: messages => this.#convertToLlm(messages),
			onPayload: this.#onPayload,
			onResponse: this.#onResponse,
			onSseEvent: this.#onSseEvent,
			obfuscator: () => this.#obfuscator,
		};
		this.#providerBoundary = new SessionProviderBoundary(providerBoundaryHost);
		const streamGuardsHost: StreamGuardsHost = {
			agent: this.agent,
			settings: this.settings,
			sessionManager: this.sessionManager,
			model: () => this.model,
			isDisposed: () => this.#isDisposed,
			promptGeneration: () => this.#promptGeneration,
			emitNotice: (level, message, source) => this.emitNotice(level, message, source),
			schedulePostPromptTask: task => this.#schedulePostPromptTask(task),
			discardAssistantTurn: message => this.#recovery.discardAssistantTurn(message),
		};
		this.#streamingEditGuard = new StreamingEditGuard(streamGuardsHost);
		this.#loopGuards = new LoopGuards(streamGuardsHost);
		this.#agentId = config.agentId;
		this.#agentKind = config.agentKind ?? "main";
		// A subagent's streamed text reaches no output sink until the run settles
		// (the parent sees only the yield), so a failed turn's partial prose is
		// replay-safe and transient provider errors after it stay retryable —
		// same buffering contract print mode declares via setTextOutputCommitted.
		this.#textOutputCommitted = this.#agentKind === "main";
		this.#scoutAllowedBySpawnPolicy = config.scoutAllowedBySpawnPolicy ?? true;
		this.#providerSessionId = config.providerSessionId;
		this.#inheritedProviderPromptCacheKey =
			config.providerPromptCacheKeySource === "fork" ? this.agent.promptCacheKey : undefined;
		// Owner-routed async delivery: completions for jobs this agent owns are
		// injected into THIS session's run as async-result follow-ups. Without a
		// registered sink the manager dead-letters owned deliveries, so this
		// registration is what makes background jobs usable — for the main
		// session and for subagents inheriting the process manager alike.
		if (this.#asyncJobManager && this.#agentId) {
			const manager = this.#asyncJobManager;
			this.#unregisterAsyncDeliverySink = manager.registerDeliverySink(this.#agentId, (jobId, text, job) =>
				this.#deliverAsyncJobResult(manager, jobId, text, job),
			);
			this.yieldQueue.register<AsyncResultEntry>("async-result", {
				isStale: entry => entry.epoch !== this.#asyncDeliveryEpoch || manager.isDeliverySuppressed(entry.jobId),
				build: buildAsyncResultBatchMessage,
			});
		}
		this.agent.setAssistantMessageEventInterceptor((message, assistantMessageEvent) => {
			this.#loopGuards.onAssistantEvent(message, assistantMessageEvent);
		});
		// Tool-result hook owns synchronous post-tool actions that must affect the current loop.
		this.agent.afterToolCall = ctx => this.#afterToolCall(ctx);
		// Pre-scheduling tool_call wiring: extension handlers run at arg-prep
		// time so a block/revision lands before concurrency resolution,
		// tool_execution_start, and the wrapper's approval gate.
		this.agent.beforeToolCall = (ctx, signal) => this.#beforeToolCall(ctx, signal);
		this.agent.providerSessionState = this.#providerSessionState;
		this.#syncAgentSessionId();
		this.#todo.syncFromBranch();
		this.#modelMentions.syncFromBranch();
		this.#goalRuntime = new GoalRuntime({
			getState: () => this.#goalModeState,
			setState: state => {
				this.#goalModeState = state;
			},
			getCurrentUsage: () => {
				const usage = this.getSessionStats().tokens;
				return {
					input: usage.input,
					output: usage.output,
					cacheRead: usage.cacheRead,
					cacheWrite: usage.cacheWrite,
				};
			},
			emit: event => {
				if (event.type === "goal_updated") {
					return this.#emitSessionEvent({ type: "goal_updated", goal: event.goal, state: event.state });
				}
			},
			persist: (mode, state) => {
				if (mode === "none") {
					this.sessionManager.appendModeChange("none");
				} else if (state) {
					this.sessionManager.appendModeChange(mode, { goal: state.goal });
				}
			},
			sendHiddenMessage: async message => {
				await this.sendCustomMessage(
					{
						customType: message.customType,
						content: message.content,
						display: false,
						attribution: "agent",
					},
					{ deliverAs: message.deliverAs },
				);
			},
		});
		this.#cancelExitRecorder = postmortem.register(`agent-session:${this.sessionManager.getSessionId()}`, reason => {
			this.#recordSessionExit(reason);
		});
		this.#cancelFatalRecoveryHint = postmortem.registerFatalRecoveryHint(() => {
			const sessionId = this.sessionManager.getSessionId();
			if (!sessionId || !this.sessionManager.getSessionFile()) return undefined;
			return {
				label: this.#agentId ?? (this.#agentKind === "main" ? "Main" : "Agent"),
				command: resumeCommand(sessionId),
			};
		});

		const advisorsHost: SessionAdvisorsHost = {
			agent: this.agent,
			sessionManager: this.sessionManager,
			settings: this.settings,
			modelRegistry: this.#modelRegistry,
			yieldQueue: this.yieldQueue,
			obfuscator: () => this.#obfuscator,
			providerSessionState: this.#providerSessionState,
			preferWebsockets: () => this.preferWebsockets,
			onPayload: this.#onPayload,
			onResponse: this.#onResponse,
			onSseEvent: this.#onSseEvent,
			isDisposed: () => this.#isDisposed,
			abortInProgress: () => this.#abortInProgress,
			allowAgentInitiatedTurns: () => this.#allowAcpAgentInitiatedTurns,
			planModeState: () => this.#planModeState,
			clientBridge: () => this.#clientBridge,
			emitSessionEvent: event => this.#emitSessionEvent(event),
			emitNotice: (level, message, source) => this.emitNotice(level, message, source),
			sendCustomMessage: (message, options) => this.sendCustomMessage(message, options),
			extractQueuedAdvisorCards: () => this.#extractQueuedAdvisorCards(),
			dropPendingAdvisorCards: () => {
				this.#pendingNextTurnMessages = this.#pendingNextTurnMessages.filter(message => !isAdvisorCard(message));
			},
			preserveAdvisorCard: card => this.#preserveAdvisorCard(card),
			hasPendingNextTurnMessages: () => this.#pendingNextTurnMessages.length > 0,
			convertToLlmForSideRequest: messages => this.#convertToLlmForSideRequest(messages),
			effectiveServiceTier: model => this.#models.effectiveServiceTier(model),
			resolveContextPromotionTarget: (model, contextWindow, signal) =>
				this.#maintenance.resolveContextPromotionTarget(model, contextWindow, signal),
			resolveCompactionModelCandidates: (model, availableModels) =>
				this.#maintenance.resolveCompactionModelCandidates(model, availableModels),
			resolveRetryFallbackRole: (selector, model, roleHint) =>
				this.#recovery.resolveRetryFallbackRole(selector, model, roleHint),
			retryFallbackChainKeys: (selector, model, options) =>
				this.#recovery.retryFallbackChainKeys(selector, model, options),
			findRetryFallbackCandidates: (role, selector, model) =>
				this.#recovery.findRetryFallbackCandidates(role, selector, model),
			isRetryFallbackSelectorSuppressed: selector => this.#recovery.isRetryFallbackSelectorSuppressed(selector),
			noteRetryFallbackCooldown: (selector, retryAfterMs, errorMessage) =>
				this.#recovery.noteRetryFallbackCooldown(selector, retryAfterMs, errorMessage),
			createCodexCompactionContext: createMaintenanceCodexCompactionContext,
			sessionId: () => this.sessionId,
		};
		this.#advisors = new SessionAdvisors(advisorsHost, {
			enabled: cfgAdvisorEnabled.get(this.settings),
			tools: config.advisorTools,
			createGrepTool: config.advisorCreateGrepTool,
			createEditTool: config.advisorCreateEditTool,
			getToolContext: config.advisorGetToolContext,
			mcpResources: config.advisorMcpResources,
			watchdogPrompt: config.advisorWatchdogPrompt,
			sharedInstructions: config.advisorSharedInstructions,
			sharedMaxNotesPerUpdate: config.advisorSharedMaxNotesPerUpdate,
			contextPrompt: config.advisorContextPrompt,
			memoryPrompt: config.advisorMemoryPrompt,
			configs: config.advisorConfigs,
			configWarnings: config.advisorConfigWarnings,
			streamFn: config.advisorStreamFn,
			transformProviderContext: config.transformProviderContext,
		});

		const maintenanceHost: SessionMaintenanceHost = {
			agent: this.agent,
			sessionManager: this.sessionManager,
			settings: this.settings,
			modelRegistry: this.#modelRegistry,
			extensionRunner: this.#extensionRunner,
			sideStreamFn: this.#sideStreamFn,
			providerSessionState: this.#providerSessionState,
			preferWebsockets: () => this.preferWebsockets,
			model: () => this.model,
			thinkingLevel: () => this.thinkingLevel,
			isDisposed: () => this.#isDisposed,
			isStreaming: () => this.isStreaming,
			isGeneratingHandoff: () => this.isGeneratingHandoff,
			promptGeneration: () => this.#promptGeneration,
			sessionId: () => this.sessionId,
			messages: () => this.messages,
			baseSystemPrompt: () => this.#tools.baseSystemPrompt,
			goalModeState: () => this.#goalModeState,
			planReferencePath: () => this.#planReferencePath,
			nonMessageTokenSource: () => this,
			hasExperimentalContextRolloverTools: () => {
				const enabled = this.#tools.getEnabledToolNames();
				for (const name in EXPERIMENTAL_CONTEXT_REQUIRED_TOOLS) {
					if (!enabled.includes(name) || !this.#tools.getToolByName(name)) return false;
				}
				return true;
			},
			takeExperimentalContextRolloverRequest: context => {
				for (const toolResult of context?.toolResults ?? []) {
					if (toolResult.isError) continue;
					const dispatch = writeDeviceDispatch(toolResult.toolName, toolResult);
					const details =
						toolResult.toolName === "new_context"
							? toolResult.details
							: dispatch?.mode === "execute" && dispatch.tool === "new_context"
								? dispatch.inner
								: undefined;
					if (isRecord(details) && details.requested === true) return true;
				}
				return false;
			},
			queueExperimentalContextNotesReminder: prompt => {
				if (this.#isDisposed) return;
				this.#experimentalContextNotesReminder = { prompt, generation: this.#promptGeneration };
			},
			memoryBackendSession: () => this,
			emitSessionEvent: (event, options) => this.#emitSessionEvent(event, options),
			emitNotice: (level, message, source) => this.emitNotice(level, message, source),
			schedulePostPromptTask: (task, options) => this.#schedulePostPromptTask(task, options),
			scheduleAgentContinue: options => this.#scheduleAgentContinue(options),
			scheduleCompactionContinuation: options => this.#scheduleCompactionContinuation(options),
			persistTurnMessagesForMidRunCompaction: context => this.#persistTurnMessagesForMidRunCompaction(context),
			findLastAssistantMessage: () => this.#findLastAssistantMessage(),
			disconnectFromAgent: () => this.#disconnectFromAgent(),
			reconnectToAgent: () => this.#reconnectToAgent(),
			drainStrandedQueuedMessages: () => this.#drainStrandedQueuedMessages(),
			buildDisplaySessionContext: () => this.buildDisplaySessionContext(),
			convertToLlmForSideRequest: messages => this.#convertToLlmForSideRequest(messages),
			obfuscateTextForProvider: text => this.#obfuscateTextForProvider(text),
			obfuscatePreparationForProvider: preparation => this.#obfuscatePreparationForProvider(preparation),
			closeCodexProviderSessionsForHistoryRewrite: () => this.#closeCodexProviderSessionsForHistoryRewrite(),
			resetCodexProviderAfterCompaction: compaction => this.#resetCodexProviderAfterCompaction(compaction),
			resetPlanReference: () => {
				this.#planReferenceSent = false;
			},
			syncTodoPhasesFromBranch: () => {
				this.#todo.syncFromBranch();
				this.#modelMentions.syncFromBranch();
			},
			resetAdvisorRuntimes: (reason?: string) => this.#advisors.resetAllRuntimes(reason),
			rebaseAdvisorPrefix: reason => this.#advisors.rebaseDeliveredPrefixes(reason),
			rebaseAfterCompaction: () => this.#stats.rebaseAfterCompaction(),
			recordAnchoredHistoryRewrite: tokensRemoved => this.#stats.recordAnchoredHistoryRewrite(tokensRemoved),
			getContextBreakdown: options => this.getContextBreakdown(options),
			getContextUsage: options => this.getContextUsage(options),
			shake: (mode, options) => this.shake(mode, options),
			dropImages: () => this.dropImages(),
			generateHandoffDocument: (customInstructions, options) =>
				this.#handoff.generateDocument(customInstructions, options),
			removeAssistantMessageFromActiveContext: message =>
				this.#recovery.removeAssistantMessageFromActiveContext(message),
			dropPersistedAssistantTurn: message => this.#recovery.dropPersistedAssistantTurn(message),
			retainTerminalFailure: message => {
				this.#prunedTerminalFailure = message;
			},
			runRecoveryCompactionWithRollback: (reason, message, allowDefer, options) =>
				this.#recovery.runRecoveryCompactionWithRollback(reason, message, allowDefer, options),
			parseRetryAfterMsFromError: errorMessage => this.#recovery.parseRetryAfterMsFromError(errorMessage),
			setModelTemporary: (model, thinkingLevel, options) => this.setModelTemporary(model, thinkingLevel, options),
			abort: options => this.abort(options),
			abortHandoff: () => this.abortHandoff(),
		};
		this.#maintenance = new SessionMaintenance(maintenanceHost);

		const handoffHost: SessionHandoffHost = {
			agent: this.agent,
			sessionManager: this.sessionManager,
			settings: this.settings,
			modelRegistry: this.#modelRegistry,
			sideStreamFn: this.#sideStreamFn,
			obfuscator: () => this.#obfuscator,
			model: () => this.model,
			thinkingLevel: () => this.thinkingLevel,
			sessionId: () => this.sessionId,
			baseSystemPrompt: () => this.#tools.baseSystemPrompt,
			setSkipPostTurnMaintenance: timestamp => {
				this.#maintenance.skipPostTurnMaintenanceAssistantTimestamp = timestamp;
				if (timestamp === undefined) this.#skippedPostTurnSpeculationCompletion = undefined;
			},
			obfuscateTextForProvider: text => this.#obfuscateTextForProvider(text),
			deobfuscateFromProvider: text => this.#deobfuscateFromProvider(text),
			convertMessagesToLlm: (messages, signal) => this.convertMessagesToLlm(messages, signal),
			prepareSimpleStreamOptions: (options, provider) => this.prepareSimpleStreamOptions(options, provider),
			effectiveServiceTier: model => this.#models.effectiveServiceTier(model),
		};
		this.#handoff = new SessionHandoff(handoffHost);

		this.#rehydrateCheckpointRewindState();

		// Always subscribe to agent events for internal handling
		// (session persistence, hooks, auto-compaction, retry logic)
		this.#unsubscribeAgent = this.agent.subscribe(this.#handleAgentEvent);
		this.#unsubscribeQueueChange = this.agent.onQueueChange(() => this.#emitQueueUpdateIfChanged());
		// Re-evaluate append-only context mode when the setting changes at runtime.
		cfgProviderAppendOnlyContext.listen(this, () => this.#syncAppendOnlyContext(this.model));
		cfgModelRoles.listen(this, () => this.#advisors.reconcileModelRoles());
		// Re-derive the active model's effective context window when the
		// extended-context setting flips at runtime: the registry re-clamps (or
		// restores) premium long-context windows, and the live model object must
		// follow so compaction thresholds and context display react immediately.
		cfgExtendedContext.listen(this, () => this.#reapplyExtendedContextPolicy());
		cfgBrowserEnabled.listen(this, enabled => this.#reconcileEvalPreludeSetting("browser.enabled", enabled));
		cfgComputerEnabled.listen(this, enabled => this.#reconcileEvalPreludeSetting("computer.enabled", enabled));
		cfgRatchetEnabled.listen(this, enabled => this.#reconcileEvalPreludeSetting("ratchet.enabled", enabled));
		cfgBrowserIdleCloseSec.listen(this, seconds => {
			const ownerId = this.sessionManager.getSessionId() ?? "";
			// Any change invalidates the armed deadline: cancel first (its
			// sequence bump stops an in-flight sweep re-arming the old
			// value), then re-arm under the new one. A non-positive value
			// arms nothing, which is the disable path.
			cancelIdleCloseForOwner(ownerId);
			if (seconds > 0) {
				armIdleCloseForOwner(ownerId, seconds * 1000);
			}
		});
		cfgCodeModeInputs.listen(this, () =>
			this.#tools.reconcileCodeMode().catch(error => {
				logger.warn("Code Mode reconcile after setting change failed", { error: String(error) });
			}),
		);

		// Config-declared resolution done against the catalog as it stands at
		// construction can be premature: background discovery is started
		// fire-and-forget (before the session in the SDK path, right after it in
		// the CLI path), so discovery-backed providers (e.g. GitHub Copilot, or a
		// models.yml LiteLLM provider with a cold cache) may not be populated yet.
		// Reactivate a `no_model` advisor (#9010), retract stale
		// retry.fallbackChains warnings (#10048), and rebind the active model to
		// its refreshed same-selector entry (#10488) once discovery settles.
		void this.#retryInactiveAdvisorAfterModelDiscovery();
		void this.#revalidateFallbackChainsAfterModelDiscovery();
		if (config.rebindModelAfterDiscovery) void this.#rebindActiveModelAfterModelDiscovery();
		this.#watchWorkspaceAndPowerSettings();
		this.#watchSessionSettings();
		this.#watchModelAvailabilitySettings();
	}

	/** Registers teardown to run when this session is disposed (e.g. handle listeners bound to it). */
	addDisposer(dispose: () => void): void {
		this.#disposers.push(dispose);
	}

	/**
	 * `browser.enabled` / `computer.enabled` / `ratchet.enabled` change the live eval preludes; the browser toggle also
	 * re-filters its MCP tools first. An empty transcript rebuilds the system prompt to advertise
	 * them; mid-session the cached prompt stays byte-stable and the next user prompt carries a
	 * hidden prelude notice instead (see {@link SessionTools.takeEvalPreludeNotice}).
	 * A failed browser switch-on reverts to off.
	 */
	async #reconcileEvalPreludeSetting(
		path: "browser.enabled" | "computer.enabled" | "ratchet.enabled",
		enabled: boolean,
	): Promise<void> {
		try {
			if (path === "browser.enabled" && this.#reconcileBrowserMcpFilter) {
				const tools = await this.#reconcileBrowserMcpFilter(enabled);
				await this.refreshMCPTools(tools);
			}
			if (this.agent.state.messages.length === 0) await this.refreshBaseSystemPrompt();
		} catch (error) {
			if (path === "browser.enabled" && enabled && cfgBrowserEnabled.get(this.settings)) {
				cfgBrowserEnabled.override(this.settings, false);
			}
			logger.warn("Failed to reconcile eval prelude setting change", { path, error: String(error) });
		}
	}

	/**
	 * `disabledProviders`: reads filter at use time; the catalog rebuild re-seeds
	 * re-enabled providers (implicit local servers, cached discoveries).
	 * `prewalk.enabled` (top-level sessions): arms the default hand-off or drops a
	 * pending one, effective from the next turn.
	 */
	#watchModelAvailabilitySettings(): void {
		cfgDisabledProviders.listen(this, () => this.#modelRegistry.reapplyModelPolicies());
		if (this.#agentKind !== "main") return;
		cfgPrewalkEnabled.listen(this, enabled => {
			if (!enabled) {
				this.#prewalk.disarm();
				return;
			}
			if (this.#prewalk.state) return;
			const scoped = this.scopedModels.map(entry => entry.model);
			const resolved = resolveCliModel({
				cliModel: DEFAULT_PREWALK_TARGET,
				modelRegistry: this.#modelRegistry,
				availableModels: scoped.length > 0 ? scoped : undefined,
				settings: this.settings,
				preferences: getModelMatchPreferences(this.settings),
			});
			const target = resolved.model;
			const problem = !target
				? (resolved.error ?? `model "${DEFAULT_PREWALK_TARGET}" not found`)
				: cfgDisabledProviders.get(this.settings).includes(target.provider)
					? `provider "${target.provider}" is disabled`
					: !this.#modelRegistry.hasConfiguredAuth(target)
						? `no API key for ${target.provider}/${target.id}`
						: undefined;
			if (!target || problem) {
				this.emitNotice("warning", `Prewalk not armed: ${problem}.`, "prewalk");
				return;
			}
			this.#prewalk.arm(target, resolved.thinkingLevel);
		});
	}

	/**
	 * Applies session-level settings (queue modes, sampling, service tiers,
	 * advisors, think tool, skillful) to the live session whenever they change.
	 * Setters that persist route back here idempotently. `defaultThinkingLevel`
	 * is deliberately absent: it seeds new sessions, and a later write (config
	 * reload, another process, a parent session) must not override a running
	 * session's selection — the settings panel and `cfg://` apply it explicitly.
	 */
	#watchSessionSettings(): void {
		cfgSteeringMode.listen(this, mode => this.agent.setSteeringMode(mode));
		cfgFollowUpMode.listen(this, mode => this.agent.setFollowUpMode(mode));
		cfgInterruptMode.listen(this, mode => this.agent.setInterruptMode(mode));
		cfgSampling.listen(this, sampling => {
			this.agent.temperature = sampling.temperature;
			this.agent.topP = sampling.topP;
			this.agent.topK = sampling.topK;
			this.agent.minP = sampling.minP;
			this.agent.presencePenalty = sampling.presencePenalty;
			this.agent.repetitionPenalty = sampling.repetitionPenalty;
			this.agent.hideThinkingSummary = sampling.hideThinkingSummary;
		});
		cfgTierOpenai.listen(this, tier => this.setServiceTierFamily("openai", serviceTierSettingToTier(tier)));
		cfgTierAnthropic.listen(this, tier => this.setServiceTierFamily("anthropic", serviceTierSettingToTier(tier)));
		cfgTierGoogle.listen(this, tier => this.setServiceTierFamily("google", serviceTierSettingToTier(tier)));
		cfgAdvisorRuntimeInputs.listen(this, (next, previous) => {
			// A budget/tier edit rebuilds a running advisor (both are part of its
			// runtime signature) without overriding a session-only `/advisor` toggle.
			if (next.enabled !== previous.enabled) this.setAdvisorEnabled(next.enabled);
			else if (this.isAdvisorEnabled()) this.setAdvisorEnabled(true);
		});
		cfgExternalThinking.listen(this, async () => {
			try {
				await this.#tools.reconcileThinkTool();
			} catch (error) {
				this.emitNotice("error", `Failed to apply external thinking: ${error}`);
			}
		});
		this.#skillfulApplied = cfgSkillful.get(this.settings);
		cfgSkillful.listen(this, skillful => this.#applySkillful(skillful));
	}

	/** Keeps workspace roots, the auto-QA prompt note, and the held power assertion in step with live settings. */
	#watchWorkspaceAndPowerSettings(): void {
		this.#settingsWorkspaceDirectories = cfgWorkspaceAdditionalDirectories.get(this.settings);
		this.#autoQaEnabled = isAutoQaEnabled(this.settings);
		cfgPowerSleepPrevention.listen(this, () => {
			// Swap the held assertion for the new mode mid-prompt; idle sessions
			// pick the mode up when the next prompt begins.
			if (this.#promptInFlightCount === 0) return;
			this.#releasePowerAssertion();
			this.#acquirePowerAssertion();
		});
		cfgWorkspacePromptInputs.listen(this, async () => {
			const rootsChanged = await this.#syncSettingsWorkspaceDirectories();
			const autoQaEnabled = isAutoQaEnabled(this.settings);
			const autoQaChanged = autoQaEnabled !== this.#autoQaEnabled;
			this.#autoQaEnabled = autoQaEnabled;
			if ((rootsChanged || autoQaChanged) && !this.#isDisposed) await this.refreshBaseSystemPrompt();
		});
	}

	/**
	 * Apply a `workspace.additionalDirectories` edit to the live session: roots
	 * dropped from the setting are removed, new ones added. Roots from `--add-dir`,
	 * `/add-dir`, or the resumed session header are left alone. Returns whether
	 * the session's workspace roots changed.
	 */
	async #syncSettingsWorkspaceDirectories(): Promise<boolean> {
		const previous = this.#settingsWorkspaceDirectories;
		const next = cfgWorkspaceAdditionalDirectories.get(this.settings);
		this.#settingsWorkspaceDirectories = next;
		let changed = false;
		for (const directory of previous) {
			if (next.includes(directory)) continue;
			if ((await this.sessionManager.removeWorkspaceDirectory(directory)) !== null) changed = true;
		}
		for (const directory of next) {
			if (previous.includes(directory)) continue;
			try {
				if ((await this.sessionManager.addWorkspaceDirectory(directory)) !== null) changed = true;
			} catch (error) {
				logger.warn("Skipping workspace.additionalDirectories entry", { directory, error: String(error) });
			}
		}
		return changed;
	}

	/** Model registry for API key resolution and model discovery */
	get modelRegistry(): ModelRegistry {
		return this.#modelRegistry;
	}

	get asyncJobManager(): AsyncJobManager | undefined {
		return this.#asyncJobManager;
	}

	getAgentId(): string | undefined {
		return this.#agentId;
	}

	/** Dequeue the next HARD forced tool choice for the upcoming LLM call, dropping
	 *  (and rejecting) one whose named tool is no longer active. */
	#nextHardToolChoice(): ToolChoice | undefined {
		const choice = this.#toolChoiceQueue.nextToolChoice();
		if (isToolChoiceActive(choice, this.agent.state.tools)) {
			return choice;
		}
		this.#toolChoiceQueue.reject("unavailable");
		return undefined;
	}

	/**
	 * The per-turn tool-choice directive for the agent loop's `getToolChoice`. Priority:
	 *   1. a HARD forced choice from the queue (genuine forces: user-force, eager-todo, …) —
	 *      consuming (advances the queue generator);
	 *   2. else, when a non-forcing preview is pending, a {@link SoftToolRequirement} — a
	 *      PEEK (advances/pops nothing), so the agent-loop injects the reminder once per head
	 *      and escalates to a forced `write` only if the model declines to
	 *      resolve via `xd://resolve` or `xd://reject`. A compliant turn
	 *      pays ZERO tool_choice change (no prompt-cache messages-cache invalidation);
	 *   3. else undefined.
	 */
	nextToolChoiceDirective(): ToolChoiceDirective | undefined {
		const hard = this.#nextHardToolChoice();
		if (hard !== undefined) return hard;
		const head = this.#toolChoiceQueue.peekPendingHead();
		if (head !== undefined) {
			return {
				soft: true,
				id: head.id,
				// Preview resolution is a `write` to xd://resolve or xd://reject;
				// only those exact shapes satisfy the requirement — a plain write
				// elsewhere is a detour.
				toolName: "write",
				satisfies: isPreviewResolutionToolCall,
				reminder: [buildResolveReminderMessage(head.sourceToolName)],
			};
		}
		return undefined;
	}

	/** Peek the head non-forcing pending preview invoker, for the preview-resolution dispatch. */
	peekPendingInvoker(): ((input: unknown) => Promise<unknown> | unknown) | undefined {
		return this.#toolChoiceQueue.peekPendingInvoker();
	}

	/** Clear stale non-forcing pending preview invokers after a resolve dispatch proves none can run. */
	clearPendingInvokers(): void {
		this.#toolChoiceQueue.clearPendingInvokers();
	}

	/**
	 * Force the next model call to target a specific active tool, then terminate
	 * the agent loop. Pushes a two-step sequence [forced, "none"] so the model
	 * calls exactly the forced tool once and then cannot call another.
	 */
	setForcedToolChoice(toolName: string): void {
		if (!this.getActiveToolNames().includes(toolName)) {
			throw new Error(`Tool "${toolName}" is not currently active.`);
		}

		const forced = buildNamedToolChoice(toolName, this.model);
		if (!forced || typeof forced === "string") {
			throw new Error("Current model does not support forcing a specific tool.");
		}

		this.#toolChoiceQueue.pushSequence([forced, "none"], {
			label: "user-force",
			onRejected: info => (info.reason === "unavailable" ? "drop_sequence" : "requeue"),
		});
	}

	/** The tool-choice queue: forces forthcoming tool invocations and carries handlers. */
	get toolChoiceQueue(): ToolChoiceQueue {
		return this.#toolChoiceQueue;
	}

	/** Peek the in-flight directive's invocation handler for the preview-resolution dispatch. */
	peekQueueInvoker(): ((input: unknown) => Promise<unknown> | unknown) | undefined {
		return this.#toolChoiceQueue.peekInFlightInvoker();
	}

	/** Plan-proposal handler consulted by `xd://propose` while plan mode is active. */
	#planProposalHandler: PlanProposalHandler | undefined;

	peekPlanProposalHandler(): PlanProposalHandler | undefined {
		return this.#planProposalHandler;
	}

	setPlanProposalHandler(handler: PlanProposalHandler | null): void {
		this.#planProposalHandler = handler ?? undefined;
	}

	#sessionBeforeSwitchReconciler: (() => Promise<void>) | undefined;

	setSessionBeforeSwitchReconciler(reconciler: (() => Promise<void>) | null): void {
		this.#sessionBeforeSwitchReconciler = reconciler ?? undefined;
	}

	#sessionSwitchReconciler: (() => Promise<void>) | undefined;

	setSessionSwitchReconciler(reconciler: (() => Promise<void>) | null): void {
		this.#sessionSwitchReconciler = reconciler ?? undefined;
	}

	/**
	 * Re-anchor mode state to the session a branch just minted. Branching mints a
	 * new session id/file (see {@link SessionManager.createBranchedSession}), so
	 * without this the interactive-mode reconciler keeps the pre-branch vibe owner
	 * scope and disabling vibe mode trips the stale-scope guard in
	 * `VibeRuntime.#persistModeExit` (issue #10468). Mirrors the reconcile step
	 * `switchSession` runs for the same reason. Best-effort: a reconcile failure
	 * must not roll back an otherwise-successful branch.
	 */
	async #reconcileModeAfterBranch(): Promise<void> {
		try {
			await this.#sessionSwitchReconciler?.();
		} catch (error) {
			logger.warn("Failed to reconcile session mode after branch", {
				sessionFile: this.sessionFile,
				error: String(error),
			});
		}
	}

	/** Provider-scoped mutable state store for transport/session caches. */
	get providerSessionState(): Map<string, ProviderSessionState> {
		return this.#providerSessionState;
	}

	/** Hint forwarded to provider calls that support websocket transport; read live from `providers.openaiWebsockets`. */
	get preferWebsockets(): boolean | undefined {
		return resolveOpenAIWebsocketPreference(this.settings);
	}

	getHindsightSessionState(): HindsightSessionState | undefined {
		return this.#hindsightSessionState;
	}

	setHindsightSessionState(state: HindsightSessionState | undefined): HindsightSessionState | undefined {
		const previous = this.#hindsightSessionState;
		this.#hindsightSessionState = state;
		return previous;
	}

	getMnemopiSessionState(): MnemopiSessionState | undefined {
		return getMnemopiSessionState(this);
	}

	/** TTSR manager for time-traveling stream rules */
	get ttsrManager(): TtsrManager | undefined {
		return this.#ttsr.manager;
	}

	/** Secret obfuscator, when secrets are configured; /share redaction reuses it. */
	get obfuscator(): SecretObfuscator | undefined {
		return this.#obfuscator;
	}

	/** Install the obfuscator built after a live `secrets.enabled` switch-on. */
	setObfuscator(obfuscator: SecretObfuscator | undefined): void {
		this.#obfuscator = obfuscator;
	}

	/** Whether a TTSR abort is pending (stream was aborted to inject rules) */
	get isTtsrAbortPending(): boolean {
		return this.#ttsr.abortPending;
	}

	/** Whether an expected internal plan-mode abort is pending. Consumed by
	 *  `#handleAgentEvent` to stamp `SILENT_ABORT_MARKER` on the next aborted
	 *  assistant message_end; callers clear it in `finally`. */
	get isPlanInternalAbortPending(): boolean {
		return this.#planInternalAbortPending;
	}

	/** Arm the silent-abort marker for the next aborted assistant message_end.
	 *  Caller MUST clear via `clearPlanInternalAbortPending()` in a `finally`
	 *  to guarantee no leak. */
	markPlanInternalAbortPending(): void {
		this.#planInternalAbortPending = true;
	}

	/** Unconditionally clear the silent-abort flag. Idempotent: safe when the
	 *  flag was never set OR was already consumed by `#handleAgentEvent`. */
	clearPlanInternalAbortPending(): void {
		this.#planInternalAbortPending = false;
	}

	getAsyncJobSnapshot(options?: { recentLimit?: number }): AsyncJobSnapshot | null {
		const manager = this.#asyncJobManager;
		if (!manager) return null;
		const ownerFilter = this.#agentId ? { ownerId: this.#agentId } : undefined;
		const running = manager.getRunningJobs(ownerFilter).map(job => ({
			id: job.id,
			type: job.type,
			status: job.status,
			label: job.label,
			startTime: job.startTime,
			agentId: job.agentId,
		}));
		const recent = manager.getRecentJobs(options?.recentLimit ?? 5, ownerFilter).map(job => ({
			id: job.id,
			type: job.type,
			status: job.status,
			label: job.label,
			startTime: job.startTime,
			endTime: job.endTime,
			agentId: job.agentId,
		}));
		const delivery = manager.getDeliveryState(ownerFilter);
		return { running, recent, delivery };
	}

	/**
	 * Cancel async jobs registered by *this* agent only. Used by lifecycle
	 * transitions (newSession, switchSession, handoff, dispose) so a subagent
	 * cleans up its own background work without touching its parent's jobs.
	 *
	 * Cleanup runs against this session's scoped manager: running jobs are
	 * cancelled, finished rows are evicted with their pending deliveries, and any
	 * async-result follow-up already queued for injection is dropped. Subagents have
	 * unique agent ids and inherit the parent's manager to clean up their own
	 * jobs. A secondary in-process top-level session gets no scoped manager,
	 * because it defaults to `MAIN_AGENT_ID`; reaching through the global
	 * singleton would tear down the owning primary session's bash/task jobs at
	 * dispose time (issue #1923).
	 *
	 * No-op when no manager is reachable or this session has no agent id.
	 */
	#cancelOwnAsyncJobs(reason?: unknown): void {
		if (!this.#agentId) return;
		releaseCompletionHandles(this.#agentId);
		releaseJudgmentBatches(this.#agentId);
		WorkPoolRegistry.global().releaseOwner(this.#agentId);
		const manager = this.#asyncJobManager;
		manager?.cancelAll({ ownerId: this.#agentId }, reason);
		manager?.evictCompletedJobs({ ownerId: this.#agentId });
		// Invalidate this owner's in-flight/drained deliveries against the new
		// generation, then drop any async-result follow-up already queued, so a
		// prior session's background result cannot inject into the next transcript.
		this.#asyncDeliveryEpoch += 1;
		this.yieldQueue.clear("async-result");
	}

	/**
	 * True when a background async job owned by this agent is still running with
	 * an unsuppressed delivery, a finished job's delivery is still queued or in
	 * flight, or a delivered result is still sitting on the yield queue awaiting
	 * injection. In every case the async-result follow-up will re-wake the loop,
	 * so a settle observed now is a scheduling pause rather than a terminal stop:
	 * stop-time passes (todo reminder, session_stop hooks) defer to the settle
	 * reached once the session is fully idle. Suppressed deliveries
	 * (acknowledged, or watched by an in-flight `wait`) never wake the loop,
	 * so they don't count.
	 */
	#hasPendingAsyncWake(): boolean {
		const manager = this.#asyncJobManager;
		if (!manager) return false;
		const ownerFilter = this.#agentId ? { ownerId: this.#agentId } : undefined;
		return (
			manager.getRunningJobs(ownerFilter).some(job => !manager.isDeliverySuppressed(job.id)) ||
			manager.hasPendingDeliveries(ownerFilter) ||
			// Delivered but not yet injected: the sink has enqueued the
			// async-result follow-up on the yield queue, and the manager no
			// longer reports it. Without this leg a terminal yield in the
			// (idle-flush delay / step-boundary) handoff window would read as
			// quiescent and the run driver would drop the queued result.
			this.yieldQueue.has(ASYNC_RESULT_MESSAGE_TYPE)
		);
	}

	/**
	 * Public view of the pending-async-wake state for run drivers: true while
	 * owner-scoped async work can still re-wake this session's run (a running
	 * background job with an unsuppressed delivery, or a queued / in-flight
	 * delivery). The task executor's quiescence barrier polls this to
	 * distinguish a scheduling pause from terminal completion.
	 */
	hasPendingAsyncWork(): boolean {
		return this.#hasPendingAsyncWake();
	}

	/** True while a submission has been admitted but has not yet started a turn, queued, or bailed. */
	get hasAdmittedSubmission(): boolean {
		return this.#admittedSubmissionCount > 0;
	}

	/** Resolves once every currently admitted submission has dispatched, queued, or bailed. */
	waitForAdmittedSubmissions(): Promise<void> {
		if (this.#admittedSubmissionCount === 0) return Promise.resolve();
		this.#admittedSubmissionsSettled ??= Promise.withResolvers<void>();
		return this.#admittedSubmissionsSettled.promise;
	}

	async #admitSubmission<T>(work: () => Promise<T>): Promise<T> {
		this.#admittedSubmissionCount++;
		try {
			return await work();
		} finally {
			if (--this.#admittedSubmissionCount === 0 && this.#admittedSubmissionsSettled) {
				const settled = this.#admittedSubmissionsSettled;
				this.#admittedSubmissionsSettled = undefined;
				settled.resolve();
			}
		}
	}

	/**
	 * Settle one generation of owner-scoped async work: wait for running owner
	 * jobs to finish, deliver their queued results (which enqueue async-result
	 * follow-ups on this session's yield queue), and wait for the injected
	 * follow-up turn(s) to go idle. Callers loop while
	 * {@link hasPendingAsyncWork} still holds — a follow-up turn may start new
	 * jobs.
	 */
	async settleAsyncWork(): Promise<void> {
		const manager = this.#asyncJobManager;
		if (!manager || !this.#agentId) return;
		await manager.waitForOwnerJobs(this.#agentId, { excludeSuppressed: true });
		await manager.drainDeliveries({ filter: { ownerId: this.#agentId } });
		await this.waitForIdle();
	}

	/**
	 * Delivery sink for async jobs owned by this agent: format the result
	 * (spilling oversized output to an artifact), enqueue it as an async-result
	 * follow-up, and settle only after the yield queue injects or discards it.
	 * This keeps the job body recoverable through `proc://` while injection is pending.
	 */
	async #deliverAsyncJobResult(manager: AsyncJobManager, jobId: string, text: string, job?: AsyncJob): Promise<void> {
		if (this.#isDisposed) return;
		if (manager.isDeliverySuppressed(jobId)) return;
		// Snapshot the generation before the async format step: a `/new` during it
		// bumps the epoch, so this delivery belongs to the replaced session and
		// must not enqueue — the suppression marker alone is unreliable because
		// job-id reuse clears it.
		const epoch = this.#asyncDeliveryEpoch;
		const formatted = await this.#formatAsyncResultForFollowUp(text, job?.latestDetails?.meta);
		if (this.#isDisposed) return;
		if (epoch !== this.#asyncDeliveryEpoch) return;
		if (manager.isDeliverySuppressed(jobId)) return;
		const durationMs = job ? Math.max(0, (job.endTime ?? Date.now()) - job.startTime) : undefined;
		await this.yieldQueue.enqueueWithReceipt<AsyncResultEntry>("async-result", {
			jobId,
			result: formatted,
			job,
			durationMs,
			epoch,
		});
	}

	/**
	 * Judge for TTSR `question` rules per `ttsr.judge`, used by live judging and
	 * `/omfg` validation. `auto` requires the judge role to resolve to a native
	 * System One model, since every completed output may cost a request. Rebuilt
	 * per call so model, credential, and session switches apply.
	 */
	ruleJudge(): Judge | undefined {
		const mode = cfgTtsrJudge.get(this.settings);
		if (mode === "off" || (mode === "auto" && !hasNativeJudge(this.settings, this.#modelRegistry))) return undefined;
		return resolveJudge({
			settings: this.settings,
			registry: this.#modelRegistry,
			sessionModel: this.model,
			sessionId: this.sessionId,
			metadataResolver: provider => this.agent.metadataForProvider(provider),
			purpose: "ttsr",
			onUsage: journalJudgmentUsage(this.sessionManager),
			telemetry: this.agent.telemetry,
			cache: sharedJudgmentCache(),
		});
	}

	/**
	 * Non-interrupting delivery: mid-run the warning joins the next step; an idle
	 * session starts a turn so the agent can act on it. Persisting the message
	 * records the rules as injected (see #persistMessageEnd).
	 */
	async #deliverRuleWarning(content: string, ruleNames: string[]): Promise<void> {
		if (this.#isDisposed) return;
		await this.sendCustomMessage(
			{ customType: "ttsr-injection", content, display: false, details: { rules: ruleNames }, attribution: "agent" },
			{ deliverAs: "aside" },
		);
	}

	async #formatAsyncResultForFollowUp(result: string, meta?: OutputMeta): Promise<string> {
		if (result.length <= ASYNC_INLINE_RESULT_MAX_CHARS) {
			return result;
		}
		// Strip the already-rendered source notice before taking the smaller preview,
		// then retain its capture warning once even when the original footer is elided.
		const body = meta?.artifactError ? stripOutputNotice(result, meta).trimEnd() : result;
		const preview = `${body.slice(0, ASYNC_PREVIEW_MAX_CHARS)}\n\n[Output truncated. Showing first ${ASYNC_PREVIEW_MAX_CHARS.toLocaleString()} characters.]`;
		if (meta?.artifactError) return `${preview}\n[${formatArtifactErrorNotice(meta.artifactError)}]`;
		// The producing tool's output sink already mirrored the raw stream to an
		// artifact; `result` is its elided inline body, so link the raw capture.
		// The capture lacks notices the tool appended after the stream (exit code,
		// wall time, timeout), so the preview keeps `result`'s tail as well.
		const rawArtifactId = meta?.truncation?.artifactId ?? meta?.limits?.columnTruncated?.artifactId;
		if (rawArtifactId) {
			const headTail = truncateMiddle(result, {
				maxBytes: ASYNC_PREVIEW_MAX_CHARS,
				maxHeadBytes: ASYNC_PREVIEW_MAX_CHARS - ASYNC_PREVIEW_TAIL_CHARS,
			}).content;
			return `${headTail}\nFull output: artifact://${rawArtifactId}`;
		}
		try {
			const { path: artifactPath, id: artifactId } = await this.sessionManager.allocateArtifactPath("async");
			if (artifactPath && artifactId) {
				await writeArtifact(artifactPath, result);
				return `${preview}\nFull output: artifact://${artifactId}`;
			}
		} catch (error) {
			logger.warn("Failed to persist async follow-up artifact", {
				error: error instanceof Error ? error.message : String(error),
			});
		}
		return preview;
	}

	// =========================================================================
	// Event Subscription
	// =========================================================================

	/** Emit an event to all listeners */
	#emit(event: AgentSessionEvent): void {
		// Copy array before iteration to avoid mutation during iteration.
		const listeners = [...this.#eventListeners];
		for (const l of listeners) {
			try {
				const result = l(event) as unknown;
				// Listener may be an async function whose returned Promise we don't await;
				// attach a catch so a rejection does not become an unhandled rejection.
				if (isPromise(result)) {
					result.catch(err => {
						logger.warn("AgentSession listener rejected", {
							error: err instanceof Error ? err.message : String(err),
						});
					});
				}
			} catch (err) {
				logger.warn("AgentSession listener threw", {
					error: err instanceof Error ? err.message : String(err),
				});
			}
		}
	}

	#emitRunState(state: "running" | "idle"): void {
		for (const listener of this.#runStateListeners) {
			try {
				listener(state);
			} catch (error) {
				logger.warn("AgentSession run-state listener threw", {
					error: error instanceof Error ? error.message : String(error),
				});
			}
		}
	}

	/**
	 * Emit a UI-only notice to the session. Surfaces in interactive mode as a
	 * `showWarning` / `showError` / `showStatus` line; non-interactive modes
	 * receive the event through the normal subscribe stream.
	 *
	 * Notices are NOT added to agent state and never reach the LLM — use this
	 * for out-of-band conditions the user should see but the model shouldn't
	 * react to (e.g. background queue flush failures).
	 */
	emitNotice(level: "info" | "warning" | "error", message: string, source?: string): void {
		this.#emit({ type: "notice", level, message, source });
	}

	#recordToolExecutionStart(event: Extract<AgentEvent, { type: "tool_execution_start" }>): void {
		const data: ToolExecutionStartData = {
			toolCallId: event.toolCallId,
			toolName: event.toolName,
			startedAt: new Date().toISOString(),
		};
		// The assistant message already persists the full arguments; store only
		// the command/path projection the resume warning renders.
		const args = summarizeToolArguments(event.args);
		if (args) data.args = args;
		if (event.intent) data.intent = event.intent;
		const entryId = this.sessionManager.appendCustomEntry(TOOL_EXECUTION_START_CUSTOM_TYPE, data);
		if (this.#childTaskRecovery?.read?.toolCallId === event.toolCallId && event.toolName === "read")
			this.#advanceTaskReadLease(entryId);
	}

	#recordSessionExit(reason: postmortem.Reason | "dispose"): void {
		if (this.#exitRecorded) return;
		this.#exitRecorded = true;
		const pendingToolCalls = collectPendingToolCalls(this.sessionManager.getBranch());
		if (
			pendingToolCalls.length === 0 &&
			!this.sessionManager.getEntries().some(entry => entry.type === "message" && entry.message.role === "assistant")
		) {
			return;
		}
		const kind: SessionExitData["kind"] =
			reason === "dispose" || reason === postmortem.Reason.MANUAL
				? "normal"
				: reason === postmortem.Reason.UNCAUGHT_EXCEPTION || reason === postmortem.Reason.UNHANDLED_REJECTION
					? "fatal"
					: reason === postmortem.Reason.EXIT
						? "process_exit"
						: "signal";
		const data: SessionExitData = {
			reason,
			kind,
			recordedAt: new Date().toISOString(),
		};
		if (pendingToolCalls.length > 0) data.pendingToolCalls = pendingToolCalls;
		try {
			this.sessionManager.appendCustomEntry(SESSION_EXIT_CUSTOM_TYPE, data);
			this.sessionManager.flushSync();
			// Only pending tool calls or an abnormal teardown are noteworthy; a
			// clean dispose logs at debug so routine exits don't read as problems.
			const exitLog = pendingToolCalls.length > 0 || kind !== "normal" ? logger.warn : logger.debug;
			exitLog("Session exit recorded", {
				sessionId: this.sessionManager.getSessionId(),
				sessionFile: this.sessionManager.getSessionFile(),
				reason,
				kind,
				pendingToolCalls: pendingToolCalls.length,
			});
		} catch (error) {
			logger.error("Failed to record session exit", {
				sessionId: this.sessionManager.getSessionId(),
				sessionFile: this.sessionManager.getSessionFile(),
				reason,
				error: error instanceof Error ? error.message : String(error),
			});
		}
	}

	#queuedExtensionEvents: Promise<void> = Promise.resolve();

	#queueExtensionEvent(event: AgentSessionEvent): Promise<void> {
		const scope = this.#childTaskRecovery;
		const emit = async () => {
			await this.#emitExtensionEvent(event);
		};
		const queued = this.#queuedExtensionEvents.then(emit, emit);
		this.#queuedExtensionEvents = queued.catch(error => {
			if (scope) this.#noteTaskReadFailure(scope, error);
		});
		return queued;
	}

	async #emitSessionEvent(event: AgentSessionEvent, options: { detachExtensions?: boolean } = {}): Promise<void> {
		if (event.type === "tool_execution_update") {
			// Returned background calls have no later tool result to persist their
			// terminal frame. Keep the latest update for future focus rebuilds;
			// logical session transitions clear the cache.
			this.#activeToolExecutionUpdates.set(event.toolCallId, event);
		} else if (event.type === "tool_execution_end") {
			this.#activeToolExecutionUpdates.delete(event.toolCallId);
		}
		if (event.type === "message_update") {
			this.#emit(event);
			// Per-delta hot path: only allocate and chain the serialized extension emit
			// when something listens (`#emitExtensionEvent` would return immediately).
			if (this.#extensionRunner?.hasHandlers("message_update")) void this.#queueExtensionEvent(event);
			return;
		}
		// Deliver synchronously before awaiting extension notifications. This keeps
		// starts/results in emission order without letting a stalled observer block
		// unrelated events, mid-turn maintenance, or queued steering.
		// RPC/ACP consumers may submit again on agent_end, so defer that frame
		// until the owning prompt unwinds and the session actually becomes idle.
		if (event.type === "agent_end" && this.#promptInFlightCount > 0) {
			this.#pendingAgentEndEmit = event;
		} else {
			this.#emit(event);
		}
		const extensionEmit = this.#emitExtensionEvent(event);
		if (options.detachExtensions) {
			void extensionEmit.catch(error => {
				logger.warn("Detached session event extension emit failed", {
					type: event.type,
					error: error instanceof Error ? error.message : String(error),
				});
			});
		} else {
			await extensionEmit;
		}
	}

	// Track last assistant message for auto-compaction check
	#lastAssistantMessage: AssistantMessage | undefined = undefined;
	/**
	 * Terminal failure whose turn was pruned from history at settle: a classifier
	 * refusal (#3591) or an abandoned length-stop recovery. Retained until the next
	 * run starts so post-settle readers ({@link getLastAssistantMessage}: print
	 * mode, task executor) still see the terminal error instead of a silently
	 * successful-looking state.
	 */
	#prunedTerminalFailure: AssistantMessage | undefined = undefined;

	/**
	 * In-flight {@link #dispatchAgentEvent} promises. agent-core invokes the
	 * event subscriber fire-and-forget, so a `message_end`/`agent_end` handler
	 * can still be awaiting extension/subscriber/maintenance work — and thus its
	 * `sessionManager`/`agent.state` append — after `agent.waitForIdle()`
	 * resolves. Dispose drains this set so the late append lands *before* the
	 * memory release, never after it.
	 */
	#inFlightEventHandlers = new Set<Promise<void>>();

	/**
	 * Subscriber entry point. Delegates to {@link #dispatchAgentEvent} and
	 * records the dispatch in {@link #inFlightEventHandlers} until it settles so
	 * {@link #drainInFlightEventHandlers} can await the session's async
	 * event/persistence pipeline during teardown.
	 */
	#handleAgentEvent = (event: AgentEvent): Promise<void> => {
		this.#ttsr.onEventEntry(event);
		const reading = this.#childTaskRecovery;
		const read = reading?.read;
		const originalReadTurn =
			read &&
			event.type === "turn_end" &&
			event.message.role === "assistant" &&
			assistantSnapshotOrigin(read.assistant) !== undefined &&
			assistantSnapshotOrigin(event.message) === assistantSnapshotOrigin(read.assistant) &&
			event.toolResults.some(result => result.toolCallId === read.toolCallId);
		const needsReadClaim =
			reading &&
			read?.ready &&
			!originalReadTurn &&
			(!read.claim || read.responsePending || read.responseGateActive) &&
			(event.type === "message_start" ||
				event.type === "message_update" ||
				event.type === "message_end" ||
				event.type === "turn_end" ||
				event.type === "agent_end");
		let processing: Promise<void>;
		if (needsReadClaim) {
			read.responseGateActive = true;
			const slot = event.type === "message_end" ? this.#createMessageEndPersistenceSlot(event.message) : undefined;
			processing = (read.responseEvents ?? Promise.resolve())
				.then(async () => {
					await this.#allowTaskReadResponse(reading, read);
					await this.#dispatchAgentEvent(event, slot);
				})
				.finally(() => {
					slot?.release();
					if (event.type === "agent_end") read.responseGateActive = false;
				});
			read.responseEvents = processing.catch(() => {});
		} else processing = this.#dispatchAgentEvent(event);
		this.#ttsr.observeProcessing(event, processing);
		this.#inFlightEventHandlers.add(processing);
		const childScope = this.#childTaskRecovery;
		if (childScope) {
			void processing.catch(error => this.#noteTaskReadFailure(childScope, error));
			const read = childScope.read;
			if (
				read &&
				event.type === "turn_end" &&
				event.message.role === "assistant" &&
				assistantSnapshotOrigin(event.message) === assistantSnapshotOrigin(read.assistant) &&
				event.toolResults.some(result => result.toolCallId === read.toolCallId)
			) {
				read.turnEndSeen = true;
				void processing.finally(read.resolveTurnEnd).catch(() => {});
			}
		}
		void processing.finally(() => this.#inFlightEventHandlers.delete(processing)).catch(() => {});
		return processing;
	};

	/**
	 * Await only message persistence already in flight at call time.
	 *
	 * Focus attach uses this after subscribing to the target so a tool result
	 * emitted during the focus blackout is present in the transcript rebuild.
	 * This intentionally excludes agent_end maintenance, which may perform
	 * provider-backed compaction and must not block switching sessions.
	 */
	async settleInFlightMessagePersistence(): Promise<void> {
		await Promise.allSettled(this.#pendingMessageEndPersistence.values());
	}

	/**
	 * Await every in-flight event handler (and any it chains into) so a late
	 * message/entry append cannot land after the caller clears session memory.
	 * The caller must stop new event production: either the agent is idle, or
	 * its exact main request is paused before transport dispatch.
	 */
	async #drainInFlightEventHandlers(signal?: AbortSignal): Promise<void> {
		while (this.#inFlightEventHandlers.size > 0) {
			const pending = Promise.allSettled(this.#inFlightEventHandlers);
			if (signal) await untilAborted(signal, pending);
			else await pending;
		}
	}

	/** Internal handler for agent events - shared by subscribe and reconnect.
	 *
	 * `agent_end` handling schedules deferred post-prompt recovery work
	 * (compaction/handoff, context-promotion continuations). It is invoked
	 * fire-and-forget by the agent's synchronous `#emit`, and only reaches
	 * `#checkCompaction` after several internal awaits. `prompt()` runs
	 * `#waitForPostPromptRecovery()` the instant `agent.prompt()` resolves — which
	 * can land BEFORE the handler registers its tasks, so the wait would observe an
	 * empty task set and return early, letting a deferred handoff/promotion race
	 * prompt completion. Tracking the `agent_end` handler as a post-prompt task
	 * that is registered SYNCHRONOUSLY (before the first await) closes that window:
	 * `#postPromptTasksPromise` is set the moment `#emit` invokes this handler, so
	 * the recovery wait always sees the in-flight handler and blocks until it — and
	 * everything it schedules — settles. */
	#dispatchAgentEvent = async (event: AgentEvent, readSlot?: MessageEndPersistenceSlot): Promise<void> => {
		if (event.type === "tool_execution_end" && this.#isTerminalYieldToolResult(event)) {
			const alreadyTerminated = this.#synchronouslyTerminatedYieldToolCallIds.delete(event.toolCallId);
			if (!alreadyTerminated) {
				this.#advisors.prepareForTerminalYieldAdvisorDrain();
				this.#markTerminalYieldToolCall(event.toolCallId);
				this.agent.abort(TERMINAL_TOOL_RESULT_ABORT_REASON);
			}
		}
		if (event.type !== "agent_end") {
			const processing = this.#processAgentEvent(event, readSlot);
			if ((event.type === "message_start" || event.type === "message_end") && isAdvisorCard(event.message)) {
				this.#advisors.trackCardEvent(processing);
			}
			return processing;
		}
		const { promise, resolve } = Promise.withResolvers<void>();
		this.#trackPostPromptTask(promise);
		try {
			await this.#processAgentEvent(event, readSlot);
		} catch (error) {
			// Post-turn maintenance (compaction, pruning rewrites, hooks) threw before
			// publishing the settle. Without it the run never reports idle and every
			// surface keeps showing a working turn that will never finish.
			const message = toError(error).message;
			logger.error("agent_end maintenance failed", { error: message });
			this.emitNotice("warning", `Post-turn maintenance failed: ${message}`, "agent-end");
			if (this.#settledAgentEnd !== event) await this.#settleAgentEnd(event, [...this.agent.state.messages]);
		} finally {
			resolve();
		}
	};

	#recordPreparedMessage(message: AgentMessage, entryId: string): void {
		this.#persistedEntryByMessage.set(message, entryId);
		const batch = this.#promptPreparationByMessage.get(message);
		if (this.#ownsTaskReadMessage(message)) this.#advanceTaskReadLease(entryId);
		if (!batch || batch.complete || batch.sessionId !== this.sessionId || batch.generation !== this.#promptGeneration)
			return;
		const initialChild = this.#childTaskRecovery;
		if (initialChild?.parent.original && batch === initialChild.initialBatch) {
			const entry = this.sessionManager.getEntry(entryId);
			if (!entry || entry.parentId !== initialChild.initialLeaf || this.sessionManager.getLeafId() !== entryId)
				this.#revokeTaskRecovery("Original child input append lost its initial journal lease");
			initialChild.initialLeaf = entryId;
		}
		if (batch.anchor === message) batch.anchorEntryId = entryId;
		if (batch.members.has(message)) batch.members.set(message, entryId);
		if (!batch.anchorEntryId || [...batch.members.values()].some(id => id === undefined)) return;
		const record: PromptPreparationRecordV1 = {
			version: 1,
			sessionId: batch.sessionId,
			anchorEntryId: batch.anchorEntryId,
			batchId: batch.id,
			preparationEntryIds: [...batch.members.values()].filter((id): id is string => id !== undefined),
			...(batch.taskBindingId ? { taskBindingId: batch.taskBindingId } : {}),
		};
		const preparedEntryId = this.sessionManager.appendCustomEntry(PROMPT_PREPARATION, record);
		if (this.#ownsTaskReadMessage(message)) this.#advanceTaskReadLease(preparedEntryId);
		if (initialChild?.parent.original && batch === initialChild.initialBatch) {
			const preparedEntry = this.sessionManager.getEntry(preparedEntryId);
			if (
				!preparedEntry ||
				preparedEntry.parentId !== initialChild.initialLeaf ||
				this.sessionManager.getLeafId() !== preparedEntryId
			)
				this.#revokeTaskRecovery("Original child preparation append lost its exact input leaf");
			initialChild.initialLeaf = preparedEntryId;
		}
		batch.complete = true;
		const child = this.#childTaskRecovery;
		if (
			child?.parent.original &&
			batch === child.initialBatch &&
			batch.taskBindingId === child.parent.binding.call.bindingId
		) {
			if (child.anchorEntryId && child.anchorEntryId !== batch.anchorEntryId)
				this.#revokeTaskRecovery("Original task prompt anchor was replaced");
			child.anchorEntryId = batch.anchorEntryId;
			child.resolvePreparation?.();
		}
	}

	#associatePromptPreparation(
		message: AgentMessage,
		members: AgentMessage[],
		generation: number,
		anchorEntryId?: string,
		taskBindingId?: string,
		preparedMessages?: readonly AgentMessage[],
	): void {
		if (!("attribution" in message) || message.attribution !== "agent") {
			this.#activePromptPreparation = undefined;
			return;
		}
		const batch: PromptPreparationBatch = {
			id: crypto.randomUUID(),
			sessionId: this.sessionId,
			generation,
			anchor: anchorEntryId ? undefined : message,
			anchorEntryId,
			taskBindingId,
			members: new Map(members.map(member => [member, undefined])),
			complete: anchorEntryId !== undefined && members.length === 0,
		};
		if (!anchorEntryId) this.#promptPreparationByMessage.set(message, batch);
		for (const member of members) this.#promptPreparationByMessage.set(member, batch);
		this.#activePromptPreparation = batch;
		const child = this.#childTaskRecovery;
		if (child?.parent.original && child.initialDispatch === "armed") {
			if (child.initialBatch || !preparedMessages || message.role !== "user")
				this.#revokeTaskRecovery("Original child initial preparation was replaced");
			child.initialBatch = batch;
			child.initialMessages = [...preparedMessages];
			child.initialMessagesHash = taskRecoveryHash(preparedMessages);
		}
	}

	/** Capture only the actual approved task call and this run's core prompt origin. */
	async captureTaskCall(
		toolCallId: string,
		params: unknown,
		signal?: AbortSignal,
	): Promise<TaskCallCapture | undefined> {
		const origin = this.#activePromptPreparation;
		if (
			!this.sessionManager.getSessionFile() ||
			!origin ||
			origin.sessionId !== this.sessionId ||
			origin.generation !== this.#promptGeneration
		) {
			const expected = this.#boundTaskCalls.get(toolCallId)?.authority;
			if (expected) {
				const failed = this.#activateOriginalTaskAttempt(expected);
				const error = new Error("Approved original task lost its session or execution prompt origin");
				this.#failOriginalTaskAttempt(failed, error);
				throw error;
			}
			return undefined;
		}
		const sessionId = this.sessionId;
		const generation = this.#promptGeneration;
		const assistant = this.messages.findLast(
			message =>
				message.role === "assistant" &&
				message.content.some(part => part.type === "toolCall" && part.id === toolCallId),
		);
		if (assistant?.role !== "assistant") {
			const expected = this.#boundTaskCalls.get(toolCallId)?.authority;
			const error = new Error("Original task assistant is unavailable");
			if (expected) this.#failOriginalTaskAttempt(this.#activateOriginalTaskAttempt(expected), error);
			throw error;
		}
		const lineage = assistantSnapshotOrigin(assistant);
		const authority = lineage ? this.#taskCallAuthorities.get(lineage)?.get(toolCallId) : undefined;
		const expectedAuthority = this.#boundTaskCalls.get(toolCallId)?.authority;
		if (expectedAuthority && expectedAuthority !== authority) {
			const failed = this.#activateOriginalTaskAttempt(expectedAuthority);
			const error = new Error("Approved task assistant has no matching core snapshot provenance");
			this.#failOriginalTaskAttempt(failed, error);
			throw error;
		}
		if (lineage) this.#taskCallAuthorities.get(lineage)?.delete(toolCallId);
		const callParts = assistant.content.filter(part => part.type === "toolCall");
		if (callParts.length > 1) {
			if (authority) {
				const error = new Error("Approved single task changed to an ambiguous tool batch");
				this.#failOriginalTaskAttempt(this.#activateOriginalTaskAttempt(authority), error);
				throw error;
			}
			return undefined;
		}
		const attempt = authority ? this.#activateOriginalTaskAttempt(authority) : undefined;
		if (attempt) attempt.projectedAssistant = assistant;
		try {
			if (
				authority &&
				(authority.origin !== origin ||
					authority.generation !== generation ||
					authority.sessionId !== sessionId ||
					authority.signal?.aborted ||
					signal?.aborted)
			)
				throw new Error("Approved task result authority lost its exact original invocation");
			await this.#waitForSessionMessagePersistence(assistant);
			if (origin.anchor) await this.#waitForSessionMessagePersistence(origin.anchor);
			await this.sessionManager.flush();
			if (!this.sessionManager.isSessionOnDisk())
				throw new Error("Original task input/assistant did not become durable");
			const branch = this.sessionManager.getBranch();
			const assistantEntryId = (assistant as PersistedAssistantMessage)[kPersistedSessionEntryId];
			const entry = branch.find(candidate => candidate.id === assistantEntryId);
			const calls =
				entry?.type === "message" && entry.message.role === "assistant"
					? entry.message.content.filter(part => part.type === "toolCall")
					: [];
			if (calls.length > 1) return undefined;
			const args = calls[0]?.arguments;
			const effectiveArgs = this.#obfuscator && args ? deobfuscateToolArguments(this.#obfuscator, args) : args;
			if (
				sessionId !== this.sessionId ||
				generation !== this.#promptGeneration ||
				!origin.complete ||
				!origin.anchorEntryId ||
				!assistantEntryId ||
				calls.length !== 1 ||
				calls[0].id !== toolCallId ||
				calls[0].name !== "task" ||
				taskRecoveryHash(effectiveTaskArguments(effectiveArgs)) !== taskRecoveryHash(effectiveTaskArguments(params))
			)
				throw new Error("Original task call or prompt could not be durably bound");
			preparedEntryIds(branch, sessionId, origin.anchorEntryId, origin.taskBindingId);
			const call = {
				bindingId: crypto.randomUUID(),
				sessionId,
				promptEntryId: origin.anchorEntryId,
				assistantEntryId,
				toolCallId,
				argumentsSha256: taskRecoveryHash(effectiveTaskArguments(params)),
			};
			const completion = attempt
				? this.#createOriginalTaskCompletion(attempt, call, signal ?? authority?.signal)
				: undefined;
			if (attempt) await attempt.scope!.validateAuthority();
			return {
				call,
				completion,
				bindChild: async binding => {
					if (
						this.#isDisposed ||
						this.#abortInProgress ||
						generation !== this.#promptGeneration ||
						sessionId !== this.sessionId ||
						taskRecoveryHash(binding.call) !== taskRecoveryHash(call)
					)
						throw new Error("Task binding lost parent ownership before child dispatch");
					const active = this.sessionManager.getBranch();
					if (
						!active.some(candidate => candidate.id === assistantEntryId) ||
						active.some(candidate => readTaskBinding(candidate)?.call.toolCallId === toolCallId)
					)
						throw new Error("Task binding conflicts with the active original call");
					const originalChild = attempt?.scope?.child;
					if (originalChild) {
						const childScope = originalChild.#childTaskRecovery;
						if (
							!childScope ||
							childScope.initialLeaf ||
							originalChild.sessionManager.getLeafId() !== binding.child.initEntryId
						)
							throw new Error("Original child initialization lost its exact pre-dispatch leaf");
						childScope.initialLeaf = binding.child.initEntryId;
					}
					attempt?.scope?.assertOwnership();
					const bindingEntryId = this.sessionManager.appendCustomEntry(TASK_RUN_BINDING, binding);
					attempt?.scope?.advanceExpectedLeaf(bindingEntryId);
					const bound = this.#boundTaskCalls.get(toolCallId) ?? {};
					bound.binding = binding;
					this.#boundTaskCalls.set(toolCallId, bound);
					await this.sessionManager.flush();
					attempt?.scope?.assertOwnership();
					if (generation !== this.#promptGeneration || sessionId !== this.sessionId || this.#isDisposed)
						throw new Error("Task binding lost parent ownership during persistence");
				},
			};
		} catch (error) {
			if (attempt) this.#failOriginalTaskAttempt(attempt, error);
			throw error;
		}
	}

	#advanceTaskReadLease(entryId: string): void {
		const scope = this.#childTaskRecovery;
		const read = scope?.read;
		if (!scope || !read || read.disqualified || read.ready || read.claim) return;
		if (read.expectedLeaf === entryId) return;
		const entry = this.sessionManager.getEntry(entryId);
		if (!entry || entry.parentId !== read.expectedLeaf || this.sessionManager.getLeafId() !== entryId) {
			if (!scope.readProtocolEntered) {
				// Before native qualification, extension metadata only makes this read ineligible.
				read.disqualified = true;
				return;
			}
			const error = new Error("Native read lost its exact pre-hook journal lease");
			this.#noteTaskReadFailure(scope, error);
			throw error;
		}
		read.expectedLeaf = entryId;
	}

	#ownsTaskReadMessage(message: AgentMessage): boolean {
		const scope = this.#childTaskRecovery;
		const read = scope?.read;
		if (!scope || !read || read.ready || read.claim) return false;
		if (message.role === "assistant")
			return assistantSnapshotOrigin(message) === assistantSnapshotOrigin(read.assistant);
		if (message.role === "toolResult") return message.toolName === "read" && message.toolCallId === read.toolCallId;
		const batch = this.#promptPreparationByMessage.get(message);
		return (
			!!batch &&
			batch.taskBindingId === scope.parent.binding.call.bindingId &&
			(batch === scope.initialBatch || batch.anchorEntryId === scope.anchorEntryId)
		);
	}

	#noteTaskReadFailure(scope: ChildTaskRecoveryScope, error: unknown): void {
		scope.readFailure ??= String(error);
		if (scope.readProtocolEntered && this.#childTaskRecovery === scope)
			this.invalidateTaskRecovery(scope.readFailure);
	}

	observeNativeTaskRead(toolCallId: string, args: unknown, result: AgentToolResult<unknown>): void {
		const scope = this.#childTaskRecovery;
		const read = scope?.read;
		if (
			!scope ||
			!read ||
			read.disqualified ||
			read.toolCallId !== toolCallId ||
			read.native ||
			this.model?.api !== "openai-completions"
		)
			return;
		const native = nativePlainReadProvenance(result);
		if (
			!native ||
			!isRecord(args) ||
			Object.keys(args).length !== 1 ||
			typeof args.path !== "string" ||
			result.isError
		)
			return;
		// Ownership and tracked failures remain authoritative even while the read is tentative.
		try {
			this.#checkTaskRecoveryDriver();
			scope.parent.assertOwnership();
			if (scope.readFailure) throw new Error(scope.readFailure);
		} catch (error) {
			scope.readProtocolEntered = true;
			this.#noteTaskReadFailure(scope, error);
			throw error;
		}
		const entries = this.sessionManager.getEntries();
		const assistant = this.messages.find(
			message =>
				message.role === "assistant" &&
				assistantSnapshotOrigin(message) === assistantSnapshotOrigin(read.assistant),
		);
		const start = entries.find(
			entry =>
				entry.type === "custom" &&
				entry.customType === TOOL_EXECUTION_START_CUSTOM_TYPE &&
				isRecord(entry.data) &&
				entry.data.toolName === "read" &&
				entry.data.toolCallId === toolCallId,
		);
		if (
			this.sessionManager.getLeafId() !== read.expectedLeaf ||
			cfgExternalThinking.get(this.settings) ||
			this.messages.some(message => "content" in message && !isTaskReadTextContent(message.content))
		) {
			read.disqualified = true;
			return;
		}
		try {
			validateTaskReadContinuationPrefix(entries, this.sessionManager.getBranch(), scope.parent.binding, {
				assistantEntryId: assistant ? this.#persistedEntryByMessage.get(assistant) : undefined,
				startEntryId: start?.id,
			});
		} catch {
			read.disqualified = true;
			return;
		}
		scope.readProtocolEntered = true;
		try {
			this.#assertTaskReadOwner(scope, read);
		} catch (error) {
			this.#noteTaskReadFailure(scope, error);
			throw error;
		}
		read.arguments = { path: args.path };
		read.native = Object.freeze({ ...native });
		read.nativeResultSha256 = taskRecoveryHash(result);
	}

	#assertTaskReadOwner(scope: ChildTaskRecoveryScope, read: TaskReadCandidate): void {
		if (this.#childTaskRecovery !== scope || scope.read !== read)
			throw new Error("Original read continuation owner changed");
		if (scope.readFailure) throw new Error(scope.readFailure);
		this.#checkTaskRecoveryDriver();
		scope.parent.assertOwnership();
		if (
			(!read.claim || read.responsePending) &&
			read.expectedLeaf &&
			this.sessionManager.getLeafId() !== read.expectedLeaf
		)
			throw new Error("Read continuation lost its exact journal leaf");
	}

	async #claimTaskRead(
		scope: ChildTaskRecoveryScope,
		read: TaskReadCandidate,
		reason: "response" | "cold-resume",
	): Promise<void> {
		if (read.claiming) return read.claiming;
		read.claiming = (async () => {
			this.#assertTaskReadOwner(scope, read);
			if (!read.ready) throw new Error("Read response has no durable native checkpoint");
			read.claim = await claimTaskReadContinuation(
				this.sessionManager,
				scope.parent.binding,
				read.ready,
				reason,
				scope.parent.validateAuthority,
				() => this.#assertTaskReadOwner(scope, read),
				id => {
					read.expectedLeaf = id;
				},
			);
		})().catch(error => {
			this.#noteTaskReadFailure(scope, error);
			throw error;
		});
		return read.claiming;
	}

	async #allowTaskReadResponse(scope: ChildTaskRecoveryScope, read: TaskReadCandidate): Promise<void> {
		this.#assertTaskReadOwner(scope, read);
		await this.#claimTaskRead(scope, read, "response");
		await scope.parent.validateAuthority();
		this.#assertTaskReadOwner(scope, read);
		read.responsePending = false;
	}

	createTaskReadRequest(model: Model, context: Context, signal?: AbortSignal): TaskReadRequestFence | undefined {
		const scope = this.#childTaskRecovery;
		const read = scope?.read;
		if (
			!scope ||
			!read?.native ||
			!read.arguments ||
			!read.nativeResultSha256 ||
			(read.claim && !read.responsePending)
		)
			return undefined;
		if (
			model.api !== "openai-completions" ||
			cfgExternalThinking.get(this.settings) ||
			context.messages.some(message => !isTaskReadTextContent(message.content))
		) {
			if (read.claim) {
				const error = new Error("Claimed read continuation requires text-only supported provider context");
				this.#noteTaskReadFailure(scope, error);
				throw error;
			}
			return undefined;
		}
		if (read.request) {
			const error = new Error("Another main request already owns read continuation");
			this.#noteTaskReadFailure(scope, error);
			throw error;
		}
		const request = {};
		read.request = request;
		read.responsePending = true;
		scope.readProtocolEntered = true;
		let payloadEntered = false;
		const check = () => {
			if (signal?.aborted) signal.throwIfAborted();
			if (read.request !== request || this.model !== model)
				throw new Error("Read continuation main request/model changed");
			this.#assertTaskReadOwner(scope, read);
		};
		const failed = (error: unknown) => this.#noteTaskReadFailure(scope, error);
		const response = async () => {
			try {
				check();
				await this.#allowTaskReadResponse(scope, read);
				check();
			} catch (error) {
				failed(error);
				throw error;
			}
		};
		return {
			check,
			failed,
			response,
			beforePayload: async () => {
				try {
					check();
					if (payloadEntered && read.ready) await response();
					payloadEntered = true;
					check();
				} catch (error) {
					failed(error);
					throw error;
				}
			},
			preparedPayload: async payload => {
				try {
					check();
					payload = JSON.parse(JSON.stringify(payload)) as unknown;
					if (
						!isRecord(payload) ||
						!Array.isArray(payload.messages) ||
						!Array.isArray(payload.tools) ||
						payload.messages.some(
							message =>
								!isRecord(message) ||
								(message.content !== null &&
									message.content !== undefined &&
									typeof message.content !== "string" &&
									(!Array.isArray(message.content) ||
										message.content.some(
											part => !isRecord(part) || part.type !== "text" || typeof part.text !== "string",
										))),
						)
					)
						throw new Error("Read continuation requires a text-only main OpenAI completion payload");
					await untilAborted(signal ?? scope.parent.signal, read.turnEnd);
					const queuedTail = this.#queuedExtensionEvents;
					await untilAborted(signal ?? scope.parent.signal, queuedTail);
					await this.#drainInFlightEventHandlers(signal ?? scope.parent.signal);
					await untilAborted(signal ?? scope.parent.signal, this.#messageEndPersistenceTail);
					await this.sessionManager.flush();
					check();
					if (
						!read.turnEndSeen ||
						queuedTail !== this.#queuedExtensionEvents ||
						this.#inFlightEventHandlers.size ||
						this.#pendingMessageEndPersistence.size ||
						this.#postPromptTasks.size ||
						this.agent.hasQueuedMessages()
					)
						throw new Error("Read continuation has unsettled prior-step work");

					let assistantId = read.ready?.record.read.assistantEntryId;
					if (!assistantId) {
						const assistant = this.messages.filter(
							message =>
								message.role === "assistant" &&
								assistantSnapshotOrigin(message) === assistantSnapshotOrigin(read.assistant),
						);
						if (assistant.length !== 1) throw new Error("Native read assistant has ambiguous core provenance");
						assistantId = this.#persistedEntryByMessage.get(assistant[0]);
						if (!assistantId) throw new Error("Native read assistant is not durable");
					} else this.#messageForPersistedEntry(assistantId);
					const record =
						read.ready?.record ??
						buildTaskReadContinuationRecord(
							this.sessionManager.getEntries(),
							this.sessionManager.getBranch(),
							scope.parent.binding,
							{
								assistantEntryId: assistantId,
								toolCallId: read.toolCallId,
								arguments: read.arguments!,
								native: read.native!,
								nativeResultSha256: read.nativeResultSha256!,
							},
						);
					const wireCalls = payload.messages.flatMap(message =>
						isRecord(message) && Array.isArray(message.tool_calls) ? message.tool_calls : [],
					);
					const wireResults = payload.messages.filter(message => isRecord(message) && message.role === "tool");
					const result = this.sessionManager.getEntry(record.read.resultEntryId);
					if (
						payload.messages.some(
							message =>
								isRecord(message) &&
								message.role !== "assistant" &&
								Array.isArray(message.tool_calls) &&
								message.tool_calls.length > 0,
						) ||
						payload.messages.findIndex(
							message =>
								isRecord(message) &&
								message.role === "assistant" &&
								Array.isArray(message.tool_calls) &&
								message.tool_calls.some(call => isRecord(call) && call.id === read.toolCallId),
						) >=
							payload.messages.findIndex(
								message =>
									isRecord(message) && message.role === "tool" && message.tool_call_id === read.toolCallId,
							) ||
						wireCalls.length !== 1 ||
						!isRecord(wireCalls[0]) ||
						wireCalls[0].id !== read.toolCallId ||
						!isRecord(wireCalls[0].function) ||
						wireCalls[0].function.name !== "read" ||
						typeof wireCalls[0].function.arguments !== "string" ||
						taskRecoveryHash(JSON.parse(wireCalls[0].function.arguments)) !== taskRecoveryHash(read.arguments) ||
						wireResults.length !== 1 ||
						!isRecord(wireResults[0]) ||
						wireResults[0].tool_call_id !== read.toolCallId ||
						result?.type !== "message" ||
						result.message.role !== "toolResult" ||
						wireResults[0].content !==
							result.message.content
								.filter(part => part.type === "text")
								.map(part => part.text)
								.join("\n")
								.toWellFormed()
					)
						throw new Error("Read continuation main payload lost original call/result pairing");
					if (read.ready) {
						await scope.parent.validateAuthority();
						check();
						return payload;
					}
					if (read.expectedLeaf !== record.prefix.leafId)
						throw new Error("Read prefix changed during prior-step settlement");
					await scope.parent.validateAuthority();
					check();
					if (
						taskRecoveryHash(this.sessionManager.getEntries()) !== record.prefix.entriesSha256 ||
						taskRecoveryHash(this.sessionManager.getBranch()) !== record.prefix.branchSha256
					)
						throw new Error("Read prefix changed before checkpoint persistence");
					const snapshot = JSON.parse(JSON.stringify(record)) as typeof record;
					const entryId = this.sessionManager.appendCustomEntry(TASK_READ_CONTINUATION_READY, snapshot);
					const entry = this.sessionManager.getEntry(entryId);
					if (!entry || entry.parentId !== read.expectedLeaf || this.sessionManager.getLeafId() !== entryId)
						throw new Error("Read checkpoint lost its exact prior leaf");
					read.expectedLeaf = entryId;
					read.ready = { entryId, sha256: taskRecoveryHash(snapshot), record: snapshot };
					await this.sessionManager.flush();
					await scope.parent.validateAuthority();
					check();
					return payload;
				} catch (error) {
					failed(error);
					throw error;
				}
			},
		};
	}

	getTaskResultProcessingGate(toolCallId: string): TaskResultProcessingGate | undefined {
		return this.#boundTaskCalls.get(toolCallId)?.original?.gate;
	}

	#failOriginalTaskAttempt(attempt: OriginalTaskResultAttempt, error: unknown): void {
		if (attempt.delivered) return;
		attempt.failure ??= error;
		attempt.rejectDurable(error);
		if (attempt.scope && this.#activeTaskRecovery === attempt.scope) this.invalidateTaskRecovery(String(error));
		else if (!this.#activeTaskRecovery && this.#boundTaskCalls.get(attempt.capture.toolCallId)?.original === attempt)
			this.agent.abort();
	}

	#activateOriginalTaskAttempt(capture: TaskCallAuthorityCapture): OriginalTaskResultAttempt {
		if (this.#activeTaskRecovery || this.#boundTaskCalls.get(capture.toolCallId)?.original)
			throw new Error("Another task invocation owns result certification");
		const deferred = Promise.withResolvers<void>();
		void deferred.promise.catch(() => {});
		const attempt: OriginalTaskResultAttempt = {
			capture,
			bootstrapLeaf: this.sessionManager.getLeafId(),
			bootstrapFile: this.sessionFile,
			bootstrapCwd: this.sessionManager.getCwd(),
			events: Promise.resolve(),
			durable: deferred.promise,
			resolveDurable: deferred.resolve,
			rejectDurable: deferred.reject,
			gate: {
				enter: async () => {
					try {
						if (attempt.failure) throw attempt.failure;
						const scope = attempt.scope;
						if (!scope || !attempt.ready) throw new Error("Original task native readiness was not certified");
						if (!attempt.processing)
							attempt.processing = (async () => {
								await this.#claimTaskResultProcessing(scope, attempt.ready!);
							})();
						await attempt.processing;
						await scope.validateAuthority();
						scope.assertOwnership();
					} catch (error) {
						this.#failOriginalTaskAttempt(attempt, error);
						throw error;
					}
				},
			},
		};
		this.#boundTaskCalls.set(capture.toolCallId, { original: attempt });
		// Allocate before any native await: the loop may reach its next model gate
		// before the asynchronous message-end consumer has registered a result slot.

		return attempt;
	}

	#assertOriginalTaskBootstrap(attempt: OriginalTaskResultAttempt): void {
		if (attempt.failure) throw attempt.failure;
		if (
			attempt.bootstrapLeaf !== this.sessionManager.getLeafId() ||
			attempt.bootstrapFile !== this.sessionFile ||
			attempt.bootstrapCwd !== this.sessionManager.getCwd() ||
			attempt.capture.sessionId !== this.sessionId ||
			attempt.capture.generation !== this.#promptGeneration ||
			attempt.capture.origin !== this.#activePromptPreparation ||
			attempt.capture.signal?.aborted ||
			this.#isDisposed ||
			this.#abortInProgress
		)
			throw new Error("Original task lost its pre-await parent persistence lease");
	}

	#createOriginalTaskCompletion(
		attempt: OriginalTaskResultAttempt,
		call: PersistedTaskCallRef,
		signal: AbortSignal | undefined,
	): OriginalTaskCompletionCapture {
		if (!signal) throw new Error("Approved original task has no execution signal");
		this.#assertOriginalTaskBootstrap(attempt);
		let expectedLeaf = attempt.bootstrapLeaf;
		const parentFile = attempt.bootstrapFile;
		const parentCwd = attempt.bootstrapCwd;
		const token = {};
		const scope: ParentTaskRecoveryScope = {
			original: attempt,
			phase: "child",
			loadedPolicyHash: this.#dispatchPolicyHash(),
			signal,
			generation: attempt.capture.generation,
			get binding() {
				const binding = owner.#boundTaskCalls.get(call.toolCallId)?.binding;
				if (!binding) throw new Error("Original child binding has not been promoted");
				return binding;
			},
			advanceExpectedLeaf: id => {
				const entry = this.sessionManager.getEntry(id);
				if (!entry || entry.parentId !== expectedLeaf || this.sessionManager.getLeafId() !== id)
					this.#revokeTaskRecovery("Original task append lost its exact parent leaf");
				expectedLeaf = id;
			},
			assertOwnership: () => {
				if (attempt.failure) throw attempt.failure;
				if (this.#activeTaskRecovery !== scope)
					throw new Error("Original task completion owner is no longer active");
				if (
					this.#activeTaskRecovery !== scope ||
					scope.revoked ||
					signal.aborted ||
					this.#isDisposed ||
					this.#abortInProgress ||
					this.isCompacting ||
					this.isGeneratingHandoff ||
					this.#promptGeneration !== scope.generation ||
					this.sessionId !== call.sessionId ||
					this.sessionFile !== parentFile ||
					this.sessionManager.getCwd() !== parentCwd ||
					this.#dispatchPolicyHash() !== scope.loadedPolicyHash ||
					this.sessionManager.getLeafId() !== expectedLeaf ||
					this.#activePromptPreparation !== attempt.capture.origin ||
					!attempt.projectedAssistant ||
					!this.messages.includes(attempt.projectedAssistant) ||
					this.agent.hasQueuedMessages() ||
					this.#pendingNextTurnMessages.length ||
					this.#irc.hasPending()
				)
					this.#revokeTaskRecovery("Original task lost its approved parent invocation or leaf");
				const branch = this.sessionManager.getBranch();
				if (
					!branch.some(entry => entry.id === call.assistantEntryId) ||
					!branch.some(entry => entry.id === call.promptEntryId)
				)
					this.#revokeTaskRecovery("Original task prompt or assistant left the active branch");
				if (
					scope.child &&
					(AgentRegistry.global().get(scope.ref!.id) !== scope.ref ||
						scope.ref!.status === "aborted" ||
						(scope.ref!.session !== null && scope.ref!.session !== scope.child))
				)
					this.#revokeTaskRecovery("Original child execution ownership changed");
				const childBootstrap = scope.child ? scope.child.#childTaskRecovery : undefined;
				if (
					childBootstrap?.initialLeaf &&
					!childBootstrap.anchorEntryId &&
					scope.child!.sessionManager.getLeafId() !== childBootstrap.initialLeaf
				)
					this.#revokeTaskRecovery("Original child initial journal changed before durable preparation");
				if (this.#boundTaskCalls.get(call.toolCallId)?.binding) {
					this.#assertSynchronousTaskPolicy?.(scope.binding);
					this.#assertTaskCompletionOwnership(scope);
				}
			},
			validateAuthority: async () => {
				scope.assertOwnership();
				if (this.#boundTaskCalls.get(call.toolCallId)?.binding)
					await this.#validateSynchronousTaskPolicy?.(scope.binding);
				if (scope.validateCompletion) scope.assertCompletionFiles = await scope.validateCompletion();
				const checked = await attempt.capture.validate({
					sessionId: call.sessionId,
					promptEntryId: call.promptEntryId,
					assistantEntryId: call.assistantEntryId,
					toolCallId: call.toolCallId,
				});
				if (!checked.ok) throw new Error(checked.reason);
				scope.assertOwnership();
			},
		};
		const owner = this;
		attempt.scope = scope;
		this.#activeTaskRecovery = scope;
		return {
			prepareChild: child => {
				if (attempt.delivered) return;
				const ref = AgentRegistry.global().get(child.getAgentId()!);
				if (!ref) throw new Error("Original child has no reserved registry identity");
				this.#installOriginalTaskChild(scope, ref, child, token);
			},
			runNative: async run => {
				try {
					return await this.#taskRecoveryOwner.run(token, run);
				} catch (error) {
					this.#failOriginalTaskAttempt(attempt, error);
					throw error;
				} finally {
					if (scope.child && scope.child.#childTaskRecovery) scope.child.#childTaskRecovery.driverActive = false;
				}
			},
			activateDriver: () => {
				scope.assertOwnership();
				const child = scope.child;
				if (!child || !child.#childTaskRecovery || !scope.ref || scope.ref.session !== child)
					throw new Error("Original child was not exclusively attached");
				const binding = scope.binding;
				const init = child.sessionManager.getEntry(binding.child.initEntryId);
				if (
					init?.type !== "session_init" ||
					taskRecoveryHash(init.taskCall) !== taskRecoveryHash(call) ||
					binding.child.sessionId !== child.sessionId ||
					binding.child.sessionFile !== child.sessionFile ||
					binding.child.cwd !== child.sessionManager.getCwd() ||
					taskRecoveryHash(initializationContract(init)) !== taskRecoveryHash(binding.contract.initialization) ||
					taskRecoveryHash(taskRuntimeContract(child)) !== taskRecoveryHash(binding.contract.runtime)
				)
					throw new Error("Original child cannot promote its real initialization binding");
				child.#childTaskRecovery.initialDispatch = "armed";
				child.#childTaskRecovery.driverActive = true;
				child.#childTaskRecovery.tools = child.agent.state.tools.map(tool => ({ tool, execute: tool.execute }));
				return child.#boundTaskDriverControls(child.#childTaskRecovery);
			},
			settleChild: async () => {
				if (!scope.child) throw new Error("Original child is unavailable");
				await scope.child.flushBoundTaskCompletion(scope.binding);
			},
			recordNativeResult: async record => {
				try {
					attempt.ready = await this.#recordNativeTaskResult(scope, record);
					return attempt.ready;
				} catch (error) {
					this.#failOriginalTaskAttempt(attempt, error);
					throw error;
				}
			},
			setCompletionGuard: guard => {
				scope.validateCompletion = guard;
			},
		};
	}

	#installOriginalTaskChild(parent: ParentTaskRecoveryScope, ref: AgentRef, child: AgentSession, token: object): void {
		parent.assertOwnership();
		if (parent.child || child.#childTaskRecovery || ref.session || ref.status === "aborted")
			throw new Error("Original task child is already owned");
		const prepared = Promise.withResolvers<void>();
		const scope: ChildTaskRecoveryScope = {
			preparationReady: prepared.promise,
			resolvePreparation: prepared.resolve,
			parent,
			context: this.#taskRecoveryOwner,
			token,
			driverActive: false,
			loadedPolicyHash: child.#dispatchPolicyHash(),
			generation: child.#promptGeneration,
		};
		child.#childTaskRecovery = scope;
		const stopReadErrors = child.#extensionRunner?.onError(error => child.#noteTaskReadFailure(scope, error.error));
		parent.child = child;
		parent.ref = ref;
		child.#extensionRunner?.setToolDispatchGuard(signal => child.#prepareBoundTaskDispatch(signal));
		const stopModel = child.agent.addBeforeModelCall(async (context, signal) => {
			const check = await child.#prepareBoundTaskDispatch(signal, context);
			check?.();
		});
		const stopQueue = child.agent.addBeforeQueuedMessageDequeueHook(() => {
			if (child.agent.hasQueuedMessages()) child.#revokeTaskRecovery("Foreign input superseded original task");
		});
		parent.releaseChild = () => {
			stopReadErrors?.();
			scope.driverActive = false;
			stopModel();
			stopQueue();
			if (child.#childTaskRecovery === scope) child.#childTaskRecovery = undefined;
		};
	}

	/**
	 * Reserve this message's place in the emission-ordered commit chain. Bound task
	 * results and gated read responses reserve it at event entry, before any
	 * authority or read-response await (OMP-246), so later commits cannot overtake them.
	 */
	#createMessageEndPersistenceSlot(message: AgentMessage): MessageEndPersistenceSlot {
		const key = sessionMessagePersistenceKey(message);
		const previous = this.#messageEndPersistenceTail;
		const { promise, resolve } = Promise.withResolvers<void>();
		const clear = () => {
			if (key !== undefined && this.#pendingMessageEndPersistence.get(key) === promise) {
				this.#pendingMessageEndPersistence.delete(key);
			}
		};
		if (key !== undefined) this.#pendingMessageEndPersistence.set(key, promise);
		this.#messageEndPersistenceTail = promise;
		return {
			promise,
			persist: async persistMessage => {
				await previous;
				try {
					await persistMessage();
				} finally {
					resolve();
					clear();
				}
			},
			release: () => {
				resolve();
				clear();
			},
		};
	}

	/** Commit messages in emission order without waiting for notification listeners. */
	#queueMessageEndPersistence(
		message: AgentMessage,
		promptGeneration: number,
		slot?: MessageEndPersistenceSlot,
	): Promise<void> {
		return (slot ?? this.#createMessageEndPersistenceSlot(message)).persist(() =>
			this.#persistMessageEndWithRecoveryGuard(message, promptGeneration),
		);
	}

	async #waitForSessionMessagePersistence(message: AgentMessage): Promise<void> {
		const key = sessionMessagePersistenceKey(message);
		if (!key) return;
		await this.#pendingMessageEndPersistence.get(key);
	}

	/**
	 * Index every message entry on the current branch by persistence key, so
	 * the mid-run-compaction planner can ask "is this turn message already on
	 * the branch?" in O(1). The set is memoized through the current leaf path
	 * and validated at use time against a (session file, leaf id) anchor.
	 *
	 * The mid-run ordering check uses key identity alone: same-key content
	 * variants are one logical message at this boundary, because otherwise a
	 * display-side rewrite can make the assistant look missing after its tool
	 * results have already persisted.
	 *
	 * Coherency is anchor-based, not invalidation-based: every branch mutation
	 * (rewind, branch switch, new session, custom-entry append) changes the
	 * session manager's leaf id or session file, so `#ensurePersistedMessageKeys`
	 * detects staleness itself and rebuilds. No mutation call site has to
	 * remember to invalidate anything.
	 *
	 * Pre-#3629 the equivalent was `sessionManager.getBranch()` called twice
	 * per turn message, each call rebuilding the path via O(n²) `unshift` and
	 * structurally JSON-comparing every entry — seconds of synchronous work
	 * per `onTurnEnd` on a long session and the load-bearing source of the
	 * `ui.loop-blocked` warnings in the bug report.
	 */
	#indexPersistedMessageKeys(): Set<string> {
		return this.#ensurePersistedMessageKeys();
	}

	#persistedMessageKeysAnchor(): string {
		return `${this.sessionManager.getSessionFile() ?? ""}\u0000${this.sessionManager.getLeafId() ?? ""}`;
	}

	#ensurePersistedMessageKeys(): Set<string> {
		const anchor = this.#persistedMessageKeysAnchor();
		let cache = this.#persistedMessageKeys;
		if (cache === undefined || cache.anchor !== anchor) {
			cache = { anchor, keys: this.#buildPersistedMessageKeySet() };
			this.#persistedMessageKeys = cache;
		}
		return cache.keys;
	}

	#buildPersistedMessageKeySet(): Set<string> {
		const keys = new Set<string>();
		for (const entry of this.sessionManager.getBranch()) {
			if (entry.type !== "message") continue;
			const key = sessionMessagePersistenceKey(entry.message);
			if (key !== undefined) keys.add(key);
		}
		return keys;
	}

	/**
	 * True when {@link message} is structurally identical to a message already
	 * appended to the current branch. Uses the current branch's memoized
	 * persistence-key cache for the common missing-key case, and only walks the
	 * branch to verify content when a key hit could be a rare collision.
	 *
	 * Error turns need one extra discriminator. An empty error turn carries no
	 * content at all, so every failed attempt of one retry saga serializes to the
	 * same `[]` — and when two attempts land in the same wall-clock millisecond
	 * (mocked/zero retry delay, or a fast provider failure) they also share a
	 * persistence key of `assistant:<ts>:<provider>:<model>::error`. Content
	 * equality alone then reports the aggregated terminal turn ("Retry budget
	 * exhausted after N retries: …") as a duplicate of the attempt error it
	 * supersedes, and the session journal silently loses the record of why the
	 * run stopped. The failure text is the only thing that distinguishes them.
	 */
	#sessionMessageAlreadyPersisted(message: AgentMessage): boolean {
		const key = sessionMessagePersistenceKey(message);
		if (key === undefined) return false;
		const keys = this.#ensurePersistedMessageKeys();
		if (!keys.has(key)) return false;
		const branch = this.sessionManager.getBranch();
		for (let index = branch.length - 1; index >= 0; index--) {
			const entry = branch[index];
			if (entry.type !== "message") continue;
			if (sessionMessagePersistenceKey(entry.message) !== key) continue;
			if (!sameMessageContent(entry.message, message)) continue;
			if (
				entry.message.role === "assistant" &&
				message.role === "assistant" &&
				entry.message.errorMessage !== message.errorMessage
			) {
				continue;
			}
			return true;
		}
		return false;
	}

	#appendSessionMessage(
		message:
			| Message
			| CustomMessage
			| HookMessage
			| BashExecutionMessage
			| PythonExecutionMessage
			| FileMentionMessage,
	): string {
		const commitScope = this.#taskResultCommitScopes.get(message);
		if (commitScope) {
			if (!this.#approvedTaskResultCommits.delete(message))
				throw new Error("Recovered task result has no current persistence authorization");
			commitScope.assertOwnership();
		}
		const cache = this.#persistedMessageKeys;
		const wasFresh = cache !== undefined && cache.anchor === this.#persistedMessageKeysAnchor();
		const binding =
			message.role === "toolResult" && message.toolName === "task"
				? this.#boundTaskCalls.get(message.toolCallId)?.binding
				: undefined;
		const taskResult =
			this.#taskResultByMessage.get(message) ??
			(binding &&
			binding.call.sessionId === this.sessionId &&
			this.sessionManager.getBranch().some(entry => entry.id === binding.call.assistantEntryId)
				? {
						bindingId: binding.call.bindingId,
						contractSha256: binding.contractSha256,
						toolCallId: binding.call.toolCallId,
						childSessionId: binding.child.sessionId,
					}
				: undefined);
		const pendingOriginal =
			message.role === "assistant"
				? [...this.#boundTaskCalls.values()].find(
						bound =>
							bound.original &&
							!bound.original.scope &&
							assistantSnapshotOrigin(bound.original.capture.assistant) === assistantSnapshotOrigin(message),
					)?.original
				: undefined;
		if (pendingOriginal) this.#assertOriginalTaskBootstrap(pendingOriginal);
		const entryId = this.sessionManager.appendMessage(message, taskResult);
		if (message.role === "assistant") this.#ttsr.onAssistantRecorded(message);
		if (this.#ownsTaskReadMessage(message)) this.#advanceTaskReadLease(entryId);
		if (pendingOriginal) {
			const entry = this.sessionManager.getEntry(entryId);
			if (!entry || entry.parentId !== pendingOriginal.bootstrapLeaf || this.sessionManager.getLeafId() !== entryId)
				throw new Error("Original assistant append lost its exact bootstrap leaf");
			pendingOriginal.bootstrapLeaf = entryId;
		}
		commitScope?.advanceExpectedLeaf(entryId);
		if (commitScope?.original) commitScope.resultEntryId = entryId;
		this.#recordPreparedMessage(message, entryId);
		if (message.role === "assistant") {
			(message as PersistedAssistantMessage)[kPersistedSessionEntryId] = entryId;
		}
		const key = sessionMessagePersistenceKey(message);
		if (wasFresh && cache && key) {
			cache.keys.add(key);
			cache.anchor = this.#persistedMessageKeysAnchor();
		}
		return entryId;
	}

	#persistSessionMessageIfMissing(message: AgentMessage): void {
		if (
			message.role !== "user" &&
			message.role !== "developer" &&
			message.role !== "assistant" &&
			message.role !== "toolResult" &&
			message.role !== "fileMention"
		) {
			return;
		}
		if (this.#sessionMessageAlreadyPersisted(message)) return;
		if (message.role === "assistant") {
			const assistantMsg = message as AssistantMessage;
			if (this.#recovery.isClassifierRefusal(assistantMsg)) return;
			if (isEmptyErrorTurn(assistantMsg)) return;
			if (assistantMsg.stopReason !== "aborted" && assistantMsg.stopReason !== "error" && assistantMsg.usage) {
				assistantMsg.contextSnapshot = {
					promptTokens: calculatePromptTokens(assistantMsg.usage),
					nonMessageTokens:
						this.#stats.pendingNonMessageTokens ??
						computeNonMessageTokens(this, this.agent.tokenizer, this.settings.revision),
					compactionEpoch: this.#stats.compactionEpoch,
				};
			}
		}
		const skipPersistedRewindResult =
			message.role === "toolResult" &&
			semanticToolResult(message.toolName, message)?.toolName === "rewind" &&
			this.#rewoundToolResultIds.delete(message.toolCallId);
		if (!skipPersistedRewindResult) {
			this.#appendSessionMessage(message);
		}
	}

	/**
	 * Builds the transient checkpoint-active reminder for a successful
	 * checkpoint tool result, or undefined otherwise. The reminder is queued as
	 * steering synchronously in the message_end handler (before any await), so
	 * the agent loop folds it into the next provider call and persists it through
	 * its normal custom-message event. Because the entry sits after the checkpoint
	 * entry, the rewind branch cut drops it from the active path.
	 */
	#checkpointActiveReminderFor(
		message: AgentMessage,
	): CustomMessage<{ goal?: string; startedAt?: string }> | undefined {
		if (message.role !== "toolResult" || message.isError) return undefined;
		const semanticResult = semanticToolResult(message.toolName, message);
		if (semanticResult?.toolName !== "checkpoint") return undefined;
		const details = isRecord(semanticResult.details) ? semanticResult.details : undefined;
		const goal = details ? stringProperty(details, "goal") : undefined;
		const startedAt = details ? stringProperty(details, "startedAt") : undefined;
		return {
			role: "custom",
			customType: CHECKPOINT_ACTIVE_REMINDER_TYPE,
			content: prompt.render(checkpointActiveNoticeTemplate),
			display: false,
			details: { goal, startedAt },
			attribution: "agent",
			timestamp: Date.now(),
		};
	}

	#discardUncommittedTaskResult(message: AgentMessage): void {
		// Preserve every concurrent owner message and every queue. This exact
		// candidate was inserted by emitExternalEvent before its durable append.
		if (this.messages.includes(message))
			this.agent.replaceMessages(this.messages.filter(candidate => candidate !== message));
		this.#taskResultByMessage.delete(message);
		this.#taskResultCommitScopes.delete(message);
		this.#approvedTaskResultCommits.delete(message);
	}

	#persistMessageEndWithRecoveryGuard(message: AgentMessage, promptGeneration: number): void | Promise<void> {
		const scope = this.#taskResultCommitScopes.get(message);
		if (!scope) return this.#persistMessageEnd(message, promptGeneration);
		return (async () => {
			try {
				await scope.validateAuthority();
				scope.assertOwnership();
				this.#taskResultByMessage.set(message, this.#taskResultRef(scope.binding));
				this.#approvedTaskResultCommits.add(message);
				this.#persistMessageEnd(message, promptGeneration);
				if (scope.original) {
					await this.sessionManager.flush();
					const appended = scope.resultEntryId ? this.sessionManager.getEntry(scope.resultEntryId) : undefined;
					if (
						this.sessionFile === scope.original.bootstrapFile &&
						this.sessionId === scope.binding.call.sessionId &&
						this.#promptGeneration === scope.generation &&
						appended?.type === "message" &&
						sameMessageContent(appended.message, message) &&
						taskRecoveryHash(appended.taskResult) === taskRecoveryHash(this.#taskResultByMessage.get(message))
					)
						scope.original.committedResult = message;
					scope.assertOwnership();
					scope.original.delivered = true;
					scope.original.resolveDurable();
					scope.releaseChild?.();
					if (this.#activeTaskRecovery === scope) this.#activeTaskRecovery = undefined;
					const bound = this.#boundTaskCalls.get(scope.binding.call.toolCallId);
					if (bound?.original === scope.original) bound.original = undefined;
				}
				this.#taskResultCommitScopes.delete(message);
			} catch (error) {
				if (scope.original) this.#failOriginalTaskAttempt(scope.original, error);
				else this.invalidateTaskRecovery(String(error));
				if (scope.original?.committedResult !== message) this.#discardUncommittedTaskResult(message);
				else this.#taskResultCommitScopes.delete(message);
				throw error;
			} finally {
				this.#approvedTaskResultCommits.delete(message);
			}
		})();
	}

	#persistMessageEnd(message: AgentMessage, promptGeneration: number): void {
		// Session transitions may replace the transcript before a queued commit
		// runs. Never append the previous conversation to the replacement session.
		if (this.#promptGeneration !== promptGeneration) {
			// The message has already left the agent queue. If it was a deferred TTSR
			// delivery, queue cleanup cannot clear its reservation.
			if (message.role === "custom" && message.customType === "ttsr-injection") {
				this.#ttsr.releaseDeferredReservationFromDetails(message.details);
			}
			return;
		}
		if (message.role === "hookMessage" || message.role === "custom") {
			// One-run instructions must not return from persisted history: prewalk
			// nudges are consumed once, and Vibe context is rebuilt only while active.
			if (!isPrewalkPlanNudge(message) && message.customType !== VIBE_MODE_CONTEXT_MESSAGE_TYPE) {
				const entryId = this.sessionManager.appendCustomMessageEntry(
					message.customType,
					message.content,
					message.display,
					message.details,
					message.attribution ?? "agent",
					// Preserve the initiating message's own timestamp: the entry
					// otherwise records emission time, which on rebuild excludes
					// provider preparation / hook time from the prompt→yield anchor.
					message.timestamp,
				);
				this.#recordPreparedMessage(message, entryId);
			}
			if (message.role === "custom" && message.customType === "ttsr-injection") {
				this.#ttsr.markInjectedFromDetails(message.details);
			}
			return;
		}
		this.#persistSessionMessageIfMissing(message);
	}

	/**
	 * On a user-interrupted (`Esc`) abort, copy a meaningful trailing thinking
	 * run into hidden continuity context for the next turn. Short fragments are
	 * omitted; `convertToLlm` still strips their incomplete thinking from replay.
	 *
	 * Skipped for anthropic-dialect targets: the continuity quote replays the
	 * model's own reasoning as conversation text, which Anthropic's
	 * `reasoning_extraction` classifier refuses (verified live against Fable 5 —
	 * the quoted fragment trips it even inside a full agentic request on
	 * OAuth/subscription auth). transform-messages already drops the unsigned
	 * trailing run from replay, so nothing else is lost.
	 *
	 * The original thinking stays on the assistant message so live render, reload,
	 * and display-reset rebuilds keep showing it.
	 */
	#demoteInterruptedThinkingOnUserInterrupt(
		message: AssistantMessage,
	): CustomMessage<InterruptedThinkingDetails> | undefined {
		if (message.stopReason !== "aborted" || !isUserInterruptAbort(message)) return undefined;
		if (preferredDialect(this.agent.state.model?.id ?? message.model) === "anthropic") return undefined;
		const demoted = demoteInterruptedThinking(message);
		if (!demoted || demoted.reasoning.length < INTERRUPTED_THINKING_MIN_CHARS) return undefined;
		const interruptedAt = Date.now();
		return {
			role: "custom",
			customType: INTERRUPTED_THINKING_MESSAGE_TYPE,
			content: prompt.render(interruptedThinkingTemplate, { reasoning: demoted.reasoning }),
			display: false,
			details: {
				interruptedAt,
				provider: message.provider,
				model: message.model,
				blockCount: demoted.blockCount,
			},
			attribution: "agent",
			timestamp: interruptedAt,
		};
	}

	async #persistTurnMessagesForMidRunCompaction(context: AgentTurnEndContext | undefined): Promise<boolean> {
		if (!context) return true;
		const turnMessages = [context.message, ...context.toolResults, ...(context.additionalMessages ?? [])];
		for (const message of turnMessages) {
			await this.#waitForSessionMessagePersistence(message);
		}
		// One branch snapshot + one persistence-key index drives the entire
		// planning pass. Pre-#3629 this re-walked the branch and structurally
		// JSON-compared every entry per turn message, which on long sessions
		// turned each `onTurnEnd` into a seconds-long sync block (the
		// `ui.loop-blocked` warnings tagged `subagent:*` in the bug report).
		const branchKeys = this.#indexPersistedMessageKeys();
		const turnKeys = turnMessages.map(sessionMessagePersistenceKey);
		const persistedKeys = new Set<string>();
		for (let index = 0; index < turnMessages.length; index++) {
			const key = turnKeys[index];
			if (key === undefined) continue;
			// Mid-run ordering is keyed by logical identity. A persisted display
			// variant (for example, redacted/deobfuscated content) must still count;
			// otherwise the assistant can look missing while later tool results are
			// present, producing a false out-of-order skip.
			if (branchKeys.has(key)) {
				persistedKeys.add(key);
			}
		}
		const plan = planTurnPersistence(turnKeys, persistedKeys);
		if (plan.kind === "out-of-order") {
			const message = turnMessages[plan.messageIndex];
			logger.debug("Skipping mid-run compaction because turn persistence is out of order", {
				role: message.role,
				timestamp: message.timestamp,
			});
			return false;
		}
		for (const index of plan.toPersist) {
			this.#persistSessionMessageIfMissing(turnMessages[index]);
		}
		return true;
	}

	/** Re-seed the rate meter from the last completed assistant turn after a conversation swap (resume, branch switch). */
	#reseedTokenRate(): void {
		const messages = this.agent.state.messages;
		for (let i = messages.length - 1; i >= 0; i--) {
			const message = messages[i];
			if (message?.role !== "assistant") continue;
			const assistant = message as AssistantMessage;
			if (assistant.duration === undefined) continue;
			this.tokenRate.seed(assistant.usage.output, assistant.duration);
			return;
		}
		this.tokenRate.reset();
	}

	#processAgentEvent = (event: AgentEvent, readSlot?: MessageEndPersistenceSlot): Promise<void> => {
		const callId =
			event.type === "tool_execution_end" && event.toolName === "task"
				? event.toolCallId
				: (event.type === "message_start" || event.type === "message_end") &&
						event.message.role === "toolResult" &&
						event.message.toolName === "task"
					? event.message.toolCallId
					: undefined;
		const attempt = callId ? this.#boundTaskCalls.get(callId)?.original : undefined;
		if (!attempt) return this.#processAgentEventNow(event, undefined, readSlot);
		// Register the persistence slot and this invocation's event order before any
		// authority await, so turn-end persistence and later result events cannot overtake it.
		const slot = event.type === "message_end" ? this.#createMessageEndPersistenceSlot(event.message) : undefined;
		const processed = attempt.events.then(() => this.#processAgentEventNow(event, attempt, slot));
		attempt.events = processed.catch(() => {});
		return processed.catch(error => {
			slot?.release();
			if (
				!attempt.delivered &&
				(event.type === "message_start" || event.type === "message_end") &&
				attempt.committedResult !== event.message
			)
				this.#discardUncommittedTaskResult(event.message);
			this.#failOriginalTaskAttempt(attempt, error);
			throw error;
		});
	};

	#processAgentEventNow = async (
		event: AgentEvent,
		originalAttempt?: OriginalTaskResultAttempt,
		originalSlot?: MessageEndPersistenceSlot,
	): Promise<void> => {
		const eventPromptGeneration = this.#promptGeneration;
		// A fresh run supersedes the previously settled (and pruned) refusal
		// turn: state-based lookups take over again.
		if (event.type === "agent_start") {
			this.#activeAgentPromptGeneration = eventPromptGeneration;
			this.#prunedTerminalFailure = undefined;
			this.#advisors.onPrimaryAgentStart();
			this.#emitRunState("running");
			this.#maintenance.noteTurnStarted();
		}
		// This must happen before event fan-out awaits: streamed tool-call deltas
		// can otherwise queue validation that a delayed turn-start reset erases.
		if (event.type === "turn_start") this.#streamingEditGuard.reset();
		if (event.type === "agent_end") {
			this.#taskCallAuthorities = new WeakMap();
			for (const bound of this.#boundTaskCalls.values()) bound.authority = undefined;
		}
		// Step the mid-run todo counter synchronously, BEFORE any await in this
		// handler. The agent loop's next-turn `getAsideMessages` poll can run
		// before queued microtasks drain, so `#takeMidRunTodoNudge` MUST see the
		// freshest counter — otherwise a turn that just invoked `todo` could
		// trip a spurious nudge against stale state, and a turn that just hit
		// the threshold could fail to nudge until a later turn (issue #3651).
		// Pure in-memory math — no ordering requirement vs persistence or
		// session-event fan-out. Keyed on toolResult (not the assistant toolCall
		// turn) so planned-but-aborted or permission-denied calls never count,
		// and only successful mutating tools tick — read-only exploration is
		// not progress an agent could mark done.
		if (event.type === "message_end" && event.message.role === "toolResult") {
			this.#todo.onToolResult(event.message.toolName, event.message.isError);
		}
		// Track the settled assistant turn synchronously as well: agent_end
		// maintenance reads `#lastAssistantMessage`, and when a turn's events all
		// land in one tick its handler can run before this handler's post-emit
		// bookkeeping — leaving maintenance looking at the previous (e.g.
		// toolUse) assistant message and skipping settle-only work.
		if (event.type === "message_end" && event.message.role === "assistant") {
			this.#lastAssistantMessage = event.message;
			this.#cacheWarmer?.onResponse(event.message);
			if (this.#deferredTitle && isTitleContextReply(event.message)) this.#advanceDeferredTitle("replied");
		}
		// Expected internal transitions stamp a structural suppression flag on the
		// persisted message BEFORE the obfuscator's display-side copy below, so the
		// streaming render and every history-replay path (resume, `/tree`, rebuild)
		// branch identically through `shouldRenderAbortReason`.
		// Invariant (must hold across refactors): this branch precedes the
		// `let displayEvent = event; ... displayEvent = { ...event, message: { ...message, content: deobfuscated } }`
		// block. After stamping, both `displayEvent.message` (via the spread)
		// and `event.message` (in-place mutation, used by SessionManager
		// persistence) carry the flag. The one-shot plan flag is consumed here,
		// scoped strictly to this aborted message_end; callers still clear it in
		// `finally` so a leaked flag cannot silence a later unrelated abort. TTSR
		// keys off the coordinator's live `abortPending` state instead of a
		// one-shot flag: the aborted message_end always fires before the deferred
		// retry clears it.
		if (
			event.type === "message_end" &&
			event.message.role === "assistant" &&
			event.message.stopReason === "aborted"
		) {
			const message = event.message as AssistantMessage;
			if (this.#planInternalAbortPending) {
				message.errorMessage = SILENT_ABORT_MARKER;
				message.errorId = AIError.create(AIError.Flag.SilentAbort);
				this.#planInternalAbortPending = false;
			} else if (this.#pendingAbortErrorId) {
				message.errorId = this.#pendingAbortErrorId;
				this.#pendingAbortErrorId = undefined;
			} else if (this.#ttsr.ownsInterruptedMessage(message)) {
				// A TTSR rule interruption is control flow, not a failure: the turn
				// re-runs and the injection surfaces via `TtsrNotificationComponent`.
				// Suppress the abort line while keeping the rule reason on the
				// message for transcript/debug (the structural flag drives
				// suppression, not the text).
				message.errorId = AIError.create(AIError.Flag.SilentAbort);
			}
		}

		const interruptedThinkingMessage =
			event.type === "message_end" && event.message.role === "assistant"
				? this.#demoteInterruptedThinkingOnUserInterrupt(event.message as AssistantMessage)
				: undefined;
		// `message_end` handling is fire-and-forget from agent-core. Make the
		// hidden continuity turn visible to the next prompt before any awaited
		// extension delivery or persistence can stall this handler.
		if (interruptedThinkingMessage) {
			this.agent.appendMessage(interruptedThinkingMessage);
		}

		// message_end listeners are fire-and-forget, and the agent loop runs against
		// a context cloned at prompt start. Appending only to agent.state would not
		// reach the next provider call in this tool loop. Queue the reminder as
		// steering before any await so the loop drains it at the next step boundary;
		// its normal custom-message event persists it after the checkpoint entry,
		// allowing the rewind branch cut to drop it from the active path.
		const checkpointReminder =
			event.type === "message_end" && event.message.role === "toolResult"
				? this.#checkpointActiveReminderFor(event.message)
				: undefined;
		if (checkpointReminder) {
			// Set #checkpointState synchronously too: the reminder is now visible to
			// the very next provider call, so a model that immediately calls `rewind`
			// must find an active checkpoint in RewindTool.execute(). The entry id is
			// backfilled post-await (see the toolResult handler) once the checkpoint
			// toolResult entry is persisted; #applyRewind runs on a later rewind turn,
			// never before that backfill.
			this.#checkpointState = {
				checkpointMessageCount: this.agent.state.messages.length,
				checkpointEntryId: null,
				startedAt:
					(checkpointReminder.details && stringProperty(checkpointReminder.details, "startedAt")) ??
					new Date().toISOString(),
			};
			this.#pendingRewindReport = undefined;
			this.#lastCompletedRewind = undefined;
			this.agent.steer(checkpointReminder);
		}

		// Local completion time for prompt→yield timing: stamped here, not by the
		// provider, so the usage row's Δ is exact and provider-independent — some
		// providers never report `duration` (gitlab-duo) or stamp `timestamp` at
		// request start. Persisted with the message and read on rebuild.
		if (event.type === "message_end" && event.message.role === "assistant") {
			event.message.completedAt = Date.now();
		}
		// Turn-boundary maintenance awaits this commit before draining steering;
		// extension notifications must not own or delay the persistence work.
		const messageEndPersistence =
			event.type === "message_end" && !originalAttempt
				? this.#queueMessageEndPersistence(event.message, eventPromptGeneration, originalSlot)
				: undefined;
		if (originalAttempt) {
			try {
				await originalAttempt.gate.enter();
				if (event.type === "message_end" && originalAttempt.scope)
					this.#taskResultCommitScopes.set(event.message, originalAttempt.scope);
			} catch (error) {
				originalSlot?.release();
				if (
					!originalAttempt.delivered &&
					(event.type === "message_start" || event.type === "message_end") &&
					originalAttempt.committedResult !== event.message
				)
					this.#discardUncommittedTaskResult(event.message);
				this.#failOriginalTaskAttempt(originalAttempt, error);
				throw error;
			}
		}

		// Deobfuscate assistant message content for display emission — the LLM echoes back
		// obfuscated placeholders, but listeners (TUI, extensions, exporters) must see real
		// values. The original event.message stays obfuscated so the persistence path below
		// writes `$$HASH$$` tokens to the session file; convertToLlm re-obfuscates outbound
		// traffic on the next turn. Walks text, thinking, and toolCall arguments/intent.
		let displayEvent: AgentEvent = event;
		const obfuscator = this.#obfuscator;
		if (obfuscator && event.type === "message_end" && event.message.role === "assistant") {
			const message = event.message;
			const deobfuscatedContent = deobfuscateAssistantContent(obfuscator, message.content);
			if (deobfuscatedContent !== message.content) {
				displayEvent = { ...event, message: { ...message, content: deobfuscatedContent } };
			}
		}

		if (event.type === "turn_start") {
			this.#advisors.onPrimaryTurnStart();
			const usage = this.getSessionStats().tokens;
			this.#goalRuntime.onTurnStart(`turn-${++this.#goalTurnCounter}`, {
				input: usage.input,
				output: usage.output,
				cacheRead: usage.cacheRead,
				cacheWrite: usage.cacheWrite,
			});
		}

		if (event.type === "tool_execution_start") {
			this.#recordToolExecutionStart(event);
		}

		// Both buffer resets run before the awaited fan-out: event handlers run
		// concurrently and message_update skips the await, so a reset placed after
		// it could land behind the new message's first deltas and clear them.
		if (event.type === "turn_start") this.#ttsr.onTurnStart();
		if (event.type === "message_start" && event.message.role === "assistant") this.#ttsr.onAssistantMessageStart();

		// Meter generation per session: each session tracks its own stream, so a
		// background subagent holds a live reading by the time it is focused and
		// the main session's reading survives focus round-trips.
		if (event.type === "message_start" && event.message.role === "assistant") {
			this.tokenRate.begin(event.message.timestamp);
		} else if (event.type === "message_update" && event.message.role === "assistant") {
			const delta = event.assistantMessageEvent;
			if (delta.type === "text_delta" || delta.type === "thinking_delta" || delta.type === "toolcall_delta") {
				this.tokenRate.push(delta.delta);
			}
		} else if (event.type === "message_end" && event.message.role === "assistant") {
			const assistant = event.message as AssistantMessage;
			this.tokenRate.end(
				assistant.usage.output,
				assistant.duration !== undefined ? assistant.timestamp + assistant.duration : undefined,
			);
		}

		if (event.type !== "agent_end") {
			try {
				await this.#emitSessionEvent(displayEvent);
			} catch (error) {
				if (originalAttempt) {
					originalSlot?.release();
					if (
						!originalAttempt.delivered &&
						(event.type === "message_start" || event.type === "message_end") &&
						originalAttempt.committedResult !== event.message
					)
						this.#discardUncommittedTaskResult(event.message);
					this.#failOriginalTaskAttempt(originalAttempt, error);
					throw error;
				}
				if (event.type === "message_end") {
					try {
						await messageEndPersistence;
					} catch (persistenceError) {
						logger.warn("Failed to persist message after session event emission failed", {
							error: String(persistenceError),
						});
					}
				}
				throw error;
			}
		}

		if (event.type === "turn_end") this.#ttsr.onTurnEnd();
		// Finalize the tool-choice queue's in-flight yield after tools have executed.
		// This must happen at turn_end (not message_end) because onInvoked handlers
		// run during tool execution, which happens between message_end and turn_end.
		if (event.type === "turn_end" && this.#toolChoiceQueue.hasInFlight) {
			const msg = event.message as AssistantMessage;
			if (msg.stopReason === "aborted" || msg.stopReason === "error") {
				this.#toolChoiceQueue.reject(msg.stopReason === "error" ? "error" : "aborted");
			} else {
				this.#toolChoiceQueue.resolve();
			}
		}
		// Settle owned headless browser tabs: close tabs idle past the
		// timeout, then freeze the survivors so animated content stops
		// burning CPU/GPU while idle (issue #8246). Detached — tool results
		// for this turn are already paired, and teardown must never block
		// the event flow.
		if (event.type === "turn_end") {
			void this.#settleOwnedBrowserTabs();
		}
		if (event.type === "tool_execution_end") {
			if (event.toolName === "goal") {
				await this.#goalRuntime.onGoalToolCompleted();
			} else {
				await this.#goalRuntime.onToolCompleted(event.toolName);
			}
			this.#planModeReminderAwaitingProgress = false;
			if (
				event.toolName === "ask" ||
				writeDeviceDispatch(event.toolName, event.result)?.tool === PROPOSE_DEVICE_NAME
			) {
				this.#planModeReminderCount = 0;
				this.#planModeReminderAwaitingProgress = false;
			}
		}

		if (event.type === "tool_stream_update") this.#streamingEditGuard.maybeAbort(event);

		if (await this.#ttsr.checkMessageUpdate(event)) return;

		// Handle session persistence
		if (event.type === "message_end") {
			// A bound original task result commits only after its listeners accept it,
			// through the slot reserved at event entry (OMP-246).
			await (messageEndPersistence ??
				this.#queueMessageEndPersistence(event.message, eventPromptGeneration, originalSlot));
			if (this.#promptGeneration !== eventPromptGeneration) return;
			if (interruptedThinkingMessage) {
				this.sessionManager.appendCustomMessageEntry(
					interruptedThinkingMessage.customType,
					interruptedThinkingMessage.content,
					interruptedThinkingMessage.display,
					interruptedThinkingMessage.details,
					interruptedThinkingMessage.attribution,
				);
			}
			// Other message types (bashExecution, compactionSummary, branchSummary) are persisted elsewhere

			if (event.message.role === "assistant") {
				const assistantMsg = event.message as AssistantMessage;
				// Fold this turn's timing into per-model perf aggregates (drives the
				// /models TPS/TTFT display). Errored turns measure nothing; aborted
				// turns with reported usage are still valid throughput samples.
				if (assistantMsg.stopReason !== "error" && assistantMsg.duration !== undefined) {
					this.settings.getStorage()?.recordModelPerf(`${assistantMsg.provider}/${assistantMsg.model}`, {
						outputTokens: assistantMsg.usage.output,
						durationMs: assistantMsg.duration,
						ttftMs: assistantMsg.ttft,
					});
				}
				if (
					assistantMsg.disabledFeatures?.includes("priority") &&
					this.serviceTierByFamily.anthropic === "priority"
				) {
					this.setServiceTierFamily("anthropic", undefined);
					this.emitNotice(
						"warning",
						"Priority/fast mode rejected for this model; retried without it. Fast mode is now off.",
						"priority",
					);
				}
				this.#ttsr.onAssistantMessageEnd(assistantMsg);
				if (this.#handoff.isGeneratingHandoff) {
					this.#maintenance.skipPostTurnMaintenanceAssistantTimestamp = assistantMsg.timestamp;
					this.#skippedPostTurnSpeculationCompletion = this.#maintenance.speculationCompletion;
				}
				await this.#recovery.onAssistantSettledSuccessfully(assistantMsg);
				// Broker deployments: report this request's burn so the broker can
				// attribute token usage per install. No-op with a local auth store.
				this.#modelRegistry.authStorage.usage.observe({
					provider: assistantMsg.provider,
					model: assistantMsg.model,
					at: assistantMsg.timestamp,
					usage: {
						input: assistantMsg.usage.input,
						output: assistantMsg.usage.output,
						cacheRead: assistantMsg.usage.cacheRead,
						cacheWrite: assistantMsg.usage.cacheWrite,
					},
					costUsd: assistantMsg.usage.cost.total,
				});
				// Persist which account served this turn so a resumed process can
				// re-pin it and keep the provider's account-scoped prompt cache
				// warm (broker-mode sticky routing is process-local).
				recordCredentialPin(
					this.#modelRegistry.authStorage,
					this.sessionManager,
					this.sessionId,
					assistantMsg.provider,
				);
			}
			if (event.message.role === "toolResult") {
				const { toolName, toolCallId, isError, content } = event.message;
				const details = isRecord(event.message.details) ? event.message.details : undefined;
				const semanticResult = semanticToolResult(toolName, event.message);
				const semanticDetails = isRecord(semanticResult?.details) ? semanticResult.details : undefined;
				if (toolName === "todo" && !isError && details && this.#todo.onTodoResultDetails(details, toolCallId)) {
					this.#scheduleReplanTitleRefresh();
				}
				if (toolName === "todo" && isError) {
					const errorText = content.find(part => part.type === "text")?.text;
					const reminderText = [
						"<system-reminder>",
						"todo failed, so todo progress is not visible to the user.",
						errorText ? `Failure: ${errorText}` : "Failure: todo returned an error.",
						"Fix the todo payload and call todo again before continuing.",
						"</system-reminder>",
					].join("\n");
					await this.sendCustomMessage(
						{
							customType: "todo-error-reminder",
							content: reminderText,
							display: false,
							details: { toolName, errorText },
						},
						{ deliverAs: "nextTurn" },
					);
				}
				if (semanticResult?.toolName === "checkpoint" && !isError) {
					// Backfill the checkpoint entry id now that the toolResult entry is
					// persisted. #checkpointState was set synchronously pre-await (with a
					// null entry id) so an immediate `rewind` still finds an active
					// checkpoint; locate the toolResult's own entry by identity since the
					// transient reminder entry follows it (last-entry would branch-cut the
					// reminder instead of leaving it on the active path).
					const entries = this.sessionManager.getEntries();
					let checkpointEntryId: string | null = null;
					for (let i = entries.length - 1; i >= 0; i--) {
						const entry = entries[i];
						if (entry.type === "message" && entry.message === event.message) {
							checkpointEntryId = entry.id;
							break;
						}
					}
					if (this.#checkpointState) {
						this.#checkpointState.checkpointEntryId = checkpointEntryId;
					}
				}
				if (semanticResult?.toolName === "rewind" && !isError && this.#checkpointState) {
					const detailReport = semanticDetails ? (stringProperty(semanticDetails, "report")?.trim() ?? "") : "";
					const textReport = content?.find(part => part.type === "text")?.text?.trim() ?? "";
					const report = detailReport || textReport;
					if (report.length > 0) {
						this.#pendingRewindReport = report;
					}
				}
			}
		}

		// Check auto-retry and auto-compaction after agent completes
		if (event.type === "agent_end") {
			const originals = [...this.#boundTaskCalls.values()].flatMap(bound =>
				bound.original ? [bound.original] : [],
			);
			for (const original of originals) {
				if (!original.failure)
					this.#failOriginalTaskAttempt(
						original,
						new Error("Original task ended without durable result delivery"),
					);
				await this.#messageEndPersistenceTail;
				original.scope?.releaseChild?.();
				if (this.#activeTaskRecovery === original.scope) this.#activeTaskRecovery = undefined;
				const bound = this.#boundTaskCalls.get(original.capture.toolCallId);
				if (bound?.original === original) bound.original = undefined;
			}
			const settledMessages = event.messages;
			const activeMessages = this.agent.state.messages;
			// TTSR retry work runs concurrently and clears the live flag before
			// maintenance can emit agent_end, so preserve the state at settle entry.
			const ttsrAbortPendingAtAgentEnd = this.#ttsr.abortPending;
			const emitAgentEndNotification = (options?: AgentEndSettleOptions) =>
				this.#settleAgentEnd(event, activeMessages, options);
			const usage = this.getSessionStats().tokens;
			await this.#goalRuntime.onAgentEnd({
				currentUsage: {
					input: usage.input,
					output: usage.output,
					cacheRead: usage.cacheRead,
					cacheWrite: usage.cacheWrite,
				},
			});
			const fallbackAssistant = [...settledMessages]
				.reverse()
				.find((message): message is AssistantMessage => message.role === "assistant");
			const msg = this.#lastAssistantMessage ?? fallbackAssistant;
			this.#lastAssistantMessage = undefined;
			if (!msg) {
				this.#lastSuccessfulYieldToolCallId = undefined;
				logger.debug("agent_end maintenance routing", {
					reason: "no-assistant-message",
					goalModeEnabled: this.#goalModeState?.enabled === true,
					goalStatus: this.#goalModeState?.goal.status,
				});
				await emitAgentEndNotification();
				return;
			}

			const yieldOnThisMessage = this.#assistantEndedWithSuccessfulYield(msg);
			const successfulYieldMessage = yieldOnThisMessage
				? msg
				: this.#findSuccessfulYieldAssistantMessage(settledMessages);

			const maintenanceRoute = (route: string, extra?: Record<string, unknown>) => {
				logger.debug("agent_end maintenance routing", {
					route,
					stopReason: msg.stopReason,
					provider: msg.provider,
					model: msg.model,
					contentBlocks: msg.content.length,
					hasToolCalls: msg.content.some(content => content.type === "toolCall"),
					hasText: msg.content.some(content => content.type === "text"),
					goalModeEnabled: this.#goalModeState?.enabled === true,
					goalStatus: this.#goalModeState?.goal.status,
					successfulYield: successfulYieldMessage !== undefined,
					...extra,
				});
			};
			maintenanceRoute("entered");

			// Surface provider stream failures in the main log. The routing trace
			// above is debug-only and drops the error fields, so a session dying
			// repeatedly on provider errors otherwise leaves no actionable trace
			// outside the session transcript (issue #6177).
			logProviderTurnError(msg);

			// Invalidate GitHub Copilot credentials on a hard auth failure (401, or an
			// expired/revoked token) so stale tokens aren't reused on the next request.
			// Account usage caps and concurrency caps leave the credential valid: the
			// former rotates until its reset window, while the latter is retried after
			// a short backoff without touching the credential pool. Model-policy 403s
			// (plan, model policy, org restriction) also preserve the credential: the
			// token is valid, and wiping it hides the provider from `/model` (#11275).
			if (msg.stopReason === "error" && msg.provider === "github-copilot") {
				const errorId = AIError.classifyMessage(msg);
				const isConcurrencyCap = AIError.parseRateLimitReason(msg.errorMessage ?? "") === "CONCURRENT_LIMIT";
				if (
					AIError.is(errorId, AIError.Flag.AuthFailed) &&
					!AIError.is(errorId, AIError.Flag.UsageLimit) &&
					!isConcurrencyCap &&
					!AIError.isGitHubCopilotPolicyDenial(msg.provider, msg.errorStatus, msg.errorMessage)
				) {
					await this.#modelRegistry.authStorage.credentials.remove("github-copilot");
				}
			}

			if (this.#maintenance.skipPostTurnMaintenanceAssistantTimestamp === msg.timestamp) {
				const skippedSpeculationCompletion = this.#skippedPostTurnSpeculationCompletion;
				this.#maintenance.skipPostTurnMaintenanceAssistantTimestamp = undefined;
				this.#skippedPostTurnSpeculationCompletion = undefined;
				this.#lastSuccessfulYieldToolCallId = undefined;
				const model = this.model;
				const requiresSpeculativeRecovery =
					model !== undefined &&
					msg.provider === model.provider &&
					msg.model === model.id &&
					(msg.stopReason === "length" ||
						(msg.stopReason === "error" && AIError.isContextOverflow(msg, model.contextWindow ?? 0)));
				const speculationCompletion = requiresSpeculativeRecovery ? skippedSpeculationCompletion : undefined;
				if (!speculationCompletion) {
					maintenanceRoute("skip-post-turn-maintenance");
					await emitAgentEndNotification();
					return;
				}

				const promptSequence = this.#promptSequence;
				const promptGeneration = this.#promptGeneration;
				maintenanceRoute("await-speculative-compaction");
				await speculationCompletion;
				if (
					this.#isDisposed ||
					this.#abortInProgress ||
					this.#promptGeneration !== promptGeneration ||
					this.#promptSequence !== promptSequence
				) {
					maintenanceRoute("skip-superseded-speculative-maintenance");
					await emitAgentEndNotification();
					return;
				}
				maintenanceRoute("resume-post-turn-maintenance");
			}

			const activeGoal = this.#goalModeState?.enabled === true && this.#goalModeState.goal.status === "active";
			// A successful `yield` in this run is terminal for execution purposes.
			// Suppress empty-stop retry, unexpected-stop retry, queued-message drain,
			// and compaction-driven continuations for the rest of this prompt cycle:
			// the executor consumed the yield as the terminal result, so a trailing
			// empty/aborted assistant stop must NOT revive the agent loop. The
			// `#yieldTerminationPending` sticky flag clears on the next `prompt()`.
			if (successfulYieldMessage || this.#yieldTerminationPending) {
				this.#lastSuccessfulYieldToolCallId = undefined;
				if (successfulYieldMessage && activeGoal) {
					maintenanceRoute(
						yieldOnThisMessage
							? "successful-yield-active-goal-checkCompaction"
							: "post-yield-trailing-stop-active-goal-checkCompaction",
					);
					const compactionTask = this.#maintenance.checkCompaction(successfulYieldMessage);
					this.#trackPostPromptTask(compactionTask);
					await compactionTask;
				} else if (successfulYieldMessage) {
					maintenanceRoute("successful-yield-no-active-goal");
				} else {
					maintenanceRoute("post-yield-trailing-stop-suppressed");
				}
				await emitAgentEndNotification();
				return;
			}
			this.#lastSuccessfulYieldToolCallId = undefined;

			// Empty-stop cleanup MUST run before any compaction continuation: an
			// empty toolUse stop must be stripped from active context + session
			// history before we schedule another turn, otherwise the next
			// Anthropic turn carries a tool_use block with no matching
			// tool_result and corrupts message history. The handler also
			// schedules its own retry, so a real empty stop never needs the
			// active-goal threshold pre-empt below.
			const emptyOutputRecovery = await this.#recovery.handleEmptyAssistantStop(msg);
			if (emptyOutputRecovery === "continue") {
				maintenanceRoute("empty-stop-handled");
				await emitAgentEndNotification({ willContinue: true });
				return;
			}
			if (emptyOutputRecovery === "terminal") {
				// The cap already closed retry state and made provider-empty errors
				// non-retryable. Continue through terminal maintenance so session_stop
				// hooks and queued follow-up handling retain their normal contract.
				maintenanceRoute("empty-stop-retry-cap");
			}

			// Record quota exhaustion before deciding whether this failed turn may be
			// replayed. Visible/side-effecting output then remains terminal while its
			// credential is still blocked or rotated exactly once.
			await this.#recovery.recordUsageLimitOutcome(msg);

			let compactionResult = COMPACTION_CHECK_NONE;
			let checkedCompaction = false;
			if (activeGoal) {
				// Payload rejections get a pre-compaction chain consult; checkCompaction()'s overflow path commits a remedy before returning (#9235).
				if (AIError.isPayloadRejection(msg) && this.#recovery.isHardErrorFallbackEligible(msg)) {
					const didRetry = await this.#recovery.handleRetryableError(msg, { hardErrorFallback: true });
					if (didRetry) {
						await emitAgentEndNotification({ willContinue: true });
						return;
					}
				}
				maintenanceRoute("active-goal-pre-empt-checkCompaction");
				const compactionTask = this.#maintenance.checkCompaction(msg);
				this.#trackPostPromptTask(compactionTask);
				compactionResult = await compactionTask;
				checkedCompaction = true;
				const compactionContinues = compactionResult.deferredHandoff || compactionResult.continuationScheduled;
				if (compactionContinues || compactionResult.automaticContinuationBlocked) {
					// Early return skips the error tail; persist the terminal 413 so the JSONL records why the goal stopped (#9235).
					if (
						compactionResult.automaticContinuationBlocked &&
						(AIError.isPayloadRejection(msg) || !AIError.isContextOverflow(msg, this.model?.contextWindow ?? 0))
					) {
						await this.#recovery.persistTerminalEmptyErrorTurn(msg);
					}
					maintenanceRoute("active-goal-pre-empt-compaction-handled", {
						deferredHandoff: compactionResult.deferredHandoff,
						continuationScheduled: compactionResult.continuationScheduled,
						automaticContinuationBlocked: compactionResult.automaticContinuationBlocked === true,
					});
					this.#recovery.resolveRetry();
					await emitAgentEndNotification(
						compactionResult.continuationScheduled ? { willContinue: true } : undefined,
					);
					return;
				}
			}

			if (await this.#recovery.handleUnexpectedAssistantStop(msg)) {
				maintenanceRoute("unexpected-stop-handled");
				await emitAgentEndNotification({ willContinue: true });
				return;
			}

			const resolvedInterruptedToolTurn = this.#recovery.classifyResolvedInterruptedToolTurn(msg);
			if (this.#recovery.isRetryableReasonlessAbort(msg) || resolvedInterruptedToolTurn === "reasonless-abort") {
				const didRetry = await this.#recovery.handleRetryableError(
					msg,
					resolvedInterruptedToolTurn === "reasonless-abort"
						? { allowModelFallback: false, preserveFailedTurn: true }
						: { allowModelFallback: false },
				);
				if (didRetry) {
					await emitAgentEndNotification({ willContinue: true });
					return;
				}
			}

			// A deliberate abort should settle the current turn, not trigger queued
			// continuations — except TTSR self-repair, which already scheduled a
			// hidden retry while #ttsrAbortPending is still true.
			if (msg.stopReason === "aborted") {
				this.#recovery.resolveRetry();
				this.#resetSessionStopContinuationState();
				await emitAgentEndNotification(ttsrAbortPendingAtAgentEnd ? { willContinue: true } : undefined);
				return;
			}
			const requestBodyTimeoutRecovery = await this.#recovery.handleResponsesRequestBodyReadTimeout(msg);
			if (requestBodyTimeoutRecovery === "handled-retry") {
				maintenanceRoute("responses-request-body-timeout-retry");
				await emitAgentEndNotification({ willContinue: true });
				return;
			}
			const requestBodyTimeoutTerminal = requestBodyTimeoutRecovery === "handled-terminal";
			// Fireworks Fast variants degrade to their base model on a failed turn —
			// including hard router errors the generic retry classifier rejects — so
			// run this gate before the standard retryability check.
			if (!requestBodyTimeoutTerminal && this.#recovery.isFireworksFastFallbackEligible(msg)) {
				const didRetry = await this.#recovery.handleRetryableError(msg, { fireworksFastFallback: true });
				if (didRetry) {
					await emitAgentEndNotification({ willContinue: true });
					return;
				}
			}
			const resumeResolvedStreamStall = resolvedInterruptedToolTurn === "stream-stall";
			if (!requestBodyTimeoutTerminal && (resumeResolvedStreamStall || this.#recovery.isRetryableError(msg))) {
				const didRetry = await this.#recovery.handleRetryableError(
					msg,
					resumeResolvedStreamStall ? { preserveFailedTurn: true } : undefined,
				);
				if (didRetry) {
					await emitAgentEndNotification({ willContinue: true });
					return;
				}
			} else if (!requestBodyTimeoutTerminal && this.#recovery.handleMalformedFunctionCallStop(msg)) {
				// A malformed call with committed text cannot be replayed, but it
				// never executed anything either: keep the turn and continue with a
				// corrective reminder rather than stopping on a pinned error.
				maintenanceRoute("malformed-function-call-handled");
				await emitAgentEndNotification({ willContinue: true });
				return;
			} else if (!requestBodyTimeoutTerminal && this.#recovery.handleCommittedTextStreamStall(msg)) {
				// The stream died after text rendered: replay would duplicate it and
				// a trailing assistant prefill is rejected, so keep the partial turn
				// and continue from where it stopped.
				maintenanceRoute("committed-text-stream-stall-continued");
				await emitAgentEndNotification({ willContinue: true });
				return;
			} else if (!requestBodyTimeoutTerminal && this.#recovery.isHardErrorFallbackEligible(msg)) {
				// A non-retryable hard error on a model covered by a configured
				// fallback chain: retrying the SAME model is pointless, but a
				// DIFFERENT model is a fresh chance — consult the chain before
				// surfacing the failure. #handleRetryableError bails out (no
				// backoff-retry of the failing model) when no switch happens.
				const didRetry = await this.#recovery.handleRetryableError(msg, { hardErrorFallback: true });
				if (didRetry) {
					await emitAgentEndNotification({ willContinue: true });
					return;
				}
			}
			// Classifier refusals are persisted-skipped above; also prune the trailing
			// stub from active context so the next turn's prompt does not replay it.
			// Keep a reference for post-settle readers (print mode, task executor via
			// getLastAssistantMessage) — pruning made the terminal error invisible to
			// anything inspecting agent state after prompt() resolved.
			// Fall through to the standard error tail so `session_stop` hooks (block,
			// continue, telemetry) still fire — matching the pre-fix flow for
			// `stopReason === "error"`.
			if (this.#recovery.isClassifierRefusal(msg)) {
				this.#prunedTerminalFailure = msg;
				this.#recovery.removeAssistantMessageFromActiveContext(msg);
			} else if (!AIError.isContextOverflow(msg, this.model?.contextWindow ?? 0)) {
				// No retry, fallback, or compaction continuation fired: this errored
				// turn ends the run. #persistSessionMessageIfMissing dropped it as an
				// empty error turn, so record it here — otherwise the JSONL stops at
				// the last tool result and the provider's errorMessage is lost (#6249).
				// Idempotent and a no-op for non-empty turns. Content-less overflow
				// rejections stay live-UI only per the auto-compaction progress guard:
				// persisting one would replay an empty assistant turn on reload.
				await this.#recovery.persistTerminalEmptyErrorTurn(msg);
			}
			this.#recovery.resolveRetry();

			if (!checkedCompaction) {
				maintenanceRoute("bottom-checkCompaction");
				const compactionTask = this.#maintenance.checkCompaction(msg);
				this.#trackPostPromptTask(compactionTask);
				compactionResult = await compactionTask;
			}
			if (compactionResult.automaticContinuationBlocked && AIError.isPayloadRejection(msg)) {
				await this.#recovery.persistTerminalEmptyErrorTurn(msg);
			}
			await this.#recovery.onErrorSettledWithoutRetry(msg, compactionResult);
			// Stop-time todo reconciliation only fires at a text-only final stop. A run
			// that ends still mid-tool-use (deadline hit, context full, etc.) skips the
			// reminder so we don't pile a follow-up onto an already in-flight turn.
			// Mid-run sync is handled separately via #takeMidRunTodoNudge so a long
			// tool-use loop still gets prodded to keep the live HUD honest (issue #3651).
			const hasToolCalls = msg.content.some(content => content.type === "toolCall");
			if (hasToolCalls) {
				await emitAgentEndNotification();
				return;
			}
			// When compaction queued recovery or hit a deliberate dead-end, skip the
			// rewind/todo/session_stop passes: any reminder or hook continuation we append
			// here would race the handoff, retry, auto-continue prompt, queued-message
			// drain, or the explicit pause that is preventing a compaction loop.
			if (
				compactionResult.deferredHandoff ||
				compactionResult.continuationScheduled ||
				compactionResult.automaticContinuationBlocked
			) {
				await emitAgentEndNotification(compactionResult.continuationScheduled ? { willContinue: true } : undefined);
				return;
			}
			// A capped empty stop still has stopReason "stop"; built-in reminders
			// must not restart it after recovery has declared the turn terminal.
			if (msg.stopReason !== "error" && emptyOutputRecovery !== "terminal") {
				if (this.#enforceRewindBeforeYield()) {
					await emitAgentEndNotification({ willContinue: true });
					return;
				}
				const planModeContinuationScheduled = await this.#enforcePlanModeDecisionAtSettle();
				if (planModeContinuationScheduled) {
					await emitAgentEndNotification({ willContinue: true });
					return;
				}
				const todoContinuationScheduled = await this.#todo.checkCompletion(msg);
				if (todoContinuationScheduled) {
					await emitAgentEndNotification({ willContinue: true });
					return;
				}
			}
			// A pending async wake means this settle is a scheduling pause, not
			// the terminal stop: the async-result delivery continues the loop and
			// the real stop settles later. Defer the session_stop hook pass until
			// the session is fully idle (the todo reminder above defers the same
			// way inside #checkTodoCompletion).
			if (this.#hasPendingAsyncWake()) {
				await emitAgentEndNotification({ willContinue: true, awaitingAsyncWork: true });
				return;
			}
			const sessionStopWillContinue = await this.#emitSessionStopEvent(activeMessages, msg);
			await emitAgentEndNotification(sessionStopWillContinue ? { willContinue: true } : undefined);
		}
	};

	#ensurePostPromptTasksPromise(): void {
		if (this.#postPromptTasksPromise) return;
		const { promise, resolve } = Promise.withResolvers<void>();
		this.#postPromptTasksPromise = promise;
		this.#postPromptTasksResolve = resolve;
	}

	#resolvePostPromptTasks(): void {
		if (!this.#postPromptTasksResolve) return;
		this.#postPromptTasksResolve();
		this.#postPromptTasksResolve = undefined;
		this.#postPromptTasksPromise = undefined;
	}

	#trackPostPromptTask(task: Promise<unknown>): void {
		this.#postPromptTasks.add(task);
		this.#ensurePostPromptTasksPromise();
		void task
			.catch(() => {})
			.finally(() => {
				this.#postPromptTasks.delete(task);
				if (this.#postPromptTasks.size === 0) {
					this.#resolvePostPromptTasks();
				}
			});
	}

	#schedulePostPromptTask(
		task: (signal: AbortSignal) => Promise<void>,
		options?: { delayMs?: number; generation?: number; onSkip?: (reason: PostPromptSkipReason) => void },
	): void {
		const delayMs = options?.delayMs ?? 0;
		const signal = this.#postPromptTasksAbortController.signal;
		const scheduled = (async () => {
			if (delayMs > 0) {
				try {
					await scheduler.wait(delayMs, { signal });
				} catch {
					if (signal.aborted) options?.onSkip?.("aborted");
					return;
				}
			}
			if (signal.aborted) {
				options?.onSkip?.("aborted");
				return;
			}
			if (options?.generation !== undefined && this.#promptGeneration !== options.generation) {
				options.onSkip?.("stale-generation");
				return;
			}
			await task(signal);
		})();
		this.#trackPostPromptTask(scheduled);
	}

	/** Schedule a cold continuation; task recovery is an explicit native opt-in. */
	requestPersistedTurnContinuation(request: PersistedTurnContinuationRequest): PersistedTurnContinuationResult {
		request = { ...request };
		const pending = this.#persistedTurnRequest;
		if (pending)
			return pending.generation === this.#promptGeneration &&
				pending.sessionId === request.sessionId &&
				pending.entryId === request.entryId &&
				pending.expectedLeafId === request.expectedLeafId
				? { status: "alreadyScheduled" }
				: {
						status: "refused",
						code: "conflicting-request",
						reason: "Another persisted turn owns continuation scheduling",
					};
		const generation = this.#promptGeneration;
		try {
			this.#assertPersistedLocal(request, generation, 0);
			this.#classifyPersistedTurn(request.entryId, request.recoverSynchronousTask === true);
		} catch (error) {
			return { status: "refused", ...this.#persistedRefusal(error) };
		}
		const scheduled = { ...request, generation };
		this.#persistedTurnRequest = scheduled;
		this.#schedulePostPromptTask(
			async signal => {
				try {
					if (!(await untilAborted(signal, this.#extensionRunner!.waitForSessionStart())))
						throw new PersistedContinuationError(
							"startup-incomplete",
							"Extension startup did not finish successfully",
						);
					this.#assertPersistedLocal(request, generation, 0);
					const binding = this.#classifyPersistedTurn(request.entryId, request.recoverSynchronousTask === true);
					if (binding) await this.#recoverPersistedTaskTurn(request, binding, signal, generation);
					else await this.#executePersistedPrompt(request, signal, generation);
				} catch (error) {
					const refusal = this.#persistedRefusal(error);
					logger.warn("Persisted turn continuation refused", { entryId: request.entryId, ...refusal });
					request.onRefused?.(refusal);
				} finally {
					if (this.#persistedTurnRequest === scheduled) this.#persistedTurnRequest = undefined;
				}
			},
			{
				generation,
				onSkip: reason => {
					if (this.#persistedTurnRequest === scheduled) this.#persistedTurnRequest = undefined;
					request.onRefused?.({ code: "stale-identity", reason });
				},
			},
		);
		return { status: "scheduled" };
	}

	#persistedRefusal(error: unknown): PersistedTurnRefusal {
		return error instanceof PersistedContinuationError
			? { code: error.code, reason: error.message }
			: { code: "dispatch-failed", reason: String(error) };
	}

	#assertPersistedLocal(request: PersistedTurnContinuationRequest, generation: number, ownedInFlight: number): void {
		if (!this.#extensionRunner)
			throw new PersistedContinuationError("unavailable", "No extension startup lifecycle is available");
		if (this.#clientBridge?.deferAgentInitiatedTurns && !this.#allowAcpAgentInitiatedTurns)
			throw new PersistedContinuationError(
				"unavailable",
				"Client must own agent-initiated turns through its prompt lifecycle",
			);
		if (
			this.#isDisposed ||
			this.#abortInProgress ||
			this.isAborting ||
			this.isCompacting ||
			this.isGeneratingHandoff ||
			this.isRetrying ||
			this.agent.state.isStreaming ||
			this.#promptInFlightCount > ownedInFlight
		)
			throw new PersistedContinuationError(
				"session-unavailable",
				"Session is busy, aborting, retrying, disposing, or in maintenance",
			);
		if (
			request.sessionId !== this.sessionId ||
			generation !== this.#promptGeneration ||
			request.expectedLeafId !== this.sessionManager.getLeafId()
		)
			throw new PersistedContinuationError("stale-identity", "Session, active leaf, or prompt generation changed");
		if (this.agent.hasQueuedMessages() || this.#pendingNextTurnMessages.some(isUserQueuedMessage))
			throw new PersistedContinuationError(
				"queued-input",
				"Queued input takes precedence over persisted turn recovery",
			);
	}

	#messageForPersistedEntry(entryId: string): AgentMessage {
		const entry = this.sessionManager.getEntry(entryId);
		let candidate =
			entry?.type === "message"
				? entry.message
				: entry?.type === "custom_message"
					? createCustomMessage(
							entry.customType,
							entry.content,
							entry.display,
							entry.details,
							entry.timestamp,
							entry.attribution,
						)
					: undefined;
		if (!candidate)
			throw new PersistedContinuationError("missing-anchor", "Persisted input is not a conversation entry");
		if (this.#obfuscator) candidate = deobfuscateAgentMessages(this.#obfuscator, [candidate])[0];
		const matches = this.messages.filter(
			message =>
				message.role === candidate.role &&
				(this.#persistedEntryByMessage.has(message)
					? this.#persistedEntryByMessage.get(message) === entryId
					: message.timestamp === candidate.timestamp) &&
				sameMessageContent(message, candidate) &&
				(message.role !== "custom" || (candidate.role === "custom" && message.customType === candidate.customType)),
		);
		if (matches.length !== 1)
			throw new PersistedContinuationError(
				"missing-anchor",
				"Persisted input is missing, ambiguous, or changed in active model context",
			);
		return matches[0];
	}

	#classifyPersistedTurn(
		entryId: string,
		recoverTask = false,
		childBinding?: PersistedTaskBindingV1,
	): PersistedTaskBindingV1 | undefined {
		const branch = this.sessionManager.getBranch();
		const anchorIndex = branch.findIndex(entry => entry.id === entryId);
		const anchor = branch[anchorIndex];
		const customAnchor = anchor?.type === "custom_message" && anchor.attribution === "agent";
		const taskAnchor =
			childBinding &&
			anchor?.type === "message" &&
			anchor.message.role === "user" &&
			anchor.message.attribution === "agent";
		if (!customAnchor && !taskAnchor)
			throw new PersistedContinuationError("missing-anchor", "Expected agent input is not on the active branch");
		let prepared = new Set<string>();
		const hasPreparation = branch.some(
			entry =>
				entry.type === "custom" &&
				entry.customType === PROMPT_PREPARATION &&
				isRecord(entry.data) &&
				entry.data.anchorEntryId === entryId,
		);
		try {
			if (hasPreparation || childBinding)
				prepared = preparedEntryIds(branch, this.sessionId, entryId, childBinding?.call.bindingId);
		} catch (error) {
			throw new PersistedContinuationError("unsafe-suffix", String(error));
		}
		for (const memberId of prepared) this.#messageForPersistedEntry(memberId);
		const suffix = branch.slice(anchorIndex + 1);
		if (
			suffix.some(
				entry => entry.type === "compaction" || entry.type === "branch_summary" || entry.type === "reset_boundary",
			)
		)
			throw new PersistedContinuationError("unsafe-suffix", "Context reset prevents persisted turn recovery");
		const conversation = suffix.filter(
			entry => (entry.type === "message" || entry.type === "custom_message") && !prepared.has(entry.id),
		);
		if (
			conversation.some(
				entry => (entry.type === "message" && entry.message.role === "user") || entry.type === "custom_message",
			)
		)
			throw new PersistedContinuationError(
				"unsafe-suffix",
				"Unassociated conversation or another assignment follows the persisted input",
			);
		const pending = describePendingToolCalls(branch);
		const last = conversation.at(-1);
		if (
			!pending &&
			last?.type === "message" &&
			last.message.role === "assistant" &&
			last.message.stopReason === "stop" &&
			!last.message.content.some(part => part.type === "toolCall")
		)
			throw new PersistedContinuationError(
				"turn-settled",
				"Persisted conversation turn already settled; workflow progress must be read from its owner",
			);
		if (recoverTask && !childBinding && conversation.length > 0) {
			try {
				return this.#boundParentTask(entryId);
			} catch (error) {
				if (error instanceof PersistedContinuationError) throw error;
				throw new PersistedContinuationError(
					pending ? "pending-tools" : "unsafe-suffix",
					`${pending ?? "Task continuation refused."} ${String(error)}`,
				);
			}
		}
		if (pending) throw new PersistedContinuationError("pending-tools", pending);
		if (conversation.length > 0)
			throw new PersistedContinuationError(
				"unsafe-suffix",
				"Assistant or tool history prevents safe no-tool continuation",
			);
		if (
			childBinding &&
			branch.some(
				entry =>
					(entry.type === "message" &&
						(entry.message.role === "assistant" || entry.message.role === "toolResult")) ||
					(entry.type === "custom" && entry.customType === TOOL_EXECUTION_START_CUSTOM_TYPE),
			)
		)
			throw new PersistedContinuationError("unsafe-suffix", "Child already has assistant, tool, or effect history");
		this.#messageForPersistedEntry(entryId);
		return undefined;
	}

	#boundParentTask(promptEntryId: string): PersistedTaskBindingV1 {
		const branch = this.sessionManager.getBranch();
		const matches = branch
			.map(readTaskBinding)
			.filter(
				(binding): binding is PersistedTaskBindingV1 =>
					binding !== undefined && binding.call.promptEntryId === promptEntryId,
			);
		if (matches.length !== 1) throw new Error("Original task has no unique durable parent/child binding");
		const binding = matches[0];
		const call = binding.call;
		const assistant = branch.find(entry => entry.id === call.assistantEntryId);
		const calls =
			assistant?.type === "message" && assistant.message.role === "assistant"
				? assistant.message.content.filter(part => part.type === "toolCall")
				: [];
		const args = calls[0]?.arguments;
		const effective = this.#obfuscator && args ? deobfuscateToolArguments(this.#obfuscator, args) : args;
		if (
			call.sessionId !== this.sessionId ||
			calls.length !== 1 ||
			calls[0].id !== call.toolCallId ||
			calls[0].name !== "task" ||
			taskRecoveryHash(effectiveTaskArguments(effective)) !== call.argumentsSha256 ||
			taskRecoveryHash(effectiveTaskArguments(binding.contract.args)) !== call.argumentsSha256
		)
			throw new Error("Task assistant/call/argument binding differs");
		const anchorIndex = branch.findIndex(entry => entry.id === promptEntryId);
		const assistantIndex = branch.findIndex(entry => entry.id === call.assistantEntryId);
		const bindingIndex = branch.findIndex(entry => readTaskBinding(entry)?.call.bindingId === call.bindingId);
		if (assistantIndex <= anchorIndex || bindingIndex <= assistantIndex)
			throw new Error("Task binding is not on the original call's active ancestry");
		const prepared = preparedEntryIds(branch, this.sessionId, promptEntryId);
		const results = branch.filter(
			entry =>
				entry.type === "message" &&
				entry.message.role === "toolResult" &&
				entry.message.toolCallId === call.toolCallId,
		);
		if (results.length > 1) throw new Error("Original task has conflicting parent results");
		for (const entry of branch.slice(anchorIndex + 1)) {
			if (entry.id === call.assistantEntryId || prepared.has(entry.id)) continue;
			if (entry.type === "custom_message") throw new Error("Unassociated task conversation follows the anchor");
			if (
				entry.type === "message" &&
				!(
					entry.message.role === "toolResult" &&
					entry.message.toolName === "task" &&
					entry.message.toolCallId === call.toolCallId &&
					!entry.message.isError &&
					taskRecoveryHash(entry.taskResult) === taskRecoveryHash(this.#taskResultRef(binding))
				)
			)
				throw new Error("Parent result or conversation does not belong to the bound original task");
			if (entry.type === "compaction" || entry.type === "branch_summary" || entry.type === "reset_boundary")
				throw new Error("Task branch was reset or compacted");
		}
		const completion = taskResultRecoveryState(this.sessionManager.getEntries(), branch, binding);
		if (
			results.length === 0 &&
			completion.processing &&
			(!this.#activeTaskRecovery?.completion ||
				taskRecoveryHash(this.#activeTaskRecovery.completion) !==
					taskRecoveryHash({
						readyEntryId: completion.ready!.entryId,
						readySha256: completion.ready!.sha256,
						processingEntryId: completion.processing.entryId,
						processingSha256: completion.processing.sha256,
					}))
		)
			throw new PersistedContinuationError(
				"task-result-processing-incomplete",
				"Retained processing claim has no durable original parent result",
			);
		const pending = collectPendingToolCalls(branch);
		if (
			results.length === 0
				? pending.length !== 1 || pending[0].toolCallId !== call.toolCallId || pending[0].toolName !== "task"
				: pending.length !== 0
		)
			throw new Error("Task recovery requires exactly the original unresolved call or its bound result");
		return binding;
	}

	#taskResultRef(binding: PersistedTaskBindingV1): PersistedTaskResultRef {
		const branch = this.sessionManager.getBranch();
		const state = taskResultRecoveryState(this.sessionManager.getEntries(), branch, binding);
		let completion: TaskResultProcessingRef | undefined;
		if (state.ready) {
			if (
				!state.processing ||
				branch.findIndex(entry => entry.id === state.processing!.entryId) <=
					branch.findIndex(entry => entry.id === state.ready!.entryId)
			)
				throw new Error("Native task result lacks its exact active-branch processing claim");
			completion = {
				readyEntryId: state.ready.entryId,
				readySha256: state.ready.sha256,
				processingEntryId: state.processing.entryId,
				processingSha256: state.processing.sha256,
			};
		}
		return {
			...(completion ? { completion } : {}),
			bindingId: binding.call.bindingId,
			contractSha256: binding.contractSha256,
			toolCallId: binding.call.toolCallId,
			childSessionId: binding.child.sessionId,
		};
	}

	async #executePersistedPrompt(
		request: PersistedTurnContinuationRequest,
		signal: AbortSignal,
		generation: number,
		ownedInFlight = 0,
		childBinding?: PersistedTaskBindingV1,
	): Promise<void> {
		this.#assertPersistedLocal(request, generation, ownedInFlight);
		this.#classifyPersistedTurn(request.entryId, request.recoverSynchronousTask === true, childBinding);
		const message = this.#messageForPersistedEntry(request.entryId);
		const context = [...this.messages];
		const runner = this.#extensionRunner;
		const check = (preparing: boolean, preparedMessages: readonly AgentMessage[] = []) => {
			if (signal.aborted)
				throw new PersistedContinuationError("session-unavailable", "Continuation aborted before dispatch");
			this.#assertPersistedLocal(request, generation, ownedInFlight + (preparing ? 1 : 0));
			if (
				runner !== this.#extensionRunner ||
				context.length !== this.messages.length ||
				context.some((entry, index) => entry !== this.messages[index])
			)
				throw new PersistedContinuationError("stale-identity", "Restored context or startup owner changed");
			if (preparedMessages.some(isUserQueuedMessage))
				throw new PersistedContinuationError("queued-input", "Owner input arrived during prompt preparation");
			this.#classifyPersistedTurn(request.entryId, request.recoverSynchronousTask === true, childBinding);
		};
		try {
			await this.sessionManager.flush();
			if (!this.sessionManager.isSessionOnDisk()) throw new Error("Session has no durable journal");
		} catch (error) {
			throw new PersistedContinuationError("persistence-failed", String(error));
		}
		check(false);
		const text =
			"content" in message && typeof message.content === "string"
				? message.content
				: "content" in message && Array.isArray(message.content)
					? message.content.flatMap(part => (part.type === "text" ? [part.text] : [])).join("\n")
					: "";
		const dispatched = await this.#promptWithMessage(message, text, {
			skipPostPromptRecoveryWait: true,
			taskBindingId: childBinding?.call.bindingId,
			existingEntry: {
				anchorEntryId: request.entryId,
				taskBound: childBinding !== undefined || request.recoverSynchronousTask === true,
				signal,
				canDispatch: preparedMessages => {
					check(true, preparedMessages);
					return true;
				},
				beforeDispatch: async preparedMessages => {
					check(true, preparedMessages);
					try {
						await this.sessionManager.flush();
					} catch (error) {
						throw new PersistedContinuationError("persistence-failed", String(error));
					}
					const authority = await request.validateDispatch();
					if (!authority.ok) throw new PersistedContinuationError("authority-refused", authority.reason);
					check(true, preparedMessages);
					return true;
				},
			},
		});
		if (!dispatched)
			throw new PersistedContinuationError("dispatch-failed", "Prompt preparation declined continuation");
	}

	async #recordNativeTaskResult(
		scope: ParentTaskRecoveryScope,
		record: NativeTaskResultReadyV1,
	): Promise<NativeTaskResultReadyCheckpoint> {
		scope.assertOwnership();
		if (
			!scope.child ||
			record.child.sessionId !== scope.child.sessionId ||
			record.child.leafId !== scope.child.sessionManager.getLeafId() ||
			taskRecoveryHash(scope.child.sessionManager.getBranch()) !== record.child.branchSha256 ||
			taskRecoveryHash(record.call) !== taskRecoveryHash(scope.binding.call) ||
			record.contractSha256 !== scope.binding.contractSha256
		)
			throw new Error("Native completion lost original child/call ownership");
		scope.child.#assertSettledTaskCompletion();
		const state = taskResultRecoveryState(
			this.sessionManager.getEntries(),
			this.sessionManager.getBranch(),
			scope.binding,
		);
		if (state.ready || state.processing)
			throw new Error("Original task already has retained completion/processing ownership");
		const snapshot = JSON.parse(JSON.stringify(record)) as NativeTaskResultReadyV1;
		const assertOriginalCompletion = scope.child.#childTaskRecovery?.assertNativeCompletion;
		if (!assertOriginalCompletion) throw new Error("Native completion has no original settled-child lease");
		scope.assertOwnership();
		assertOriginalCompletion();
		const entryId = this.sessionManager.appendCustomEntry(TASK_NATIVE_RESULT_READY, snapshot);
		scope.advanceExpectedLeaf(entryId);
		const ready = taskResultRecoveryState(
			this.sessionManager.getEntries(),
			this.sessionManager.getBranch(),
			scope.binding,
		).ready!;
		await this.sessionManager.flush();
		scope.assertOwnership();
		assertOriginalCompletion();
		if (
			scope.child.sessionManager.getLeafId() !== snapshot.child.leafId ||
			taskRecoveryHash(scope.child.sessionManager.getBranch()) !== snapshot.child.branchSha256
		)
			throw new Error("Completed child changed while native checkpoint became durable");
		scope.child.#assertSettledTaskCompletion();
		if (taskRecoveryHash(scope.child.sessionManager.getEntries()) !== snapshot.child.entriesSha256)
			throw new Error("Completed child retained history changed");
		return { entryId, sha256: ready.sha256, record: JSON.parse(JSON.stringify(snapshot)) as NativeTaskResultReadyV1 };
	}

	async #claimTaskResultProcessing(
		scope: ParentTaskRecoveryScope,
		expected: NativeTaskResultReadyCheckpoint,
	): Promise<TaskResultProcessingRef> {
		await scope.validateAuthority();
		scope.assertOwnership();
		const state = taskResultRecoveryState(
			this.sessionManager.getEntries(),
			this.sessionManager.getBranch(),
			scope.binding,
		);
		if (
			!state.ready ||
			state.ready.entryId !== expected.entryId ||
			state.ready.sha256 !== expected.sha256 ||
			taskRecoveryHash(expected.record) !== state.ready.sha256 ||
			state.processing
		)
			throw new Error("task-result-processing-incomplete: completion missing, changed, or already claimed");
		const record: TaskResultProcessingStartedV1 = {
			version: 1,
			protocol: TASK_RESULT_PROCESSING_PROTOCOL,
			call: { ...scope.binding.call },
			contractSha256: scope.binding.contractSha256,
			readyEntryId: state.ready.entryId,
			readySha256: state.ready.sha256,
		};
		const entryId = this.sessionManager.appendCustomEntry(TASK_RESULT_PROCESSING_STARTED, record);
		scope.advanceExpectedLeaf(entryId);
		scope.completion = {
			readyEntryId: state.ready.entryId,
			readySha256: state.ready.sha256,
			processingEntryId: entryId,
			processingSha256: taskRecoveryHash(record),
		};
		await this.sessionManager.flush();
		await scope.validateAuthority();
		scope.assertOwnership();
		return { ...scope.completion };
	}

	#assertSettledTaskCompletion(): void {
		if (
			this.agent.state.isStreaming ||
			this.agent.isAborting ||
			this.#promptInFlightCount > 0 ||
			this.#inFlightEventHandlers.size > 0 ||
			this.#pendingMessageEndPersistence.size > 0 ||
			this.#postPromptTasks.size > 0
		)
			throw new Error("Task child has unsettled completion-critical work");
	}

	/** Drain only the settled recovered child, before native finalization publishes its output artifact. */
	async flushBoundTaskCompletion(binding: PersistedTaskBindingV1): Promise<() => void> {
		const scope = this.#childTaskRecovery;
		if (!scope || taskRecoveryHash(scope.parent.binding) !== taskRecoveryHash(binding))
			throw new Error("No original task driver owns completion persistence");
		const existing = scope.assertNativeCompletion;
		if (existing) {
			existing();
			return existing;
		}
		this.#checkTaskRecoveryDriver();
		if (this.agent.state.isStreaming || this.#promptInFlightCount > 0)
			throw new Error("Task child is not settled for native completion certification");
		await this.#drainInFlightEventHandlers();
		await this.#messageEndPersistenceTail;
		await this.sessionManager.flush();
		if (this.#childTaskRecovery !== scope) throw new Error("Original completion driver changed during persistence");
		const published = scope.assertNativeCompletion;
		if (published) {
			published();
			return published;
		}
		this.#checkTaskRecoveryDriver();
		this.#assertSettledTaskCompletion();
		const leaf = this.sessionManager.getLeafId();
		const entriesHash = taskRecoveryHash(this.sessionManager.getEntries());
		const tail = this.#messageEndPersistenceTail;
		const assertOriginal = () => {
			if (this.#childTaskRecovery !== scope) throw new Error("Original completion driver was replaced");
			this.#checkTaskRecoveryDriver();
			this.#assertSettledTaskCompletion();
			if (
				this.sessionManager.getLeafId() !== leaf ||
				taskRecoveryHash(this.sessionManager.getEntries()) !== entriesHash ||
				this.#messageEndPersistenceTail !== tail
			)
				throw new Error("Settled child changed during native finalization");
		};
		scope.assertNativeCompletion = assertOriginal;
		return assertOriginal;
	}

	/** Restore only the bound call that ordinary replay projected away while it lacked a result. */
	#restorePairedTaskAssistant(scope: ParentTaskRecoveryScope, priorProjection: readonly AgentMessage[]): void {
		scope.assertOwnership();
		const entry = this.sessionManager.getEntry(scope.binding.call.assistantEntryId);
		if (entry?.type !== "message" || entry.message.role !== "assistant")
			throw new Error("Original task assistant is unavailable for paired context restoration");
		const original = this.#obfuscator
			? deobfuscateAgentMessages(this.#obfuscator, [entry.message])[0]
			: entry.message;
		const key = sessionMessagePersistenceKey(original);
		const paired = this.buildDisplaySessionContext().messages;
		const matching = (messages: readonly AgentMessage[]) =>
			messages.filter(message => sessionMessagePersistenceKey(message) === key);
		const expected = matching(paired);
		const prior = matching(priorProjection);
		const current = matching(this.messages);
		if (
			!key ||
			expected.length !== 1 ||
			prior.length > 1 ||
			current.length > 1 ||
			(current.length === 1 &&
				this.#persistedEntryByMessage.has(current[0]) &&
				this.#persistedEntryByMessage.get(current[0]) !== entry.id) ||
			taskRecoveryHash(expected[0]) !== taskRecoveryHash(original) ||
			(current.length === 1 &&
				taskRecoveryHash(current[0]) !== taskRecoveryHash(original) &&
				(prior.length !== 1 || taskRecoveryHash(current[0]) !== taskRecoveryHash(prior[0])))
		)
			throw new Error("Original task assistant projection changed before paired context restoration");
		const remaining = this.messages.filter(message => message !== current[0]);
		const expectedRemaining = paired.filter(message => message !== expected[0]);
		if (
			remaining.length !== expectedRemaining.length ||
			remaining.some((message, index) => taskRecoveryHash(message) !== taskRecoveryHash(expectedRemaining[index]))
		)
			throw new Error("Parent context changed outside the original task assistant projection");
		// Preserve every unrelated live object and all queues. No event or journal append:
		// the original assistant is already durable, now paired by the actual result.
		const restored =
			current.length === 1 && taskRecoveryHash(current[0]) === taskRecoveryHash(original) ? current[0] : expected[0];
		remaining.splice(paired.indexOf(expected[0]), 0, restored);
		scope.assertOwnership();
		this.#persistedEntryByMessage.set(restored, entry.id);
		this.agent.replaceMessages(remaining);
	}

	async #recoverPersistedTaskTurn(
		request: PersistedTurnContinuationRequest,
		binding: PersistedTaskBindingV1,
		signal: AbortSignal,
		generation: number,
	): Promise<void> {
		if (!this.#recoverSynchronousTask)
			throw new PersistedContinuationError(
				"unavailable",
				"Native synchronous task recovery is unavailable in this host",
			);
		const projectionBeforeRecovery = this.buildDisplaySessionContext().messages;
		this.#beginInFlight();
		let currentRequest = { ...request };
		const scope: ParentTaskRecoveryScope = {
			phase: "child",
			loadedPolicyHash: this.#dispatchPolicyHash(),
			validatePolicy: this.#validateSynchronousTaskPolicy
				? () => this.#validateSynchronousTaskPolicy!(binding)
				: undefined,
			binding,
			signal,
			generation,
			revoked: undefined,
			assertOwnership: () => {
				if (scope.loadedPolicyHash !== this.#dispatchPolicyHash())
					this.#revokeTaskRecovery("Loaded parent approval/spawn policy changed before dispatch or attachment");
				this.#assertSynchronousTaskPolicy?.(binding);
				if (scope !== this.#activeTaskRecovery || scope.revoked || signal.aborted)
					throw new Error(scope.revoked ?? "Task result/dispatch scope was revoked");
				this.#assertTaskCompletionOwnership(scope);
				if (scope.phase === "child") {
					this.#assertPersistedLocal(currentRequest, generation, 1);
					this.#boundParentTask(request.entryId);
				} else this.#assertParentTaskRecovery(scope);
				if (
					scope.child &&
					(AgentRegistry.global().get(binding.child.registryId) !== scope.ref ||
						scope.ref?.session !== scope.child ||
						scope.ref.status === "aborted")
				)
					throw new Error("Task child ownership changed before parent attachment");
			},
			advanceExpectedLeaf: entryId => {
				const entry = this.sessionManager.getEntry(entryId);
				if (
					!entry ||
					entry.parentId !== currentRequest.expectedLeafId ||
					this.sessionManager.getLeafId() !== entryId
				)
					this.#revokeTaskRecovery("Task journal append lost its exact prior leaf lease");
				currentRequest = { ...currentRequest, expectedLeafId: entryId };
			},
			validateAuthority: async () => {
				scope.assertOwnership();
				await scope.validatePolicy?.();
				if (scope.validateCompletion) scope.assertCompletionFiles = await scope.validateCompletion();
				const authority = await request.validateDispatch();
				if (!authority.ok) throw new PersistedContinuationError("authority-refused", authority.reason);
				scope.assertOwnership();
			},
		};
		if (this.#activeTaskRecovery) throw new Error("Another task recovery owns this session");
		this.#activeTaskRecovery = scope;
		this.#extensionRunner?.setToolDispatchGuard(signal => this.#prepareBoundTaskDispatch(signal));
		const ignoredTasks = new Set(this.#postPromptTasks);
		let candidateResult: ToolResultMessage | undefined;
		let candidateDurable = false;
		const stopModel = this.agent.addBeforeModelCall(async (_context, signal) => {
			const check = await this.#prepareBoundTaskDispatch(signal);
			check?.();
		});
		const stopQueues = this.agent.addBeforeQueuedMessageDequeueHook(() => {
			if (this.agent.hasQueuedMessages()) this.#revokeTaskRecovery("Queued owner input superseded task recovery");
		});
		try {
			await scope.validateAuthority();
			const persistedResult = this.sessionManager
				.getBranch()
				.find(
					entry =>
						entry.type === "message" &&
						entry.message.role === "toolResult" &&
						entry.message.toolCallId === binding.call.toolCallId,
				);
			if (!persistedResult) {
				const completed = await this.#recoverSynchronousTask({
					binding,
					signal,
					validateAuthority: scope.validateAuthority,
					setPolicyGuard: guard => {
						scope.validatePolicy = guard;
					},
					validateChild: (ref, child) => this.validateTaskRecoveryChild(ref, child),
					prepareReadContinuation: (ref, ready) => {
						scope.assertOwnership();
						if (
							scope.readPreparation ||
							scope.child ||
							AgentRegistry.global().get(ref.id) !== ref ||
							ref.status !== "parked" ||
							ref.session ||
							ref.id !== binding.child.registryId ||
							ref.sessionFile !== binding.child.sessionFile
						)
							throw new Error("Read continuation cannot reserve the exact parked child");
						scope.readPreparation = {
							ref,
							ready: JSON.parse(JSON.stringify(ready)) as TaskReadContinuationCheckpoint,
							expectedLeaf: ready.entryId,
						};
					},
					findNativeResultReady: () => {
						scope.assertOwnership();
						return taskResultRecoveryState(
							this.sessionManager.getEntries(),
							this.sessionManager.getBranch(),
							binding,
						).ready;
					},
					recordNativeResultReady: record => this.#recordNativeTaskResult(scope, record),
					claimResultProcessing: ready => this.#claimTaskResultProcessing(scope, ready),
					assertProcessingOwnership: completion => {
						scope.assertOwnership();
						if (taskRecoveryHash(scope.completion) !== taskRecoveryHash(completion))
							throw new Error("Task result processing caller has no exact core claim");
					},
					setCompletionGuard: guard => {
						scope.assertOwnership();
						scope.validateCompletion = guard;
					},
					pinCompletedChild: ref => {
						scope.assertOwnership();
						if (
							ref.id !== binding.child.registryId ||
							ref.session ||
							ref.status !== "parked" ||
							AgentRegistry.global().get(ref.id) !== ref
						)
							throw new Error("Completed task child is not exclusively parked");
						scope.completedChildRef = ref;
					},
				});
				await scope.validateAuthority();
				scope.assertOwnership();
				if (taskRecoveryHash(completed.completion ?? null) !== taskRecoveryHash(scope.completion ?? null))
					throw new Error("Native task result lost its core processing identity");
				if (taskRecoveryHash(completed.binding) !== taskRecoveryHash(binding) || completed.result.isError)
					throw new Error("Native task did not return the bound successful result");
				const message: ToolResultMessage = {
					role: "toolResult",
					toolCallId: binding.call.toolCallId,
					toolName: "task",
					content: completed.result.content,
					details: completed.result.details,
					isError: false,
					timestamp: Date.now(),
					...(completed.result.providerMetadata ? { providerMetadata: completed.result.providerMetadata } : {}),
				};
				candidateResult = message;
				this.#taskResultCommitScopes.set(message, scope);
				this.agent.emitExternalEvent({
					type: "tool_execution_end",
					toolCallId: message.toolCallId,
					toolName: "task",
					result: completed.result,
					isError: false,
				});
				this.agent.emitExternalEvent({ type: "message_start", message });
				this.agent.emitExternalEvent({ type: "message_end", message });
				await this.#waitForSessionMessagePersistence(message);
				if (scope.revoked) throw new Error(scope.revoked);
				await this.sessionManager.flush();
				this.#boundParentTask(request.entryId);
				const result = this.sessionManager
					.getBranch()
					.find(
						entry =>
							entry.type === "message" &&
							entry.message.role === "toolResult" &&
							entry.message.toolCallId === message.toolCallId,
					);
				if (
					result?.type !== "message" ||
					taskRecoveryHash(result.taskResult) !== taskRecoveryHash(this.#taskResultRef(binding))
				)
					throw new Error("Original task result did not become durable");
				candidateDurable = true;
				scope.assertOwnership();
			}
			await scope.validateAuthority();
			if (candidateDurable) this.#restorePairedTaskAssistant(scope, projectionBeforeRecovery);
			const resultEntry = this.sessionManager
				.getBranch()
				.find(
					entry =>
						entry.type === "message" &&
						entry.message.role === "toolResult" &&
						entry.message.toolCallId === binding.call.toolCallId,
				);
			if (!resultEntry) throw new Error("Original task result is unavailable for parent continuation");
			scope.resultEntryId = resultEntry.id;
			scope.parentRuntime = taskRuntimeContract(this);
			scope.parentTools = this.agent.state.tools.map(tool => ({ tool, execute: tool.execute }));
			scope.phase = "parent";
			await this.#executePersistedPrompt(currentRequest, signal, generation, 1);
			if (scope.revoked) throw new Error(scope.revoked);
			await this.#drainInFlightEventHandlers();
			await this.#waitForPostPromptRecovery(generation, ignoredTasks);
		} catch (error) {
			if (candidateResult && !candidateDurable) this.#discardUncommittedTaskResult(candidateResult);
			throw error;
		} finally {
			stopModel();
			stopQueues();
			scope.releaseChild?.();
			scope.releaseChild = undefined;
			scope.child = undefined;
			scope.ref = undefined;
			if (this.#activeTaskRecovery === scope) this.#activeTaskRecovery = undefined;
			this.#endInFlight();
		}
	}

	async #hasDurableTaskDelivery(ref: AgentRef, child: SessionManager): Promise<boolean> {
		const file = this.sessionFile;
		const sessionId = this.sessionId;
		const parentScope = this.#activeTaskRecovery;
		if (!file) return false;
		const branch = this.sessionManager.getBranch();
		const branchHash = taskRecoveryHash(branch);
		const entries = this.sessionManager.getEntries();
		const childEntries = child.getEntries();
		const childHash = taskRecoveryHash(childEntries);
		const childLeaf = child.getLeafId();
		const childFile = child.getSessionFile();
		const childCwd = child.getCwd();
		const bindings = branch
			.map(readTaskBinding)
			.filter(
				binding =>
					binding?.child.registryId === ref.id &&
					binding.child.sessionFile === ref.sessionFile &&
					binding.child.sessionId === child.getSessionId() &&
					binding.call.sessionId === sessionId,
			);
		if (bindings.length !== 1) return false;
		const binding = bindings[0]!;
		const expected = this.#taskResultRef(binding);
		if (!expected.completion) return false;
		const delivered = branch.filter(
			entry =>
				entry.type === "message" &&
				entry.message.role === "toolResult" &&
				entry.message.toolCallId === binding.call.toolCallId &&
				!entry.message.isError &&
				taskRecoveryHash(entry.taskResult) === taskRecoveryHash(expected),
		);
		if (delivered.length !== 1) return false;
		const deliveryBranch = branch.slice(0, branch.indexOf(delivered[0]) + 1);
		const complete = taskResultRecoveryState(entries, branch, binding).ready;
		if (!complete) return false;
		const completedIndex = childEntries.findIndex(entry => entry.id === complete.record.child.leafId);
		if (completedIndex < 0) return false;
		const completedEntries = childEntries.slice(0, completedIndex + 1);
		if (
			taskRecoveryHash(completedEntries) !== complete.record.child.entriesSha256 ||
			taskRecoveryHash(child.getBranch(complete.record.child.leafId)) !== complete.record.child.branchSha256
		)
			return false;
		const markers = childEntries.filter(
			entry =>
				entry.type === "custom" &&
				(entry.customType === TASK_READ_CONTINUATION_READY || entry.customType === TASK_READ_CONTINUATION_STARTED),
		);
		if (
			markers.some(
				entry =>
					entry.type !== "custom" ||
					!isRecord(entry.data) ||
					taskRecoveryHash(entry.data.call) !== taskRecoveryHash(binding.call) ||
					entry.data.contractSha256 !== binding.contractSha256 ||
					!completedEntries.some(done => done.id === entry.id),
			)
		)
			return false;
		const saved = await loadSessionFile(file);
		if (
			this.sessionFile !== file ||
			this.sessionId !== sessionId ||
			this.#activeTaskRecovery !== parentScope ||
			taskRecoveryHash(this.sessionManager.getBranch()) !== branchHash ||
			child.getLeafId() !== childLeaf ||
			child.getSessionFile() !== childFile ||
			child.getCwd() !== childCwd ||
			fs.existsSync(getAgentTombstonePath(childFile!)) ||
			taskRecoveryHash(child.getEntries()) !== childHash ||
			AgentRegistry.global().get(ref.id) !== ref ||
			ref.session ||
			ref.status !== "parked" ||
			saved.malformedRecords ||
			!saved.entries.some(entry => entry.type === "session" && entry.id === sessionId)
		)
			return false;
		const durable = new Map(saved.entries.map(entry => [entry.id, entry]));
		return deliveryBranch.every(
			entry => durable.has(entry.id) && taskRecoveryHash(durable.get(entry.id)) === taskRecoveryHash(entry),
		);
	}

	/** Called only inside the coalesced cold reviver, after its sole open and before SDK/startup effects. */
	async prepareTaskRecoveryRevival(ref: AgentRef, manager: SessionManager): Promise<void> {
		const scope = this.#activeTaskRecovery;
		if (!scope || !this.isTaskRecoveryRevival(ref)) {
			if (!hasTaskReadContinuationMarkers(manager.getEntries())) return;
			if (await this.#hasDurableTaskDelivery(ref, manager)) return;
			throw new Error("Undelivered read continuation requires its exact bound recovery owner before startup");
		}
		if (scope.completedChildRef)
			this.#revokeTaskRecovery("Completed task cannot be revived during cached result processing");
		if (!AgentLifecycleManager.global().hasPendingRevival(ref.id, ref))
			throw new Error("Read preparation requires the existing managed revival operation");
		const prepared = scope.readPreparation;
		if (!prepared) {
			const classification = classifyTaskChildContinuation(manager.getEntries(), manager.getBranch(), scope.binding);
			if (classification.kind === "read")
				throw new Error("Read continuation was not reserved before managed revival");
			return;
		}
		if (prepared.ref !== ref || (prepared.manager && prepared.manager !== manager))
			throw new Error("Another manager owns bound read revival preparation");
		if (prepared.pending) return prepared.pending;
		prepared.manager = manager;
		const check = () => {
			if (
				this.#activeTaskRecovery !== scope ||
				!AgentLifecycleManager.global().hasPendingRevival(ref.id, ref) ||
				scope.revoked ||
				scope.signal.aborted ||
				scope.child ||
				prepared.manager !== manager ||
				AgentRegistry.global().get(ref.id) !== ref ||
				ref.status !== "parked" ||
				ref.session ||
				ref.sessionFile !== scope.binding.child.sessionFile ||
				manager.getSessionId() !== scope.binding.child.sessionId ||
				manager.getSessionFile() !== scope.binding.child.sessionFile ||
				manager.getCwd() !== scope.binding.child.cwd ||
				manager.getLeafId() !== prepared.expectedLeaf ||
				fs.existsSync(getAgentTombstonePath(scope.binding.child.sessionFile))
			)
				throw new Error("Read revival lost parked ref, manager, path or journal lease");
			scope.assertOwnership();
		};
		prepared.pending = (async () => {
			check();
			prepared.claim = await claimTaskReadContinuation(
				manager,
				scope.binding,
				prepared.ready,
				"cold-resume",
				scope.validateAuthority,
				check,
				id => {
					prepared.expectedLeaf = id;
				},
			);
			check();
		})().catch(error => {
			if (this.#activeTaskRecovery === scope) this.invalidateTaskRecovery(String(error));
			throw error;
		});
		return prepared.pending;
	}

	/** True only for the exact child selected by this parent's native recovery. */
	isTaskRecoveryRevival(ref: AgentRef): boolean {
		const scope = this.#activeTaskRecovery;
		return (
			scope !== undefined &&
			scope.binding.child.registryId === ref.id &&
			scope.binding.child.sessionFile === ref.sessionFile
		);
	}

	/** SDK calls synchronously before making a rebuilt child reachable by peers. */
	installTaskRecoveryChild(ref: AgentRef, child: AgentSession): void {
		const parent = this.#activeTaskRecovery;
		if (parent?.completedChildRef)
			this.#revokeTaskRecovery("Completed task cannot be revived during cached result processing");
		if (
			!parent ||
			!this.isTaskRecoveryRevival(ref) ||
			parent.signal.aborted ||
			parent.revoked ||
			parent.child ||
			ref.status === "aborted" ||
			ref.session
		)
			throw new Error("Task revival no longer exclusively owns the original child");
		if (child.sessionId !== parent.binding.child.sessionId || child.sessionFile !== parent.binding.child.sessionFile)
			throw new Error("Revived task session identity differs");
		if (
			parent.readPreparation &&
			(!parent.readPreparation.claim ||
				parent.readPreparation.manager !== child.sessionManager ||
				parent.readPreparation.ref !== ref)
		)
			throw new Error("Read continuation claim did not precede this exact SDK manager");
		const scope: ChildTaskRecoveryScope = {
			parent,
			context: child.#taskRecoveryOwner,
			token: {},
			driverActive: false,
			loadedPolicyHash: child.#dispatchPolicyHash(),
			generation: child.#promptGeneration,
		};
		child.#childTaskRecovery = scope;
		const stopReadErrors = child.#extensionRunner?.onError(error => child.#noteTaskReadFailure(scope, error.error));
		child.#extensionRunner?.setToolDispatchGuard(signal => child.#prepareBoundTaskDispatch(signal));
		parent.child = child;
		parent.ref = ref;
		const stopModel = child.agent.addBeforeModelCall(async (_context, signal) => {
			const check = await child.#prepareBoundTaskDispatch(signal);
			check?.();
		});
		const stopQueues = child.agent.addBeforeQueuedMessageDequeueHook(() => {
			if (child.agent.hasQueuedMessages())
				child.#revokeTaskRecovery("Foreign queued input arrived during bound task recovery");
		});
		parent.releaseChild = () => {
			stopReadErrors?.();
			scope.driverActive = false;
			stopModel();
			stopQueues();
			if (child.#childTaskRecovery === scope) child.#childTaskRecovery = undefined;
		};
	}

	/** Rechecked after SDK tool registration/clamping and again before the driver. */
	async validateTaskRecoveryChild(ref: AgentRef, child: AgentSession): Promise<void> {
		const scope = this.#activeTaskRecovery;
		if (!scope || scope.child !== child || scope.ref !== ref || !child.#childTaskRecovery)
			throw new Error("Task recovery lost its exact revived child");
		if (AgentRegistry.global().get(ref.id) !== ref) throw new Error("Original child registry generation changed");
		await scope.validateAuthority();
		if (
			child.sessionFile !== scope.binding.child.sessionFile ||
			child.sessionManager.getCwd() !== scope.binding.child.cwd
		)
			throw new Error("Original child session path or workspace changed during revival");
		const init = child.sessionManager.getEntry(scope.binding.child.initEntryId);
		if (
			init?.type !== "session_init" ||
			taskRecoveryHash(init.taskCall) !== taskRecoveryHash(scope.binding.call) ||
			taskRecoveryHash(initializationContract(init)) !== taskRecoveryHash(scope.binding.contract.initialization)
		)
			throw new Error("Revived child initialization or reverse binding differs");
		if (
			child.asyncJobManager ||
			cfgAdvisorEnabled.get(child.settings) ||
			taskRecoveryHash(taskRuntimeContract(child)) !== taskRecoveryHash(scope.binding.contract.runtime)
		)
			throw new Error("Revived child model/tool/async/advisor contract differs");
		const classification = classifyTaskChildContinuation(
			child.sessionManager.getEntries(),
			child.sessionManager.getBranch(),
			scope.binding,
			scope.readPreparation?.claim,
		);
		const anchor = classification.anchorEntryId;
		if (classification.kind === "read") {
			if (
				!scope.readPreparation?.claim ||
				scope.readPreparation.manager !== child.sessionManager ||
				classification.ready.sha256 !== scope.readPreparation.ready.sha256
			)
				throw new Error("Revived read continuation lost its exact owned claim");
			const assistant = child.#messageForPersistedEntry(classification.ready.record.read.assistantEntryId);
			child.#messageForPersistedEntry(classification.ready.record.read.resultEntryId);
			if (assistant.role !== "assistant") throw new Error("Read continuation assistant projection is unavailable");
			child.#childTaskRecovery.readProtocolEntered = true;
			child.#childTaskRecovery.read = {
				assistant,
				toolCallId: classification.ready.record.read.toolCallId,
				arguments: classification.ready.record.read.arguments,
				native: classification.ready.record.read.native,
				nativeResultSha256: classification.ready.record.read.nativeResultSha256,
				turnEnd: Promise.resolve(),
				resolveTurnEnd: () => {},
				turnEndSeen: true,
				ready: classification.ready,
				claim: scope.readPreparation.claim,
				responsePending: true,
				expectedLeaf: scope.readPreparation.claim.entryId,
				claiming: Promise.resolve(),
			};
		} else child.#classifyPersistedTurn(anchor, false, scope.binding);
		child.#childTaskRecovery.anchorEntryId = anchor;
		child.#childTaskRecovery.tools = child.agent.state.tools.map(tool => ({ tool, execute: tool.execute }));
	}

	#revokeTaskRecovery(reason: string): never {
		this.invalidateTaskRecovery(reason);
		throw new Error(reason);
	}

	#assertTaskRecoveryInput(kind?: "prompt"): void {
		const scope = this.#childTaskRecovery;
		if (scope) {
			const permitted =
				kind === "prompt" && this.#taskControlPermit === "prompt" && scope.driverActive && !scope.parent.revoked;
			this.#taskControlPermit = undefined;
			if (!permitted) this.#revokeTaskRecovery("Public input cannot take over a bound task recovery");
		} else if (this.#activeTaskRecovery) {
			this.invalidateTaskRecovery("Owner input superseded parent task recovery");
		}
	}

	#checkTaskRecoveryDriver(
		signal?: AbortSignal,
		initialContext?: Context,
		initialProjection?: readonly Message[],
	): void {
		const scope = this.#childTaskRecovery;
		if (!scope) return;
		if (scope.readProtocolEntered && scope.readFailure) this.#revokeTaskRecovery(scope.readFailure);
		if (!scope.driverActive || scope.context.getStore() !== scope.token)
			this.#revokeTaskRecovery("No original task driver owns dispatch");
		if (signal?.aborted) signal.throwIfAborted();
		if (scope.loadedPolicyHash !== this.#dispatchPolicyHash())
			this.#revokeTaskRecovery("Loaded child approval/spawn policy changed before dispatch");
		if (
			scope.parent.signal.aborted ||
			scope.parent.revoked ||
			this.#isDisposed ||
			this.#abortInProgress ||
			this.isCompacting ||
			this.isGeneratingHandoff ||
			scope.parent.child !== this ||
			scope.parent.binding.child.sessionId !== this.sessionId ||
			scope.parent.binding.child.sessionFile !== this.sessionFile ||
			scope.parent.binding.child.cwd !== this.sessionManager.getCwd() ||
			AgentRegistry.global().get(scope.parent.binding.child.registryId) !== scope.parent.ref ||
			scope.parent.ref?.session !== this ||
			scope.parent.ref.status === "aborted"
		)
			this.#revokeTaskRecovery(scope.parent.revoked ?? "Bound task recovery lost dispatch ownership");
		let initial = false;
		if (!scope.anchorEntryId && initialContext && scope.parent.original && scope.initialDispatch === "armed") {
			const batch = scope.initialBatch;
			if (
				!batch ||
				batch !== this.#activePromptPreparation ||
				batch.generation !== this.#promptGeneration ||
				batch.sessionId !== this.sessionId ||
				batch.taskBindingId !== scope.parent.binding.call.bindingId ||
				batch.anchor?.role !== "user" ||
				batch.anchor.attribution !== "agent" ||
				!scope.initialMessages ||
				taskRecoveryHash(scope.initialMessages) !== scope.initialMessagesHash
			)
				this.#revokeTaskRecovery("Original initial task preparation lost its core identity");
			if (
				initialProjection &&
				(initialProjection.length !== initialContext.messages.length ||
					initialProjection.some((message, index) => !sameMessageContent(message, initialContext.messages[index])))
			)
				this.#revokeTaskRecovery("Original task provider context differs from its core initial preparation");
			initial = true;
		}
		if (scope.read?.claim && scope.read.responsePending) {
			if (this.sessionManager.getLeafId() !== scope.read.expectedLeaf)
				throw new Error("Claimed read prefix changed before response dispatch");
			classifyTaskChildContinuation(
				this.sessionManager.getEntries(),
				this.sessionManager.getBranch(),
				scope.parent.binding,
				scope.read.claim,
			);
		}
		const branch = this.sessionManager.getBranch();
		const initIndex = branch.findIndex(entry => entry.id === scope.parent.binding.child.initEntryId);
		if (
			scope.generation !== this.#promptGeneration ||
			initIndex < 0 ||
			(!initial && (!scope.anchorEntryId || !branch.some(entry => entry.id === scope.anchorEntryId))) ||
			branch
				.slice(initIndex + 1)
				.some(
					entry =>
						entry.type === "compaction" || entry.type === "reset_boundary" || entry.type === "branch_summary",
				)
		)
			this.#revokeTaskRecovery("Original child generation or active ancestry changed");
		if (scope.anchorEntryId) this.#messageForPersistedEntry(scope.anchorEntryId);
		if (this.agent.hasQueuedMessages() || this.#irc.hasPending() || this.#pendingNextTurnMessages.length > 0)
			this.#revokeTaskRecovery("Queued input conflicts with bound task recovery");
		if (
			taskRecoveryHash(taskRuntimeContract(this)) !== taskRecoveryHash(scope.parent.binding.contract.runtime) ||
			scope.tools?.some(
				({ tool, execute }, index) => this.agent.state.tools[index] !== tool || tool.execute !== execute,
			)
		)
			this.#revokeTaskRecovery("Bound task model or executable tool contract changed");
	}

	#dispatchPolicyHash(): string {
		return taskRecoveryHash({
			approval: cfgToolsApproval.get(this.settings),
			mode: cfgToolsApprovalMode.get(this.settings),
			roles: this.settings.getModelRoles(),
			async: cfgAsyncEnabled.get(this.settings),
			batch: cfgTaskBatch.get(this.settings),
			isolation: cfgTaskIsolationEnabled.get(this.settings),
			depth: cfgTaskMaxRecursionDepth.get(this.settings),
			disabledAgents: cfgTaskDisabledAgents.get(this.settings),
			prewalk: cfgTaskPrewalk.get(this.settings),
			agentPrewalk: cfgTaskAgentPrewalk.get(this.settings),
			agentAdvisor: cfgTaskAgentAdvisor.get(this.settings),
			modelOverride: cfgTaskAgentModelOverrides.get(this.settings),
		});
	}

	#assertTaskCompletionOwnership(scope: ParentTaskRecoveryScope): void {
		if (
			scope.completedChildRef &&
			(AgentRegistry.global().get(scope.binding.child.registryId) !== scope.completedChildRef ||
				scope.completedChildRef.session !== null ||
				scope.completedChildRef.status !== "parked")
		)
			this.#revokeTaskRecovery("Completed task child acquired a different execution owner");
		if (
			scope.completion &&
			taskRecoveryHash(this.#taskResultRef(scope.binding).completion) !== taskRecoveryHash(scope.completion)
		)
			this.#revokeTaskRecovery("Task completion/processing ownership changed");
		scope.assertCompletionFiles?.();
	}

	#assertParentTaskRecovery(scope: ParentTaskRecoveryScope, signal?: AbortSignal): void {
		this.#assertTaskCompletionOwnership(scope);
		if (scope.loadedPolicyHash !== this.#dispatchPolicyHash())
			this.#revokeTaskRecovery("Loaded parent policy changed during final authorization await");
		this.#assertSynchronousTaskPolicy?.(scope.binding);
		if (
			scope !== this.#activeTaskRecovery ||
			scope.phase !== "parent" ||
			scope.revoked ||
			signal?.aborted ||
			scope.signal.aborted ||
			this.#isDisposed ||
			this.#abortInProgress ||
			scope.generation !== this.#promptGeneration ||
			scope.binding.call.sessionId !== this.sessionId ||
			this.isCompacting ||
			this.isGeneratingHandoff
		)
			this.#revokeTaskRecovery(scope.revoked ?? "Parent task continuation lost ownership");
		if (this.agent.hasQueuedMessages() || this.#pendingNextTurnMessages.length > 0 || this.#irc.hasPending())
			this.#revokeTaskRecovery("Owner input superseded parent task continuation");
		const branch = this.sessionManager.getBranch();
		const call = scope.binding.call;
		const anchorIndex = branch.findIndex(entry => entry.id === call.promptEntryId);
		const assistantIndex = branch.findIndex(entry => entry.id === call.assistantEntryId);
		const resultIndex = branch.findIndex(entry => entry.id === scope.resultEntryId);
		const result = branch[resultIndex];
		const binding = branch.map(readTaskBinding).filter(value => value?.call.bindingId === call.bindingId);
		if (
			anchorIndex < 0 ||
			assistantIndex <= anchorIndex ||
			resultIndex <= assistantIndex ||
			binding.length !== 1 ||
			taskRecoveryHash(binding[0]) !== taskRecoveryHash(scope.binding) ||
			result?.type !== "message" ||
			result.message.role !== "toolResult" ||
			result.message.isError ||
			taskRecoveryHash(result.taskResult) !== taskRecoveryHash(this.#taskResultRef(scope.binding)) ||
			branch
				.slice(anchorIndex + 1)
				.some(
					entry =>
						entry.type === "compaction" || entry.type === "branch_summary" || entry.type === "reset_boundary",
				)
		)
			this.#revokeTaskRecovery("Parent original task/result ancestry changed during continuation");
		this.#messageForPersistedEntry(call.promptEntryId);
		this.#messageForPersistedEntry(call.assistantEntryId);
		this.#messageForPersistedEntry(result.id);
		if (
			!scope.parentTools ||
			scope.parentTools.length !== this.agent.state.tools.length ||
			scope.parentTools.some(
				({ tool, execute }, index) => this.agent.state.tools[index] !== tool || tool.execute !== execute,
			)
		)
			this.#revokeTaskRecovery("Parent executable tool ownership changed during task continuation");
		if (taskRecoveryHash(taskRuntimeContract(this)) !== taskRecoveryHash(scope.parentRuntime))
			this.#revokeTaskRecovery("Parent model or tool contract changed during task continuation");
	}

	#prepareBoundTaskDispatch(signal?: AbortSignal, initialContext?: Context): Promise<() => void> | undefined {
		const scope = this.#childTaskRecovery;
		if (!scope) {
			const parent = this.#activeTaskRecovery;
			if (!parent) return undefined;
			return (async () => {
				this.#assertParentTaskRecovery(parent, signal);
				try {
					await parent.validateAuthority();
				} catch (error) {
					this.invalidateTaskRecovery(String(error));
					throw error;
				}
				this.#assertParentTaskRecovery(parent, signal);
				return () => this.#assertParentTaskRecovery(parent, signal);
			})();
		}
		return (async () => {
			let initialProjection: readonly Message[] | undefined;
			if (!initialContext && scope.parent.original && !scope.anchorEntryId && scope.preparationReady)
				await untilAborted(signal ?? scope.parent.signal, scope.preparationReady);
			this.#checkTaskRecoveryDriver(signal, initialContext, initialProjection);
			try {
				if (initialContext && scope.initialDispatch === "armed" && scope.initialMessages) {
					const converted = await this.#convertToLlm([...scope.initialMessages]);
					initialProjection = (await this.agent.buildSideRequestContext(converted)).messages;
					this.#checkTaskRecoveryDriver(signal, initialContext, initialProjection);
				}
				await scope.parent.validateAuthority();
			} catch (error) {
				this.invalidateTaskRecovery(String(error));
				throw error;
			}
			this.#checkTaskRecoveryDriver(signal, initialContext, initialProjection);
			return () => {
				this.#checkTaskRecoveryDriver(signal, initialContext, initialProjection);
				if (initialContext && scope.initialDispatch === "armed") scope.initialDispatch = "dispatched";
			};
		})();
	}

	#boundTaskDriverControls(scope: ChildTaskRecoveryScope): BoundTaskDriverControls {
		return {
			prompt: (text, options) =>
				scope.context.run(scope.token, () => {
					this.#taskControlPermit = "prompt";
					try {
						return this.prompt(text, options);
					} finally {
						this.#taskControlPermit = undefined;
					}
				}),
			abort: () => {
				const aborted = scope.context.run(scope.token, () => {
					this.#taskControlPermit = "abort";
					try {
						return this.abort();
					} finally {
						this.#taskControlPermit = undefined;
					}
				});
				return aborted.finally(() => {
					if (!scope.parent.revoked) scope.generation = this.#promptGeneration;
				});
			},
		};
	}

	/** Called only by the task-owned monitored driver after guarded cold revival. */
	async runBoundTaskRecovery<T>(
		binding: PersistedTaskBindingV1,
		run: (start: () => Promise<void>, controls: BoundTaskDriverControls) => Promise<T>,
	): Promise<T> {
		const scope = this.#childTaskRecovery;
		if (!scope || scope.driverActive || taskRecoveryHash(binding) !== taskRecoveryHash(scope.parent.binding))
			throw new Error("No exclusive task recovery driver owns this child");
		scope.driverActive = true;
		try {
			return await scope.context.run(scope.token, async () => {
				this.#checkTaskRecoveryDriver();
				if (scope.read?.claim) {
					const controls = this.#boundTaskDriverControls(scope);
					return run(async () => {
						this.#beginInFlight();
						try {
							await scope.parent.validateAuthority();
							this.#checkTaskRecoveryDriver();
							this.#messageForPersistedEntry(scope.read!.ready!.record.read.assistantEntryId);
							this.#messageForPersistedEntry(scope.read!.ready!.record.read.resultEntryId);
							classifyTaskChildContinuation(
								this.sessionManager.getEntries(),
								this.sessionManager.getBranch(),
								binding,
								scope.read!.claim,
							);
							if (scope.parent.readPreparation?.manager !== this.sessionManager)
								throw new Error("Read continuation manager changed before dispatch");
							await this.agent.continue(scope.parent.signal);
						} finally {
							this.#endInFlight();
						}
					}, controls);
				}
				const records = this.sessionManager
					.getBranch()
					.map(readPreparationRecord)
					.filter(record => record?.taskBindingId === binding.call.bindingId);
				const anchors = new Set(records.map(record => record!.anchorEntryId));
				if (anchors.size !== 1) throw new Error("Task recovery original prompt association differs");
				const request: PersistedTurnContinuationRequest = {
					sessionId: this.sessionId,
					entryId: [...anchors][0],
					expectedLeafId: this.sessionManager.getLeafId()!,
					validateDispatch: async () => {
						await scope.parent.validateAuthority();
						return { ok: true };
					},
				};
				const controls = this.#boundTaskDriverControls(scope);
				return run(
					() => this.#executePersistedPrompt(request, scope.parent.signal, this.#promptGeneration, 0, binding),
					controls,
				);
			});
		} finally {
			scope.driverActive = false;
		}
	}

	invalidateTaskRecovery(reason: string): void {
		const child = this.#childTaskRecovery;
		const scope = child?.parent ?? this.#activeTaskRecovery;
		if (!scope) return;
		scope.revoked ??= reason;
		if (scope.original) {
			scope.original.failure ??= new Error(reason);
			scope.original.rejectDurable(scope.original.failure);
		}
		if (child) child.driverActive = false;
		if (scope.child && scope.child.#childTaskRecovery) scope.child.#childTaskRecovery.driverActive = false;
		scope.child?.agent.abort();
		this.agent.abort();
	}

	#skipAgentContinue(reason: AgentContinueSkipReason, request: ScheduledAgentContinueRequest): void {
		logger.debug("agent.continue skipped after scheduling", {
			reason,
			source: request.options.source,
			schedulerToken: request.schedulerToken,
		});
		request.options.onSkip?.(reason);
	}

	#handleAgentContinueOutcome(outcome: AgentContinueOutcome, request: ScheduledAgentContinueRequest): void {
		if (outcome.status === "skipped") {
			this.#skipAgentContinue(outcome.reason, request);
		} else if (outcome.status === "failed") {
			request.options.onError?.(outcome.error);
		}
	}

	async #runAgentContinue(
		signal: AbortSignal,
		request: ScheduledAgentContinueRequest,
		coalescedSources: Set<string>,
	): Promise<AgentContinueOutcome> {
		try {
			const reverted = await this.#recovery.maybeRestoreRetryFallbackPrimary();
			if (signal.aborted || this.#isDisposed) {
				return { status: "skipped", reason: "post-restore-unavailable" };
			}
			// A cooldown-expiry revert can drop the active window below the
			// accumulated context. The user-prompt path re-checks context after
			// the revert via runPrePromptCompactionIfNeeded; the auto-continue
			// path must do the same so agent.continue() never sends a
			// predictably oversized request to the reverted (smaller) model.
			if (reverted) {
				await this.#maintenance.runPrePromptCompactionIfNeeded([]);
				if (signal.aborted || this.#isDisposed) {
					return { status: "skipped", reason: "post-restore-unavailable" };
				}
			}
			if (cfgRetryUsageAwareFallback.get(this.settings)) {
				if (!(await this.#runQueuedUsageAwarePreflight(signal))) {
					return { status: "skipped", reason: "session-unavailable" };
				}
			}
			for (;;) {
				try {
					await this.agent.continue(signal);
					return { status: "completed" };
				} catch (error) {
					if (!(error instanceof AgentBusyError)) throw error;

					// A local scheduling overlap is not a failed continuation. Let the
					// active run and its async agent_end routing settle, then revalidate
					// this request before claiming the agent again.
					logger.debug("agent.continue waiting for active run", {
						source: request.options.source,
						schedulerToken: request.schedulerToken,
					});
					await this.agent.waitForIdle();
					await this.#drainInFlightEventHandlers();
					if (signal.aborted || this.#isDisposed || this.isCompacting || this.isGeneratingHandoff) {
						return { status: "skipped", reason: "session-unavailable" };
					}
					if (request.options.generation !== undefined && this.#promptGeneration !== request.options.generation) {
						return { status: "skipped", reason: "stale-generation" };
					}
					if (request.options.shouldContinue && !request.options.shouldContinue()) {
						return { status: "skipped", reason: "should-continue-false" };
					}
				}
			}
		} catch (error) {
			logger.warn("agent.continue failed after scheduling", {
				source: request.options.source,
				schedulerToken: request.schedulerToken,
				coalescedSources: [...coalescedSources].filter(source => source !== request.options.source),
				error: error instanceof Error ? error.message : String(error),
				stack: error instanceof Error ? error.stack : undefined,
			});
			return { status: "failed", error };
		}
	}

	#scheduleAgentContinue(options: ScheduledAgentContinueOptions): void {
		const request: ScheduledAgentContinueRequest = {
			schedulerToken: ++this.#agentContinueSchedulerToken,
			options,
		};
		logger.debug("agent.continue scheduled", {
			source: options.source,
			schedulerToken: request.schedulerToken,
		});
		this.#schedulePostPromptTask(
			async signal => {
				// Defense in depth: if compaction/handoff slipped onto the post-prompt queue
				// alongside us (e.g. via a scheduler we don't own), refuse to start a fresh
				// streaming turn — agent.continue() here would race the handoff's session
				// reset. The first-class fix is in #checkCompaction/the agent_end handler,
				// but this guard catches anything that bypasses that path.
				if (signal.aborted || this.#isDisposed || this.isCompacting || this.isGeneratingHandoff) {
					this.#skipAgentContinue("session-unavailable", request);
					return;
				}
				if (options.shouldContinue && !options.shouldContinue()) {
					this.#skipAgentContinue("should-continue-false", request);
					return;
				}

				const active = this.#activeAgentContinue;
				if (active) {
					active.coalescedSources.add(options.source);
					logger.debug("agent.continue coalesced after scheduling", {
						source: options.source,
						schedulerToken: request.schedulerToken,
						activeSource: active.source,
						activeSchedulerToken: active.schedulerToken,
					});
					this.#handleAgentContinueOutcome(await active.promise, request);
					return;
				}

				this.#beginInFlight();
				const coalescedSources = new Set([options.source]);
				const promise = this.#runAgentContinue(signal, request, coalescedSources);
				const attempt: ActiveAgentContinue = {
					schedulerToken: request.schedulerToken,
					source: options.source,
					coalescedSources,
					promise,
				};
				this.#activeAgentContinue = attempt;
				try {
					this.#handleAgentContinueOutcome(await promise, request);
				} finally {
					// Clear the active attempt BEFORE #endInFlight(): the settle drain it
					// triggers (#drainStrandedQueuedMessages -> queued-message-drain) runs
					// synchronously and must start a fresh continue for messages queued
					// after this attempt's final poll, not coalesce onto the finished one.
					if (this.#activeAgentContinue === attempt) {
						this.#activeAgentContinue = undefined;
					}
					this.#usagePreflightReadyForNextModelCall = false;
					this.#endInFlight();
				}
			},
			{
				delayMs: options.delayMs,
				generation: options.generation,
				onSkip: reason => this.#skipAgentContinue(reason, request),
			},
		);
	}

	#scheduleCompactionContinuation(options: {
		generation: number;
		autoContinue: boolean;
		terminalTextAnswer: boolean;
		suppressContinuation: boolean;
	}): boolean {
		if (options.suppressContinuation) return false;
		if (this.agent.hasQueuedMessages()) {
			this.#scheduleAgentContinue({
				source: "compaction-queued-message",
				delayMs: 100,
				generation: options.generation,
				shouldContinue: () => this.agent.hasQueuedMessages(),
			});
			return true;
		}
		if (!options.autoContinue) return false;
		const activeGoal = this.#goalModeState?.enabled === true && this.#goalModeState.goal.status === "active";
		if (options.terminalTextAnswer && !activeGoal) return false;
		return this.#scheduleAutoContinuePrompt(options.generation);
	}

	#scheduleAutoContinuePrompt(generation: number): boolean {
		const continuePrompt = async () => {
			// Compaction summarizes away the first-message eager preludes, so re-assert the
			// delegate-via-tasks / phased-todo reminders on this auto-resumed turn. This runs
			// at invocation (past the abort check below), so an aborted continuation queues
			// nothing; scoped to this request via prependMessages, never the shared queue.
			const eagerNudges = this.#todo.buildPostCompactionEagerNudges();
			await this.#promptWithMessage(
				{
					role: "developer",
					content: [{ type: "text", text: autoContinuePrompt }],
					attribution: "agent",
					timestamp: Date.now(),
					// Distinguishes this run-initiating prompt from same-turn
					// continuation reminders (todo/plan) that are also persisted as
					// developer messages; replay uses it for the prompt→yield anchor.
					synthetic: true,
				},
				autoContinuePrompt,
				{
					skipPostPromptRecoveryWait: true,
					prependMessages: eagerNudges.length > 0 ? eagerNudges : undefined,
				},
			);
		};
		this.#schedulePostPromptTask(
			async signal => {
				await Promise.resolve();
				if (signal.aborted) return;
				if (this.agent.hasQueuedMessages()) {
					this.#scheduleAgentContinue({
						source: "auto-continue-queued-message",
						generation,
						shouldContinue: () => this.agent.hasQueuedMessages(),
					});
					return;
				}
				await continuePrompt();
			},
			{ generation },
		);
		return true;
	}

	async #cancelPostPromptTasks(): Promise<void> {
		this.#postPromptTasksAbortController.abort();
		this.#postPromptTasksAbortController = new AbortController();
		this.#ttsr.resolveResume();

		const pendingTasks = Array.from(this.#postPromptTasks);
		if (pendingTasks.length === 0) {
			this.#resolvePostPromptTasks();
			return;
		}

		await Promise.allSettled(pendingTasks);
		if (this.#postPromptTasks.size === 0) {
			this.#resolvePostPromptTasks();
		}
	}
	/**
	 * Wait for retry, TTSR resume, and any background continuation to settle.
	 * Loops because a TTSR continuation can trigger a retry (or vice-versa),
	 * and fire-and-forget `agent.continue()` may still be streaming after
	 * the TTSR resume gate resolves.
	 */
	async #waitForPostPromptRecovery(generation?: number, ignoredTasks?: ReadonlySet<Promise<unknown>>): Promise<void> {
		while (true) {
			// An abort bumps #promptGeneration. When this wait runs on behalf of a
			// specific prompt turn, stop as soon as that turn has been superseded:
			// its promise must resolve on the abort, not block on a queued
			// steer/follow-up that the post-abort drain starts as a fresh turn.
			if (generation !== undefined && this.#promptGeneration !== generation) return;
			const retryPromise = this.#recovery.retryPromise;
			if (retryPromise) {
				await retryPromise;
				continue;
			}
			const ttsrResumeGate = this.#ttsr.resumeGate;
			if (ttsrResumeGate) {
				await ttsrResumeGate;
				continue;
			}
			if (this.#postPromptTasksPromise) {
				const tasks = ignoredTasks ? [...this.#postPromptTasks].filter(task => !ignoredTasks.has(task)) : undefined;
				if (!tasks || tasks.length > 0) {
					await (tasks ? Promise.allSettled(tasks) : this.#postPromptTasksPromise);
					continue;
				}
			}
			// Tracked post-prompt tasks cover deferred continuations scheduled from
			// event handlers. Keep the streaming fallback for direct agent activity
			// outside the scheduler.
			if (this.agent.state.isStreaming) {
				await this.agent.waitForIdle();
				continue;
			}
			break;
		}
	}

	#afterToolCall(ctx: AfterToolCallContext): AfterToolCallResult | undefined {
		const assistantOrigin = assistantSnapshotOrigin(ctx.assistantMessage);
		if (assistantOrigin) this.#taskCallAuthorities.get(assistantOrigin)?.delete(ctx.toolCall.id);
		const bound = this.#boundTaskCalls.get(ctx.toolCall.id);
		if (bound) bound.authority = undefined;
		if (
			this.#isTerminalYieldToolResult({
				toolName: ctx.toolCall.name,
				isError: ctx.isError,
				result: ctx.result,
			})
		) {
			this.#advisors.prepareForTerminalYieldAdvisorDrain();
			this.#markTerminalYieldToolCall(ctx.toolCall.id);
			this.#synchronouslyTerminatedYieldToolCallIds.add(ctx.toolCall.id);
			this.agent.abort(TERMINAL_TOOL_RESULT_ABORT_REASON);
		}
		return this.#ttsr.afterToolCall(ctx);
	}
	/**
	 * Emits the extension `tool_call` event for a loop-dispatched call at
	 * arg-prep time — before concurrency scheduling, `tool_execution_start`,
	 * and the wrapper's approval gate. A handler block becomes a blocked tool
	 * result; a handler `input` revision becomes the arguments the loop
	 * schedules, displays, persists, and executes, so approval resolves against
	 * what actually runs. Marks the dispatch so `ExtensionToolWrapper` does not
	 * emit a second event (nested xd:// device dispatches and direct non-loop
	 * execution still emit there).
	 */
	async #beforeToolCall(ctx: BeforeToolCallContext, signal?: AbortSignal): Promise<BeforeToolCallResult | undefined> {
		const childScope = this.#childTaskRecovery;
		const readAssistantOrigin = assistantSnapshotOrigin(ctx.assistantMessage);
		if (
			childScope &&
			!childScope.read &&
			ctx.tool.name === "read" &&
			this.model?.api === "openai-completions" &&
			ctx.assistantMessage.content.filter(part => part.type === "toolCall").length === 1 &&
			!this.messages.some(
				message =>
					message.role === "toolResult" ||
					(message.role === "assistant" &&
						(!readAssistantOrigin || assistantSnapshotOrigin(message) !== readAssistantOrigin)),
			)
		) {
			const turnEnd = Promise.withResolvers<void>();
			childScope.read = {
				assistant: ctx.assistantMessage,
				toolCallId: ctx.toolCall.id,
				turnEnd: turnEnd.promise,
				resolveTurnEnd: turnEnd.resolve,
				turnEndSeen: false,
				expectedLeaf: this.sessionManager.getLeafId() ?? undefined,
			};
		}
		const runner = this.#extensionRunner;
		runner?.markLoopToolCall?.(ctx.toolCall.id, ctx.tool.name);
		const ttsrResult = await this.#ttsr.beforeToolCall(ctx);
		if (ttsrResult) {
			runner?.clearLoopToolCall?.(ctx.toolCall.id, ctx.tool.name);
			return ttsrResult;
		}
		if (!runner?.hasHandlers("tool_call")) return undefined;
		const metadata = ctx.toolCall.providerMetadata;
		const computer = metadata?.type === "computer" ? metadata : undefined;
		// Parity with the wrapper's pre-emit short-circuit: an already-denied
		// call never reaches extensions. Deny is mode-independent (tool decision
		// or user policy), so resolving under the most permissive mode is exact;
		// the wrapper still enforces the mode-accurate gate before execution.
		const userPolicies: Record<string, unknown> = cfgToolsApproval.get(this.settings);
		const approvalArgs = computer ? { actions: computer.actions } : ctx.args;
		if (resolveApproval(ctx.tool, approvalArgs, "yolo", userPolicies).policy === "deny") {
			return undefined;
		}
		const eventArgs = computer
			? { actions: computer.actions, pendingSafetyChecks: computer.pendingSafetyChecks }
			: ctx.args;
		runner.markToolCallEmitted(ctx.toolCall.id, ctx.tool.name);
		const origin = this.#activePromptPreparation;
		const taskOrigin =
			ctx.tool.name === "task" &&
			ctx.assistantMessage.content.filter(part => part.type === "toolCall").length === 1 &&
			origin?.complete &&
			origin.anchorEntryId &&
			origin.generation === this.#promptGeneration &&
			origin.sessionId === this.sessionId
				? Object.freeze({ sessionId: this.sessionId, promptEntryId: origin.anchorEntryId })
				: undefined;
		const assistantOrigin = assistantSnapshotOrigin(ctx.assistantMessage);
		if (assistantOrigin) this.#taskCallAuthorities.get(assistantOrigin)?.delete(ctx.toolCall.id);
		const bound = this.#boundTaskCalls.get(ctx.toolCall.id);
		if (bound) bound.authority = undefined;
		let callResult: Awaited<ReturnType<ExtensionRunner["emitToolCall"]>>;
		try {
			callResult = await runner.emitToolCall(
				{
					type: "tool_call",
					...(taskOrigin ? { taskResultOrigin: taskOrigin } : {}),
					toolName: ctx.tool.name,
					toolCallId: ctx.toolCall.id,
					input: normalizeToolEventInput(ctx.tool.name, resolveToolEventInput(ctx.tool, eventArgs)),
				},
				signal,
			);
		} catch (error) {
			runner.clearLoopToolCall?.(ctx.toolCall.id, ctx.tool.name);
			throw error;
		}
		if (callResult?.block) {
			runner.clearLoopToolCall?.(ctx.toolCall.id, ctx.tool.name);
			return { block: true, reason: callResult.reason || "Tool execution was blocked by an extension" };
		}
		if (callResult?.taskResultAuthority) {
			if (
				!taskOrigin ||
				!origin ||
				signal?.aborted ||
				origin !== this.#activePromptPreparation ||
				origin.generation !== this.#promptGeneration ||
				origin.sessionId !== this.sessionId
			)
				return { block: true, reason: "Task result authority lost its exact invocation before capture" };
			if (!assistantOrigin)
				return { block: true, reason: "Task result authority requires a core assistant snapshot" };
			let captures = this.#taskCallAuthorities.get(assistantOrigin);
			if (!captures) {
				captures = new Map();
				this.#taskCallAuthorities.set(assistantOrigin, captures);
			}
			const capture: TaskCallAuthorityCapture = {
				assistant: ctx.assistantMessage,
				origin,
				sessionId: this.sessionId,
				generation: this.#promptGeneration,
				toolCallId: ctx.toolCall.id,
				validate: callResult.taskResultAuthority,
				signal,
			};
			captures.set(ctx.toolCall.id, capture);
			if (this.#boundTaskCalls.get(ctx.toolCall.id)?.original)
				return { block: true, reason: "Original task invocation is still owned" };
			this.#boundTaskCalls.set(ctx.toolCall.id, { authority: capture });
		}
		// A computer call's event input is a synthetic {actions, pendingSafetyChecks}
		// view, not the execution params — a revision cannot map back onto them.
		const args = callResult?.input !== undefined && !computer ? callResult.input : undefined;
		const additionalContext = callResult?.additionalContext;
		if (args === undefined && additionalContext === undefined) return undefined;
		return { args, additionalContext };
	}

	/** Find the last assistant message in agent state (including aborted ones) */
	#findLastAssistantMessage(): AssistantMessage | undefined {
		const messages = this.agent.state.messages;
		for (let i = messages.length - 1; i >= 0; i--) {
			const msg = messages[i];
			if (msg.role === "assistant") {
				return msg as AssistantMessage;
			}
		}
		return undefined;
	}

	#localProtocolOptions(): LocalProtocolOptions {
		return {
			getArtifactsDir: () => this.sessionManager.getArtifactsDir(),
			getSessionId: () => this.sessionManager.getSessionId(),
		};
	}

	#resetSessionStopContinuationState(): void {
		this.#sessionStopContinuationCount = 0;
		this.#sessionStopHookActive = false;
	}

	#clearPendingSessionStopContinuations(): void {
		if (!this.#pendingNextTurnMessages.some(message => message.customType === "session-stop-continuation")) {
			return;
		}
		this.#pendingNextTurnMessages = this.#pendingNextTurnMessages.filter(
			message => message.customType !== "session-stop-continuation",
		);
	}

	#sessionStopContinuationContext(result: SessionStopEventResult | undefined): string | undefined {
		if (!result) return undefined;
		const additionalContext =
			typeof result.additionalContext === "string" && result.additionalContext.length > 0
				? result.additionalContext
				: undefined;
		const reason = typeof result.reason === "string" && result.reason.length > 0 ? result.reason : undefined;
		if (result.decision === "block") {
			return reason ?? additionalContext ?? prompt.render(sessionStopBlockedPrompt);
		}
		if (result.continue === true) {
			return additionalContext ?? reason;
		}
		return undefined;
	}

	/**
	 * Publish a run's settle: report idle, emit the public `agent_end` (held out
	 * of the eager display pass until maintenance routing decides whether the
	 * agent continues), then notify extensions. Every `agent_end` MUST reach this
	 * exactly once; `#dispatchAgentEvent` calls it when maintenance throws first.
	 */
	async #settleAgentEnd(
		event: AgentEndEvent,
		activeMessages: AgentMessage[],
		options?: AgentEndSettleOptions,
	): Promise<void> {
		this.#settledAgentEnd = event;
		this.#emitRunState("idle");
		// Tagged isTerminal so subscribers can tell final settles from scheduled
		// continuations, and `yielded` so they can tell the agent's own follow-up
		// work (retries, reminders, compaction) from a finished turn that only
		// background work resumes. `awaitingAsyncWork` singles out that last case:
		// `yielded` alone also covers queued steer/follow-up and IRC continuations,
		// which `#flushPendingAgentEnd` re-tags non-terminal.
		const awaitingAsyncWork = options?.willContinue === true && options.awaitingAsyncWork === true;
		await this.#emitSessionEvent({
			...event,
			isTerminal: !options?.willContinue,
			yielded: !options?.willContinue || awaitingAsyncWork,
			...(awaitingAsyncWork ? { awaitingAsyncWork } : {}),
		});
		void this.#emitAgentEndNotification([...activeMessages], options).catch(err => {
			logger.error("Agent end extension notification failed", { err });
		});
	}

	async #emitAgentEndNotification(messages: AgentMessage[], options?: { willContinue?: boolean }): Promise<void> {
		await this.#extensionRunner?.emit({
			type: "agent_end",
			messages,
			willContinue: options?.willContinue,
		});
	}

	/** @returns true when a hidden session_stop continuation turn was scheduled. */
	async #emitSessionStopEvent(
		messages: AgentMessage[],
		lastAssistantMessage = this.getLastAssistantMessage(),
	): Promise<boolean> {
		if (this.#abortInProgress || this.#isDisposed || this.#activeAgentPromptGeneration !== this.#promptGeneration) {
			this.#resetSessionStopContinuationState();
			return false;
		}
		if (this.#agentKind === "sub" || !this.#extensionRunner?.hasHandlers("session_stop")) {
			return false;
		}
		const generation = this.#promptGeneration;
		const result = await this.#extensionRunner.emitSessionStop({
			messages,
			turn_id: Math.max(0, this.#turnIndex - 1),
			last_assistant_message: lastAssistantMessage,
			session_id: this.sessionId,
			session_file: this.sessionFile,
			stop_hook_active: this.#sessionStopHookActive,
			signal: this.#postPromptTasksAbortController.signal,
		});
		if (this.#promptGeneration !== generation || this.#abortInProgress || this.#isDisposed) {
			this.#resetSessionStopContinuationState();
			return false;
		}
		const additionalContext = this.#sessionStopContinuationContext(result);
		if (!additionalContext) {
			this.#resetSessionStopContinuationState();
			return false;
		}
		if (result?.decision !== "block" && this.#sessionStopContinuationCount >= SESSION_STOP_CONTINUATION_CAP) {
			logger.warn("session_stop continuation cap reached", {
				sessionId: this.sessionId,
				cap: SESSION_STOP_CONTINUATION_CAP,
			});
			this.#resetSessionStopContinuationState();
			return false;
		}
		if (result?.decision !== "block") this.#sessionStopContinuationCount++;
		this.#sessionStopHookActive = true;
		this.#queueHiddenNextTurnMessage(
			{
				role: "custom",
				customType: "session-stop-continuation",
				content: additionalContext,
				display: false,
				attribution: "agent",
				timestamp: Date.now(),
			},
			true,
		);
		return true;
	}

	/** Emit extension events based on session events */
	async #emitExtensionEvent(event: AgentSessionEvent): Promise<void> {
		if (!this.#extensionRunner) return;
		if (event.type === "agent_start") {
			this.#turnIndex = 0;
			await this.#extensionRunner.emit({ type: "agent_start" });
			return;
		}

		if (!this.#extensionRunner.hasHandlers(event.type)) return;
		if (event.type === "agent_end") {
			// `agent_end` extension notification is emitted from the settled
			// agent_end maintenance path so `session_stop` control hooks are not
			// blocked by unrelated notification-only work.
		} else if (event.type === "turn_start") {
			const hookEvent: TurnStartEvent = {
				type: "turn_start",
				turnIndex: this.#turnIndex,
				timestamp: Date.now(),
			};
			await this.#extensionRunner.emit(hookEvent);
		} else if (event.type === "turn_end") {
			const hookEvent: TurnEndEvent = {
				type: "turn_end",
				turnIndex: this.#turnIndex,
				message: event.message,
				toolResults: event.toolResults,
			};
			await this.#extensionRunner.emit(hookEvent);
			this.#turnIndex++;
		} else if (event.type === "message_start") {
			const extensionEvent: MessageStartEvent = {
				type: "message_start",
				message: event.message,
			};
			await this.#extensionRunner.emit(extensionEvent);
		} else if (event.type === "message_update") {
			const extensionEvent: MessageUpdateEvent = {
				type: "message_update",
				message: event.message,
				assistantMessageEvent: event.assistantMessageEvent,
			};
			await this.#extensionRunner.emit(extensionEvent);
		} else if (event.type === "message_end") {
			// `message_end` is a notification, not a context-rewrite hook. Detach its
			// payload from agent-owned history so an async observer that mutates the
			// event after an `await` cannot race mid-run maintenance and enlarge (or
			// otherwise rewrite) the next provider request after its threshold check.
			// Explicit `tool_result` / `context` hooks remain the supported mutation
			// surfaces. Third-party metadata that is not structured-cloneable is
			// sanitized field-by-field without retaining nested live references.
			const extensionEvent: MessageEndEvent = {
				type: "message_end",
				message: cloneMessageEndNotification(event.message),
			};
			await this.#extensionRunner.emit(extensionEvent);
		} else if (event.type === "tool_execution_start") {
			const extensionEvent: ToolExecutionStartEvent = {
				type: "tool_execution_start",
				toolCallId: event.toolCallId,
				toolName: event.toolName,
				args: event.args,
				intent: event.intent,
			};
			await this.#extensionRunner.emit(extensionEvent);
		} else if (event.type === "tool_execution_update") {
			const extensionEvent: ToolExecutionUpdateEvent = {
				type: "tool_execution_update",
				toolCallId: event.toolCallId,
				toolName: event.toolName,
				args: event.args,
				partialResult: event.partialResult,
			};
			await this.#extensionRunner.emit(extensionEvent);
		} else if (event.type === "tool_execution_end") {
			const extensionEvent: ToolExecutionEndEvent = {
				type: "tool_execution_end",
				toolCallId: event.toolCallId,
				toolName: event.toolName,
				result: event.result,
				isError: event.isError ?? false,
			};
			await this.#extensionRunner.emit(extensionEvent);
		} else if (event.type === "auto_compaction_start") {
			await this.#extensionRunner.emit({
				type: "auto_compaction_start",
				reason: event.reason,
				action: event.action,
			});
		} else if (event.type === "auto_compaction_end") {
			await this.#extensionRunner.emit({
				type: "auto_compaction_end",
				action: event.action,
				result: event.result,
				aborted: event.aborted,
				willRetry: event.willRetry,
				errorMessage: event.errorMessage,
				skipped: event.skipped,
			});
		} else if (event.type === "auto_retry_start") {
			await this.#extensionRunner.emit({
				type: "auto_retry_start",
				attempt: event.attempt,
				maxAttempts: event.maxAttempts,
				delayMs: event.delayMs,
				errorMessage: event.errorMessage,
				errorId: event.errorId,
			});
		} else if (event.type === "auto_retry_end") {
			await this.#extensionRunner.emit({
				type: "auto_retry_end",
				success: event.success,
				attempt: event.attempt,
				finalError: event.finalError,
				retryErrors: event.retryErrors,
			});
		} else if (event.type === "retry_fallback_applied") {
			await this.#extensionRunner.emit({
				type: "retry_fallback_applied",
				from: event.from,
				to: event.to,
				role: event.role,
				reason: event.reason,
			});
		} else if (event.type === "retry_fallback_succeeded") {
			await this.#extensionRunner.emit({
				type: "retry_fallback_succeeded",
				model: event.model,
				role: event.role,
			});
		} else if (event.type === "ttsr_triggered") {
			await this.#extensionRunner.emit({ type: "ttsr_triggered", rules: event.rules });
		} else if (event.type === "todo_reminder") {
			await this.#extensionRunner.emit({
				type: "todo_reminder",
				todos: event.todos,
				attempt: event.attempt,
				maxAttempts: event.maxAttempts,
			});
		} else if (event.type === "goal_updated") {
			await this.#extensionRunner.emit({
				type: "goal_updated",
				goal: event.goal,
				state: event.state,
			});
		}
	}

	/**
	 * Subscribe to agent events.
	 * Session persistence is handled internally (saves messages on message_end).
	 * Multiple listeners can be added. Returns unsubscribe function for this listener.
	 */
	subscribe(listener: AgentSessionEventListener): () => void {
		this.#eventListeners.push(listener);

		// Return unsubscribe function for this specific listener
		return () => {
			const index = this.#eventListeners.indexOf(listener);
			if (index !== -1) {
				this.#eventListeners.splice(index, 1);
			}
		};
	}

	/**
	 * Snapshot the latest unpersisted display result for each active tool or
	 * returned background call. Focus rebuilds replay these after reconstructing
	 * persisted transcript state.
	 */
	activeToolExecutionUpdates(): readonly Extract<AgentSessionEvent, { type: "tool_execution_update" }>[] {
		return [...this.#activeToolExecutionUpdates.values()];
	}

	/**
	 * Observe authoritative run-state transitions before public `agent_end`
	 * deferral, for lifecycle owners that must not remain stale while prompts unwind.
	 */
	subscribeRunState(listener: (state: "running" | "idle") => void): () => void {
		this.#runStateListeners.add(listener);
		return () => this.#runStateListeners.delete(listener);
	}

	/**
	 * Current prompt-cache warming state, for hosts that surface it. Undefined
	 * when the session has no warmer (side-channels, subagents, older hosts).
	 */
	get cacheWarmingStatus(): CacheWarmingStatus | undefined {
		return this.#cacheWarmer?.status;
	}

	/**
	 * Arms the prompt-cache warmer for a main-loop request. Called from the
	 * session streamFn with its raw request options; retention settings are
	 * resolved here to match the settings-aware stream wrapper.
	 * A no-op when the session has no warmer.
	 */
	startCacheWarming(model: Model, context: Context, options: SimpleStreamOptions): void {
		const warmer = this.#cacheWarmer;
		if (!warmer) return;
		const armMessages = this.messages;
		const retentionSetting = cfgProvidersCacheRetention.get(this.settings);
		const warmingOptions = {
			...options,
			cacheRetention: options.cacheRetention ?? (retentionSetting === "auto" ? undefined : retentionSetting),
		};
		const armShape = this.#cacheWarmingShape(model);
		warmer.start({ model, context, options: warmingOptions }, () => {
			// The armed request must still be a prefix of the live messages by
			// entry identity: appends are fine (tool results mid-run), but a
			// rewrite, shallow array copy with new objects, compaction, branch,
			// or session switch invalidates the cache key being warmed.
			const current = this.messages;
			if (current.length < armMessages.length) return false;
			for (let index = 0; index < armMessages.length; index++) {
				if (current[index] !== armMessages[index]) return false;
			}
			// So does anything else the next real request would send differently:
			// replaying the old shape would keep an entry nobody reads.
			return this.#cacheWarmingShape(this.model) === armShape;
		});
	}

	/**
	 * Fingerprint of the request inputs outside the transcript that are part of
	 * the cache key: model, system prompt, tool set, thinking level, retention.
	 */
	#cacheWarmingShape(model: Model | undefined): number | bigint {
		return Bun.hash(
			JSON.stringify([
				model?.provider,
				model?.id,
				this.agent.state.systemPrompt,
				this.agent.state.tools.map(tool => tool.name),
				this.thinkingLevel,
				cfgProvidersCacheRetention.get(this.settings),
			]),
		);
	}

	/** Prompt size (input + cacheRead + cacheWrite) of the most recent real provider response. */
	lastPromptTokens(): number {
		const messages = this.messages;
		for (let index = messages.length - 1; index >= 0; index--) {
			const message = messages[index];
			if (message.role === "assistant")
				return message.usage.input + message.usage.cacheRead + message.usage.cacheWrite;
		}
		return 0;
	}

	/** Persist a completed warm request as off-transcript usage so session totals include its cost. */
	#recordCacheWarmUsage(message: AssistantMessage, extensionOverride: boolean): void {
		try {
			this.sessionManager.appendModelUsage(
				{
					purpose: extensionOverride ? "cache-warm:extension-override" : "cache-warm",
					api: message.api,
					provider: message.provider,
					model: message.model,
					usage: message.usage,
					stopReason: message.stopReason,
				},
				{ sessionId: this.sessionId, parentId: this.sessionManager.getLeafId() },
			);
		} catch (error) {
			logger.debug("Failed to persist cache-warm usage", { error: String(error) });
		}
	}

	/** True while a session identity or transcript transition is still applying or rolling back. */
	get isSessionTransitioning(): boolean {
		return this.#sessionTransitionDepth > 0;
	}

	/** Wait until all active session/transcript transitions have settled, including rollback. */
	async waitForSessionTransition(): Promise<void> {
		while (this.#sessionTransitionSettled) await this.#sessionTransitionSettled;
	}

	#beginSessionTransition(): Disposable {
		if (this.#sessionTransitionDepth++ === 0) {
			const settled = Promise.withResolvers<void>();
			this.#sessionTransitionSettled = settled.promise;
			this.#resolveSessionTransition = settled.resolve;
		}
		return this.#sessionTransitionScope;
	}

	/** Register cleanup that runs when this AgentSession adopts a different session ID. */
	registerSessionChangeCallback(callback: () => void): () => void {
		this.#sessionChangeCallbacks.add(callback);
		return () => this.#sessionChangeCallbacks.delete(callback);
	}

	subscribeCommandMetadataChanged(listener: CommandMetadataChangedListener): () => void {
		this.#commandMetadataChangedListeners.push(listener);
		return () => {
			const index = this.#commandMetadataChangedListeners.indexOf(listener);
			if (index !== -1) {
				this.#commandMetadataChangedListeners.splice(index, 1);
			}
		};
	}

	#notifyCommandMetadataChanged(): void {
		const listeners = [...this.#commandMetadataChangedListeners];
		for (const listener of listeners) {
			try {
				void listener();
			} catch (err) {
				logger.error("Command metadata listener threw", { err });
			}
		}
	}

	/**
	 * Temporarily disconnect from agent events.
	 * User listeners are preserved and will receive events again after resubscribe().
	 * Used internally during operations that need to pause event processing.
	 */
	#disconnectFromAgent(): void {
		if (this.#unsubscribeAgent) {
			this.#unsubscribeAgent();
			this.#unsubscribeAgent = undefined;
		}
		if (this.#unsubscribeQueueChange) {
			this.#unsubscribeQueueChange();
			this.#unsubscribeQueueChange = undefined;
		}
	}

	/**
	 * Reconnect to agent events after _disconnectFromAgent().
	 * Preserves all existing listeners.
	 */
	#reconnectToAgent(): void {
		if (this.#unsubscribeAgent) return; // Already connected
		this.#unsubscribeAgent = this.agent.subscribe(this.#handleAgentEvent);
		this.#unsubscribeQueueChange = this.agent.onQueueChange(() => this.#emitQueueUpdateIfChanged());
	}

	#activeProviderSessionId(sessionId?: string): string {
		return this.#freshProviderSessionId ?? this.#providerSessionId ?? sessionId ?? this.sessionManager.getSessionId();
	}

	#adoptInheritedProviderPromptCacheKey(): void {
		const key = this.sessionManager.getHeader()?.providerPromptCacheKey;
		if (!key) return;
		if (this.#inheritedProviderPromptCacheKey !== undefined || this.agent.promptCacheKey === undefined) {
			this.agent.promptCacheKey = key;
			this.#inheritedProviderPromptCacheKey = key;
		}
	}

	#clearInheritedProviderPromptCacheKey(): void {
		const key = this.#inheritedProviderPromptCacheKey;
		this.#inheritedProviderPromptCacheKey = undefined;
		if (key !== undefined && this.agent.promptCacheKey === key) {
			this.agent.promptCacheKey = undefined;
		}
	}

	/**
	 * Set agent.sessionId from the session manager and install a dynamic
	 * metadata resolver so every Anthropic API request carries
	 * `metadata.user_id` shaped like real Claude Code's `getAPIMetadata` output:
	 * `{ session_id, account_uuid, device_id }`. `account_uuid` is included only
	 * when an Anthropic OAuth credential with a known account UUID is loaded;
	 * `device_id` is derived from both the persistent omp install id and that
	 * account UUID. Resolving live keeps the value in sync with auth-state changes
	 * (login/logout, token refresh that surfaces a new account UUID) without
	 * needing to re-call `#syncAgentSessionId()` on every such event.
	 */
	#syncAgentSessionId(sessionId?: string, notifyChange = true): void {
		const currentSessionId = this.sessionManager.getSessionId();
		if (this.#observedSessionId === undefined) {
			this.#observedSessionId = currentSessionId;
		} else if (this.#observedSessionId !== currentSessionId) {
			this.#observedSessionId = currentSessionId;
			if (notifyChange) this.#notifySessionChangeCallbacks();
		}
		const sid = this.#activeProviderSessionId(sessionId);
		this.agent.sessionId = sid;
		this.agent.setMetadataResolver((provider: string) =>
			buildSessionMetadata(sid, provider, this.#modelRegistry.authStorage),
		);
		// Restore the session's recorded provider accounts before the first
		// request routes: sticky rows are process-local under a remote auth
		// broker, and losing them re-ranks onto a different account, cold-missing
		// the account-scoped prompt cache. Skipped for fresh provider sessions —
		// those explicitly want new routing identity.
		if (!this.#freshProviderSessionId) {
			seedCredentialPins(this.#modelRegistry.authStorage, this.sessionManager, sid);
		}
		// Keep every live advisor's provider identity in lockstep with the primary's
		// across every session-boundary transition — including branch paths that
		// skip conversation restore — so advisors never emit the previous
		// conversation's session id/metadata (issue #6625). Guarded because this
		// runs once during construction before the advisor controller exists.
		if (this.#advisors) this.#advisors.refreshProviderIdentity();
	}

	#notifySessionChangeCallbacks(): void {
		for (const callback of Array.from(this.#sessionChangeCallbacks)) {
			try {
				callback();
			} catch (error) {
				logger.warn("Session change callback failed", { error: String(error) });
			}
		}
	}

	/** Run one abortable auto-learn capture outside the primary agent loop. */
	async runAutolearnCapture(capture: (signal: AbortSignal) => Promise<void>): Promise<void> {
		if (this.#autolearnCaptureTask || this.#isDisposed) return;
		const controller = new AbortController();
		this.#autolearnCaptureAbortController = controller;
		const task = (async () => {
			try {
				await capture(controller.signal);
			} catch (error) {
				if (!controller.signal.aborted) throw error;
			} finally {
				if (this.#autolearnCaptureAbortController === controller) {
					this.#autolearnCaptureAbortController = undefined;
				}
			}
		})();
		this.#autolearnCaptureTask = task;
		try {
			await task;
		} finally {
			if (this.#autolearnCaptureTask === task) this.#autolearnCaptureTask = undefined;
		}
	}

	#abortAutolearnCapture(): void {
		this.#autolearnCaptureAbortController?.abort();
	}

	async #drainAutolearnCapture(): Promise<void> {
		const task = this.#autolearnCaptureTask;
		if (!task) return;
		try {
			await withTimeout(task, 3_000, "Timed out draining auto-learn capture during dispose");
		} catch (error) {
			logger.warn("Auto-learn capture did not settle during dispose", { error: String(error) });
		}
	}

	/** True once dispose() has begun; deferred background work (e.g. the deferred
	 *  MCP discovery task in sdk.ts) must not touch the session past this point. */
	get isDisposed(): boolean {
		return this.#isDisposed;
	}

	markMovedFromEmptySessionFile(sessionFile: string): void {
		this.#movedFromEmptySessionFile = path.resolve(sessionFile);
	}

	/**
	 * Synchronously mark the session as disposing so new work is rejected
	 * immediately: eval starts throw, queued asides are dropped, the aside
	 * provider is detached, and settings listeners bound to the session stop
	 * (a config reload mid-teardown must not reconnect or re-steer anything).
	 * Idempotent; `dispose()` runs it first.
	 *
	 * Wrappers that await other teardown before delegating to `dispose()` MUST
	 * call this before their first await — otherwise work started in that async
	 * gap slips past the disposal guards.
	 */
	beginDispose(): void {
		this.invalidateTaskRecovery("Session disposal superseded task recovery");
		this.#isDisposed = true;
		for (const dispose of this.#disposers.splice(0)) dispose();
		this.#modelDiscoveryAbortController.abort();
		this.#queuedMessageDrainBlocked = false;
		this.#usagePreflightReadyForNextModelCall = false;
		this.#detachUsageBeforeQueueDequeue?.();
		this.#detachUsageBeforeQueueDequeue = undefined;
		this.#detachUsageBeforeModelCall?.();
		this.#detachUsageBeforeModelCall = undefined;
		if (this.agent.prepareQueuedMessages === this.#prepareQueuedUserMessages) {
			this.agent.prepareQueuedMessages = undefined;
		}
		this.#memory.cancelLocalMemoryStartup();
		this.#titleGenerationAbortController.abort();
		this.#abortAutolearnCapture();
		this.#irc.flushPending();
		this.yieldQueue.clear();
		this.agent.setAsideMessageProvider(undefined);
		this.agent.hasIrcInterrupts = undefined;
		this.agent.hasBackgroundCompletions = undefined;
		this.#advisors.stopRuntime();
		this.#eval.beginDispose();
	}

	/**
	 * Remove all listeners, flush pending writes, and disconnect from agent.
	 * Call this when completely done with the session.
	 *
	 * Idempotent: concurrent or repeated calls share one settled promise. The
	 * keypress `InteractiveMode.shutdown()` path and the postmortem
	 * `SIGTERM`/`SIGHUP`/`uncaughtException` callback can both target this
	 * method, so a second invocation must never re-emit `session_shutdown` or
	 * double-drain the owned `AsyncJobManager` (issue #4080).
	 */
	#disposeCall?: Promise<void>;
	dispose(options: AgentSessionDisposeOptions = {}): Promise<void> {
		if (!this.#disposeCall) this.#disposeCall = this.#doDispose(options);
		return this.#disposeCall;
	}

	async #disposeOwnedAsyncJobs(): Promise<void> {
		// Unregister before cancelling: a job completing during teardown must
		// dead-letter rather than enqueue a follow-up into a disposing session.
		this.#unregisterAsyncDeliverySink?.();
		this.#unregisterAsyncDeliverySink = undefined;
		const manager = this.#ownedAsyncJobManager;
		// The shutdown reason is reserved for the top-level session that OWNS the
		// manager — the genuine process/handled-shutdown path — so the task
		// executor parks (rather than tombstones) interrupted subagents. A
		// subagent session dispose (e.g. `release({ tombstone: true })` during an
		// explicit hard kill) leaves `#ownedAsyncJobManager` undefined and must
		// propagate a generic cancellation so its nested children stay terminal.
		this.#cancelOwnAsyncJobs(manager ? ASYNC_JOB_MANAGER_SHUTDOWN_REASON : undefined);
		if (!manager) return;

		try {
			const drained = await manager.dispose({ timeoutMs: 3_000 });
			const deliveryState = manager.getDeliveryState();
			if (drained === false && deliveryState) {
				logger.warn("Async job completion deliveries still pending during dispose", { ...deliveryState });
			}
		} finally {
			if (AsyncJobManager.instance() === manager) {
				AsyncJobManager.setInstance(undefined);
			}
		}
	}

	async #releaseOwnedBrowserTabs(ownerId: string | undefined): Promise<void> {
		if (!ownerId) return;
		try {
			const released = await withTimeout(
				releaseTabsForOwner(ownerId, { kill: true }),
				3_000,
				"Timed out releasing owned browser tabs during dispose",
			);
			if (released > 0) {
				logger.debug("Released owned browser tabs during dispose", { ownerId, released });
			}
		} catch (error) {
			logger.warn("Failed to release owned browser tabs during dispose", { error: String(error) });
		}
	}

	/**
	 * Turn-settle checkpoint for owned headless browser tabs (issue #8246).
	 * Close tabs idle past `browser.idleCloseSec` as the memory backstop,
	 * then freeze the survivors so idle animated pages stop burning CPU/GPU
	 * while keeping their state for millisecond resume. Scoped to OMP-owned
	 * headless tabs of this session only — relay/CDP/spawned tabs, other
	 * sessions' tabs, and `persist` tabs are never touched. Best-effort:
	 * never throws, so teardown cannot break the event flow.
	 */
	async #settleOwnedBrowserTabs(): Promise<void> {
		const ownerId = this.sessionManager.getSessionId();
		if (!ownerId) return;
		try {
			const idleSec = cfgBrowserIdleCloseSec.get(this.settings);
			if (idleSec > 0) {
				const closed = await withTimeout(
					releaseIdleTabsForOwner(ownerId, { idleMs: idleSec * 1000 }),
					3_000,
					"Timed out closing idle browser tabs at turn settle",
				);
				if (closed > 0) {
					logger.debug("Closed idle owned browser tabs at turn settle", { ownerId, closed });
				}
			} else {
				// Idle close disabled at runtime: drop any deadline armed
				// under a previous positive value so it cannot fire stale.
				cancelIdleCloseForOwner(ownerId);
			}
			if (cfgBrowserFreezeOnTurnEnd.get(this.settings)) {
				const frozen = await withTimeout(
					freezeTabsForOwner(ownerId),
					3_000,
					"Timed out freezing owned browser tabs at turn settle",
				);
				if (frozen > 0) {
					logger.debug("Froze owned browser tabs at turn settle", { ownerId, frozen });
				}
			}
		} catch (error) {
			logger.warn("Failed to settle owned browser tabs at turn end", { error: String(error) });
		}
	}

	async #releaseOwnedComputerSessions(ownerId: string | undefined): Promise<void> {
		if (!ownerId) return;
		try {
			await withTimeout(
				releaseComputerSessionsForOwner(ownerId),
				3_000,
				"Timed out releasing native computer session during dispose",
			);
		} catch (error) {
			logger.warn("Failed to release native computer session during dispose", { error: String(error) });
		}
	}

	async #disconnectOwnedMcp(): Promise<void> {
		if (!this.#disconnectOwnedMcpManager) return;
		try {
			await withTimeout(
				this.#disconnectOwnedMcpManager(),
				3_000,
				"Timed out disconnecting owned MCP manager during dispose",
			);
		} catch (error) {
			logger.warn("Failed to disconnect owned MCP manager during dispose", { error: String(error) });
		}
	}

	async #disposeMnemopi(
		state: MnemopiSessionState | undefined,
		consolidateTimeoutMs: number | undefined,
	): Promise<void> {
		try {
			await state?.dispose({ timeoutMs: consolidateTimeoutMs });
		} finally {
			// Consolidation may embed final memories, so terminate its worker only afterward.
			await shutdownMnemopiEmbedClient();
		}
	}

	async #doDispose(options: AgentSessionDisposeOptions = {}): Promise<void> {
		this.beginDispose();
		// Stop cache warming before the drain windows below: an armed tick firing
		// mid-dispose would issue a paid warm request and persist usage into the
		// closing session writer.
		if (this.#cacheWarmer) {
			this.#cacheWarmer.onWarmed = undefined;
			this.#cacheWarmer.onRefreshStart = undefined;
			this.#cacheWarmer.onRefreshEnd = undefined;
			this.#cacheWarmer.cancel();
		}
		this.#recordSessionExit(options.reason ?? "dispose");
		this.#cancelExitRecorder?.();
		this.#cancelExitRecorder = undefined;
		this.#cancelFatalRecoveryHint?.();
		this.#cancelFatalRecoveryHint = undefined;
		try {
			await emitSessionShutdownEvent(this.#extensionRunner);
		} catch (error) {
			logger.warn("Failed to emit session_shutdown event", { error: String(error) });
		}

		// Stop fallback extension timers before aborting deferred work they could enqueue.
		this.#fallbackExtensionTimers?.clearAll();
		this.abortRetry();
		this.abortCompaction();
		const postPromptDrain = this.#cancelPostPromptTasks();
		this.agent.abort();
		try {
			await withTimeout(
				postPromptDrain,
				POST_PROMPT_DRAIN_TIMEOUT_MS,
				"Timed out draining post-prompt tasks during dispose",
			);
		} catch (error) {
			logger.warn("Post-prompt tasks still draining at dispose deadline", { error: String(error) });
		}
		await this.#drainAutolearnCapture();
		await this.#memory.transition;

		const hindsightState = this.getHindsightSessionState();
		const mnemopiState = setMnemopiSessionState(this, undefined);
		// Bound the wait for a just-fired sharpshooter extraction before dropping
		// its subscriptions, so print-mode exits don't cut queued-delta writes.
		const sharpshooterFlushed = flushSharpshooterExtraction(this, options.mnemopiConsolidateTimeoutMs);
		try {
			releaseSharpshooterSession(this);
		} catch (error) {
			logger.warn("Session dispose: Sharpshooter release failed", { error: String(error) });
		}
		const advisorRecorderClosed = this.#advisors.recorderClosed();
		const results = await Promise.allSettled([
			this.#disposeOwnedAsyncJobs(),
			this.#eval.disposeKernels(),
			this.#releaseOwnedBrowserTabs(this.sessionManager.getSessionId()),
			this.#releaseOwnedComputerSessions(this.#eval.getKernelOwnerId()),
			shutdownTinyTitleClient(),
			this.#disconnectOwnedMcp(),
			advisorRecorderClosed,
			hindsightState?.flushRetainQueue() ?? Promise.resolve(),
			this.#disposeMnemopi(mnemopiState, options.mnemopiConsolidateTimeoutMs),
			sharpshooterFlushed,
		]);
		for (const result of results) {
			if (result.status === "rejected") {
				logger.warn("Session dispose subsystem failed during parallel teardown", {
					error: String(result.reason),
				});
			}
		}

		this.#releasePowerAssertion();
		await cleanupEmptyMoveSession(this.sessionManager, this.#movedFromEmptySessionFile);
		this.#movedFromEmptySessionFile = undefined;
		this.#closeAllProviderSessions("dispose");
		this.#maintenance.cancelSpeculation();
		this.setHindsightSessionState(undefined);
		hindsightState?.dispose();
		this.#disconnectFromAgent();
		// beginDispose() drained the rest; this catches registrations made during teardown.
		for (const dispose of this.#disposers.splice(0)) dispose();
		this.#eventListeners = [];
		this.#runStateListeners.clear();
		this.#sessionChangeCallbacks.clear();

		// A dispose triggered mid-turn (Ctrl-C / timeout / hard-killed subagent)
		// only *signals* the agent loop via the earlier abort(); the loop and the
		// session's fire-and-forget event handlers still unwind asynchronously.
		// Detach the response/SSE interceptors so a late frame cannot re-record
		// into rawSseDebugBuffer, then wait (bounded) for both the core run AND
		// the in-flight event/persistence handlers to settle — the latter can
		// still append the finished message/entries after agent.waitForIdle()
		// alone. Without this the release races the unwind and a disposed session
		// is repopulated with exactly the state we are trying to drop.
		this.agent.setProviderResponseInterceptor(undefined);
		this.agent.setRawSseEventInterceptor(undefined);
		let drained = false;
		try {
			await withTimeout(
				(async () => {
					await this.agent.waitForIdle();
					await this.#drainInFlightEventHandlers();
				})(),
				options.drainTimeoutMs ?? POST_PROMPT_DRAIN_TIMEOUT_MS,
				"Timed out waiting for the active agent run to settle during dispose",
			);
			drained = true;
		} catch (error) {
			logger.warn("Active agent run still settling at dispose deadline", { error: String(error) });
		}

		// Event handlers can reopen the append writer while they persist their
		// terminal message; that pipeline has drained (or hit the deadline).
		// Raise the write barrier BEFORE the final close: a handler that
		// outlived the deadline could otherwise enqueue disk work behind the
		// closing tail while we await it, and that work would run against the
		// file after a revival reopens it. The seal also bumps the disk epoch,
		// superseding queued tail work and fencing already-running atomic
		// rewrites at their commit guard; hot-path appends drained above are
		// already durable, and close() (scheduled post-seal) still flushes and
		// closes the writer.
		this.sessionManager.seal();
		await this.sessionManager.close();
		this.#activePromptPreparation = undefined;
		this.#boundTaskCalls.clear();

		// Release retained conversation memory. dispose() is terminal, and every
		// revival path reopens the transcript from disk (AgentLifecycleManager
		// reviver / persisted-revive / `history://`), so the in-memory copy is
		// dead weight from here on. Dropping it lets a parked subagent's session
		// graph shed its heavy payloads even while the lifecycle adoption record's
		// reviver closure still references the session object. Fixes #8003.
		this.#releaseRetainedSessionMemory();

		// The deadline does not cancel the drain: a handler parked in a slow
		// extension hook resumes afterwards and would repopulate exactly the
		// state released above. Its disk writes are already dead — the release
		// SEALED the session manager (a revival may reopen the same JSONL
		// through a new manager the moment dispose returns, and this manager
		// must never race that writer) — so re-run only the in-memory reset
		// once the pipeline genuinely settles. The extension runner bounds hook
		// runtime, so this deferred pass is not unbounded.
		if (!drained) {
			void (async () => {
				await this.agent.waitForIdle();
				await this.#drainInFlightEventHandlers();
				this.#releaseRetainedSessionMemory();
			})().catch(error => logger.warn("Deferred dispose finalization failed", { error: String(error) }));
		}
	}

	/** Drop the in-memory conversation state after the terminal dispose flush. */
	#releaseRetainedSessionMemory(): void {
		this.#releaseQueuedTtsrReservations();
		this.agent.reset();
		this.agent.setAppendOnlyContext(undefined);
		this.rawSseDebugBuffer.clear();
		this.sessionManager.releaseRetainedEntries();
	}

	/** Releases deferred TTSR deliveries discarded by a session reset. */
	#releaseQueuedTtsrReservations(): void {
		this.#releaseTtsrReservations([...this.agent.peekSteeringQueue(), ...this.agent.peekFollowUpQueue()]);
	}

	#releaseTtsrReservations(messages: AgentMessage[]): void {
		for (const message of messages) {
			if (message.role === "custom" && message.customType === "ttsr-injection") {
				this.#ttsr.releaseDeferredReservationFromDetails(message.details);
			}
		}
	}

	#closeAllProviderSessions(reason: string): void {
		for (const [providerKey, state] of this.#providerSessionState) {
			try {
				state.close();
			} catch (error) {
				logger.warn("Failed to close provider session state", {
					providerKey,
					reason,
					error: String(error),
				});
			}
		}

		this.#providerSessionState.clear();
	}

	freshSession(): FreshSessionResult | undefined {
		this.#assertTaskRecoveryInput();
		if (this.isStreaming) return undefined;
		const previousSessionId = this.sessionId;
		const closedProviderSessions = this.#providerSessionState.size;
		this.#closeAllProviderSessions("fresh session");
		this.#freshProviderSessionId = Bun.randomUUIDv7();
		this.#syncAgentSessionId();
		this.#memory.rekeyForCurrentSessionId();
		this.agent.appendOnlyContext?.invalidateForModelChange();
		return {
			previousSessionId,
			sessionId: this.sessionId,
			closedProviderSessions,
		};
	}

	/**
	 * Reset the current conversation in place: drop every message, queued turn,
	 * and pending tool call from the model's context while keeping the session
	 * itself — its id, title, cwd, model, settings, and on-disk transcript all
	 * survive. The next turn is sent with only the base system prompt plus the
	 * project rules/AGENTS.md.
	 *
	 * This is the in-place sibling of {@link newSession}: it reuses the same
	 * conversation-boundary teardown (drop the conversation, rotate provider-side
	 * session state so providers that keep history server-side resume nothing,
	 * re-prime the advisors, and undo any memory promotion) but skips minting a
	 * new session id and opening a fresh transcript file. Unlike
	 * {@link freshSession} (which only rotates provider stream state) it also
	 * clears the conversation.
	 *
	 * Returns `undefined` without mutating anything while a response is
	 * streaming or a foreground bash/python execution is in flight.
	 */
	async resetSessionContext(): Promise<ResetSessionContextResult | undefined> {
		this.#assertTaskRecoveryInput();
		using _transition = this.#beginSessionTransition();
		// Refuse while a response streams OR a foreground user bash/python
		// execution is in flight: those complete via recordBashResult()/
		// recordPythonResult(), which append directly to agent.state when not
		// streaming, so a command finishing after the reset would land its output
		// after the boundary and re-enter the supposedly empty context. The
		// sibling boundary op (branchFromBtw) guards on the same predicates.
		if (this.isStreaming || this.isBashRunning || this.isEvalRunning) return undefined;
		const droppedCount = this.agent.state.messages.length;

		// Tear down the same per-turn runtime state that newSession() resets across
		// a conversation boundary, so work scheduled from the pre-reset turn cannot
		// re-enter the cleared context:
		//   - bump #promptGeneration + drain post-prompt tasks so an already-queued
		//     post-prompt continuation (recovery can be scheduled after agent_end
		//     while isStreaming is false) sees a stale generation and skips
		//     (mirrors abort()).
		//   - cancel this agent's async bash/task jobs so their completions can't
		//     re-deliver stale tool output into the cleared conversation
		//     (mirrors newSession()).
		this.#promptGeneration++;
		await this.#cancelPostPromptTasks();
		this.#cancelOwnAsyncJobs();

		// Drop the conversation: messages, queued steers/follow-ups, pending tool
		// calls, and error state. agent.reset() keeps the model and system prompt.
		this.#releaseQueuedTtsrReservations();
		this.agent.reset();
		this.#pendingNextTurnMessages = [];
		this.#experimentalContextNotesReminder = undefined;
		this.#scheduledHiddenNextTurnGeneration = undefined;
		// Reset the session_stop continuation chain: the queued continuation
		// message is gone with the conversation, but the counters would otherwise
		// carry over, so the next post-reset turn is reported to hooks as part of
		// the old chain and can hit SESSION_STOP_CONTINUATION_CAP early (mirrors
		// abort()/newSession()).
		this.#resetSessionStopContinuationState();

		// Drop checkpoint/rewind runtime state and deferred tool directives
		// alongside the messages that carried them: the checkpoint tool result is
		// gone from agent.state, so an intact #checkpointState would otherwise
		// force a rewind onto the pre-reset transcript on the next turn (mirrors
		// newSession()).
		this.#clearCheckpointRuntimeState();
		this.#clearSessionScopedToolState();

		// Rotate provider-side session state so a provider that keeps conversation
		// history server-side starts a brand-new exchange rather than resuming the
		// context we just dropped (mirrors freshSession()).
		this.#closeAllProviderSessions("reset context");
		this.#freshProviderSessionId = Bun.randomUUIDv7();
		this.#syncAgentSessionId();
		this.#memory.rekeyForCurrentSessionId();
		this.agent.appendOnlyContext?.invalidateForModelChange();

		// Re-arm the approved-plan reference: the reset dropped the plan-approved
		// prompt/reference from agent.state, so mark it unsent (preserving the
		// path — the plan file on disk is still the active plan) to let
		// #buildPlanReferenceMessage re-read and re-inject it on the next turn.
		// Mirrors the sent-flag reset newSession() and compaction perform after a
		// history rewrite (issue #1246).
		this.#planReferenceSent = false;

		// Re-prime the advisors across the conversation boundary and undo any
		// memory promotion so the next turn rebuilds from the base system prompt.
		this.#advisors.resetSessionState();
		await this.#memory.resetContextForNewTranscript();

		// Record a durable boundary on the persisted branch. The collapsed live
		// transcript and the model-context rebuild start emission after the latest
		// boundary, so a rebuild across a `/clear` (theme change, focus attach,
		// on-disk record and the plain `transcript:true` export path keep the full
		// pre-reset history.
		this.sessionManager.appendResetBoundary();

		resetCapabilities();
		await this.refreshBaseSystemPrompt();

		return { droppedCount };
	}

	// =========================================================================
	// Read-only State Access
	// =========================================================================

	/** Full agent state */
	get state(): AgentState {
		return this.agent.state;
	}

	/** Current model (may be undefined if not yet selected) */
	get model(): Model | undefined {
		return this.agent.state.model;
	}

	/**
	 * On the first successful response from a lazy-load local model, re-probe its
	 * runtime context window and fold the result into the live session model.
	 *
	 * Discovery snapshots a not-yet-loaded LM Studio model with its architectural
	 * `max_context_length`; the runtime `loaded_context_length` only exists once
	 * the model JIT-loads on the first inference (llama.cpp has the same cold-start
	 * gap for `meta.n_ctx`). A 2xx here means the load completed, so the probe now
	 * returns the window the backend actually serves. Compaction and the context
	 * bar read `agent.state.model` every turn, so `agent.setModel` propagates it
	 * immediately without a provider-session reset (#9001).
	 *
	 * Returns `void` synchronously when nothing is due — the common case — so the
	 * no-callback `#onResponse` fast path stays allocation-free.
	 */
	#maybeRefreshLazyLocalContext(response: ProviderResponseMetadata, model: Model | undefined): void | Promise<void> {
		if (!model || response.status < 200 || response.status >= 300) return;
		const key = `${model.provider}/${model.id}`;
		if (this.#lazyContextRefreshed.has(key)) return;
		if (!this.#modelRegistry.hasLazyRuntimeMetadata(model.provider)) return;
		this.#lazyContextRefreshed.add(key);
		return this.#refreshLazyLocalContext(model);
	}

	async #refreshLazyLocalContext(model: Model): Promise<void> {
		try {
			const refreshed = await this.#modelRegistry.refreshSelectedModelMetadata(model);
			const current = this.model;
			// Skip if the user switched models mid-stream, or the runtime window
			// matches what the session already holds.
			if (!current || !modelsAreEqual(current, refreshed) || refreshed.contextWindow === current.contextWindow) {
				return;
			}
			this.agent.setModel(refreshed);
		} catch (error) {
			logger.debug("Lazy local model context refresh failed", {
				provider: model.provider,
				model: model.id,
				error,
			});
		}
	}

	/**
	 * Model this session's produced work is attributed to. Holds the last model
	 * that actually served while a fallback is armed but unproven, so observers
	 * never credit a run to a candidate that produced nothing.
	 */
	get servingModel(): ServingModel | undefined {
		return this.#recovery.servingModel;
	}

	/** Install the interactive decision surface for reserve-triggered model changes. */
	setUsageFallbackConfirmer(confirmer: UsageFallbackConfirmer | undefined): void {
		this.#usageFallbackConfirmer = confirmer;
	}

	#allowQueuedMessageDrainRetry(): void {
		this.#queuedMessageDrainBlocked = false;
	}

	#reconcileQueuedMessageDrain(): void {
		if (!this.agent.hasQueuedMessages()) {
			this.#queuedMessageDrainBlocked = false;
		}
	}

	async #runQueuedUsageAwarePreflight(signal?: AbortSignal): Promise<boolean> {
		try {
			const allowed = await this.#runUsageAwarePreflight(signal);
			this.#usagePreflightReadyForNextModelCall = allowed;
			this.#usagePreflightReadyModel = allowed ? this.model : undefined;
			this.#queuedMessageDrainBlocked = !allowed && this.agent.hasQueuedMessages();
			return allowed;
		} catch (error) {
			this.#queuedMessageDrainBlocked = this.agent.hasQueuedMessages();
			throw error;
		}
	}

	async #runUsageAwarePreflightForNextModelCall(signal?: AbortSignal): Promise<boolean> {
		const allowed = await this.#runUsageAwarePreflight(signal);
		this.#usagePreflightReadyForNextModelCall = allowed;
		this.#usagePreflightReadyModel = allowed ? this.model : undefined;
		return allowed;
	}

	async #runUsageAwarePreflight(signal?: AbortSignal): Promise<boolean> {
		if (signal?.aborted) return false;
		const generation = this.#promptGeneration;

		const controller = new AbortController();
		const onAbort = () => controller.abort(signal?.reason);
		signal?.addEventListener("abort", onAbort, { once: true });
		this.#usagePreflightAbortControllers.add(controller);
		try {
			while (true) {
				const model = this.model;
				try {
					const fallbackCommitted = await this.#recovery.maybeApplyUsageAwareFallback(
						controller.signal,
						this.#usageFallbackConfirmer,
					);
					if (fallbackCommitted) return true;
					if (controller.signal.aborted || this.#promptGeneration !== generation) return false;
					if (this.model === model || modelsAreEqual(this.model, model)) return true;
				} catch (error) {
					if (controller.signal.aborted || this.#promptGeneration !== generation) return false;
					if (this.model !== model && !modelsAreEqual(this.model, model)) continue;
					throw error;
				}
			}
		} finally {
			signal?.removeEventListener("abort", onAbort);
			this.#usagePreflightAbortControllers.delete(controller);
		}
	}

	/** Effective thinking level applied to the agent (the resolved level when `auto`). */
	get thinkingLevel(): ThinkingLevel | undefined {
		return this.#models.thinkingLevel;
	}

	/** The selector the user configured: `auto` when auto mode is active, else the effective level. */
	configuredThinkingLevel(): ConfiguredThinkingLevel | undefined {
		return this.#models.configuredThinkingLevel();
	}

	/** True when `auto` thinking mode is active. */
	get isAutoThinking(): boolean {
		return this.#models.isAutoThinking;
	}

	/** The level `auto` resolved to for the current turn (undefined until classified). */
	autoResolvedThinkingLevel(): Effort | undefined {
		return this.#models.autoResolvedThinkingLevel;
	}

	/** Live per-family service tiers (OpenAI / Anthropic / Google). */
	get serviceTierByFamily(): ServiceTierByFamily {
		return this.#models.serviceTierByFamily;
	}

	/** Whether agent is currently streaming a response */
	get isStreaming(): boolean {
		return this.agent.state.isStreaming || this.#promptInFlightCount > 0;
	}

	get isAborting(): boolean {
		return this.agent.isAborting;
	}

	/**
	 * Wait until streaming, event persistence, and deferred recovery work are fully settled.
	 * Call outside callbacks whose completion the session awaits to avoid waiting on yourself.
	 */
	async waitForIdle(): Promise<void> {
		while (true) {
			await this.agent.waitForIdle();
			await this.#advisors.waitForPendingCardEvents();
			// Core subscribers run asynchronously. Retry recovery can still be
			// rewriting entries before it publishes auto_retry_end.
			await this.#drainInFlightEventHandlers();
			await this.#waitForPostPromptRecovery();
			if (!this.agent.state.isStreaming && this.#inFlightEventHandlers.size === 0) return;
		}
	}
	/**
	 * Prevent advisor notes from starting hidden primary turns while a headless
	 * caller prints and drains the final primary response.
	 */
	prepareForHeadlessAdvisorDrain(): void {
		this.#advisors.prepareForHeadlessAdvisorDrain();
	}

	/**
	 * Wait for active advisor reviews and their emitted card events before a
	 * headless caller disposes the session. Returns `false` and logs work disposal
	 * will abandon when the shared deadline expires or an advisor fails;
	 * `waitThroughRecovery` waits through a failing advisor's fallback recovery.
	 */
	waitForAdvisorCatchup(timeoutMs: number, options?: { waitThroughRecovery?: boolean }): Promise<boolean> {
		return this.#advisors.waitForAdvisorCatchup(timeoutMs, options);
	}

	async drainAsyncJobDeliveriesForAcp(options?: { timeoutMs?: number }): Promise<boolean> {
		const manager = this.#asyncJobManager;
		if (!manager) return false;
		const ownerFilter = this.#agentId ? { ownerId: this.#agentId } : undefined;
		const before = manager.getDeliveryState(ownerFilter);
		if (before.queued === 0 && !before.delivering) return false;
		const previousAllowAcpAgentInitiatedTurns = this.#allowAcpAgentInitiatedTurns;
		this.#allowAcpAgentInitiatedTurns = true;
		try {
			const drained = await manager.drainDeliveries({ timeoutMs: options?.timeoutMs, filter: ownerFilter });
			const after = manager.getDeliveryState(ownerFilter);
			return drained && (before.queued !== after.queued || before.delivering !== after.delivering);
		} finally {
			this.#allowAcpAgentInitiatedTurns = previousAllowAcpAgentInitiatedTurns;
		}
	}

	/**
	 * Most recent settled assistant message. A classifier-refusal turn pruned
	 * from active context at settle is still reported until the next run
	 * starts, so terminal-outcome consumers (print mode, task executor) see
	 * the refusal error rather than the previous turn — or nothing.
	 */
	getLastAssistantMessage(): AssistantMessage | undefined {
		return this.#prunedTerminalFailure ?? this.#findLastAssistantMessage();
	}
	/** Current effective system prompt blocks (includes any per-turn extension modifications) */
	get systemPrompt(): string[] {
		return this.agent.state.systemPrompt;
	}

	/** Required instruction-prep degradations from the latest prompt build. */
	get instructionPrepDegradations(): readonly InstructionPrepDegradation[] {
		return this.#getInstructionPrepDegradations?.() ?? [];
	}

	/** Marks streamed text as committed or buffered for turn-recovery replay decisions. */
	setTextOutputCommitted(committed: boolean): void {
		this.#textOutputCommitted = committed;
	}

	/** Current retry attempt (0 if not retrying) */
	get retryAttempt(): number {
		return this.#recovery.attempt;
	}

	/** Names of tools currently exposed at the top level. */
	getActiveToolNames(): string[] {
		return this.#tools.getActiveToolNames();
	}

	/** Enabled top-level and discoverable tool names. */
	getEnabledToolNames(): string[] {
		return this.#tools.getEnabledToolNames();
	}

	/** Names of dynamic tools mounted under `xd://`. */
	getMountedXdevToolNames(): string[] {
		return this.#tools.getMountedXdevToolNames();
	}

	/** Whether the edit tool is registered in this session. */
	get hasEditTool(): boolean {
		return this.#tools.hasEditTool;
	}

	/** Looks up a registered tool by name. */
	getToolByName(name: string): AgentTool | undefined {
		return this.#tools.getToolByName(name);
	}

	/** Looks up an enabled eval-bridge tool with the session's permission gate applied. */
	getToolForEvalBridge(name: string): AgentTool | undefined {
		return this.#tools.getToolForEvalBridge(name);
	}

	/** Names currently authorized through the eval bridge. */
	getEvalBridgeToolNames(): string[] {
		return this.#tools.getEvalBridgeToolNames();
	}

	/** Tools left directly model-visible by Code Mode; undefined when inactive. */
	getCodeModeDirectToolNames(): readonly string[] | undefined {
		return this.#tools.getCodeModeDirectToolNames();
	}

	/** Whether a registry entry came from a built-in factory. */
	hasBuiltInTool(name: string): boolean {
		return this.#tools.hasBuiltInTool(name);
	}

	/**
	 * Re-resolves settings-gated tools (built-in `*.enabled` toggles, eval backends,
	 * image/speech generation, `tools.xdev`) against live settings and refreshes the
	 * prompt once (`refreshPrompt: false` refreshes only if the tool set changed). The
	 * SDK runs it whenever a gating setting changes; other runtime owners may call it
	 * after changing an input the gate reads.
	 */
	reconcileBuiltinTools(options?: { refreshPrompt?: boolean }): Promise<void> {
		return this.#tools.reconcileBuiltinTools(options);
	}

	/** Updates source provenance when a live registry entry is replaced or restored. */
	setToolBuiltIn(name: string, builtIn: boolean): void {
		this.#tools.setToolBuiltIn(name, builtIn);
	}

	/** Whether the live registry entry is owned by the RPC host. */
	hasRpcHostTool(name: string): boolean {
		return this.#tools.hasRpcHostTool(name);
	}

	/** Whether the current MCP entry came from the manager snapshot. */
	hasMCPManagerTool(name: string): boolean {
		return this.#tools.hasMCPManagerTool(name);
	}

	/** Restores manager ownership after a lifecycle registration rollback. */
	setMCPManagerTool(name: string, managerOwned: boolean): void {
		this.#tools.setMCPManagerTool(name, managerOwned);
	}

	/** Current extension-owned MCP entry retained across manager refreshes. */
	getExtensionMCPTool(name: string): AgentTool | undefined {
		return this.#tools.getExtensionMCPTool(name);
	}

	/** Updates extension MCP ownership after a lifecycle registration commit or rollback. */
	setExtensionMCPTool(name: string, tool: AgentTool | undefined): void {
		this.#tools.setExtensionMCPTool(name, tool);
	}

	/** Runs a registry/presentation mutation in this session's shared queue. */
	runToolRegistryMutation<T>(mutation: () => Promise<T>, signal?: AbortSignal): Promise<T> {
		return this.#tools.runToolRegistryMutation(mutation, signal);
	}

	/** Names of every registered tool. */
	getAllToolNames(): string[] {
		return this.#tools.getAllToolNames();
	}

	/** Full metadata for every registered tool, including source provenance (backs `getAllTools()`). */
	getAllToolInfos(): ToolInfo[] {
		return this.#tools.getAllToolInfos();
	}

	/** Installs and activates the ephemeral vibe tool set. */
	activateVibeTools(baseToolNames: string[]): Promise<void> {
		return this.#tools.activateVibeTools(baseToolNames);
	}

	/** Uninstalls vibe tools and activates the replacement set. */
	deactivateVibeTools(nextToolNames: string[]): Promise<void> {
		return this.#tools.deactivateVibeTools(nextToolNames);
	}

	/** Removes vibe tools without restoring a source-session snapshot. */
	removeVibeToolsPreservingActive(): Promise<void> {
		return this.#tools.removeVibeToolsPreservingActive();
	}

	#resolveActiveEditMode(): EditMode {
		return this.#tools.resolveActiveEditMode();
	}

	/** Enabled MCP tools in their current presentation partition. */
	getSelectedMCPToolNames(): string[] {
		return this.#tools.getSelectedMCPToolNames();
	}

	/** Rediscovers reloadable skills and refreshes prompt metadata. */
	refreshSkills(): Promise<void> {
		return this.#tools.refreshSkills();
	}

	/**
	 * Rediscovers skills and file-based slash commands for the current cwd, rebuilds the
	 * system prompt, and notifies command-metadata listeners (TUI autocomplete, RPC/ACP
	 * command lists). Serialized so overlapping reloads apply in call order.
	 */
	refreshSkillsAndCommands(): Promise<void> {
		const refresh = this.#skillsAndCommandsRefresh
			.catch(() => {})
			.then(async () => {
				resetCapabilities();
				this.#slashCommands = await loadSlashCommands({
					cwd: this.sessionManager.getCwd(),
					extensionRoots: this.effectiveExtensionRoots,
				});
				// Resets the capability cache again, rediscovers skills, rebuilds the prompt,
				// and fires the command-metadata notification after both lists are current.
				await this.#tools.refreshSkills();
			});
		this.#skillsAndCommandsRefresh = refresh;
		return refresh;
	}

	/**
	 * Applies Code Mode at session startup: when the initial model activates
	 * it (`codeMode` `on`, or `auto` matching a `code_mode_only` catalog flag),
	 * the initial tool surface is routed through the Code Mode-aware path so
	 * the restricted direct surface and namespaces snapshot exist before the
	 * first provider turn instead of waiting for an unrelated reconciliation.
	 *
	 * Inactive sessions keep their initial surface untouched: re-applying an
	 * unchanged set would seed the prompt-rebuild signature cache and suppress
	 * the first late tool registration's rebuild (non-MCP `xd://` mounts are
	 * deliberately not part of that signature).
	 */
	initializeCodeMode(): Promise<void> {
		const model = this.model;
		if (!model || !this.#tools.codeModeChangesBetween(undefined, model)) return Promise.resolve();
		return this.#tools.reconcileCodeMode();
	}

	/** Current Code Mode `tool_namespaces_info` snapshot, or `undefined` when inactive. */
	get codeModeNamespacesInfo(): unknown {
		return this.#codeModeState.namespacesInfo;
	}

	/** Selects enabled tools, ignoring names absent from the registry. */
	setActiveToolsByName(toolNames: string[]): Promise<void> {
		return this.#tools.setActiveToolsByName(toolNames);
	}

	/** Restores an exact top-level versus `xd://` tool partition. */
	setActiveToolPresentation(
		toolNames: string[],
		mountedToolNames: string[],
		forcePromptRefresh = false,
		signal?: AbortSignal,
	): Promise<void> {
		return this.#tools.setActiveToolPresentation(toolNames, mountedToolNames, forcePromptRefresh, signal);
	}

	/** Restores a non-MCP presentation snapshot while retaining the current MCP selection. */
	restoreNonMCPToolPresentation(nonMCPToolNames: string[], nonMCPMountedToolNames: string[]): Promise<void> {
		return this.#tools.restoreNonMCPToolPresentation(nonMCPToolNames, nonMCPMountedToolNames);
	}

	/** Current enabled eval prelude definitions. */
	getEvalPreludes(): readonly EvalPreludeDefinition[] {
		return this.#getEvalPreludes?.() ?? [];
	}

	/** Eval preludes frozen into the provider-visible prompt (see {@link SessionTools.advertisedEvalPreludes}). */
	getAdvertisedEvalPreludes(): readonly EvalPreludeDefinition[] {
		return this.#tools.advertisedEvalPreludes;
	}

	/**
	 * User-tagged model agents frozen into the task description (see
	 * {@link SessionTools.advertisedSessionAgents}). Later tags ride a hidden
	 * notice so the provider cache prefix stays intact.
	 */
	getAdvertisedSessionAgents(): readonly AgentDefinition[] {
		return this.#tools.advertisedSessionAgents;
	}

	/** Cancels the local rollout-memory startup owned by this session. */
	cancelLocalMemoryStartup(): void {
		this.#memory.cancelLocalMemoryStartup();
	}

	/** Starts a new local rollout-memory generation and cancels its predecessor. */
	beginLocalMemoryStartup(): AbortSignal {
		return this.#memory.beginLocalMemoryStartup();
	}

	/** Releases the local startup slot if `signal` still owns it. */
	endLocalMemoryStartup(signal: AbortSignal): void {
		this.#memory.endLocalMemoryStartup(signal);
	}

	/** Apply the backend; cwd rebinding can skip Mnemopi auto-retention while still draining writes. */
	applyMemoryBackend(options: { retainMnemopi?: boolean } = {}): Promise<void> {
		if (!this.memoryEnabled) return Promise.resolve();
		return this.#memory.applyMemoryBackend(options);
	}

	/** Resolves once every memory-setting edit so far, and the backend transitions it started, has settled. */
	settleMemoryBackend(): Promise<void> {
		return this.#memory.settle();
	}

	/** Rebuilds the stable base prompt, optionally discarding a stale asynchronous rebuild. */
	refreshBaseSystemPrompt(commitIf?: () => boolean): Promise<void> {
		return this.#tools.refreshBaseSystemPrompt(commitIf);
	}

	/** Replaces connected MCP tools and enables them immediately. */
	refreshMCPTools(mcpTools: CustomTool[]): Promise<void> {
		return this.#tools.refreshMCPTools(mcpTools);
	}

	/** Replaces host-owned RPC tools before the next model call. */
	refreshRpcHostTools(rpcTools: AgentTool[]): Promise<void> {
		return this.#tools.refreshRpcHostTools(rpcTools);
	}

	/** Whether auto-compaction is currently running */
	get isCompacting(): boolean {
		return this.#maintenance.isCompacting;
	}

	/** Background speculative-compaction state, for UI indicators. */
	get compactionSpeculation(): "idle" | "running" | "armed" {
		return this.#maintenance.speculationState;
	}
	/** Strip image content from the current branch and persist the rewrite. */
	dropImages(): Promise<{ removed: number }> {
		return this.#maintenance.dropImages();
	}

	/** Reduce stored context with the selected shake strategy. */
	shake(mode: ShakeMode, opts: { config?: ShakeConfig; signal?: AbortSignal } = {}): Promise<ShakeResult> {
		return this.#maintenance.shake(mode, opts);
	}

	/** Compact the active session history. */
	compact(customInstructions?: string, options?: CompactOptions): Promise<CompactionResult> {
		return this.#maintenance.compact(customInstructions, options);
	}

	/** Cancel active manual, automatic, and handoff maintenance, preserving an optional source reason. */
	abortCompaction(reason?: unknown): void {
		void this.#maintenance.abortCompaction(reason);
	}

	/** Trigger idle compaction through the automatic maintenance flow. */
	async runIdleCompaction(): Promise<void> {
		// A pending async wake means the session is waiting, not idle: a
		// background job (bash/task) owned by this agent re-wakes the loop when it
		// completes, and the async-result delivery continues the run. Idle
		// compaction is a stop-time pass like the todo reminder and session_stop
		// hook — defer it until the session is fully idle so the resumed turn
		// keeps its context (the async settle, or the threshold path, compacts if
		// still needed).
		if (this.#hasPendingAsyncWake()) return;
		await this.#maintenance.runIdleCompaction();
	}

	/** Override cache warming for this session only, never writing config.yml; returns the effective mode. */
	setCacheWarmingMode(mode: CacheWarmingMode): CacheWarmingMode {
		cfgProvidersCacheWarming.override(this.settings, mode);
		return cfgProvidersCacheWarming.get(this.settings);
	}

	/** Toggle automatic compaction. `persist` saves it to global config; the default applies a session-scoped override. */
	setAutoCompactionEnabled(enabled: boolean, persist = false): void {
		this.#maintenance.setAutoCompactionEnabled(enabled, persist);
	}

	/** Whether automatic compaction is enabled. */
	get autoCompactionEnabled(): boolean {
		return this.#maintenance.autoCompactionEnabled;
	}

	/**
	 * Whether idle-flush tasks, auto-continuations, or other short-lived
	 * post-prompt work are pending.  True in the brief window after
	 * `session.prompt()` returns but before a scheduled background delivery
	 * (e.g. an async-job result) has finished its own streaming turn.
	 * Loop-mode and similar auto-submit paths should treat this as a block
	 * to avoid racing against the delivery turn.
	 */
	get hasPostPromptWork(): boolean {
		return this.#postPromptTasks.size > 0;
	}

	/** Register post-prompt work in tests without driving a full agent turn. */
	trackPostPromptTaskForTests(task: Promise<unknown>): void {
		if (!isBunTestRuntime()) throw new Error("trackPostPromptTaskForTests is test-only");
		this.#trackPostPromptTask(task);
	}

	/** All messages including custom types like BashExecutionMessage */
	get messages(): AgentMessage[] {
		return this.agent.state.messages;
	}

	/** Latest image attachments addressable by tools as `Image #N` or `attachment://N`. */
	getImageAttachments(): ImageAttachmentEntry[] {
		return this.#providerBoundary.getImageAttachments();
	}

	buildDisplaySessionContext(): SessionContext {
		return this.#withEvalStateContext(this.#providerBoundary.buildDisplaySessionContext());
	}

	#withEvalStateContext(context: SessionContext): SessionContext {
		const evalStateContext = this.#buildEvalStateContextMessage();
		if (!evalStateContext) return context;
		return { ...context, messages: [...context.messages, evalStateContext] };
	}

	#buildEvalStateContextMessage(): CustomMessage | undefined {
		const session = this.#evalToolSession;
		if (!session) return undefined;
		const historyHasEval = this.sessionManager.getBranch().some(entry => {
			if (entry.type !== "message") return false;
			const message = entry.message;
			if (message.role === "pythonExecution" || (message.role === "toolResult" && message.toolName === "eval")) {
				return true;
			}
			return (
				message.role === "assistant" &&
				message.content.some(block => block.type === "toolCall" && block.name === "eval")
			);
		});
		const content = formatEvalStateContext(session, { historyHasEval });
		if (!content) return undefined;
		return {
			role: "custom",
			customType: "eval-state-context",
			content,
			display: false,
			attribution: "agent",
			timestamp: Date.now(),
		};
	}

	/**
	 * Transcript for TUI display. Full history is kept for export/resume-style
	 * callers; live chat can collapse compacted history to keep the hot render
	 * surface bounded. Display-only — NEVER feed the result to
	 * `agent.replaceMessages` or a provider.
	 */
	buildTranscriptSessionContext(
		options?: Pick<BuildSessionContextOptions, "collapseCompactedHistory" | "keepDanglingToolCalls">,
	): SessionContext {
		return this.#providerBoundary.buildTranscriptSessionContext(options);
	}

	#obfuscateTextForProvider(text: string | undefined): string | undefined {
		return this.#providerBoundary.obfuscateText(text);
	}

	#obfuscatePreparationForProvider(preparation: CompactionPreparation): CompactionPreparation {
		return this.#providerBoundary.obfuscateCompactionPreparation(preparation);
	}

	#deobfuscateFromProvider(text: string): string {
		return this.#providerBoundary.deobfuscateText(text);
	}

	#deobfuscatedProviderTextReadyForDelta(text: string): string {
		return this.#providerBoundary.deobfuscateDelta(text);
	}

	#convertToLlmForSideRequest(messages: AgentMessage[]): Message[] {
		return this.#providerBoundary.convertToLlmForSideRequest(messages);
	}

	/** Convert session messages using the same pre-LLM pipeline as the active session. */
	async convertMessagesToLlm(messages: AgentMessage[], signal?: AbortSignal): Promise<Message[]> {
		return await this.#providerBoundary.convertMessagesToLlm(messages, signal);
	}

	/** Apply session-level stream hooks to a direct side request. */
	prepareSimpleStreamOptions(options: SimpleStreamOptions, provider = "anthropic"): SimpleStreamOptions {
		return this.#providerBoundary.prepareSimpleStreamOptions(options, provider);
	}

	/** Current steering mode */
	get steeringMode(): "all" | "one-at-a-time" {
		return this.agent.getSteeringMode();
	}

	/** Current follow-up mode */
	get followUpMode(): "all" | "one-at-a-time" {
		return this.agent.getFollowUpMode();
	}

	/** Current interrupt mode */
	get interruptMode(): "immediate" | "wait" {
		return this.agent.getInterruptMode();
	}

	/** Current session file path, or undefined if sessions are disabled */
	get sessionFile(): string | undefined {
		return this.sessionManager.getSessionFile();
	}

	/** Current session ID */
	get sessionId(): string {
		return this.#activeProviderSessionId();
	}
	getEvalSessionId(): string {
		return this.#eval.getSessionId();
	}
	getEvalKernelOwnerId(): string {
		return this.#eval.getKernelOwnerId();
	}

	/** Current session display name, if set */
	get sessionName(): string | undefined {
		return this.sessionManager.getSessionName();
	}

	/** Scoped models for cycling (from --models flag) */
	get scopedModels(): ReadonlyArray<{ model: Model; thinkingLevel?: ThinkingLevel }> {
		return this.#models.scopedModels;
	}

	/** Replace the Ctrl+P/`/models` cycle scope (post-discovery rebuild; see {@link ModelControls.setScopedModels}). */
	setScopedModels(scopedModels: Array<{ model: Model; thinkingLevel?: ThinkingLevel }>): void {
		this.#models.setScopedModels(scopedModels);
	}

	/** Prompt templates */
	getPlanModeState(): PlanModeState | undefined {
		return this.#planModeState;
	}

	/** Prewalk state, if armed and active */
	getPrewalkState(): Prewalk | undefined {
		return this.#prewalk.state;
	}

	setPlanModeState(state: PlanModeState | undefined): void {
		this.#planModeState = state;
		if (state?.enabled) {
			this.#planReferenceSent = false;
			this.#planReferencePath = state.planFilePath;
		} else {
			this.#planModeReminderCount = 0;
			this.#planModeReminderAwaitingProgress = false;
			// Drop any unconsumed forced decision so a post-plan execution turn
			// does not inherit a stale `required` tool choice.
			this.#toolChoiceQueue.removeByLabel("plan-mode-decision");
		}
	}

	getGoalModeState(): GoalModeState | undefined {
		return this.#goalModeState;
	}

	setGoalModeState(state: GoalModeState | undefined): void {
		this.#goalModeState = state;
	}

	getVibeModeState(): VibeModeState | undefined {
		return this.#vibeModeState;
	}

	setVibeModeState(state: VibeModeState | undefined): void {
		this.#vibeModeState = state;
		if (state?.enabled) return;

		const isVibeContext = (message: AgentMessage): boolean =>
			message.role === "custom" && message.customType === VIBE_MODE_CONTEXT_MESSAGE_TYPE;
		const messages = this.agent.state.messages;
		const filtered = messages.filter(message => !isVibeContext(message));
		const historyChanged = filtered.length !== messages.length;
		if (historyChanged) this.agent.replaceMessages(filtered);

		const steering = this.agent.peekSteeringQueue();
		const followUp = this.agent.peekFollowUpQueue();
		const filteredSteering = steering.filter(message => !isVibeContext(message));
		const filteredFollowUp = followUp.filter(message => !isVibeContext(message));
		if (filteredSteering.length !== steering.length || filteredFollowUp.length !== followUp.length) {
			this.agent.replaceQueues(filteredSteering, filteredFollowUp);
			this.#reconcileQueuedMessageDrain();
		}
		this.#pendingNextTurnMessages = this.#pendingNextTurnMessages.filter(message => !isVibeContext(message));

		if (!historyChanged) return;
		this.#advisors.resetAllRuntimes("vibe-mode-exit");
		this.#closeCodexProviderSessionsForHistoryRewrite();
	}

	#assertVibeSessionTransitionAllowed(action: string): void {
		if (this.#vibeModeState?.enabled) {
			throw new Error(`Cannot ${action} while vibe mode is active. Exit vibe mode first.`);
		}
	}

	get goalRuntime(): GoalRuntime {
		return this.#goalRuntime;
	}

	markPlanReferenceSent(): void {
		this.#planReferenceSent = true;
	}

	setPlanReferencePath(path: string): void {
		this.#planReferencePath = path;
	}

	getPlanReferencePath(): string {
		return this.#planReferencePath;
	}

	get clientBridge(): ClientBridge | undefined {
		return this.#clientBridge;
	}

	setClientBridge(bridge: ClientBridge | undefined): void {
		this.#clientBridge = bridge;
		this.#tools.refreshAcpPermissionGates();
	}

	#clearCheckpointRuntimeState(): void {
		this.#checkpointState = undefined;
		this.#pendingRewindReport = undefined;
		this.#lastCompletedRewind = undefined;
		this.#rewoundToolResultIds.clear();
	}

	/** Drop mutable tool decisions and directives owned by the previous logical session. */
	#clearSessionScopedToolState(): void {
		this.agent.clearDeferredToolDirectives();
		this.#toolChoiceQueue.clear();
		this.#tools.clearAcpPermissionDecisions();
		this.#tools.resetAnnouncedMounts();
		// A `/new`, session switch, or tree navigation reuses tool-call ids, so a
		// still-cached background-task snapshot from the old conversation must not
		// survive to be replayed by a focus rebuild in the reset session (#10447).
		this.#activeToolExecutionUpdates.clear();
	}

	/**
	 * Rebuild checkpoint/rewind runtime state from the current branch. Handles two
	 * cases surfaced by session resume, `switchSession()` reloading the same file,
	 * and tree navigation:
	 *   - The branch's most recent checkpoint has already been rewound → restore
	 *     `#lastCompletedRewind` so a repeat `rewind` call receives the
	 *     "checkpoint already completed" recovery guidance.
	 *   - The branch's most recent checkpoint has NOT been rewound (e.g. the run
	 *     was aborted between `checkpoint` and `rewind`) → restore
	 *     `#checkpointState` so the next `rewind` call can complete the
	 *     checkpoint instead of failing with "No active checkpoint".
	 */
	#rehydrateCheckpointRewindState(): void {
		this.#clearCheckpointRuntimeState();
		let completed: CompletedRewindState | undefined;
		let pending: { entryId: string; startedAt: string; messageCount: number } | undefined;
		let messageCount = 0;
		for (const entry of this.sessionManager.getBranch()) {
			if (entry.type === "message") messageCount++;
			if (isSuccessfulCheckpointEntry(entry)) {
				completed = undefined;
				pending = {
					entryId: entry.id,
					startedAt: checkpointStartedAtFromEntry(entry) ?? entry.timestamp,
					messageCount,
				};
				continue;
			}
			const completedFromEntry = completedRewindFromEntry(entry);
			if (completedFromEntry) {
				completed = completedFromEntry;
				pending = undefined;
			}
		}
		if (pending) {
			this.#checkpointState = {
				checkpointEntryId: pending.entryId,
				startedAt: pending.startedAt,
				checkpointMessageCount: pending.messageCount,
			};
			return;
		}
		this.#lastCompletedRewind = completed;
	}

	getCheckpointState(): CheckpointState | undefined {
		return this.#checkpointState;
	}

	getLastCompletedRewind(): CompletedRewindState | undefined {
		return this.#lastCompletedRewind;
	}

	setCheckpointState(state: CheckpointState | undefined): void {
		this.#checkpointState = state;
		if (state) {
			this.#lastCompletedRewind = undefined;
		} else {
			this.#pendingRewindReport = undefined;
		}
	}

	/**
	 * Inject the plan mode context message into the conversation history.
	 */
	async sendPlanModeContext(options?: { deliverAs?: "steer" | "followUp" | "nextTurn" | "aside" }): Promise<void> {
		const message = await this.#buildPlanModeMessage();
		if (!message) return;
		await this.sendCustomMessage(
			{
				customType: message.customType,
				content: message.content,
				display: message.display,
				details: message.details,
			},
			options ? { deliverAs: options.deliverAs } : undefined,
		);
	}

	async sendGoalModeContext(options?: { deliverAs?: "steer" | "followUp" | "nextTurn" | "aside" }): Promise<void> {
		const message = this.#buildGoalModeMessage();
		if (!message) return;
		await this.sendCustomMessage(
			{
				customType: message.customType,
				content: message.content,
				display: message.display,
				details: message.details,
				attribution: message.attribution,
			},
			options ? { deliverAs: options.deliverAs } : undefined,
		);
	}

	async sendVibeModeContext(options?: { deliverAs?: "steer" | "followUp" | "nextTurn" | "aside" }): Promise<void> {
		const message = this.#buildVibeModeMessage();
		if (!message) return;
		await this.sendCustomMessage(
			{
				customType: message.customType,
				content: message.content,
				display: message.display,
				details: message.details,
				attribution: message.attribution,
			},
			options ? { deliverAs: options.deliverAs } : undefined,
		);
	}

	resolveRoleModel(role: string): Model | undefined {
		return this.#models.resolveRoleModel(role);
	}

	/**
	 * Resolve a role to its model AND thinking level.
	 * Unlike resolveRoleModel(), this preserves the thinking level suffix
	 * from role configuration (e.g., "anthropic/claude-sonnet-4-5:xhigh").
	 */
	resolveRoleModelWithThinking(role: string): ResolvedModelRoleValue {
		return this.#models.resolveRoleModelWithThinking(role);
	}

	/**
	 * Resolve the explicit thinking suffix that should apply when a temporary
	 * picker selects a model already assigned to a configured role.
	 */
	resolveTemporaryModelThinkingLevel(model: Model): ConfiguredThinkingLevel | undefined {
		return this.#models.resolveTemporaryModelThinkingLevel(model);
	}

	get promptTemplates(): ReadonlyArray<PromptTemplate> {
		return this.#promptTemplates;
	}

	/** Replace file-based slash commands used for prompt expansion. */
	setSlashCommands(slashCommands: FileSlashCommand[]): void {
		this.#slashCommands = [...slashCommands];
	}
	/** File-based slash commands discovered at session construction (or last set). */
	get slashCommands(): ReadonlyArray<FileSlashCommand> {
		return this.#slashCommands;
	}

	/** Custom commands (TypeScript slash commands and MCP prompts) */
	get customCommands(): ReadonlyArray<LoadedCustomCommand> {
		if (this.#mcpPromptCommands.length === 0) return this.#customCommands;
		return [...this.#customCommands, ...this.#mcpPromptCommands];
	}

	/** MCP prompt commands only, for command-list metadata. */
	get mcpPromptCommands(): ReadonlyArray<LoadedCustomCommand> {
		return this.#mcpPromptCommands;
	}

	/** Update the MCP prompt commands list. Called when server prompts are (re)loaded. */
	setMCPPromptCommands(commands: LoadedCustomCommand[]): void {
		this.#mcpPromptCommands = commands;
		this.#notifyCommandMetadataChanged();
	}

	// =========================================================================
	// Prompting
	// =========================================================================

	/**
	 * Build the approved-plan reference message re-injected after a history
	 * rewrite (new session, compaction, edit). Inlines the plan body so the
	 * executor need not re-read it; the durable `local://` path stays in the
	 * prompt as the recovery route when a compressor expires the inline copy.
	 * Returns null during plan mode, once already sent, or when no plan exists.
	 */
	async #buildPlanReferenceMessage(): Promise<CustomMessage | null> {
		if (this.#planModeState?.enabled) return null;
		if (this.#planReferenceSent) return null;

		const plan = await loadOverallPlanReference(this.#planReferencePath, this.#localProtocolOptions());
		if (!plan) return null;

		const content = prompt.render(planModeReferencePrompt, {
			planFilePath: plan.path,
			planContent: plan.content,
		});

		return {
			role: "custom",
			customType: "plan-mode-reference",
			content,
			display: false,
			attribution: "agent",
			timestamp: Date.now(),
		};
	}

	#isScoutAvailable(): boolean {
		return this.#scoutAllowedBySpawnPolicy && !cfgTaskDisabledAgents.get(this.settings).includes("scout");
	}

	async #buildPlanModeMessage(): Promise<CustomMessage | null> {
		const state = this.#planModeState;
		if (!state?.enabled) return null;
		const sessionPlanUrl = "local://PLAN.md";
		const planPathOptions = { localProtocolOptions: this.#localProtocolOptions(), cwd: this.sessionManager.getCwd() };
		const resolvedPlanPath = resolvePlanFilePath(state.planFilePath, planPathOptions);
		const resolvedSessionPlan = resolvePlanFilePath(sessionPlanUrl, planPathOptions);
		const displayPlanPath =
			InternalUrlRouter.instance().canHandle(state.planFilePath) || resolvedPlanPath !== resolvedSessionPlan
				? state.planFilePath
				: sessionPlanUrl;

		const planExists = fs.existsSync(resolvedPlanPath);
		// Capability gates, not the visible surface: a Code Mode partition keeps
		// `task` and `ask` callable through the eval bridge after demoting them.
		const capableToolNames = this.getEnabledToolNames();
		const content = prompt.render(planModeActivePrompt, {
			planFilePath: displayPlanPath,
			planExists,
			askToolName: "ask",
			writeToolName: "write",
			editToolName: "edit",
			askAvailable: capableToolNames.includes("ask"),
			taskAvailable: capableToolNames.includes("task"),
			isHashlineEditMode: this.#resolveActiveEditMode() === "hashline",
			reentry: state.reentry ?? false,
			iterative: state.workflow === "iterative",
			scoutAvailable: this.#isScoutAvailable(),
		});

		return {
			role: "custom",
			customType: "plan-mode-context",
			content,
			display: false,
			attribution: "agent",
			timestamp: Date.now(),
		};
	}

	#buildGoalModeMessage(): CustomMessage | null {
		const content = this.#goalRuntime.buildActivePrompt();
		if (!content) return null;
		const todoContext = this.#buildGoalTodoContext();
		return {
			role: "custom",
			customType: "goal-mode-context",
			content: prompt.render(goalModeContextPrompt, { goalContext: content, todoContext }),
			display: false,
			attribution: "agent",
			timestamp: Date.now(),
		};
	}

	#buildVibeModeMessage(): CustomMessage | null {
		if (!this.#vibeModeState?.enabled) return null;
		return {
			role: "custom",
			customType: VIBE_MODE_CONTEXT_MESSAGE_TYPE,
			content: prompt.render(vibeModeActivePrompt, {
				todoAvailable: this.getActiveToolNames().includes("todo"),
			}),
			display: false,
			attribution: "agent",
			timestamp: Date.now(),
		};
	}

	#sanitizeGoalTodoText(text: string): string {
		return escapeXmlText(text)
			.replace(/\r\n/g, "\\n")
			.replace(/\r/g, "\\r")
			.replace(/\n/g, "\\n")
			.replace(/\t/g, "\\t")
			.replace(/[\u0000-\u0008\u000b\u000c\u000e-\u001f\u007f-\u009f\u2028\u2029]/g, " ");
	}

	#buildGoalTodoContext(): string | undefined {
		if (!cfgTodoEnabled.get(this.settings)) return undefined;
		const canCallTodoTool = this.getActiveToolNames().includes("todo");
		if (!canCallTodoTool) return undefined;
		const phases = this.getTodoPhases().filter(phase => phase.tasks.length > 0);
		if (phases.length === 0) return undefined;

		let total = 0;
		let closed = 0;
		let open = 0;
		const promptPhases = phases.map(phase => ({
			name: this.#sanitizeGoalTodoText(phase.name),
			tasks: phase.tasks.map(task => {
				total++;
				if (task.status === "completed" || task.status === "abandoned") {
					closed++;
				} else {
					open++;
				}
				return { content: this.#sanitizeGoalTodoText(task.content), status: task.status };
			}),
		}));

		return prompt.render(goalTodoContextPrompt, {
			canCallTodoTool,
			closed: String(closed),
			open: String(open),
			phases: promptPhases,
			total: String(total),
		});
	}

	#normalizeImagesForModel(images: ImageContent[] | undefined): Promise<ImageContent[] | undefined> {
		return normalizeModelContextImages(images, { model: this.model });
	}

	/**
	 * Emit source paths for file-backed attachments (path-pasted/drag-and-dropped
	 * images, clipboard images committed to the session artifact directory, video
	 * contact-sheet previews) as hidden user context. The visible message
	 * deliberately contains only its `[Image #N]`/`[Video #N]` marker and the
	 * attachment itself, while the agent gets the path required to act on the file
	 * (e.g. `read`, uploads, or video frame subselectors) without exposing the
	 * user's filesystem layout in the TUI. Attachments without a file on disk are
	 * skipped — no path is invented for them.
	 */
	#createAttachmentSourceNotices(images: readonly ImageContent[] | undefined, timestamp: number): CustomMessage[] {
		if (!images?.length) return [];
		const notices: CustomMessage[] = [];
		for (let index = 0; index < images.length; index++) {
			const notice = renderAttachmentSourceNotice(images[index]!, index + 1);
			if (!notice) continue;
			notices.push({
				role: "custom",
				customType: notice.customType,
				content: notice.content,
				display: false,
				attribution: "user",
				timestamp,
			});
		}
		return notices;
	}

	/**
	 * Every caller runs this before its message is admitted (queued or dispatched), and
	 * RPC acknowledges `prompt` only after admission. Bound the vision call so a slow
	 * provider cannot hold admission past the bundled clients' 30 s request timeout, and
	 * let abort() cancel it. Either way the image stays saved and the notice says the
	 * description is unavailable.
	 */
	async #buildImageDescriptionNotice(normalizedImages: ImageContent[]): Promise<CustomMessage | undefined> {
		const controller = new AbortController();
		this.#imageDescriptionAbortControllers.add(controller);
		try {
			return await this.#providerBoundary.buildImageDescriptionNotice(
				normalizedImages,
				AbortSignal.any([controller.signal, AbortSignal.timeout(IMAGE_DESCRIPTION_ADMISSION_TIMEOUT_MS)]),
			);
		} finally {
			this.#imageDescriptionAbortControllers.delete(controller);
		}
	}

	#normalizeAgentMessageImages<T extends AgentMessage>(message: T): Promise<T> {
		return this.#providerBoundary.normalizeAgentMessageImages(message);
	}

	#magicKeywordEnabled(keyword: MagicKeywordId): boolean {
		return cfgMagicKeywordsEnabled.get(this.settings) && cfgMagicKeyword[keyword].get(this.settings);
	}

	#createMagicKeywordNotices(text: string): CustomMessage[] {
		const timestamp = Date.now();
		const turnBudget = parseTurnBudget(text);
		this.sessionManager.beginTurnBudget(turnBudget?.total ?? null, turnBudget?.hard ?? false);
		const keywordNotices: CustomMessage[] = [];
		let context: MagicKeywordContext | undefined;
		for (const keyword of MAGIC_KEYWORDS) {
			if (!this.#magicKeywordEnabled(keyword.id) || !containsMagicKeyword(text, keyword.word)) continue;
			context ??= {
				tools: this.getEnabledToolNames(),
				taskBatch: cfgTaskBatch.get(this.settings),
				scoutAvailable: this.#isScoutAvailable(),
				evalTools: cfgEvalToolsEnabled.get(this.settings),
			};
			// A notice whose contract needs an inactive tool would demand an
			// unavailable capability; skip it rather than mislead the model.
			const tools = context.tools;
			if (!keyword.requires.every(tool => tools.includes(tool))) continue;
			keywordNotices.push({
				role: "custom",
				customType: `${keyword.id}-notice`,
				content: keyword.notice(context),
				display: false,
				attribution: "user",
				timestamp,
			});
		}
		return keywordNotices;
	}

	/**
	 * Send a prompt to the agent.
	 * - Handles extension commands (registered via pi.registerCommand) immediately, even during streaming
	 * - Expands file-based prompt templates by default
	 * - During streaming, queues via steer() or followUp() based on streamingBehavior option
	 * - Validates model and API key before sending (when not streaming)
	 * @throws Error if streaming and no streamingBehavior specified
	 * @throws Error if no model selected or no API key available (when not streaming)
	 *
	 * Returns `false` when the command was fully handled locally (extension or
	 * custom-TS command consumed without calling the LLM). Returns `true` when
	 * the prompt was forwarded to the agent — either directly or queued as a
	 * steer/follow-up. Callers that render a UI or manage turn lifecycle (e.g.
	 * the ACP agent) use this to know whether to expect an `agent_end` event.
	 *
	 * A prompt dropped before dispatch also resolves `true` (RPC reports it as
	 * aborted once no run started); pass `throwOnDrop: true` to reject with
	 * {@link PromptDroppedError} instead.
	 */
	async prompt(text: string, options?: PromptOptions): Promise<boolean> {
		this.#assertTaskRecoveryInput("prompt");
		return this.#admitSubmission(() => this.#prompt(text, options));
	}

	async #prompt(text: string, options?: PromptOptions): Promise<boolean> {
		// Stamp the operator's submission instant before ANY async preprocessing —
		// command execution, image normalization, vision-model description — so the
		// prompt→yield delta includes the whole wait, whatever path the prompt takes.
		const submittedAt = Date.now();
		// A manual `/compact` runs with the agent subscription disconnected until its
		// cleanup finally re-drains the preserved queues. Starting a turn before then
		// would neither persist nor forward its events and could race the in-flight
		// history rewrite. `abort` still overtakes compaction; ordinary prompts wait
		// here, and a waiting prompt supersedes the interrupted-turn resume the
		// compaction would otherwise schedule — but only once it actually claims the
		// session (a turn dispatched or queued, or one already running). A locally
		// handled command, a pre-dispatch throw, or a prompt dropped by the
		// abort/preflight race hands the resume back via `release(false)`. A prompt
		// arriving after the cleanup while an earlier parked prompt is still settling
		// takes part in the same decision. No-op otherwise.
		const release = await this.#maintenance.waitForManualCompactionCleanup();
		const outcome: PromptDispatchOutcome = { sessionClaimed: false };
		if (!release) return this.#dispatchPrompt(text, options, submittedAt, outcome);
		try {
			return await this.#dispatchPrompt(text, options, submittedAt, outcome);
		} finally {
			release(outcome.sessionClaimed);
		}
	}

	async #dispatchPrompt(
		text: string,
		options: PromptOptions | undefined,
		submittedAt: number,
		outcome: PromptDispatchOutcome,
	): Promise<boolean> {
		const expandPromptTemplates = options?.expandPromptTemplates ?? true;
		// Slash/custom-command handling below rewrites `text`; keep the original
		// so a dropped prompt is handed back exactly as the user typed it.
		const typedText = text;
		// Handle extension commands first (execute immediately, even during streaming)
		if (expandPromptTemplates && text.startsWith("/")) {
			if (options?.runCommands !== false) {
				const handled = await this.#tryExecuteExtensionCommand(text, options?.onPromptAdmitted);
				if (handled) {
					return false;
				}

				// Try custom commands (TypeScript slash commands)
				const customResult = await this.#tryExecuteCustomCommand(text);
				if (customResult !== null) {
					if (customResult === "") {
						return false;
					}
					text = customResult;
				}
			}

			// Try file-based slash commands (markdown files from commands/ directories)
			// Only if text still starts with "/" (wasn't transformed by custom command)
			if (text.startsWith("/")) {
				text = expandSlashCommand(text, this.#slashCommands);
			}
		}

		// Expand file-based prompt templates if requested
		const templated = expandPromptTemplates ? expandPromptTemplate(text, [...this.#promptTemplates]) : text;
		const expandedText = options?.synthetic ? templated : this.#modelMentions.expandMentions(templated);

		// Magic keywords (see modes/magic-keywords.ts): append hidden system notices after the
		// user's message that steer this turn. User-authored prompts only — synthetic /
		// agent-initiated turns never trigger them.
		const keywordNotices = options?.synthetic ? [] : this.#createMagicKeywordNotices(expandedText);

		// A user-initiated prompt (typed message or the `.`/`c` continue shortcut)
		// re-enables advisor auto-resume that a prior user interrupt suppressed.
		// Agent-initiated synthetic prompts (auto-continue, plan, reminders) do not.
		if (options?.userInitiated ?? !options?.synthetic) {
			this.#advisors.autoResumeSuppressed = false;
			this.#planModeReminderCount = 0;
			this.#planModeReminderAwaitingProgress = false;
			// A user turn owns the next decision; drop a queued forced choice from
			// a reminder continuation this prompt just preempted.
			this.#toolChoiceQueue.removeByLabel("plan-mode-decision");
		}

		const promptAttribution = options?.attribution ?? (options?.synthetic ? "agent" : "user");

		// If streaming, queue via steer()/followUp()/aside based on option
		if (this.isStreaming) {
			const streamingBehavior = options?.streamingBehavior;
			if (!streamingBehavior) {
				// Busy because the agent owns a turn: that turn supersedes the interrupted
				// one (after compaction it is the queued-message drain). Busy only from
				// another prompt's setup claims nothing yet.
				outcome.sessionClaimed = this.agent.state.isStreaming;
				throw new AgentBusyError();
			}

			// abort() can land while the images are prepared; the message is then
			// dropped instead of queued (same contract as the idle drop below).
			const queueGeneration = this.#promptGeneration;
			const queued = await this.#queueUserMessage(expandedText, options?.images, streamingBehavior, {
				timestamp: submittedAt,
				attribution: promptAttribution,
				prependMessages: keywordNotices,
				rawText: typedText,
				onPromptAdmitted: options?.onPromptAdmitted,
				promptGeneration: queueGeneration,
			});
			outcome.sessionClaimed = queued;
			if (!queued && this.#promptGeneration !== queueGeneration && !options?.synthetic) {
				this.#promptDropped?.({ text: typedText, images: options?.images });
			}
			return true;
		}

		// Captured before the normalization/vision-description awaits below so an
		// abort() landing during either can be told apart from a fresh submission —
		// see the drop check right after those awaits.
		const preflightGeneration = this.#promptGeneration;
		// Skip eager preludes when the user has already queued a directive
		const hasPendingUserDirective = this.#toolChoiceQueue.inspect().includes("user-force");
		const activeModel = this.agent.state.model;
		const externalThinkingToolChoice =
			!options?.synthetic &&
			!hasPendingUserDirective &&
			cfgExternalThinking.get(this.settings) &&
			this.getEnabledToolNames().includes("think") &&
			supportsExternalThinking(activeModel)
				? buildNamedToolChoice("think", activeModel)
				: undefined;
		const eagerTodoPrelude =
			!options?.synthetic && !hasPendingUserDirective ? this.#todo.createEagerTodoPrelude(expandedText) : undefined;
		const eagerTaskPrelude =
			!options?.synthetic && !hasPendingUserDirective ? this.#todo.createEagerTaskPrelude(expandedText) : undefined;
		const attachmentSourceNotices = this.#createAttachmentSourceNotices(options?.images, submittedAt);
		const normalizedImages = await this.#normalizeImagesForModel(options?.images);

		const userContent: (TextContent | ImageContent)[] = [{ type: "text", text: expandedText }];
		if (normalizedImages?.length) {
			userContent.push(...normalizedImages);
		}
		// Text-only model + image attachment: describe via a vision model and inject the
		// description as a hidden companion (the image stays in the visible user message).
		const imageDescriptionNotice = normalizedImages?.length
			? await this.#buildImageDescriptionNotice(normalizedImages)
			: undefined;

		// abort() bumps #promptGeneration and can land while normalization and the
		// vision-description call above are still in flight. #promptWithMessage below
		// captures its own generation fresh at entry, so it cannot see this race and
		// would dispatch a brand-new turn as if the abort never happened. Drop the
		// prompt here instead — same contract as #promptWithMessage's own
		// generation-race checks further down.
		if (this.#promptGeneration !== preflightGeneration) {
			outcome.sessionClaimed = false;
			if (!options?.synthetic) {
				this.#promptDropped?.({ text: typedText, images: options?.images });
			}
			return true;
		}

		// A concurrent prompt() can start a turn during the awaits above: image
		// normalization and the vision-description call suspend after the
		// isStreaming check at the top, so two callers — the CLI initial message
		// and a freshly typed submission — can both observe an idle session.
		// Re-check before dispatch so the loser queues exactly like the early
		// branch instead of racing #promptWithMessage into AgentBusyError. No
		// await sits between this check and #beginInFlight, so the winner's
		// in-flight increment is visible to every later re-check.
		if (this.isStreaming) {
			const streamingBehavior = options?.streamingBehavior;
			if (!streamingBehavior) {
				outcome.sessionClaimed = this.agent.state.isStreaming;
				throw new AgentBusyError();
			}
			await this.#queueUserMessage(expandedText, options?.images, streamingBehavior, {
				timestamp: submittedAt,
				attribution: promptAttribution,
				prependMessages: keywordNotices,
				rawText: typedText,
				preprocessed: {
					images: normalizedImages,
					descriptionNotice: imageDescriptionNotice,
				},
				onPromptAdmitted: options?.onPromptAdmitted,
			});
			outcome.sessionClaimed = true;
			return true;
		}

		if (externalThinkingToolChoice) {
			this.#toolChoiceQueue.pushOnce(externalThinkingToolChoice, {
				label: "external-thinking",
				now: true,
			});
		}
		const message = options?.synthetic
			? {
					role: "developer" as const,
					content: userContent,
					attribution: promptAttribution,
					timestamp: submittedAt,
					synthetic: true,
					userInitiated: options?.userInitiated === true ? true : undefined,
				}
			: { role: "user" as const, content: userContent, attribution: promptAttribution, timestamp: submittedAt };

		const preludeMessages: AgentMessage[] = [];
		if (eagerTodoPrelude) {
			if (eagerTodoPrelude.toolChoice) {
				this.#toolChoiceQueue.pushOnce(eagerTodoPrelude.toolChoice, {
					label: "eager-todo",
				});
			}
			preludeMessages.push(eagerTodoPrelude.message);
		}
		if (eagerTaskPrelude) {
			preludeMessages.push(eagerTaskPrelude);
		}

		let dispatched = false;
		try {
			dispatched = await this.#promptWithMessage(message, expandedText, {
				...options,
				images: normalizedImages,
				prependMessages:
					preludeMessages.length > 0 ||
					keywordNotices.length > 0 ||
					attachmentSourceNotices.length > 0 ||
					imageDescriptionNotice
						? [
								...preludeMessages,
								...keywordNotices,
								...attachmentSourceNotices,
								...(imageDescriptionNotice ? [imageDescriptionNotice] : []),
							]
						: undefined,
			});
		} catch (error) {
			if (error instanceof AgentStartPolicyChangedError && message.role === "user") {
				this.#promptDropped?.({ text: typedText, images: options?.images });
			}
			throw error;
		} finally {
			// Clean up residual eager-todo directive if the prompt never consumed it
			// (e.g., compaction aborted, validation failed).
			this.#toolChoiceQueue.removeByLabel("eager-todo");
			this.#toolChoiceQueue.removeByLabel("external-thinking");
		}
		outcome.sessionClaimed = dispatched;
		if (!dispatched && message.role === "user") {
			// An abort (Esc) or preflight denial raced turn setup: the prompt never
			// reached the agent or the session file. Hand it back to the host so the
			// user can edit/resubmit instead of losing it (tree/branch can't offer
			// a message that was never persisted).
			this.#promptDropped?.({ text: typedText, images: options?.images });
		}
		if (!dispatched && options?.throwOnDrop) throw new PromptDroppedError();
		return true;
	}

	/**
	 * @returns true when the message is (or will be) picked up by an agent turn
	 * — queued into a running turn, or a new turn started synchronously. false
	 * when dispatch bailed before invoking the agent (e.g. a concurrent abort
	 * won the generation race), so hosts waiting on a terminal `agent_end` can
	 * stop instead of hanging.
	 */
	async promptCustomMessage<T = unknown>(
		message: Pick<CustomMessage<T>, "customType" | "content" | "display" | "details" | "attribution">,
		options?: Pick<PromptOptions, "streamingBehavior" | "toolChoice" | "onPromptAdmitted"> & {
			queueChipText?: string;
			queueOnly?: boolean;
		},
	): Promise<boolean> {
		this.#assertTaskRecoveryInput();
		return this.#admitSubmission(() => this.#promptCustomMessage(message, options));
	}

	async #promptCustomMessage<T = unknown>(
		message: Pick<CustomMessage<T>, "customType" | "content" | "display" | "details" | "attribution">,
		options?: Pick<PromptOptions, "streamingBehavior" | "toolChoice" | "onPromptAdmitted"> & {
			queueChipText?: string;
			queueOnly?: boolean;
		},
	): Promise<boolean> {
		// Same barrier/claim protocol as prompt(): skill invocations, collab peer
		// prompts and the CLI initial message arrive here and must neither start a
		// turn against the disconnected session nor lose the session to the
		// interrupted-turn resume once compaction ends.
		const release = await this.#maintenance.waitForManualCompactionCleanup();
		const outcome: PromptDispatchOutcome = { sessionClaimed: false };
		if (!release) return this.#dispatchCustomPrompt(message, options, outcome);
		try {
			return await this.#dispatchCustomPrompt(message, options, outcome);
		} finally {
			release(outcome.sessionClaimed);
		}
	}

	async #dispatchCustomPrompt<T = unknown>(
		message: Pick<CustomMessage<T>, "customType" | "content" | "display" | "details" | "attribution">,
		options:
			| (Pick<PromptOptions, "streamingBehavior" | "toolChoice" | "onPromptAdmitted"> & {
					queueChipText?: string;
					queueOnly?: boolean;
			  })
			| undefined,
		outcome: PromptDispatchOutcome,
	): Promise<boolean> {
		const textContent =
			typeof message.content === "string"
				? message.content
				: message.content
						.filter((content): content is TextContent => content.type === "text")
						.map(content => content.text)
						.join("");

		let keywordNotices: CustomMessage[] = [];
		if (message.customType === SKILL_PROMPT_MESSAGE_TYPE && message.attribution === "user") {
			const details = message.details;
			let skillName: string | undefined;
			let skillArgs = "";
			if (details && typeof details === "object") {
				if ("name" in details && typeof details.name === "string") skillName = details.name;
				if ("args" in details && typeof details.args === "string") skillArgs = details.args;
			}
			keywordNotices = this.#createMagicKeywordNotices(skillArgs);
			this.maybeStartTitleGeneration(
				skillPromptTitleInput({
					name: skillName,
					args: skillArgs,
					queueChipText: options?.queueChipText,
				}),
			);
		}

		if (options?.queueOnly || this.isStreaming) {
			const streamingBehavior = options?.streamingBehavior;
			if (!streamingBehavior) {
				// Mirrors #dispatchPrompt: busy because the agent owns a turn claims the
				// session; busy only from queueOnly or another prompt's setup claims
				// nothing.
				if (this.isStreaming) outcome.sessionClaimed = this.agent.state.isStreaming;
				throw new AgentBusyError();
			}

			await this.#queueCustomMessage(message, streamingBehavior, {
				queueChipText: options?.queueChipText,
				prependMessages: keywordNotices,
				onPromptAdmitted: options?.onPromptAdmitted,
			});
			outcome.sessionClaimed = true;
			return true;
		}

		const customMessage: CustomMessage<T> = {
			role: "custom",
			customType: message.customType,
			content: message.content,
			display: message.display,
			details: message.details,
			attribution: message.attribution ?? "agent",
			timestamp: Date.now(),
		};
		const hasSkillImages =
			isUserInvokedSkillPrompt(customMessage) &&
			Array.isArray(customMessage.content) &&
			customMessage.content.some(part => part.type === "image");
		const preparedMessage = hasSkillImages ? await this.#normalizeAgentMessageImages(customMessage) : customMessage;
		const descriptionNotice = hasSkillImages
			? await this.#buildSkillImageDescriptionNotice(preparedMessage)
			: undefined;

		// Image normalization and the vision-description call suspend after the
		// isStreaming check above, so a concurrent submission can start a turn in
		// between. Re-check before dispatch and queue with the already-prepared
		// content, mirroring #dispatchPrompt; no await sits between this check and
		// #promptWithMessage's in-flight increment.
		if (this.isStreaming) {
			const streamingBehavior = options?.streamingBehavior;
			if (!streamingBehavior) {
				outcome.sessionClaimed = this.agent.state.isStreaming;
				throw new AgentBusyError();
			}
			await this.#queueCustomMessage(message, streamingBehavior, {
				queueChipText: options?.queueChipText,
				preprocessed: { content: preparedMessage.content, descriptionNotice },
				prependMessages: keywordNotices,
				onPromptAdmitted: options?.onPromptAdmitted,
			});
			outcome.sessionClaimed = true;
			return true;
		}
		outcome.sessionClaimed = await this.#promptWithMessage(preparedMessage, textContent, {
			...options,
			prependMessages:
				keywordNotices.length > 0 || descriptionNotice
					? [...keywordNotices, ...(descriptionNotice ? [descriptionNotice] : [])]
					: undefined,
		});
		return outcome.sessionClaimed;
	}

	/** Describe normalized images in a user-invoked skill prompt before delivery. */
	async #buildSkillImageDescriptionNotice(message: CustomMessage): Promise<CustomMessage | undefined> {
		if (!isUserInvokedSkillPrompt(message) || !Array.isArray(message.content)) return undefined;
		const images = message.content.filter((part): part is ImageContent => part.type === "image");
		return images.length > 0 ? this.#buildImageDescriptionNotice(images) : undefined;
	}

	/** Queue ownership belongs to Agent; only actual user deliveries refresh submission policy. */
	#prepareQueuedUserMessages = (
		messages: readonly AgentMessage[],
		signal: AbortSignal,
	): Promise<QueuedMessagePreparation> | undefined => {
		const userMessages = messages.filter(isUserAuthoredQueuedMessage);
		const first = userMessages[0];
		if (!first) return undefined;
		const text: string[] = [];
		const images: ImageContent[] = [];
		for (const message of userMessages) {
			if (!("content" in message)) continue;
			if (typeof message.content === "string") {
				text.push(message.content);
				continue;
			}
			const parts: string[] = [];
			for (const part of message.content) {
				if (part.type === "text") parts.push(part.text);
				else if (part.type === "image") images.push(part);
			}
			text.push(parts.join(""));
		}
		return this.#prepareAgentStart(
			first,
			text.join("\n\n"),
			images.length > 0 ? images : undefined,
			this.#promptGeneration,
			signal,
			"queued",
		);
	};

	/**
	 * Stage extension results; committing them must remain synchronous with delivery validation.
	 *
	 * `signal` cancels awaited setup (memory auto-recall) for both direct and queued turns.
	 * `origin` decides the disposal contract: a direct prompt admitted before {@link beginDispose}
	 * still runs to a settled turn, while a queued turn never starts on a disposed session.
	 */
	async #prepareAgentStart(
		message: AgentMessage,
		prompt: string,
		images: ImageContent[] | undefined,
		generation: number,
		signal: AbortSignal | undefined,
		origin: "direct" | "queued",
	): Promise<QueuedMessagePreparation & { baseXdevCatalogDelivered: boolean }> {
		const sessionGeneration = this.#sessionGeneration;
		const alreadyDisposing = this.#isDisposed && origin === "direct";
		const isCurrent = () =>
			this.#promptGeneration === generation &&
			this.#sessionGeneration === sessionGeneration &&
			(!this.#isDisposed || alreadyDisposing) &&
			!signal?.aborted;
		const cancelled = { baseXdevCatalogDelivered: false, commit: () => undefined };
		for (let attempt = 0; attempt < AGENT_START_POLICY_MAX_ATTEMPTS; attempt++) {
			await this.#memory.transition;
			if (!isCurrent()) return cancelled;
			const sourceBase = this.#tools.baseSystemPrompt;
			const basePreparation = await this.#tools.buildSystemPromptForAgentStart(prompt, isCurrent, signal);
			if (!isCurrent()) return cancelled;
			const result = await this.#extensionRunner?.emitBeforeAgentStart(prompt, images, basePreparation.systemPrompt);
			if (!isCurrent()) return cancelled;
			// Overrides are opaque replacements, not string patches. Re-run only policy preparation
			// against the winning base; discard this attempt's returned context and staged memory.
			const overrideIsCurrent = () => {
				if (result?.systemPrompt === undefined) return true;
				const currentBase = this.#tools.baseSystemPrompt;
				// Refreshing an unchanged tool set may replace the array without changing policy.
				return (
					sourceBase === currentBase ||
					(sourceBase.length === currentBase.length &&
						sourceBase.every((part, index) => part === currentBase[index]))
				);
			};
			if (!overrideIsCurrent()) continue;
			const messages: AgentMessage[] = [];
			const attribution = "attribution" in message ? message.attribution : undefined;
			for (const payload of result?.messages ?? []) {
				const normalized = normalizeCustomMessagePayload(payload);
				const explicitAttribution =
					payload !== null &&
					typeof payload === "object" &&
					!Array.isArray(payload) &&
					(payload.attribution === "user" || payload.attribution === "agent");
				messages.push(
					await this.#normalizeAgentMessageImages({
						role: "custom",
						customType: normalized.customType,
						content: normalized.content,
						display: normalized.display,
						details: normalized.details,
						attribution: explicitAttribution
							? normalized.attribution
							: (attribution ?? (message.role === "user" ? "user" : "agent")),
						timestamp: Date.now(),
					}),
				);
				if (!isCurrent()) return cancelled;
			}
			if (!overrideIsCurrent()) continue;
			return {
				baseXdevCatalogDelivered: result?.systemPrompt === undefined,
				commit: () => {
					// No await may separate ownership validation from publishing memory and policy.
					if (!isCurrent() || !overrideIsCurrent()) return undefined;
					if (basePreparation.commit?.() === false) return undefined;
					if (result?.systemPrompt !== undefined) {
						this.#tools.setTurnSystemPromptOverride(result.systemPrompt);
					} else {
						this.#tools.clearTurnSystemPromptOverride();
						this.agent.setSystemPrompt(this.#tools.baseSystemPrompt);
					}
					return messages;
				},
			};
		}
		if (origin === "queued") {
			// Block the queued settle drain before Agent converts this error into an
			// assistant message and resolves the running turn.
			this.#queuedMessageDrainBlocked = true;
		}
		throw new AgentStartPolicyChangedError();
	}

	async #promptWithMessage(
		message: AgentMessage,
		expandedText: string,
		options?: Pick<
			PromptOptions,
			"toolChoice" | "images" | "skipCompactionCheck" | "solutionSpace" | "onPromptAdmitted"
		> & {
			prependMessages?: AgentMessage[];
			taskBindingId?: string;
			skipPostPromptRecoveryWait?: boolean;
			acceptTerminalEmptyStop?: boolean;
			existingEntry?: {
				anchorEntryId: string;
				taskBound?: boolean;
				signal: AbortSignal;
				beforeDispatch: (preparedMessages: readonly AgentMessage[]) => Promise<boolean>;
				canDispatch: (preparedMessages: readonly AgentMessage[]) => boolean;
			};
		},
	): Promise<boolean> {
		// Returns false when the prompt was dropped before reaching the agent —
		// every pre-dispatch bail (generation bump from abort, disposal, usage
		// preflight denial) exits silently, and prompt() uses the outcome to hand
		// the typed text back to the host instead of losing it.
		this.#beginInFlight();
		const generation = this.#promptGeneration;
		this.#promptSequence++;
		let releaseDrainedGuard: (() => void) | undefined;
		const setupAbort = new AbortController();
		this.#promptSetupAbortController = setupAbort;
		try {
			options?.onPromptAdmitted?.();
			await this.#recovery.maybeRestoreRetryFallbackPrimary();
			if (!(await this.#runUsageAwarePreflightForNextModelCall())) return false;
			// Flush any pending bash messages before the new prompt
			await this.#bash.flushPending();
			this.#eval.flushPending();
			this.#irc.flushPending();

			this.#todo.resetCycle();
			this.#resetPromptMaintenanceState();
			this.#recovery.setAcceptTerminalEmptyStop(options?.acceptTerminalEmptyStop === true);

			// Validate model
			if (!this.model) {
				throw new Error(
					"No model selected.\n\n" +
						`Use /login, set an API key environment variable, or create ${getAgentDbPath()}\n\n` +
						"Then use /model to select a model.",
				);
			}

			// Validate API key
			const apiKey = this.#getApiKey
				? await resolveApiKeyOnce(await this.#getApiKey(this.model))
				: await this.#modelRegistry.getApiKey(this.model, this.sessionId);
			if (!apiKey) {
				throw new Error(
					`No API key found for ${this.model.provider}.\n\n` +
						`Use /login, set an API key environment variable, or create ${getAgentDbPath()}`,
				);
			}

			// Recover a previously failed/incomplete assistant turn before sending.
			// Successful historical turns take the cheaper pre-prompt threshold path
			// below; re-running the full post-turn check on resume can synchronously
			// rewrite/re-render old context before the new prompt starts.
			const lastAssistant = this.#findLastAssistantMessage();
			if (
				lastAssistant &&
				!options?.skipCompactionCheck &&
				(lastAssistant.stopReason === "error" || lastAssistant.stopReason === "length")
			) {
				await this.#maintenance.checkCompaction(lastAssistant, false, false, false);
			}

			await this.#prewalk.armPlanYoloIfNeeded();

			// Build messages array (session context, eager todo prelude, then active prompt message)
			const messages: AgentMessage[] = [];
			const planReferenceMessage = await this.#buildPlanReferenceMessage?.();
			if (planReferenceMessage) {
				messages.push(planReferenceMessage);
			}
			const planModeMessage = await this.#buildPlanModeMessage();
			if (planModeMessage) {
				messages.push(planModeMessage);
			}
			const goalModeMessage = this.#buildGoalModeMessage();
			if (goalModeMessage) {
				messages.push(goalModeMessage);
			}
			const vibeModeMessage = this.#buildVibeModeMessage();
			if (vibeModeMessage) {
				messages.push(vibeModeMessage);
			}
			if (options?.prependMessages) {
				messages.push(...options.prependMessages);
			}

			// Early bail-out: if a newer abort/prompt cycle started during setup,
			// return before mutating shared state (nextTurn messages, system prompt).
			if (this.#promptGeneration !== generation) {
				return false;
			}

			// Pending tool-roster and xd:// deltas accompany the next user-authored
			// prompt, never an agent-initiated continuation. Reserve their pre-user
			// position now. Non-consuming previews count toward pre-prompt context
			// maintenance, while the live deltas are consumed only after maintenance:
			// promotion/summary can rebuild the base prompt and clear a roster delta
			// it subsumes, avoiding a contradictory materialized notice.
			const xdevMountNoticeIndex = messages.length;
			if (!options?.existingEntry) messages.push(message);
			// Queued nextTurn messages land directly after the active user message
			// even though the drain itself runs after before_agent_start below.
			const nextTurnInsertIndex = messages.length;

			// Auto-read @filepath mentions
			const fileMentions = extractFileMentions(expandedText);
			if (fileMentions.length > 0) {
				const fileMentionMessages = await generateFileMentionMessages(fileMentions, this.sessionManager.getCwd(), {
					autoResizeImages: cfgImagesAutoResize.get(this.settings),
					useHashLines: resolveFileDisplayMode(this).hashLines,
					snapshotStore: getEditStore(this),
				});
				for (const fileMentionMessage of fileMentionMessages) {
					messages.push(await this.#normalizeAgentMessageImages(fileMentionMessage));
				}
			}

			const preparation = await this.#prepareAgentStart(
				message,
				expandedText,
				options?.images,
				generation,
				setupAbort.signal,
				"direct",
			);
			// A newer abort/prompt cycle started during the hook await: return
			// BEFORE consuming queued nextTurn messages, so anything queued for
			// this prompt (e.g. a barrier-delivered session-ledger note) survives
			// for the next prompt instead of vanishing with the discarded array.
			if (this.#promptGeneration !== generation) {
				return false;
			}
			// Inject any pending "nextTurn" messages as context directly after the
			// user message. Drained AFTER the awaited before_agent_start hook so
			// messages queued while that hook ran (e.g. a barrier-delivered
			// session-ledger note) join this prompt instead of slipping to the
			// following turn. Order: active user message, queued nextTurn messages
			// in queue order, then messages returned by before_agent_start.
			//
			// A hidden next-turn message may carry a dispatch-time authority check
			// (S2.5): re-read it now, before the message joins the prompt, and drop
			// any refusal so no session entry and no provider request is produced.
			const queuedNextTurn = this.#pendingNextTurnMessages;
			this.#pendingNextTurnMessages = [];
			const drainedNextTurn = this.#hasAnyHiddenNextTurnDispatchValidator(queuedNextTurn)
				? await this.#admitHiddenNextTurnMessages(queuedNextTurn)
				: queuedNextTurn;
			// Transactional drain: any generation bail below hands the drained
			// batch back to the queue (ahead of anything queued since), so it
			// survives for the next prompt instead of dying with this array.
			const restoreDrainedNextTurn = () => {
				if (drainedNextTurn.length > 0) {
					this.#pendingNextTurnMessages = [...drainedNextTurn, ...this.#pendingNextTurnMessages];
				}
			};
			if (this.#promptGeneration !== generation) {
				restoreDrainedNextTurn();
				return false;
			}
			// Publishing the hook's policy and context must stay synchronous with its
			// ownership validation; the drain above already finished awaiting.
			const preparedMessages = preparation.commit();
			if (!preparedMessages) {
				restoreDrainedNextTurn();
				return false;
			}
			messages.splice(nextTurnInsertIndex, 0, ...drainedNextTurn);
			messages.push(...preparedMessages);
			// Guard the turn's first model call with every hidden next-turn message
			// admitted for this prompt — the anchor plus any prepended siblings and
			// the live drain — so a validator that flips after this point (e.g. inside
			// the before_agent_start handler above) still refuses before the request.
			releaseDrainedGuard = this.#armHiddenNextTurnDispatchGuard([
				message,
				...(options?.prependMessages ?? []),
				...drainedNextTurn,
			]);
			const baseXdevCatalogDelivered = preparation.baseXdevCatalogDelivered;

			// Auto thinking: classify this real user turn and set the effective level
			// before the model request. A user-invoked `/skill:<name>` arrives as a
			// user-attributed skill custom message whose expanded body is the task
			// prompt, so it counts as a user turn. Synthetic/tool-continuation turns
			// (developer roles), agent-originated or autoloaded skill injections, and
			// non-auto sessions are skipped. Never blocks the turn — failures fall
			// back to a concrete level inside the helper.
			const isUserTurn = message.role === "user" || (message.role === "custom" && isUserInvokedSkillPrompt(message));
			if (this.isAutoThinking && isUserTurn) {
				await this.#models.applyAutoThinkingLevel(expandedText, generation, options?.solutionSpace);
				if (this.#promptGeneration !== generation) {
					restoreDrainedNextTurn();
					return false;
				}
			}

			// Only the xd:// mount notice can carry substantial inline docs (up to
			// XDEV_DOCS_TOTAL_BUDGET), so preview it in a copy and let context
			// maintenance see the request's true size without consuming a delta a
			// rebuild may supersede. The tool-roster notice is a tiny name list with
			// no budget impact, so it is not previewed here — it must always ship
			// alongside the schema change it describes (see below).
			const previewXdevMountNotice = isUserQueuedMessage(message)
				? this.#tools.peekPendingXdevMountNotice({ baseCatalogDelivered: baseXdevCatalogDelivered })
				: undefined;
			const maintenanceMessages = previewXdevMountNotice?.notice ? [...messages] : messages;
			if (maintenanceMessages !== messages && previewXdevMountNotice?.notice) {
				maintenanceMessages.splice(xdevMountNoticeIndex, 0, previewXdevMountNotice.notice);
			}
			await this.#maintenance.runPrePromptCompactionIfNeeded(maintenanceMessages);
			if (this.#promptGeneration !== generation) {
				restoreDrainedNextTurn();
				return false;
			}
			// Consume the xd:// notice only when its previewed revision still holds.
			// A mount delta or catalog rebuild during the await invalidates it: any
			// additions carried by the delivered base are recorded as announced,
			// while remaining notice content waits for the next context check.
			// The roster notice is re-derived from the live delta here and always
			// delivered, keeping the model's stated availability in lockstep with
			// the wire tool list even when a roster change landed during maintenance.
			const xdevMountNotice = previewXdevMountNotice
				? this.#tools.takePendingXdevMountNotice({
						baseCatalogDelivered: baseXdevCatalogDelivered,
						expectedContentKey: previewXdevMountNotice.contentKey,
					})
				: undefined;
			const toolRosterNotice = isUserQueuedMessage(message)
				? this.#tools.takePendingToolRosterNotice({ baseDelivered: baseXdevCatalogDelivered })
				: undefined;
			const evalPreludeNotice = isUserQueuedMessage(message) ? this.#tools.takeEvalPreludeNotice() : undefined;
			const sessionAgentNotice = isUserQueuedMessage(message) ? this.#tools.takeSessionAgentNotice() : undefined;
			if (xdevMountNotice || toolRosterNotice || evalPreludeNotice || sessionAgentNotice) {
				messages.splice(
					xdevMountNoticeIndex,
					0,
					...(xdevMountNotice ? [xdevMountNotice] : []),
					...(toolRosterNotice ? [toolRosterNotice] : []),
					...(evalPreludeNotice ? [evalPreludeNotice] : []),
					...(sessionAgentNotice ? [sessionAgentNotice] : []),
				);
			}

			if (options?.existingEntry) {
				try {
					if (options.existingEntry.taskBound && drainedNextTurn.length > 0)
						throw new PersistedContinuationError(
							"queued-input",
							"Unassociated queued context conflicts with task recovery",
						);
					if (!(await options.existingEntry.beforeDispatch(messages))) {
						restoreDrainedNextTurn();
						return false;
					}
				} catch (error) {
					restoreDrainedNextTurn();
					throw error;
				}
			}

			const agentPromptOptions = options?.toolChoice ? { toolChoice: options.toolChoice } : undefined;
			const nonMessageTokens = computeNonMessageTokens(this, this.agent.tokenizer, this.settings.revision);
			const contextWindow = this.model?.contextWindow ?? 0;
			const breakdown = this.getContextBreakdown({ contextWindow, pendingMessages: messages });
			const promptTokens =
				breakdown?.usedTokens ??
				nonMessageTokens +
					this.agent.tokenizer.countMessages(this.messages) +
					this.agent.tokenizer.countMessages(messages);
			this.#stats.setPendingSnapshot({
				promptTokens,
				nonMessageTokens,
				cutoffCount: this.messages.length + messages.length,
			});
			// Commit the plan-reference delivery flag only now that the message is
			// actually handed to agent.prompt. Every pre-send setup step above can
			// return (generation-bail) or throw (@-mention reads, before_agent_start
			// hooks, pre-prompt compaction) before this point; setting the flag at
			// construction time (#buildPlanReferenceMessage) stranded it `true` with
			// nothing delivered, so the retry skipped re-injection and the executor
			// lost the approved plan (issue #4094). The compaction-success resets
			// (issue #1246) still clear it for re-injection on the next turn.
			try {
				// No await may separate this ownership check from agent dispatch.
				try {
					if (options?.existingEntry && !options.existingEntry.canDispatch(messages)) {
						restoreDrainedNextTurn();
						return false;
					}
				} catch (error) {
					restoreDrainedNextTurn();
					throw error;
				}
				this.#associatePromptPreparation(
					message,
					messages.filter(member => member !== message && !drainedNextTurn.some(queued => queued === member)),
					generation,
					options?.existingEntry?.anchorEntryId,
					options?.taskBindingId,
					messages,
				);
				if (planReferenceMessage) this.#planReferenceSent = true;
				if (options?.existingEntry) {
					if (messages.length === 0) await this.agent.continue(options.existingEntry.signal);
					else await this.agent.prompt(messages, agentPromptOptions);
				} else {
					await this.#recovery.promptAgentWithIdleRetry(messages, agentPromptOptions);
				}
			} finally {
				this.#stats.setPendingSnapshot(undefined);
			}
			if (!options?.skipPostPromptRecoveryWait) {
				await this.#waitForPostPromptRecovery(generation);
			}
			return true;
		} finally {
			// The per-turn before_agent_start override lives only for this turn.
			releaseDrainedGuard?.();
			this.#tools.clearTurnSystemPromptOverride();
			this.#usagePreflightReadyForNextModelCall = false;
			this.#endInFlight();
			if (this.#promptSetupAbortController === setupAbort) this.#promptSetupAbortController = undefined;
		}
	}

	/**
	 * Try to execute an extension command. Returns true if command was found and executed.
	 * `onRouted` fires once the command is found, before its handler runs.
	 */
	async #tryExecuteExtensionCommand(text: string, onRouted?: () => void): Promise<boolean> {
		if (!this.#extensionRunner) return false;

		// Parse command name and args
		const spaceIndex = text.indexOf(" ");
		const commandName = spaceIndex === -1 ? text.slice(1) : text.slice(1, spaceIndex);
		const args = spaceIndex === -1 ? "" : text.slice(spaceIndex + 1);

		const command = this.#extensionRunner.getCommand(commandName);
		if (!command) return false;
		onRouted?.();

		// Get command context from extension runner (includes session control methods)
		const ctx = this.#extensionRunner.createCommandContext();

		try {
			await this.#extensionRunner.runScoped(() => command.handler(args, ctx));
			return true;
		} catch (err) {
			// Emit error via extension runner
			this.#extensionRunner.emitError({
				extensionPath: `command:${commandName}`,
				event: "command",
				error: err instanceof Error ? err.message : String(err),
			});
			return true;
		}
	}

	#createCommandContext(): ExtensionCommandContext {
		if (this.#extensionRunner) {
			return this.#extensionRunner.createCommandContext();
		}

		return {
			ui: noOpUIContext,
			mode: "print",
			hasUI: false,
			taskDepth: this.#taskDepth,
			cwd: this.sessionManager.getCwd(),
			sessionManager: this.sessionManager,
			modelRegistry: this.#modelRegistry,
			isProjectTrusted: () => true,
			// Used only when the session has no extension runner. `createAgentSession` always builds
			// one (carrying the real identity), so only hand-constructed sessions land here.
			agent: TOP_LEVEL_AGENT,

			model: this.model ?? undefined,
			models: createExtensionModelQuery(this.#modelRegistry, this.settings, () => this.model ?? undefined),
			isIdle: () => !this.isStreaming,
			abort: () => {
				void this.abort();
			},
			hasPendingMessages: () => this.queuedMessageCount > 0,
			shutdown: () => {
				// Await the idempotent dispose() before exiting so the browser
				// reaper and other bounded teardown complete — a fire-and-forget
				// `void this.dispose()` raced process.exit() and could leave an
				// OMP-owned Chromium alive (#5643).
				void this.dispose().finally(() => process.exit(0));
			},
			getContextUsage: () => this.getContextUsage(),
			getAsyncJobSnapshot: () => this.getAsyncJobSnapshot(),
			waitForIdle: () => this.waitForIdle(),
			newSession: async options => {
				const success = await this.newSession({ parentSession: options?.parentSession });
				if (!success) {
					return { cancelled: true };
				}
				if (options?.setup) {
					await options.setup(this.sessionManager);
				}
				return { cancelled: false };
			},
			branch: async entryId => {
				const result = await this.branch(entryId);
				return { cancelled: result.cancelled };
			},
			navigateTree: async (targetId, options) => {
				const result = await this.navigateTree(targetId, { summarize: options?.summarize });
				return { cancelled: result.cancelled };
			},
			compact: async instructionsOrOptions => {
				const instructions = typeof instructionsOrOptions === "string" ? instructionsOrOptions : undefined;
				const options =
					instructionsOrOptions && typeof instructionsOrOptions === "object" ? instructionsOrOptions : undefined;
				await this.compact(instructions, options);
			},
			switchSession: async sessionPath => {
				const success = await this.switchSession(sessionPath);
				return { cancelled: !success };
			},
			reload: async () => {
				await this.reload();
			},
			getSystemPrompt: () => this.systemPrompt,
			runEphemeralTurn: args => this.runEphemeralTurn(args),
			setInterval: (callback, ms, ...args) => this.#fallbackTimers().setInterval(callback, ms, ...args),
			setTimeout: (callback, ms, ...args) => this.#fallbackTimers().setTimeout(callback, ms, ...args),
			clearTimer: timer => this.#fallbackTimers().clear(timer),
		};
	}

	/** Lazily create the runner-less command-context timer registry (#5664). */
	#fallbackTimers(): ManagedTimers {
		this.#fallbackExtensionTimers ??= new ManagedTimers((event, error) =>
			logger.warn("Extension timer callback threw", { event, error }),
		);
		return this.#fallbackExtensionTimers;
	}

	/**
	 * Try to execute a custom command. Returns the prompt string if found, null otherwise.
	 * If the command returns void, returns empty string to indicate it was handled.
	 */
	async #tryExecuteCustomCommand(text: string): Promise<string | null> {
		if (this.#customCommands.length === 0 && this.#mcpPromptCommands.length === 0) return null;

		// Parse command name and args
		const spaceIndex = text.indexOf(" ");
		const commandName = spaceIndex === -1 ? text.slice(1) : text.slice(1, spaceIndex);
		const argsString = spaceIndex === -1 ? "" : text.slice(spaceIndex + 1);

		// Find matching command
		const loaded =
			this.#customCommands.find(c => c.command.name === commandName) ??
			this.#mcpPromptCommands.find(c => c.command.name === commandName);
		if (!loaded) return null;

		// Get command context from extension runner (includes session control methods)
		const baseCtx = this.#createCommandContext();
		const ctx = {
			...baseCtx,
			hasQueuedMessages: baseCtx.hasPendingMessages,
		} as unknown as CustomCommandContext;

		try {
			const args = parseCommandArgs(argsString);
			const result = await loaded.command.execute(args, ctx, argsString);
			// If result is a string, it's a prompt to send to LLM
			// If void/undefined, command handled everything
			return result ?? "";
		} catch (err) {
			// Emit error via extension runner
			if (this.#extensionRunner) {
				this.#extensionRunner.emitError({
					extensionPath: `custom-command:${commandName}`,
					event: "command",
					error: err instanceof Error ? err.message : String(err),
				});
			} else {
				const message = err instanceof Error ? err.message : String(err);
				logger.error("Custom command failed", { commandName, error: message });
			}
			return ""; // Command was handled (with error)
		}
	}

	/**
	 * Queue a steering message to interrupt the agent mid-run.
	 */
	async steer(text: string, images?: ImageContent[], options?: SteerOptions): Promise<void> {
		this.#assertTaskRecoveryInput();
		if (text.startsWith("/")) {
			this.#throwIfExtensionCommand(text);
		}

		const expandedText = expandPromptTemplate(text, [...this.#promptTemplates]);
		// Stamp before image preprocessing so a queued image steer measures from
		// the operator's submission, not after the vision-model description.
		const submittedAt = Date.now();
		await this.#queueUserMessage(expandedText, images, "steer", {
			timestamp: submittedAt,
			attribution: options?.attribution,
			rawText: text,
		});
	}

	/**
	 * Queue a follow-up message to process after the agent would otherwise stop.
	 * Set `options.synthetic` to enqueue a hidden developer message (agent-attributed
	 * by default) instead of a user-attributed follow-up; the plan-approval flow
	 * uses this to land its execution directive behind a queued user turn without
	 * flipping advisor auto-resume.
	 */
	async followUp(text: string, images?: ImageContent[], options?: FollowUpOptions): Promise<void> {
		this.#assertTaskRecoveryInput();
		if (text.startsWith("/")) {
			this.#throwIfExtensionCommand(text);
		}

		const expandedText =
			options?.expandPromptTemplates === false ? text : expandPromptTemplate(text, [...this.#promptTemplates]);
		// Stamp before image preprocessing so a queued image follow-up measures
		// from the operator's submission, not after the vision-model description.
		const submittedAt = Date.now();
		if (!options?.synthetic) {
			await this.#queueUserMessage(expandedText, images, "followUp", {
				timestamp: submittedAt,
				attribution: options?.attribution,
				rawText: text,
			});
			return;
		}
		// Synthetic branch: agent-initiated hidden developer message. Bypass
		// #queueUserMessage (which clears advisor auto-resume suppression and
		// enqueues as a user-role message) and place the developer message
		// directly on the follow-up queue.
		const normalizedImages = await this.#normalizeImagesForModel(images);
		const content: (TextContent | ImageContent)[] = [{ type: "text", text: expandedText }];
		if (normalizedImages?.length) {
			content.push(...normalizedImages);
		}
		const imageDescriptionNotice = normalizedImages?.length
			? await this.#buildImageDescriptionNotice(normalizedImages)
			: undefined;
		this.#allowQueuedMessageDrainRetry();
		if (imageDescriptionNotice) this.agent.followUp(imageDescriptionNotice);
		this.agent.followUp({
			role: "developer",
			content,
			attribution: options.attribution ?? "agent",
			timestamp: Date.now(),
			// Run-initiating synthetic prompt (e.g. approved-plan execution queued
			// behind a busy turn): replay uses the marker to clear the preceding
			// user's prompt anchor, matching the live agent_start clear.
			synthetic: true,
		});
		this.#scheduleIdleQueueDrain();
	}

	/**
	 * Run a mode-exit `teardown` (abort the active turn, swap the toolset, clear
	 * mode state) with queued-message auto-resume suppressed, then re-arm the
	 * drain so a queued user turn resumes cleanly once the previous toolset is
	 * back.
	 *
	 * `abort()`'s stranded-queue drain runs from its own `finally`; without this
	 * guard a queued steer/follow-up behind the aborted turn would start a fresh
	 * `agent.continue()` during the teardown's `await`s — while the exiting mode's
	 * tools/context are still live — and then have those tools removed underneath
	 * it, reintroducing the mode's stale-tool failure on the restarted turn
	 * (issue #8326). Suppressing the drain across teardown guarantees the queued
	 * turn resumes only after teardown, so it runs as a clean non-mode turn.
	 */
	async runModeExitTeardown(teardown: () => Promise<void>): Promise<void> {
		this.#modeExitDrainSuppressionDepth++;
		try {
			await teardown();
		} finally {
			this.#modeExitDrainSuppressionDepth--;
			if (this.#modeExitDrainSuppressionDepth === 0) {
				this.#scheduleIdleQueueDrain();
				this.#resumeStrandedIrcAsides();
			}
		}
	}

	async #queueUserMessage(
		text: string,
		images: ImageContent[] | undefined,
		mode: "steer" | "followUp" | "aside",
		options?: {
			timestamp?: number;
			attribution?: MessageAttribution;
			prependMessages?: readonly CustomMessage[];
			/** Text the caller originally submitted, before slash/custom-command
			 *  rewriting, prompt-template expansion, or `^model` mention substitution.
			 *  Recorded via `#queuedMessageRawText` so `removeQueuedMessage` can match
			 *  it later. Defaults to `text` (the common case: no transformation ran,
			 *  so raw and queued content are identical). */
			rawText?: string;
			/**
			 * Set only when image normalization and the vision description already
			 * ran for this prompt; its presence suppresses both here. Companions
			 * travel in `prependMessages` so a notice-only caller cannot claim
			 * attachments were prepared (they would be silently dropped).
			 */
			preprocessed?: {
				images?: ImageContent[];
				descriptionNotice?: CustomMessage;
			};
			/** Called synchronously once the message is pushed onto its queue. See {@link PromptOptions.onPromptAdmitted}. */
			onPromptAdmitted?: () => void;
			/**
			 * `#promptGeneration` captured when prompt() took this submission. abort() (or a
			 * history rewrite) bumps it; if that lands while images are being prepared, the
			 * message is not queued, matching prompt()'s idle drop.
			 */
			promptGeneration?: number;
		},
	): Promise<boolean> {
		const attribution = options?.attribution ?? "user";
		const timestamp = options?.timestamp;
		const rawText = options?.rawText ?? text;
		const preprocessed = options?.preprocessed;
		const prependMessages = options?.prependMessages ?? [];
		// Captured before any await below so the aside branch can detect a
		// newSession()/switchSession() that completed while normalization/vision
		// description was in flight and drop a record that would otherwise land in a
		// different session's queue.
		const sessionGeneration = this.#sessionGeneration;
		// A queued user message (RPC/SDK/collab steer or follow-up, or a typed message
		// while streaming) is a deliberate resume; re-enable advisor auto-resume that
		// a user interrupt suppressed. An aside is non-interrupting by design — it must
		// not re-enable auto-resume a user interrupt deliberately suppressed, so it stays
		// user-driven (folds into context via #resumeStrandedIrcAsides's post-interrupt
		// branch) until the next deliberate steer/follow-up/prompt, matching the
		// sendCustomMessage aside path (queueAside), which never touches this flag.
		if (mode !== "aside") this.#advisors.autoResumeSuppressed = false;
		// The pre-dispatch re-check in prompt() arrives with normalization and the
		// vision description already done — reuse them instead of paying a second
		// vision-model request for the same attachment.
		const attachmentSourceNotices = this.#createAttachmentSourceNotices(images, timestamp ?? Date.now());
		const normalizedImages = preprocessed ? preprocessed.images : await this.#normalizeImagesForModel(images);
		const content: (TextContent | ImageContent)[] = [{ type: "text", text }];
		if (normalizedImages?.length) {
			content.push(...normalizedImages);
		}
		// Text-only model + image attachment: describe via a vision model and enqueue the
		// description as a hidden companion immediately before the user message.
		const imageDescriptionNotice = preprocessed
			? preprocessed.descriptionNotice
			: normalizedImages?.length
				? await this.#buildImageDescriptionNotice(normalizedImages)
				: undefined;
		if (options?.promptGeneration !== undefined && this.#promptGeneration !== options.promptGeneration) {
			return false;
		}
		if (mode === "aside") {
			if (await this.#sessionGenerationChanged(sessionGeneration)) return false;
			const records: AgentMessage[] = [...prependMessages, ...attachmentSourceNotices];
			if (imageDescriptionNotice) records.push(imageDescriptionNotice);
			const userMessage: AgentMessage = { role: "user", content, attribution, timestamp: timestamp ?? Date.now() };
			this.#queuedMessageRawText.set(userMessage, rawText);
			records.push(userMessage);
			this.#irc.queueAside(records);
			options?.onPromptAdmitted?.();
			// The awaits above (image normalization / vision description) can span the run's
			// settle, so the run may already be idle by the time the record lands in the aside
			// queue with no loop left to drain it. Resuming here is a no-op while streaming and
			// wakes/folds correctly once idle (see #resumeStrandedIrcAsides).
			this.#resumeStrandedIrcAsides();
			return true;
		}
		this.#allowQueuedMessageDrainRetry();
		// Publish the complete group without yielding: removal owns contiguous companions.
		if (mode === "followUp") {
			for (const notice of prependMessages) this.agent.followUp(notice);
			for (const notice of attachmentSourceNotices) this.agent.followUp(notice);
			if (imageDescriptionNotice) this.agent.followUp(imageDescriptionNotice);
			const userMessage: AgentMessage = {
				role: "user",
				content,
				attribution,
				timestamp: timestamp ?? Date.now(),
			};
			this.#queuedMessageRawText.set(userMessage, rawText);
			this.agent.followUp(userMessage);
		} else {
			for (const notice of prependMessages) this.agent.steer(notice);
			for (const notice of attachmentSourceNotices) this.agent.steer(notice);
			if (imageDescriptionNotice) this.agent.steer(imageDescriptionNotice);
			const userMessage: AgentMessage = {
				role: "user",
				content,
				steering: true,
				attribution,
				timestamp: timestamp ?? Date.now(),
			};
			this.#queuedMessageRawText.set(userMessage, rawText);
			this.agent.steer(userMessage);
		}
		options?.onPromptAdmitted?.();
		this.#scheduleIdleQueueDrain();
		return true;
	}

	#scheduleIdleQueueDrain(): void {
		this.#scheduleQueuedMessageDrain();
	}

	#scheduleQueuedMessageDrain(): void {
		if (
			this.#queuedMessageDrainScheduled ||
			this.#modeExitDrainSuppressionDepth > 0 ||
			this.#queuedMessageDrainBlocked ||
			!this.#canAutoContinueForFollowUp() ||
			!this.agent.hasQueuedMessages()
		) {
			return;
		}
		this.#queuedMessageDrainScheduled = true;
		this.#scheduleAgentContinue({
			source: "queued-message-drain",
			shouldContinue: () => {
				this.#queuedMessageDrainScheduled = false;
				return (
					this.#modeExitDrainSuppressionDepth === 0 &&
					this.#canAutoContinueForFollowUp() &&
					this.agent.hasQueuedMessages()
				);
			},
			onSkip: () => {
				this.#queuedMessageDrainScheduled = false;
			},
			onError: () => {
				this.#queuedMessageDrainScheduled = false;
				this.#queuedMessageDrainBlocked = this.agent.hasQueuedMessages();
			},
		});
	}

	/**
	 * Gate for idle-path queued-message auto-continue. See `#scheduleIdleQueueDrain` for rationale.
	 */
	#canAutoContinueForFollowUp(): boolean {
		if (this.isStreaming) return false;
		if (this.isRetrying) return false;
		// A queued steer resumes from ANY tail: Agent.continue() runs #runLoop(undefined),
		// whose initial steering poll injects the steer before the first provider call, so the
		// request tail becomes the steer (valid) regardless of any injected custom / bashExecution
		// / pythonExecution record a user interrupt left as the literal transcript tail. This is
		// why a queued user steer stranded behind a preserved advisor card (or a flushed IRC aside
		// / eval execution record) still resumes — no tail-role enumeration needed.
		if (this.agent.peekSteeringQueue().length > 0) return true;
		// Follow-up-only auto-resume stays suppressed while a deliberate user interrupt is in effect
		// (#advisorAutoResumeSuppressed, cleared on the next user prompt): the user stopped, so their
		// queued follow-up waits for an explicit resume — even if an interleaving IRC wake turn has
		// since left a provider-valid tail.
		if (this.#advisors.autoResumeSuppressed) return false;
		// Follow-up-only resume has no steer to inject, so Agent.continue() continues from the
		// existing context tail — which must itself be a valid provider tail. An injected
		// non-conversational tail (advisor card → `developer`, bash/python execution) would make
		// the first model call invalid, so leave the follow-up queued for the next explicit resume.
		const messages = this.agent.state.messages;
		const last = messages[messages.length - 1];
		return last?.role === "assistant" || last?.role === "toolResult";
	}

	queueDeferredMessage(message: CustomMessage): void {
		this.#queueHiddenNextTurnMessage(message, true);
	}

	queueLaunchCompletion(notification: DaemonCompletionNotification): Promise<void> {
		if (this.#isDisposed) return Promise.reject(new Error("Session disposed before launch completion delivery"));
		const delivered = this.yieldQueue.enqueueWithReceipt<LaunchCompletionEntry>(
			LAUNCH_COMPLETION_MESSAGE_TYPE,
			notification,
		);
		this.yieldQueue.requestIdleFlush();
		return delivered;
	}

	/** Receipt-backed extension delivery (OMP-51): mirrors queueLaunchCompletion —
	 *  the returned promise settles only after real streaming/idle injection into
	 *  THIS session (the enqueue-time session id is stamped on the entry). */
	async queueExtensionDelivery(entry: ExtensionDeliveryEntry): Promise<void> {
		this.#assertTaskRecoveryInput();
		if (this.#isDisposed) throw new Error("Session disposed before extension delivery");
		if (entry.triggerTurn === false) {
			if (this.isStreaming) {
				throw new Error("Cannot deliver display-only extension message while agent is streaming");
			}
			const ownerSessionId = this.sessionManager.getSessionId();
			if (entry.owner !== undefined && entry.owner !== ownerSessionId) {
				throw new Error("Session switched before extension delivery");
			}
			const record: CustomMessage = {
				role: "custom",
				customType: entry.customType,
				content: entry.content,
				display: entry.display ?? true,
				details: entry.details,
				attribution: "agent",
				timestamp: Date.now(),
			};
			this.agent.appendMessage(record);
			this.sessionManager.appendCustomMessageEntry(
				record.customType,
				record.content,
				record.display,
				record.details,
				record.attribution,
			);
			await this.#emitSessionEvent({ type: "message_start", message: record });
			await this.#emitSessionEvent({ type: "message_end", message: record });
			return;
		}
		const stamped = { ...entry, owner: entry.owner ?? this.sessionManager.getSessionId() };
		const delivered = this.yieldQueue.enqueueWithReceipt<ExtensionDeliveryEntry>(
			EXTENSION_DELIVERY_MESSAGE_TYPE,
			stamped,
		);
		this.yieldQueue.requestIdleFlush();
		return delivered;
	}

	#queueHiddenNextTurnMessage(message: CustomMessage, triggerTurn: boolean): void {
		this.#pendingNextTurnMessages.push(message);
		if (!triggerTurn) return;
		const generation = this.#promptGeneration;
		if (this.#scheduledHiddenNextTurnGeneration === generation) {
			return;
		}
		this.#scheduledHiddenNextTurnGeneration = generation;
		this.#schedulePostPromptTask(
			async () => {
				if (this.#scheduledHiddenNextTurnGeneration === generation) {
					this.#scheduledHiddenNextTurnGeneration = undefined;
				}
				if (this.#pendingNextTurnMessages.length === 0) {
					return;
				}
				try {
					await this.#promptQueuedHiddenNextTurnMessages();
				} catch {
					// Leave the hidden next-turn messages queued for the next explicit prompt.
				}
			},
			{
				generation,
				onSkip: () => {
					if (this.#scheduledHiddenNextTurnGeneration === generation) {
						this.#scheduledHiddenNextTurnGeneration = undefined;
					}
				},
			},
		);
	}

	async #promptQueuedHiddenNextTurnMessages(): Promise<void> {
		if (this.#pendingNextTurnMessages.length === 0) {
			return;
		}

		const queuedMessages = [...this.#pendingNextTurnMessages];
		this.#pendingNextTurnMessages = [];
		// Re-read each queued message's dispatch-time authority BEFORE it can own a
		// turn here: a refusal is dropped outright, so it never becomes the turn's
		// anchor (or a prepended member) and never reaches append/persist.
		const admittedMessages = this.#hasAnyHiddenNextTurnDispatchValidator(queuedMessages)
			? await this.#admitHiddenNextTurnMessages(queuedMessages)
			: queuedMessages;
		const message = admittedMessages[admittedMessages.length - 1];
		if (!message) {
			return;
		}

		const prependMessages = admittedMessages.slice(0, -1);
		const textContent = this.#getCustomMessageTextContent(message);
		try {
			await this.#promptWithMessage(message, textContent, {
				prependMessages,
				skipPostPromptRecoveryWait: true,
			});
		} catch (error) {
			this.#pendingNextTurnMessages = [...admittedMessages, ...this.#pendingNextTurnMessages];
			throw error;
		}
	}

	#hasAnyHiddenNextTurnDispatchValidator(messages: readonly CustomMessage[]): boolean {
		for (const message of messages) {
			if (this.#hiddenNextTurnDispatchValidators.has(message)) return true;
		}
		return false;
	}

	/** Record the dispatch-time authority check for a queued hidden next-turn
	 *  message. Honored only for `deliverAs: "nextTurn"` + `triggerTurn: true`. */
	#associateHiddenNextTurnDispatchValidator(
		message: CustomMessage,
		options?: {
			triggerTurn?: boolean;
			deliverAs?: "steer" | "followUp" | "nextTurn" | "aside";
			validateDispatch?: DispatchAuthorityValidation;
		},
	): void {
		if (options?.deliverAs !== "nextTurn" || options.triggerTurn !== true || !options.validateDispatch) return;
		this.#hiddenNextTurnDispatchValidators.set(message, options.validateDispatch);
	}

	/** Await a hidden next-turn message's dispatch-time authority check, if any.
	 *  A refusal (`ok: false`) or a thrown validator drops the message: `false`. */
	async #runHiddenNextTurnDispatchValidation(message: CustomMessage): Promise<boolean> {
		const validateDispatch = this.#hiddenNextTurnDispatchValidators.get(message);
		if (!validateDispatch) return true;
		try {
			const result = await validateDispatch();
			if (result.ok) return true;
			logger.warn("Hidden next-turn extension message refused at dispatch", {
				customType: message.customType,
				reason: result.reason,
			});
			return false;
		} catch (error) {
			logger.warn("Hidden next-turn extension message dispatch validation threw", {
				customType: message.customType,
				error: String(error),
			});
			return false;
		}
	}

	/** Drop any hidden next-turn messages whose dispatch-time authority check refuses. */
	async #admitHiddenNextTurnMessages(messages: readonly CustomMessage[]): Promise<CustomMessage[]> {
		const admitted: CustomMessage[] = [];
		for (const message of messages) {
			if (await this.#runHiddenNextTurnDispatchValidation(message)) admitted.push(message);
		}
		return admitted;
	}

	/** Arm this turn's first model call with the hidden next-turn messages that
	 *  still carry a dispatch-time authority check. The hook re-reads each
	 *  validator once, then removes itself; the caller also releases it when the
	 *  turn ends before that call. A refusal or throw stops the provider request. */
	#armHiddenNextTurnDispatchGuard(messages: readonly AgentMessage[]): (() => void) | undefined {
		const guarded: CustomMessage[] = [];
		for (const candidate of messages) {
			if (candidate.role !== "custom") continue;
			const message = candidate as CustomMessage;
			if (this.#hiddenNextTurnDispatchValidators.has(message)) guarded.push(message);
		}
		if (guarded.length === 0) return undefined;
		let remove: (() => void) | undefined;
		const release = () => {
			const current = remove;
			remove = undefined;
			current?.();
		};
		remove = this.agent.addBeforeModelCall(async () => {
			// Unregister before awaiting so a later model call in this turn cannot re-enter.
			release();
			for (const message of guarded) {
				if (!(await this.#runHiddenNextTurnDispatchValidation(message))) {
					return { stop: true, reason: "Hidden next-turn extension message refused at dispatch" };
				}
			}
			return undefined;
		});
		return release;
	}

	#getCustomMessageTextContent(message: Pick<CustomMessage, "content">): string {
		if (typeof message.content === "string") {
			return message.content;
		}
		return message.content
			.filter((content): content is TextContent => content.type === "text")
			.map(content => content.text)
			.join("");
	}

	/**
	 * Throw an error if the text is an extension command.
	 */
	#throwIfExtensionCommand(text: string): void {
		if (!this.#extensionRunner) return;

		const spaceIndex = text.indexOf(" ");
		const commandName = spaceIndex === -1 ? text.slice(1) : text.slice(1, spaceIndex);
		const command = this.#extensionRunner.getCommand(commandName);

		if (command) {
			throw new Error(
				`Extension command "/${commandName}" cannot be queued. Use prompt() or execute the command when not streaming.`,
			);
		}
	}

	/** @returns true iff `agent.prompt` was actually invoked. An abort or session-generation
	 *  change racing the usage-aware preflight can return before dispatch — callers that treat
	 *  this as proof of agent work (e.g. suppressing a local prompt_result because agent events
	 *  are expected) must not assume dispatch happened just because this was awaited. */
	async #promptAgentInitiatedMessage(
		message: CustomMessage,
		options?: { acceptTerminalEmptyStop?: boolean },
	): Promise<boolean> {
		this.#beginInFlight();
		let releaseDispatchGuard: (() => void) | undefined;
		try {
			if (!(await this.#runUsageAwarePreflightForNextModelCall())) return false;
			// Re-read the dispatch-time authority check before this message can be
			// appended/persisted or reach the provider: an idle `triggerTurn` send is
			// never queued, so this is its only pre-append gate. A refusal drops it.
			if (!(await this.#runHiddenNextTurnDispatchValidation(message))) return false;
			releaseDispatchGuard = this.#armHiddenNextTurnDispatchGuard([message]);
			const acceptTerminalEmptyStop = options?.acceptTerminalEmptyStop === true;
			if (acceptTerminalEmptyStop) {
				this.#resetPromptMaintenanceState();
			}
			this.#recovery.setAcceptTerminalEmptyStop(acceptTerminalEmptyStop);
			// This core path sends one agent-authored custom input without the user
			// prompt pipeline; it still owns that exact input's persistence origin.
			this.#associatePromptPreparation(message, [], this.#promptGeneration);
			await this.agent.prompt(message);
			await this.#waitForPostPromptRecovery();
			return true;
		} finally {
			releaseDispatchGuard?.();
			this.#usagePreflightReadyForNextModelCall = false;
			this.#recovery.setAcceptTerminalEmptyStop(false);
			this.#endInFlight();
		}
	}

	/** Queue a custom message without starting a turn, matching steer/follow-up/aside delivery. */
	async #queueCustomMessage<T = unknown>(
		message: Pick<CustomMessage<T>, "customType" | "content" | "display" | "details" | "attribution">,
		deliverAs: "steer" | "followUp" | "aside",
		options?: {
			queueChipText?: string;
			/** Content and vision companion already prepared by the caller; skips re-normalizing and re-describing. */
			preprocessed?: { content: CustomMessage<T>["content"]; descriptionNotice?: CustomMessage };
			/** Hidden notices published immediately before this message, in the same synchronous group. */
			prependMessages?: readonly CustomMessage[];
			/** Called synchronously once the message is pushed onto its queue. See {@link PromptOptions.onPromptAdmitted}. */
			onPromptAdmitted?: () => void;
		},
	): Promise<void> {
		// Captured before the normalization await below — see #sessionGeneration's doc comment.
		const sessionGeneration = this.#sessionGeneration;
		const details =
			options?.queueChipText !== undefined
				? ({
						...((message.details && typeof message.details === "object" ? message.details : {}) as Record<
							string,
							unknown
						>),
						__queueChipText: options.queueChipText,
					} as T)
				: message.details;
		const appMessage: CustomMessage<T> = {
			role: "custom",
			customType: message.customType,
			content: message.content,
			display: message.display,
			details,
			attribution: message.attribution ?? "agent",
			timestamp: Date.now(),
		};
		const preprocessed = options?.preprocessed;
		const prependMessages = options?.prependMessages ?? [];
		const onPromptAdmitted = options?.onPromptAdmitted;
		const normalizedAppMessage = preprocessed
			? { ...appMessage, content: preprocessed.content }
			: await this.#normalizeAgentMessageImages(appMessage);
		const descriptionNotice = preprocessed
			? preprocessed.descriptionNotice
			: await this.#buildSkillImageDescriptionNotice(normalizedAppMessage);
		if (deliverAs === "aside") {
			if (await this.#sessionGenerationChanged(sessionGeneration)) return;
			// Non-interrupting: rides the same step-boundary aside poll as
			// sendCustomMessage's streaming aside branch — not an agent-core queue
			// entry, so no drain-retry latch and no idle-queue drain scheduling.
			this.#irc.queueAside([
				...prependMessages,
				...(descriptionNotice ? [descriptionNotice] : []),
				normalizedAppMessage,
			]);
			onPromptAdmitted?.();
			// The image-normalization await above can span the run's settle, so the run may
			// already be idle by the time the record lands in the aside queue with no loop
			// left to drain it. Resuming here is a no-op while streaming and wakes/folds
			// correctly once idle, matching #queueUserMessage's aside branch.
			this.#resumeStrandedIrcAsides();
			return;
		}
		this.#allowQueuedMessageDrainRetry();
		// Keyword notices and their user message must enter the queue in one synchronous phase.
		if (deliverAs === "followUp") {
			for (const notice of prependMessages) this.agent.followUp(notice);
			if (descriptionNotice) this.agent.followUp(descriptionNotice);
			this.agent.followUp(normalizedAppMessage);
		} else {
			for (const notice of prependMessages) this.agent.steer(notice);
			if (descriptionNotice) this.agent.steer(descriptionNotice);
			this.agent.steer(normalizedAppMessage);
		}
		onPromptAdmitted?.();
		this.#scheduleIdleQueueDrain();
	}

	/**
	 * Send a custom message to the session. Creates a CustomMessageEntry.
	 *
	 * Handles three cases:
	 * - Streaming: queue as steer/follow-up, aside (next step boundary), or store for next turn
	 * - Not streaming + triggerTurn: appends to state/session, starts new turn unless the client cannot own it
	 * - Not streaming + no trigger: appends to state/session, no turn; with the default delivery
	 *   (no deliverAs) a display:true message also paints to the interactive transcript
	 *   immediately (message_start/message_end, no turn)
	 *
	 * @returns true iff this call synchronously started a new turn (awaited
	 * `agent.prompt`); false when the message was queued/appended without a turn
	 * — including when `triggerTurn` is downgraded because the client defers
	 * agent-initiated turns. Callers that must mirror the resulting `agent_end`
	 * use this to avoid acting on a turn that never ran.
	 */
	async sendCustomMessage<T = unknown>(
		message: CustomMessagePayload<T>,
		options?: {
			triggerTurn?: boolean;
			deliverAs?: "steer" | "followUp" | "nextTurn" | "aside";
			queueChipText?: string;
			acceptTerminalEmptyStop?: boolean;
		},
	): Promise<boolean> {
		return this.#admitSubmission(() => this.#sendCustomMessage(message, options));
	}

	async #sendCustomMessage<T = unknown>(
		message: CustomMessagePayload<T>,
		options?: {
			triggerTurn?: boolean;
			deliverAs?: "steer" | "followUp" | "nextTurn" | "aside";
			queueChipText?: string;
			acceptTerminalEmptyStop?: boolean;
			/**
			 * Dispatch-time authority check, honored only for a hidden
			 * `deliverAs: "nextTurn"` message with `triggerTurn: true`. Re-read before
			 * this message can reach a provider (or be persisted) and again before the
			 * turn's first model call; a refusal or throw drops it silently.
			 */
			validateDispatch?: DispatchAuthorityValidation;
		},
	): Promise<boolean> {
		this.#assertTaskRecoveryInput();
		// An extension command parked on a manual compaction may fire this
		// (`pi.sendMessage(..., { triggerTurn: true })`) and return without awaiting
		// it. Claim synchronously, before the normalization await below, so the
		// parked command's `release(false)` cannot hand the interrupted-turn resume
		// back while this turn is still in setup. Only a definitive dispatch, or a
		// live agent turn this message was queued into, counts as a claim.
		const release = this.#maintenance.claimPendingResume();
		const outcome: PromptDispatchOutcome = { sessionClaimed: false };
		if (!release) return this.#dispatchCustomMessage(message, options, outcome);
		try {
			return await this.#dispatchCustomMessage(message, options, outcome);
		} finally {
			release(outcome.sessionClaimed);
		}
	}

	async #dispatchCustomMessage<T = unknown>(
		message: CustomMessagePayload<T>,
		options:
			| {
					triggerTurn?: boolean;
					deliverAs?: "steer" | "followUp" | "nextTurn" | "aside";
					queueChipText?: string;
					acceptTerminalEmptyStop?: boolean;
					validateDispatch?: DispatchAuthorityValidation;
			  }
			| undefined,
		outcome: PromptDispatchOutcome,
	): Promise<boolean> {
		// Captured before the normalization await below — see #sessionGeneration's doc comment.
		const sessionGeneration = this.#sessionGeneration;
		const normalizedPayload = normalizeCustomMessagePayload<T>(message);
		const suppressQueueChip = options?.deliverAs === "nextTurn" || options?.deliverAs === "aside";
		const details =
			options?.queueChipText && !suppressQueueChip
				? ({
						...((normalizedPayload.details && typeof normalizedPayload.details === "object"
							? normalizedPayload.details
							: {}) as Record<string, unknown>),
						__queueChipText: options.queueChipText,
					} as T)
				: normalizedPayload.details;
		const appMessage: CustomMessage<T> = {
			role: "custom",
			customType: normalizedPayload.customType,
			content: normalizedPayload.content,
			display: normalizedPayload.display,
			details,
			attribution: normalizedPayload.attribution,
			timestamp: Date.now(),
		};
		const normalizedAppMessage = await this.#normalizeAgentMessageImages(appMessage);
		this.#associateHiddenNextTurnDispatchValidator(normalizedAppMessage, options);
		if (this.isStreaming) {
			// Queued into a turn the agent owns: that turn holds the session. Busy only
			// from another prompt's setup claims nothing (that prompt decides).
			outcome.sessionClaimed = this.agent.state.isStreaming;
			if (options?.deliverAs === "nextTurn") {
				this.#queueHiddenNextTurnMessage(normalizedAppMessage, options?.triggerTurn ?? false);
				return false;
			}
			if (options?.deliverAs === "aside") {
				if (await this.#sessionGenerationChanged(sessionGeneration)) return false;
				// Non-interrupting: the agent loop's step-boundary poll (see the setAsideMessageProvider
				// registration in the constructor) picks this up without interrupting the current tool
				// batch. Not an agent-core queue entry, so no drain-retry latch and no idle-queue drain
				// scheduling here.
				this.#irc.queueAside([normalizedAppMessage]);
				return false;
			}
			this.#allowQueuedMessageDrainRetry();

			if (options?.deliverAs === "followUp") {
				this.agent.followUp(normalizedAppMessage);
			} else {
				this.agent.steer(normalizedAppMessage);
			}
			this.#scheduleIdleQueueDrain();
			return false;
		}

		if (options?.deliverAs === "nextTurn") {
			if (options?.triggerTurn) {
				if (this.#clientBridge?.deferAgentInitiatedTurns && !this.#allowAcpAgentInitiatedTurns) {
					this.#queueHiddenNextTurnMessage(normalizedAppMessage, false);
					return false;
				}
				outcome.sessionClaimed = await this.#promptAgentInitiatedMessage(normalizedAppMessage, {
					acceptTerminalEmptyStop: options.acceptTerminalEmptyStop === true,
				});
				return outcome.sessionClaimed;
			}
			this.agent.appendMessage(normalizedAppMessage);
			this.sessionManager.appendCustomMessageEntry(
				normalizedAppMessage.customType,
				normalizedAppMessage.content,
				normalizedAppMessage.display,
				normalizedAppMessage.details,
				normalizedAppMessage.attribution,
			);
			return false;
		}

		if (options?.deliverAs === "aside") {
			if (await this.#sessionGenerationChanged(sessionGeneration)) return false;
			if (this.#planModeState?.enabled) {
				// Plan mode stays user-driven: fold into context without an autonomous turn, same as
				// IrcBridge.deliver()/#resumeStrandedIrcAsides do in plan mode. Routed through the
				// event-emitting fold path (not a direct append) so a displayable aside that began
				// streaming still gets the message_end its sender's rebuild-skip decision expects.
				this.#foldStrandedIrcAsidesIntoContext([normalizedAppMessage]);
				return false;
			}
			if (this.#advisors.autoResumeSuppressed) {
				// A user interrupt (Esc) is still in effect. isStreaming was true when this method
				// was entered but image normalization above outlasted the interrupt, landing here
				// instead of the streaming branch's queueAside — starting a fresh autonomous turn
				// would undo the user's deliberate stop. Fold into context (same event-emitting path
				// as the plan-mode branch above) and stay user-driven, matching
				// #resumeStrandedIrcAsides's post-interrupt fold branch.
				this.#foldStrandedIrcAsidesIntoContext([normalizedAppMessage]);
				return false;
			}
			if (this.#clientBridge?.deferAgentInitiatedTurns && !this.#allowAcpAgentInitiatedTurns) {
				this.#queueHiddenNextTurnMessage(normalizedAppMessage, false);
				return false;
			}
			outcome.sessionClaimed = await this.#promptAgentInitiatedMessage(normalizedAppMessage, {
				acceptTerminalEmptyStop: options.acceptTerminalEmptyStop === true,
			});
			return outcome.sessionClaimed;
		}

		if (options?.triggerTurn) {
			if (this.#clientBridge?.deferAgentInitiatedTurns && !this.#allowAcpAgentInitiatedTurns) {
				this.#queueHiddenNextTurnMessage(normalizedAppMessage, false);
				return false;
			}
			outcome.sessionClaimed = await this.#promptAgentInitiatedMessage(normalizedAppMessage);
			return outcome.sessionClaimed;
		}

		this.agent.appendMessage(normalizedAppMessage);
		this.sessionManager.appendCustomMessageEntry(
			normalizedAppMessage.customType,
			normalizedAppMessage.content,
			normalizedAppMessage.display,
			normalizedAppMessage.details,
			normalizedAppMessage.attribution,
		);
		if (normalizedAppMessage.display === true) {
			// Idle display append with no turn: notify session listeners so the interactive
			// transcript paints it now instead of on the next rebuild. The entry is persisted
			// above, before any listener sees these events, so a transcript replay racing this
			// append always finds it — EventController defers pre-initial-render custom paints
			// to that replay. Extension observers are detached so they cannot stall the caller.
			await this.#emitSessionEvent(
				{ type: "message_start", message: normalizedAppMessage },
				{ detachExtensions: true },
			);
			await this.#emitSessionEvent(
				{ type: "message_end", message: normalizedAppMessage },
				{ detachExtensions: true },
			);
		}
		return false;
	}

	/**
	 * Send a user message through the prompt flow.
	 *
	 * Omitted `deliverAs` starts a turn when idle and queues as a steer while streaming.
	 * Explicit `deliverAs` queues without starting a turn in either state; `aside` at
	 * an idle session instead starts a turn, since there is no live run to inject into.
	 */
	async sendUserMessage(
		content: string | (TextContent | ImageContent)[],
		options?: SendUserMessageOptions,
	): Promise<void> {
		this.#assertTaskRecoveryInput();
		// Normalize content to text string + optional images
		let text: string;
		let images: ImageContent[] | undefined;

		if (typeof content === "string") {
			text = content;
		} else {
			const textParts: string[] = [];
			images = [];
			for (const part of content) {
				if (part.type === "text") {
					textParts.push(part.text);
				} else {
					images.push(part);
				}
			}
			text = textParts.join("\n");
			if (images.length === 0) images = undefined;
		}

		let deliveredAsAside = false;
		if (options?.deliverAs === "aside") {
			if (this.isStreaming) {
				await this.#queueUserMessage(text, images, "aside", { attribution: options.attribution });
				return;
			}
			// Idle: fall through to the prompt flow below (starts a turn, like an omitted
			// deliverAs) — there is no live run to inject an aside into.
			deliveredAsAside = true;
		} else if (options?.deliverAs === "followUp") {
			await this.#queueUserMessage(text, images, "followUp", { attribution: options.attribution });
			return;
		} else if (options?.deliverAs === "steer") {
			await this.#queueUserMessage(text, images, "steer", { attribution: options.attribution });
			return;
		}

		// Use prompt() with expandPromptTemplates: false to skip command handling and template
		// expansion. prompt() awaits manual-compaction cleanup and (on the non-streaming path)
		// image normalization/vision description before dispatching, so a stream can start in
		// that gap; prompt() re-checks isStreaming at each await boundary and queues via
		// `streamingBehavior` when it does. Passing "aside" through (instead of hard-coding
		// "steer") keeps that race from degrading a non-interrupting aside into a
		// tool-batch-aborting steer.
		await this.prompt(text, {
			attribution: options?.attribution,
			expandPromptTemplates: false,
			images,
			streamingBehavior: deliveredAsAside ? "aside" : "steer",
		});
	}

	/** Clear queued messages and return the user-restorable ones (text plus any attached images).
	 *  Only user-authored messages (plain user turns, `attribution:"user"` custom like `/skill`) are
	 *  returned for editor restore. Other queued messages stay in the agent-core queues so a continuing
	 *  stream still delivers them — EXCEPT on `forInterrupt` (Esc+abort), where only advisor cards are
	 *  kept (abort()'s #extractQueuedAdvisorCards preserves them as visible advice) and every other
	 *  non-user steer (hidden goal/plan/budget, IRC/extension asides) is dropped, so abort()'s
	 *  #drainStrandedQueuedMessages can't auto-resume the run the user just interrupted (the drain only
	 *  fires while agent.hasQueuedMessages()). `forInterrupt` also withdraws live-steered input the
	 *  aborted response took but never recorded, returning it first (it was queued first).
	 *  Plain Alt+Up dequeue preserves those non-user steers. */
	clearQueue(options?: { forInterrupt?: boolean }): {
		steering: RestoredQueuedMessage[];
		followUp: RestoredQueuedMessage[];
	} {
		const steeringAll = this.agent.peekSteeringQueue();
		const followUpAll = this.agent.peekFollowUpQueue();
		const withdrawn = options?.forInterrupt ? this.agent.withdrawLiveSteering() : [];
		const steering = [...withdrawn, ...steeringAll].filter(isUserAuthoredQueuedMessage).map(toRestoredQueuedMessage);
		const followUp = followUpAll.filter(isUserAuthoredQueuedMessage).map(toRestoredQueuedMessage);
		const keep: (m: AgentMessage) => boolean = options?.forInterrupt
			? isAdvisorCard
			: m => !isUserAuthoredQueuedMessage(m) && !isHiddenUserCompanion(m);
		for (const message of [...steeringAll, ...followUpAll]) {
			if (!keep(message) && message.role === "custom" && message.customType === "ttsr-injection") {
				this.#ttsr.releaseDeferredReservationFromDetails(message.details);
			}
		}
		this.agent.replaceQueues(steeringAll.filter(keep), followUpAll.filter(keep));
		this.#reconcileQueuedMessageDrain();
		return { steering, followUp };
	}

	/** Number of pending displayable messages (includes steering, follow-up, and next-turn messages).
	 *  Reflects actual queued work (advisor cards included) — feeds hasPendingMessages()/RPC and the
	 *  empty-submit abort gate. The user-restorable subset is surfaced by getQueuedMessages()/clearQueue(). */
	get queuedMessageCount(): number {
		return (
			this.agent.peekSteeringQueue().filter(isDisplayableQueuedMessage).length +
			this.agent.peekFollowUpQueue().filter(isDisplayableQueuedMessage).length +
			this.#pendingNextTurnMessages.length
		);
	}

	/** Whether an empty submit should interrupt the streaming turn: displayable input is
	 *  queued, or live steering sits in the in-flight response, which the abort requeues
	 *  for the continuation turn. */
	get hasInterruptibleInput(): boolean {
		return this.queuedMessageCount > 0 || this.agent.peekUndeliveredQueuedMessages().some(isDisplayableQueuedMessage);
	}

	/** Chip texts for the queue display. Steering live steering took for the streaming response
	 *  stays listed until the transcript records it, when the model actually switches to it. */
	getQueuedMessages(): { steering: readonly string[]; followUp: readonly string[] } {
		return {
			steering: [...this.agent.peekLiveSteeredMessages(), ...this.agent.peekSteeringQueue()]
				.filter(isUserAuthoredQueuedMessage)
				.map(queueChipText),
			followUp: this.agent.peekFollowUpQueue().filter(isUserAuthoredQueuedMessage).map(queueChipText),
		};
	}

	/** Last {@link getQueuedMessages} snapshot emitted as a `queue_update` event.
	 *  Coalesces the agent's internal `onQueueChange` notification down to the
	 *  externally observable transitions RPC/ACP/TUI subscribers actually care
	 *  about, so a mutation that leaves the displayable queue unchanged (e.g. an
	 *  agent-authored aside, or a claim/restore round-trip) never re-emits. */
	#lastEmittedQueueSnapshot: { steering: readonly string[]; followUp: readonly string[] } | undefined;

	#emitQueueUpdateIfChanged(): void {
		const snapshot = this.getQueuedMessages();
		const last = this.#lastEmittedQueueSnapshot;
		const unchanged =
			last !== undefined &&
			last.steering.length === snapshot.steering.length &&
			last.followUp.length === snapshot.followUp.length &&
			last.steering.every((text, i) => text === snapshot.steering[i]) &&
			last.followUp.every((text, i) => text === snapshot.followUp[i]);
		if (unchanged) return;
		this.#lastEmittedQueueSnapshot = snapshot;
		this.#emit({ type: "queue_update", steering: [...snapshot.steering], followUp: [...snapshot.followUp] });
	}

	/**
	 * Remove the first matching user message and its hidden companions from one queue.
	 * Matches the raw text the caller originally submitted — recorded by
	 * `#queueUserMessage` before any slash/custom-command rewrite, prompt-template
	 * expansion, or `^model` mention substitution — first, then the queued chip
	 * text itself (exact). Raw-text matching covers every transformation `prompt()`
	 * can apply, including the slash/custom-command step no replay can safely
	 * redo (custom commands can have side effects); the chip-text fallback keeps
	 * exact matches working for callers that already hold the queued text (e.g. a
	 * skill invocation's `__queueChipText`, or untransformed text). A missing or
	 * already delivered target changes nothing; repeated calls may remove further
	 * duplicates.
	 */
	removeQueuedMessage(text: string, queue: "steering" | "followUp"): boolean {
		const selected = queue === "steering" ? this.agent.peekSteeringQueue() : this.agent.peekFollowUpQueue();
		const index = this.#findQueuedUserMessage(selected, text);
		if (index < 0) return false;

		this.agent.replaceQueue(queue, this.#withoutQueuedUserMessage(selected, index));
		this.#reconcileQueuedMessageDrain();
		return true;
	}

	/**
	 * Move the first matching user follow-up and its hidden companions to the end of the
	 * steering queue without preprocessing them again. Matches exactly like
	 * {@link removeQueuedMessage}; agent-attributed handoffs are never promoted. A missing
	 * or already delivered target changes nothing; repeated calls may promote duplicates.
	 */
	promoteQueuedMessage(text: string): boolean {
		const followUp = this.agent.peekFollowUpQueue();
		const index = this.#findQueuedUserMessage(followUp, text);
		if (index < 0) return false;

		const promoted = followUp.slice(this.#queuedUserGroupStart(followUp, index), index + 1);
		const message = promoted[promoted.length - 1];
		// Plain user turns opt into model-side emphasis. Collab prompts are already
		// recognized by customType in wrapSteeringForModel; other custom types keep
		// their existing rendering semantics. Queue membership controls interruption.
		if (message.role === "user") message.steering = true;
		// One agent-core mutation edits the follow-up queue and appends to steering, so a
		// live steering claim is left alone, queue listeners (and `queue_update`) see a
		// single transition — never the group in both queues or in neither — and the
		// agent's in-flight steering watchers wake.
		this.agent.moveFollowUpsToSteering(this.#withoutQueuedUserMessage(followUp, index), promoted);
		this.#allowQueuedMessageDrainRetry();
		this.#scheduleIdleQueueDrain();
		return true;
	}

	/**
	 * Queue-editing matcher shared by removal and promotion (see {@link removeQueuedMessage});
	 * matches the raw text the caller originally submitted first, then the queued chip text
	 * itself (exact); -1 when nothing matches.
	 */
	#findQueuedUserMessage(queue: readonly AgentMessage[], text: string): number {
		let index = queue.findIndex(
			message => isUserAuthoredQueuedMessage(message) && this.#queuedMessageRawText.get(message) === text,
		);
		if (index < 0) {
			index = queue.findIndex(message => isUserAuthoredQueuedMessage(message) && queueChipText(message) === text);
		}
		return index;
	}

	/** Companions are inserted contiguously before their user; this is where that group starts. */
	#queuedUserGroupStart(queue: readonly AgentMessage[], userIndex: number): number {
		let start = userIndex;
		while (start > 0 && isHiddenUserCompanion(queue[start - 1])) start--;
		return start;
	}

	/** Drop one user message together with its companions; preserve every other group. */
	#withoutQueuedUserMessage(queue: readonly AgentMessage[], userIndex: number): AgentMessage[] {
		const start = this.#queuedUserGroupStart(queue, userIndex);
		const remaining = queue.slice();
		remaining.splice(start, userIndex - start + 1);
		return remaining;
	}

	/**
	 * Pop the last queued message (steering first, then follow-up).
	 * Used by dequeue keybinding to restore messages to editor one at a time.
	 * Steps over agent-authored queued messages (advisor cards, hidden/internal steers).
	 */
	popLastQueuedMessage(): RestoredQueuedMessage | undefined {
		const steering = this.agent.peekSteeringQueue();
		const followUp = this.agent.peekFollowUpQueue();
		const lastUserIndex = (queue: readonly AgentMessage[]): number => {
			for (let i = queue.length - 1; i >= 0; i--) {
				if (isUserAuthoredQueuedMessage(queue[i])) return i;
			}
			return -1;
		};
		const fromSteer = lastUserIndex(steering);
		if (fromSteer >= 0) {
			const removed = steering[fromSteer];
			this.agent.replaceQueues(this.#withoutQueuedUserMessage(steering, fromSteer), followUp.slice());
			this.#reconcileQueuedMessageDrain();
			return toRestoredQueuedMessage(removed);
		}
		const fromFollowUp = lastUserIndex(followUp);
		if (fromFollowUp >= 0) {
			const removed = followUp[fromFollowUp];
			this.agent.replaceQueues(steering.slice(), this.#withoutQueuedUserMessage(followUp, fromFollowUp));
			this.#reconcileQueuedMessageDrain();
			return toRestoredQueuedMessage(removed);
		}
		return undefined;
	}

	get skillsSettings(): SkillsSettings | undefined {
		return this.#tools.skillsSettings;
	}

	/** Skills loaded by SDK (empty if --no-skills or skills: [] was passed) */
	get skills(): readonly Skill[] {
		return this.#tools.skills;
	}

	/** Descriptions frozen when this session's system prompt was built. */
	get renderedSkills(): readonly Skill[] {
		const skills = this.skills;
		if (skills !== this.#promptSkillsSource) {
			this.#promptSkillsSource = skills;
			this.#promptSkills = this.#skillDescriptions.snapshot(skills);
		}
		return this.#promptSkills;
	}

	/** Frozen skill-URI hint visibility snapshot (see {@link SessionTools.skillHintVisible}). */
	getSkillHintVisible(): boolean {
		return this.#tools.skillHintVisible;
	}

	/** Skill loading warnings captured by SDK */
	get skillWarnings(): readonly SkillWarning[] {
		return this.#tools.skillWarnings;
	}

	/** Session-local general-purpose agents pinned to user-tagged models. */
	getSessionAgents(): AgentDefinition[] {
		return this.#modelMentions.sessionAgents();
	}

	/** Registered model pseudonyms on the active branch. */
	get modelMentions(): readonly ModelMention[] {
		return this.#modelMentions.mentions;
	}

	/** Resolve a model selector within the session picker's scope. */
	findMentionableModel(selector: string): Model | undefined {
		return this.#modelMentions.findMentionable(selector);
	}

	getTodoPhases(): TodoPhase[] {
		return this.#todo.phases;
	}

	setTodoPhases(phases: TodoPhase[]): void {
		this.#todo.setPhases(phases);
	}

	/** Active item labels accepted by this pooled turn's incremental yield tool. */
	getWorkPoolYieldItems(): readonly WorkPoolYieldItem[] {
		return this.#workPoolYieldItems;
	}

	/** Replace the pooled-turn yield contract and rebuild the provider prompt when it changes. */
	setWorkPoolYieldItems(items: readonly WorkPoolYieldItem[]): Promise<void> {
		// Publish the new contract synchronously: prompt dispatchers (IRC wakes,
		// follow-up turns) decide on live state in await-free sections, so the
		// mutation must be visible before the first await. Live state is always
		// post-last-call, so the change check cannot go stale; the prompt rebuild
		// stays async on the serialized tail below.
		const current = this.#workPoolYieldItems;
		if (
			current.length === items.length &&
			current.every((item, index) => item.id === items[index]?.id && item.index === items[index]?.index)
		) {
			return this.#workPoolYieldTransition;
		}
		const applied = items.map(item => ({ ...item }));
		this.#workPoolYieldItems = applied;
		const run = this.#workPoolYieldTransition.then(async () => {
			try {
				await this.refreshBaseSystemPrompt();
			} catch (error) {
				// Roll back to the last successfully published contract so gated
				// readers never observe a half-applied runtime/provider pair. A
				// newer transition may have replaced the set meanwhile; only
				// restore what this one installed. `previous` is deliberately not
				// the target: when overlapping transitions fail in sequence, it can
				// belong to a transition whose caller already saw a rejection.
				if (this.#workPoolYieldItems === applied) {
					this.#workPoolYieldItems = this.#lastPublishedWorkPoolYieldItems;
					// Republish inline so waiters gated on this transition observe
					// the restored pair: a trailing entry would settle those
					// waiters before the repair runs. An overlapping refresh may
					// already have published newer bytes, and the equality fast
					// path would otherwise never repair the mismatch. A republish
					// failure only warns since the caller already sees error.
					try {
						await this.refreshBaseSystemPrompt();
					} catch (republishError) {
						logger.warn("WorkPool yield contract republish failed", {
							error: republishError instanceof Error ? republishError.message : String(republishError),
						});
						throw error;
					}
					this.#resumeStrandedIrcAsides();
				}
				throw error;
			}
			// Record what this rebuild published for future rollbacks: the live set
			// as of success. Then drain any wake parked while pooled.
			this.#lastPublishedWorkPoolYieldItems = this.#workPoolYieldItems.map(item => ({ ...item }));
			// A deferred wake may be parked while pooled; now that the fresh
			// contract is published, let it wake (or stay parked when pooled).
			this.#resumeStrandedIrcAsides();
		});
		this.#workPoolYieldTransition = run.catch(() => {});
		return run;
	}

	/** Settles when any in-flight yield prompt rebuild completes. Wake-turn entry
	 *  joins it so a turn never builds from stale provider bytes. */
	whenWorkPoolYieldSettled(): Promise<void> {
		return this.#workPoolYieldTransition;
	}

	#buildReplanTitleContext(): string {
		return buildReplanTitleContext(this.agent.state.messages);
	}

	#scheduleReplanTitleRefresh(): void {
		if ($env.PI_NO_TITLE) return;
		// Headless subagent sessions have no operator-visible title, so a todo-init
		// replan refresh only burns a tiny-model call whose result lands in JSONL
		// and is never shown (issue #5910). In an interactive host the operator can
		// focus a live subagent from the Agent Hub, where the status line renders
		// its session name — so keep the refresh there and only skip subagents when
		// no focusable UI exists (print/RPC/ACP/eval/SDK/CI).
		if (this.#agentKind === "sub" && !isInteractiveHost()) return;
		if (this.#replanTitleRefreshInFlight) return;
		if (!cfgTitleRefreshOnReplan.get(this.settings)) return;
		if (this.sessionManager.titleSource === "user") return;
		const context = this.#buildReplanTitleContext();
		if (!context) return;
		const sessionId = this.sessionManager.getSessionId();
		const refresh = this.#refreshTitleAfterReplan(context, sessionId)
			.catch(err => {
				logger.warn("title-generator: replan refresh failed", {
					sessionId,
					error: err instanceof Error ? err.message : String(err),
				});
			})
			.finally(() => {
				if (this.#replanTitleRefreshInFlight === refresh) {
					this.#replanTitleRefreshInFlight = undefined;
				}
			});
		this.#replanTitleRefreshInFlight = refresh;
	}

	/**
	 * Start automatic title generation when the session and input are eligible.
	 * Interactive and CLI-bootstrap submissions share this gate so every first
	 * user message persists titles with the same environment, signal, and local
	 * extension-command policy.
	 */
	maybeStartTitleGeneration(firstMessage: string): void {
		const extensionCommandSpace = firstMessage.indexOf(" ");
		const isLocalExtensionCommand =
			firstMessage.startsWith("/") &&
			this.#extensionRunner?.getCommand(
				extensionCommandSpace === -1 ? firstMessage.slice(1) : firstMessage.slice(1, extensionCommandSpace),
			) !== undefined;
		const sessionId = this.sessionManager.getSessionId();
		if (
			isLocalExtensionCommand ||
			this.sessionName ||
			this.#titleGenerationInFlightFor === sessionId ||
			$env.PI_NO_TITLE ||
			isLowSignalTitleInput(firstMessage)
		) {
			return;
		}
		this.#deferredTitle = { sessionId, declined: false, replied: false };
		this.#startAutoTitle(firstMessage, sessionId);
	}

	/**
	 * Run one automatic title generation for `sessionId`, applying the result
	 * unless the session was renamed or replaced meanwhile. A settled request
	 * that left the session unnamed advances {@link #deferredTitle}.
	 */
	#startAutoTitle(input: string, sessionId: string): void {
		this.#titleGenerationInFlightFor = sessionId;
		const signal = this.#titleGenerationAbortController.signal;
		this.generateTitle(input)
			.then(async title => {
				// Re-check after generation so a later completion cannot replace
				// the first title, and a request from a replaced session cannot
				// name the current one.
				if (this.sessionManager.getSessionId() !== sessionId) return;
				if (title && !this.sessionName) {
					await this.sessionManager.setSessionName(title, "auto");
				}
			})
			.catch(err => {
				logger.warn("title-generator: uncaught auto-title error", {
					sessionId: this.sessionId,
					reason: "uncaught-auto-title-error",
					error: err instanceof Error ? err.message : String(err),
				});
			})
			.finally(() => {
				if (this.#titleGenerationInFlightFor === sessionId) {
					this.#titleGenerationInFlightFor = undefined;
				}
				// An interrupted request is cancelled inference, not a decline.
				if (signal.aborted) this.#deferredTitle = undefined;
				else this.#advanceDeferredTitle("declined");
			});
	}

	/**
	 * Record one half of the deferred-title condition; once the title model has
	 * declined and the assistant has replied, retitle from conversation context.
	 * The retry runs at most once per deferral, so a still-ambiguous exchange
	 * waits for the next user message instead of retrying every assistant turn.
	 */
	#advanceDeferredTitle(step: "declined" | "replied"): void {
		const deferred = this.#deferredTitle;
		if (!deferred) return;
		const sessionId = this.sessionManager.getSessionId();
		if (deferred.sessionId !== sessionId || this.sessionName) {
			this.#deferredTitle = undefined;
			return;
		}
		deferred[step] = true;
		if (!deferred.declined || !deferred.replied) return;
		this.#deferredTitle = undefined;
		if (this.#titleGenerationInFlightFor === sessionId || $env.PI_NO_TITLE) return;
		const context = this.#buildReplanTitleContext();
		if (!context || isLowSignalTitleInput(context)) return;
		this.#startAutoTitle(context, sessionId);
	}

	#resolveTitleProviderSessionId(parentSessionId: string): string {
		if (this.#titleProviderParentSessionId === parentSessionId && this.#titleProviderSessionId) {
			return this.#titleProviderSessionId;
		}
		const titleSessionId = Bun.randomUUIDv7();
		this.#titleProviderParentSessionId = parentSessionId;
		this.#titleProviderSessionId = titleSessionId;
		return titleSessionId;
	}

	/**
	 * Generate an automatic session title tied to this session's lifecycle.
	 * Input and replan callers share the signal so interruption and disposal cancel
	 * provider and local-worker requests instead of leaving background inference alive.
	 * Online calls use a stable side-request identity so they cannot advance the
	 * foreground provider session while its request is waiting.
	 * `customSystemPrompt` swaps the title prompt for special-purpose titling
	 * (e.g. plan-save filename topics) without touching the session override.
	 */
	async generateTitle(
		firstMessage: string,
		customSystemPrompt?: string,
		signal?: AbortSignal,
	): Promise<string | null> {
		const parentSessionId = this.sessionId;
		const sessionGeneration = this.#sessionGeneration;
		const sessionId = this.#resolveTitleProviderSessionId(parentSessionId);
		const titleSignal = signal
			? AbortSignal.any([signal, this.#titleGenerationAbortController.signal])
			: this.#titleGenerationAbortController.signal;
		if (titleSignal.aborted) return null;
		// The title request carries user text, so it follows this session's own credential
		// redaction policy like its conversation requests (see `settingsAwareStreamFn`).
		const title = await withCredentialRedaction(cfgSecretsEnabled.get(this.settings), () =>
			generateSessionTitle(
				firstMessage,
				this.#modelRegistry,
				this.settings,
				sessionId,
				this.model,
				provider => buildSessionMetadata(sessionId, provider, this.#modelRegistry.authStorage),
				customSystemPrompt ?? this.#titleSystemPrompt,
				titleSignal,
				parentSessionId,
			),
		);
		if (await this.#sessionGenerationChanged(sessionGeneration)) return null;
		return !titleSignal.aborted && this.sessionId === parentSessionId ? title : null;
	}

	/** Capture before generation to detect interruption or disposal of a title request. */
	get titleGenerationSignal(): AbortSignal {
		return this.#titleGenerationAbortController.signal;
	}

	async #refreshTitleAfterReplan(context: string, sessionId: string): Promise<void> {
		const title = await this.generateTitle(context);
		if (!title) return;
		if (this.sessionManager.getSessionId() !== sessionId) return;
		if (!cfgTitleRefreshOnReplan.get(this.settings)) return;
		if (this.sessionManager.titleSource === "user") return;
		const setSessionName = this.sessionManager.setSessionName as SetSessionNameWithTrigger;
		await setSessionName.call(this.sessionManager, title, "auto", "replan");
	}

	/** Currently-applied {@link TITLE_SYSTEM.md} override, or undefined when the
	 *  bundled prompt is in effect. Consumed by {@link InteractiveMode} so the
	 *  first-input title path and the replan refresh share one source. */
	get titleSystemPrompt(): string | undefined {
		return this.#titleSystemPrompt;
	}

	/** Replace the title-generation system prompt override. Called by
	 *  {@link InteractiveMode.refreshTitleSystemPrompt} after the session cwd
	 *  changes (e.g. `/move` relocation) so the next replan refresh resolves
	 *  against the destination project's override. */
	setTitleSystemPrompt(prompt: string | undefined): void {
		this.#titleSystemPrompt = prompt;
	}

	/** Install the host hook that receives a typed user prompt dropped before
	 *  dispatch (an Esc abort or usage preflight denial raced turn setup). The
	 *  prompt never reached the agent or the session file, so without this hook
	 *  it would vanish; interactive mode restores it to the editor for editing. */
	setPromptDropped(handler: ((prompt: DroppedPrompt) => void) | undefined): void {
		this.#promptDropped = handler;
	}

	/**
	 * Abort current operation and wait for agent to become idle.
	 *
	 * `reason` (e.g. `USER_INTERRUPT_LABEL`) rides the agent's `AbortController`
	 * and surfaces verbatim on the aborted assistant message's `errorMessage`, so
	 * the transcript can distinguish a deliberate user interrupt from an opaque
	 * abort. Omit it for internal/lifecycle aborts.
	 */
	async abort(options?: {
		goalReason?: "interrupted" | "internal";
		reason?: string;
		/** Internal `/compact` startup keeps the manual-compaction marker alive while aborting the active turn. */
		preserveCompaction?: boolean;
	}): Promise<void> {
		const internalTaskAbort = this.#childTaskRecovery && this.#taskControlPermit === "abort";
		this.#taskControlPermit = undefined;
		if (!internalTaskAbort) this.invalidateTaskRecovery("Public abort superseded task recovery");
		const userInterrupt = options?.reason === USER_INTERRUPT_LABEL;
		this.#pendingAbortErrorId = userInterrupt ? AIError.create(AIError.Flag.UserInterrupt) : undefined;
		if (userInterrupt) this.#advisors.autoResumeSuppressed = true;
		// Pull advisor concerns out of the steer/follow-up queues before any await so
		// the post-abort stranded-message drain can't auto-resume the run on them.
		// They are re-recorded as visible advice once the agent settles (below).
		const strandedAdvisorCards = userInterrupt ? this.#extractQueuedAdvisorCards() : [];
		// Session switch/compact paths disconnect first; explicit aborts should
		// leave any queued steer/follow-up visible for the user rather than
		// auto-starting a fresh turn during cleanup.
		this.#abortInProgress = true;
		try {
			this.#titleGenerationAbortController.abort();
			if (!this.#isDisposed) this.#titleGenerationAbortController = new AbortController();
			this.#abortAutolearnCapture();
			for (const controller of this.#usagePreflightAbortControllers) controller.abort();
			for (const controller of this.#imageDescriptionAbortControllers) controller.abort(options?.reason);
			this.abortRetry();
			this.#promptGeneration++;
			// Cancel any awaited pre-dispatch setup (e.g. Hindsight auto-recall) so the
			// admitted submission unwinds now instead of at the recall timeout (#12668).
			this.#promptSetupAbortController?.abort(options?.reason);
			this.#scheduledHiddenNextTurnGeneration = undefined;
			// Abort the handoff first so generic compaction cancellation cannot replace
			// the harness reason with an unreasoned "Handoff cancelled".
			this.#handoff.abortHandoff(new Error(options?.reason ?? "Handoff aborted by session"));
			let manualCompactionCleanup: Promise<void> | undefined;
			if (options?.preserveCompaction) {
				// Manual `/compact` installed its own #compactionAbortController before
				// this internal abort and must keep it alive (that marker is what makes
				// isCompacting report true during startup). Any in-flight
				// auto-compaction MUST still be cancelled, though: otherwise a
				// background maintenance pass races the manual run and both
				// appendCompaction/replaceMessages, double-rewriting session history.
				this.#maintenance.abortAutomaticCompaction();
			} else {
				manualCompactionCleanup = this.#maintenance.abortCompaction(options?.reason);
			}
			this.abortBash();
			this.abortEval();
			const postPromptDrain = this.#cancelPostPromptTasks();
			this.agent.abort(options?.reason);
			await postPromptDrain;
			await this.agent.waitForIdle();
			// `/compact` disconnects the agent subscription until its finally block.
			// Do not let abort-and-replace callers start a new prompt before that cleanup
			// finishes, or the replacement turn's events are neither forwarded nor persisted.
			await manualCompactionCleanup;
			await this.#drainAutolearnCapture();
			await this.#goalRuntime.onTaskAborted({ reason: options?.goalReason ?? "interrupted" });
			// Clear prompt-in-flight state: waitForIdle resolves when the agent loop's finally
			// block runs, but nested prompt setup/finalizers may still be unwinding. Without this,
			// a subsequent prompt() can incorrectly observe the session as busy after an abort.
			this.#resetInFlight();
			this.#resetSessionStopContinuationState();
			this.#clearPendingSessionStopContinuations();
			// Safety net: if the agent loop aborted without producing an assistant
			// message (e.g. failed before the first stream), the in-flight yield was
			// never resolved or rejected by the normal message_end path. Reject it now
			// so any requeue callback still fires and the queue stays consistent.
			if (this.#toolChoiceQueue.hasInFlight) {
				this.#toolChoiceQueue.reject("aborted");
			}
			// Re-record advisor concerns the interrupt would otherwise strand, as
			// visible/persisted advice without triggering a turn (the agent is idle
			// now): cards steered into the queue before the user stopped, plus any
			// that arrived via AdviseTool routing mid-abort and were parked hidden in
			// #pendingNextTurnMessages while the turn was still tearing down. Other
			// deferred next-turn context (non-advisor) stays queued, in order.
			const parkedAdvisorCards = this.#pendingNextTurnMessages.filter(isAdvisorCard);
			if (parkedAdvisorCards.length > 0) {
				this.#pendingNextTurnMessages = this.#pendingNextTurnMessages.filter(m => !isAdvisorCard(m));
			}
			for (const card of [...strandedAdvisorCards, ...parkedAdvisorCards]) {
				this.#preserveAdvisorCard(card);
			}
		} finally {
			this.#abortInProgress = false;
			this.#drainStrandedQueuedMessages();
		}
	}

	/**
	 * Start a new session, optionally with initial messages and parent tracking.
	 * Clears all messages and starts a new session.
	 * Listeners are preserved and will continue receiving events.
	 * @param options - Optional initial messages and parent session path
	 * @returns true if completed, false if cancelled by hook
	 */
	async newSession(options?: NewSessionOptions): Promise<boolean> {
		this.#assertTaskRecoveryInput();
		using _transition = this.#beginSessionTransition();
		this.#assertVibeSessionTransitionAllowed("start a new session");
		const previousSessionFile = this.sessionFile;

		// Emit session_before_switch event with reason "new" (can be cancelled)
		if (this.#extensionRunner?.hasHandlers("session_before_switch")) {
			const result = (await this.#extensionRunner.emit({
				type: "session_before_switch",
				reason: "new",
			})) as SessionBeforeSwitchResult | undefined;

			if (result?.cancel) {
				return false;
			}
		}

		this.#disconnectFromAgent();
		let advisorRecordersDetached = false;
		await this.abort();
		this.#cancelOwnAsyncJobs();
		this.#closeAllProviderSessions("new session");
		await this.#bash.flushPending();
		const bashTransition = this.#bash.beginSessionTransition({ persistDetached: options?.drop !== true });
		let sessionTransitioned = false;
		try {
			advisorRecordersDetached = true;
			await this.#advisors.drainAndDetachRecorders();
			try {
				this.#releaseQueuedTtsrReservations();
				this.agent.reset();
				this.tokenRate.reset();
				if (options?.drop && previousSessionFile) {
					try {
						await this.sessionManager.dropSession(previousSessionFile);
					} catch (err) {
						logger.error("Failed to delete session during /delete", { err });
					}
				} else {
					await this.sessionManager.flush();
				}
				await this.sessionManager.newSession({
					...options,
					additionalDirectories: cfgWorkspaceAdditionalDirectories.get(this.settings),
				});
				this.#bash.markSessionTransition(bashTransition);
				// The new session owns the transcript from here, so the previous
				// conversation's advisor spend is retired with it. Clearing at the commit
				// point keeps the status line honest even if a later step below throws.
				this.#advisors.clearCost();
				sessionTransitioned = true;
			} finally {
				this.#bash.finishSessionTransition(bashTransition, sessionTransitioned);
			}

			this.#clearSessionScopedToolState();
			this.#clearCheckpointRuntimeState();
			this.setTodoPhases([]);
			this.#freshProviderSessionId = undefined;
			this.#clearInheritedProviderPromptCacheKey();
			this.#syncAgentSessionId();
			// Re-apply the configured selector so the new session does not inherit
			// the previous session's auto-classified effort: auto stays auto but
			// restarts at the provisional level; a pinned level re-resolves to itself.
			this.#models.restoreThinkingLevel(this.configuredThinkingLevel());
			// Drop the frozen system-prompt/tool snapshot and synced message bytes
			// (mirrors freshSession()/resetSessionContext()): without this the first
			// post-/new turns keep sending the previous session's StablePrefix, and
			// #syncAppendOnlyContext only re-runs on model or setting changes.
			this.agent.appendOnlyContext?.invalidateForModelChange();
			this.#memory.rekeyForCurrentSessionId();
			await this.#memory.resetContextForNewTranscript();
			this.#pendingNextTurnMessages = [];
			// The abort above may have skipped the loop's final aside poll (issue: stranded
			// asides survive an aborted turn by design so a resumed session can still see
			// them); discard here so they cannot leak into the new session's transcript via
			// the first ordinary prompt's IrcBridge.flushPending(). Bump #sessionGeneration in
			// the same breath so an aside-queueing call still awaiting normalization for the
			// outgoing session also drops its record instead of landing in this new one.
			this.#irc.clearPending();
			this.#sessionGeneration++;
			this.#scheduledHiddenNextTurnGeneration = undefined;
			this.#queuedMessageDrainBlocked = false;
			this.#usagePreflightReadyForNextModelCall = false;

			this.sessionManager.appendThinkingLevelChange(this.thinkingLevel, this.configuredThinkingLevel());
			this.sessionManager.appendServiceTierChange(this.#models.serviceTierEntry());

			this.#todo.resetCycle();
			this.#planReferenceSent = false;
			this.#planReferencePath = "local://PLAN.md";
			this.#advisors.resetSessionState();
			advisorRecordersDetached = false;
			this.#reconnectToAgent();
			// Drop the process-lifetime context-file cache so the rebuild re-reads
			// AGENTS.md and friends from disk: the user may have edited them since
			// the previous session started, and refreshBaseSystemPrompt() re-runs
			// discovery but would otherwise hit stale cached bytes (issue #9273).
			// The workspace-roots block must also reflect the new session's
			// directory set, not the previous session's — refresh before the next
			// turn goes out.
			resetCapabilities();
			await this.refreshBaseSystemPrompt();

			// Emit session_switch event with reason "new" to hooks
			if (this.#extensionRunner) {
				await this.#extensionRunner.emit({
					type: "session_switch",
					reason: "new",
					previousSessionFile,
				});
			}

			return true;
		} finally {
			if (advisorRecordersDetached) {
				if (sessionTransitioned) this.#advisors.resetSessionState();
				else this.#advisors.reattachRecorderFeeds();
			}
		}
	}

	/**
	 * Set a display name for the current session.
	 */
	setSessionName(name: string, source: "auto" | "user" = "auto", trigger?: SessionNameTrigger): Promise<boolean> {
		const setSessionName = this.sessionManager.setSessionName as SetSessionNameWithTrigger;
		return setSessionName.call(this.sessionManager, name, source, trigger);
	}

	/**
	 * Fork the current session, creating a new session file with the exact same state.
	 * Copies all entries and artifacts to the new session.
	 * Unlike newSession(), this preserves all messages in the agent state.
	 * @returns true if completed, false if cancelled by hook or not persisting
	 */
	async fork(): Promise<boolean> {
		this.#assertTaskRecoveryInput();
		using _transition = this.#beginSessionTransition();
		this.#assertVibeSessionTransitionAllowed("fork the session");
		const previousSessionFile = this.sessionFile;
		const previousSessionId = this.sessionManager.getSessionId();

		// Emit session_before_switch event with reason "fork" (can be cancelled)
		if (this.#extensionRunner?.hasHandlers("session_before_switch")) {
			const result = (await this.#extensionRunner.emit({
				type: "session_before_switch",
				reason: "fork",
			})) as SessionBeforeSwitchResult | undefined;

			if (result?.cancel) {
				return false;
			}
		}

		await this.#bash.flushPending();
		// Flush current session to ensure all entries are written
		await this.sessionManager.flush();
		let advisorRecordersDetached = false;
		try {
			advisorRecordersDetached = true;
			// Fork keeps the conversation, but still needs a quiet artifact boundary:
			// stop and settle in-flight advisors before muting their feeds.
			await this.#advisors.drainAndDetachRecorders();
			const bashTransition = this.#bash.beginSessionTransition();

			// Fork the session (creates new session file with same entries)
			let forkResult: { oldSessionFile: string; newSessionFile: string } | undefined;
			try {
				// No file means fork() is a no-op. Otherwise invalidate admitted
				// prompt setup before the asynchronous identity rewrite begins.
				if (previousSessionFile) this.#promptGeneration++;
				forkResult = await this.sessionManager.fork();
			} catch (error) {
				this.#bash.finishSessionTransition(bashTransition, false);
				throw error;
			}
			if (!forkResult) {
				this.#bash.finishSessionTransition(bashTransition, false);
				return false;
			}
			this.#bash.markSessionTransition(bashTransition);
			this.#bash.finishSessionTransition(bashTransition, true);
			// The fork clones the transcript and keeps this recovery state running
			// under a fresh id, so the work already produced is still this session's.
			this.#recovery.reanchorServedAttribution(previousSessionId);

			await copySessionArtifacts(forkResult.oldSessionFile, forkResult.newSessionFile);

			// Update agent session ID
			this.#freshProviderSessionId = undefined;
			this.#adoptInheritedProviderPromptCacheKey();
			this.#syncAgentSessionId();
			this.#memory.rekeyForCurrentSessionId();
			this.#advisors.reattachRecorderFeeds();
			advisorRecordersDetached = false;
			await this.#memory.resetContextForNewTranscript();

			// Emit session_switch event with reason "fork" to hooks
			if (this.#extensionRunner) {
				await this.#extensionRunner.emit({
					type: "session_switch",
					reason: "fork",
					previousSessionFile,
				});
			}

			return true;
		} finally {
			if (advisorRecordersDetached) this.#advisors.reattachRecorderFeeds();
		}
	}

	/** Move the active session and artifacts after enforcing mode transition invariants. */
	async moveSession(newCwd: string, targetSessionDir?: string): Promise<void> {
		this.#assertTaskRecoveryInput();
		this.#assertVibeSessionTransitionAllowed("move the session");
		await this.sessionManager.moveTo(newCwd, targetSessionDir);
	}

	// =========================================================================
	// Model Management
	// =========================================================================

	/**
	 * Set model directly.
	 * Validates that a credential source is configured (synchronously, without
	 * refreshing OAuth or running command-backed key programs). Active switches
	 * always take effect; if the current transcript is too large for the target
	 * model, the next prompt's compaction/error path owns that recovery instead
	 * of leaving the session pinned to the old model.
	 * @throws Error if no API key available for the model
	 */
	async setModel(
		model: Model,
		role: string = "default",
		options?: {
			selector?: string;
			thinkingLevel?: ThinkingLevel;
			persist?: boolean;
		},
	): Promise<{ switched: boolean }> {
		return this.#models.setModel(model, role, options);
	}

	/** Selects a model for this session without updating persisted model settings. */
	setModelTemporary(
		model: Model,
		thinkingLevel?: ConfiguredThinkingLevel,
		options?: { ephemeral?: boolean },
	): Promise<void> {
		return this.#models.setModelTemporary(model, thinkingLevel, options);
	}

	/** Cycles the scoped model set, or all available models when no scope exists. */
	cycleModel(direction: "forward" | "backward" = "forward"): Promise<ModelCycleResult | undefined> {
		return this.#models.cycleModel(direction);
	}

	/** Resolves configured role models and the currently active role index. */
	getRoleModelCycle(roleOrder: readonly string[]): RoleModelCycle | undefined {
		return this.#models.getRoleModelCycle(roleOrder);
	}

	/** Applies a resolved role model without changing global settings. */
	applyRoleModel(entry: ResolvedRoleModel): Promise<void> {
		return this.#models.applyRoleModel(entry);
	}

	/** Cycles the configured role models in the supplied order. */
	cycleRoleModels(
		roleOrder: readonly string[],
		direction: "forward" | "backward" = "forward",
	): Promise<RoleModelCycleResult | undefined> {
		return this.#models.cycleRoleModels(roleOrder, direction);
	}

	/** Lists available models after applying the configured enabled-model filter. */
	getAvailableModels(): Model[] {
		return this.#models.getAvailableModels();
	}

	/** Selects the session thinking level and optionally persists it as the default. */
	setThinkingLevel(level: ConfiguredThinkingLevel | undefined, persist: boolean = false): void {
		this.#models.setThinkingLevel(level, persist);
	}

	/** Advances through the thinking selectors supported by the active model. */
	cycleThinkingLevel(): ConfiguredThinkingLevel | undefined {
		return this.#models.cycleThinkingLevel();
	}

	/** Reports whether `/fast` is enabled for the active model family. */
	isFastModeEnabled(): boolean {
		return this.#models.isFastModeEnabled();
	}

	/** Reports whether priority service is realized by the active model. */
	isFastModeActive(): boolean {
		return this.#models.isFastModeActive();
	}

	/** Record the Claude account lane that served this session's latest Anthropic request. */
	noteAnthropicSlowModeLane(lane: string): void {
		this.#anthropicSlowModeLane = lane;
	}

	/**
	 * Slow-mode lane of the Claude account this session last used, or
	 * undefined before its first Anthropic subscription request.
	 */
	getAnthropicSlowModeLane(): AnthropicSlowModeController | undefined {
		const lane = this.#anthropicSlowModeLane;
		return lane === undefined ? undefined : anthropicSlowModeLanes.lane(lane);
	}

	/**
	 * Status-line label for the Claude account's usage-limit stage, e.g.
	 * `limit reached · wrapping up · resets 14:30` or (with `/slow on`)
	 * `low priority until 14:30 · 62% left`; undefined outside both stages or
	 * off an Anthropic model.
	 */
	getAnthropicSlowModeLabel(): string | undefined {
		if (this.model?.provider !== "anthropic") return undefined;
		return this.getAnthropicSlowModeLane()?.statusLabel(
			undefined,
			cfgProvidersAnthropicSlowMode.get(this.settings) === "auto",
		);
	}

	/**
	 * Mid-run, once per wrap-up window: tell the model to checkpoint when its
	 * Claude account runs on the wrap-up allowance and nothing (low priority,
	 * extra usage) will carry the work past it.
	 */
	#steerAnthropicWrapUp(): void {
		const lane = this.#anthropicSlowModeLane;
		if (lane === undefined || this.model?.provider !== "anthropic") return;
		const window = anthropicSlowModeLanes
			.lane(lane)
			.wrapUpHintKey(cfgProvidersAnthropicSlowMode.get(this.settings) === "auto");
		if (window === undefined) return;
		const key = `${lane}#${window}`;
		if (this.#anthropicWrapUpHinted === key) return;
		this.#anthropicWrapUpHinted = key;
		this.agent.steer({
			role: "custom",
			customType: "anthropic-usage-wrap-up",
			content: anthropicUsageWrapUpPrompt,
			attribution: "agent",
			display: false,
			timestamp: Date.now(),
		});
	}

	/** Sets or clears one model family's live service tier. */
	setServiceTierFamily(family: ServiceTierFamily, tier: ServiceTier | undefined): void {
		this.#models.setServiceTierFamily(family, tier);
	}

	/** Enables or disables priority service for the active model family. */
	setFastMode(enabled: boolean): boolean {
		return this.#models.setFastMode(enabled);
	}

	/** Toggles priority service for the active model family. */
	toggleFastMode(): boolean {
		return this.#models.toggleFastMode();
	}

	/** Reports whether `/fast ultra` (the OpenAI `ultrafast` tier) is selected for the active model. */
	isUltrafastModeEnabled(): boolean {
		return this.#models.isUltrafastModeEnabled();
	}

	/** Enables or disables the OpenAI `ultrafast` tier; `false` when the active model does not offer it. */
	setUltrafastMode(enabled: boolean): boolean {
		return this.#models.setUltrafastMode(enabled);
	}

	/**
	 * What `/slow` controls for the active model: the `flex` service tier on the
	 * OpenAI/Google families, or subscription slow mode on direct Anthropic.
	 */
	#slowModeTarget(): { kind: "flex"; family: ServiceTierFamily } | { kind: "anthropic" } | undefined {
		const model = this.model;
		if (!model) return undefined;
		if (model.provider === "anthropic") return { kind: "anthropic" };
		const family = serviceTierFamily(model);
		return family && isServiceTierForFamily(family, "flex") ? { kind: "flex", family } : undefined;
	}

	/** Reports whether `/slow` is on for the active model. */
	isSlowModeEnabled(): boolean {
		const target = this.#slowModeTarget();
		if (!target) return false;
		if (target.kind === "anthropic") return cfgProvidersAnthropicSlowMode.get(this.settings) === "auto";
		return this.serviceTierByFamily[target.family] === "flex";
	}

	/**
	 * `/slow on|off` for the active model. OpenAI/Google: sets or clears this
	 * session's `flex` tier. Anthropic: sets `providers.anthropic.slowMode` to
	 * `auto`/`off`; on also enters an already-offered (or user-stopped) slow
	 * window right away, off stops the active one. Returns false when the model
	 * has no slow mode.
	 */
	setSlowMode(enabled: boolean): boolean {
		const target = this.#slowModeTarget();
		if (!target) return false;
		if (target.kind === "flex") {
			if (enabled) this.setServiceTierFamily(target.family, "flex");
			else if (this.serviceTierByFamily[target.family] === "flex") {
				this.setServiceTierFamily(target.family, undefined);
			}
			return true;
		}
		cfgProvidersAnthropicSlowMode.set(this.settings, enabled ? "auto" : "off");
		const lane = this.getAnthropicSlowModeLane();
		if (enabled) lane?.accept();
		else lane?.stop("user");
		return true;
	}

	/** Flips the `skillful` setting for this session only. See {@link setSkillful}. */
	async toggleSkillful(): Promise<boolean> {
		return this.setSkillful(!cfgSkillful.get(this.settings));
	}

	/**
	 * Sets the `skillful` setting for this session only (never persisted).
	 * Returns the new value.
	 *
	 * With an empty transcript the rebuilt system prompt simply carries or
	 * drops the `<skills>` listing. Mid-session the provider-visible prompt
	 * stays byte-stable: disabling is a no-op until the next session, and
	 * enabling appends a single hidden notice carrying the listing so the
	 * model learns the skills without a prompt-prefix rewrite.
	 */
	async setSkillful(enabled: boolean): Promise<boolean> {
		if (enabled === cfgSkillful.get(this.settings)) return enabled;
		cfgSkillful.override(this.settings, enabled);
		await this.#applySkillful(enabled);
		return enabled;
	}

	/**
	 * Applies a `skillful` change to the live session per {@link setSkillful};
	 * idempotent per value so the setter and the setting watch never double-apply.
	 */
	async #applySkillful(enabled: boolean): Promise<void> {
		if (enabled === this.#skillfulApplied) return;
		this.#skillfulApplied = enabled;
		if (this.agent.state.messages.length === 0) {
			await this.refreshBaseSystemPrompt();
		} else if (enabled) {
			// Enabled covers top-level, xd://-mounted, and Code Mode bridge-demoted
			// tools: every path through which the model can still reach a reader.
			const hasSkillReader = this.getEnabledToolNames().some(name => toolReadsSkillUris(this.getToolByName(name)));
			const renderedSkills = this.#skillDescriptions.render(
				hasSkillReader ? this.skills.filter(skill => skill.hide !== true) : [],
			);
			// Hidden-only sessions have no catalog rows, but the notice template
			// still carries the `skill://<name>` syntax the model needs: hidden
			// skills stay reachable by URI even though they are never listed.
			const hasReadableSkills = hasSkillReader && this.skills.length > 0;
			const alreadyAnnounced = this.agent.state.messages.some(
				message => message.role === "custom" && message.customType === "skillful-notice",
			);
			if (hasReadableSkills && !alreadyAnnounced) {
				await this.sendCustomMessage(
					{
						customType: "skillful-notice",
						content: prompt.render(skillfulNoticePrompt, { skills: renderedSkills }),
						display: false,
					},
					{ deliverAs: "nextTurn" },
				);
			}
		}
	}

	/** Lists thinking levels supported by the active model. */
	getAvailableThinkingLevels(): ReadonlyArray<Effort> {
		return this.#models.getAvailableThinkingLevels();
	}

	// =========================================================================
	// Message Queue Mode Management
	// =========================================================================

	/**
	 * Set steering mode. Persists to global config by default; pass
	 * `persist: false` for a session-only change (RPC) that leaves Settings —
	 * and therefore later sessions and subagents — untouched.
	 */
	setSteeringMode(mode: "all" | "one-at-a-time", persist = true): void {
		this.agent.setSteeringMode(mode);
		if (persist) {
			cfgSteeringMode.set(this.settings, mode);
		}
	}

	/**
	 * Set follow-up mode. Persists to global config by default; pass
	 * `persist: false` for a session-only change (RPC) that leaves Settings —
	 * and therefore later sessions and subagents — untouched.
	 */
	setFollowUpMode(mode: "all" | "one-at-a-time", persist = true): void {
		this.agent.setFollowUpMode(mode);
		if (persist) {
			cfgFollowUpMode.set(this.settings, mode);
		}
	}

	/**
	 * Set interrupt mode. Persists to global config by default; pass
	 * `persist: false` for a session-only change (RPC) that leaves Settings —
	 * and therefore later sessions and subagents — untouched.
	 */
	setInterruptMode(mode: "immediate" | "wait", persist = true): void {
		this.agent.setInterruptMode(mode);
		if (persist) {
			cfgInterruptMode.set(this.settings, mode);
		}
	}

	/**
	 * Cancel in-progress branch summarization.
	 */
	abortBranchSummary(): void {
		this.#branchSummaryAbortController?.abort();
	}

	/**
	 * Cancel in-progress handoff generation.
	 */
	abortHandoff(): void {
		this.#handoff.abortHandoff();
	}

	/**
	 * Check if handoff generation is in progress.
	 */
	get isGeneratingHandoff(): boolean {
		return this.#handoff.isGeneratingHandoff;
	}

	/**
	 * Generate a handoff document with a oneshot LLM call and commit it as a
	 * compaction entry on the current session (the document becomes the summary;
	 * recent history is kept).
	 *
	 * @param customInstructions Optional focus for the handoff document
	 * @param options Handoff execution options
	 * @returns The handoff document text, or undefined if cancelled/failed
	 */
	handoff(customInstructions?: string, options?: SessionHandoffOptions): Promise<HandoffResult | undefined> {
		return this.#maintenance.handoff(customInstructions, options);
	}

	#isTerminalYieldToolResult(event: { toolName: string; isError?: boolean; result?: { details?: unknown } }): boolean {
		if (event.toolName !== "yield" || event.isError) return false;
		const details = event.result?.details;
		if (!details || typeof details !== "object") return true;
		const record = details as Record<string, unknown>;
		return !(
			record.status === "success" &&
			Array.isArray(record.type) &&
			record.type.length > 0 &&
			record.type.every(item => typeof item === "string")
		);
	}

	#markTerminalYieldToolCall(toolCallId: string): void {
		this.#lastSuccessfulYieldToolCallId = toolCallId;
		this.#yieldTerminationPending = true;
	}

	#assistantMessageHasSuccessfulYieldToolCall(assistantMessage: AssistantMessage, toolCallId: string): boolean {
		const lastToolCall = assistantMessage.content
			.slice()
			.reverse()
			.find((content): content is ToolCall => content.type === "toolCall");
		return lastToolCall?.name === "yield" && lastToolCall.id === toolCallId;
	}

	#assistantEndedWithSuccessfulYield(assistantMessage: AssistantMessage): boolean {
		const toolCallId = this.#lastSuccessfulYieldToolCallId;
		return toolCallId ? this.#assistantMessageHasSuccessfulYieldToolCall(assistantMessage, toolCallId) : false;
	}

	#findSuccessfulYieldAssistantMessage(messages: readonly AgentMessage[]): AssistantMessage | undefined {
		const toolCallId = this.#lastSuccessfulYieldToolCallId;
		if (!toolCallId) return undefined;
		for (let i = messages.length - 1; i >= 0; i--) {
			const message = messages[i];
			if (message.role !== "assistant") continue;
			if (this.#assistantMessageHasSuccessfulYieldToolCall(message, toolCallId)) return message;
		}
		return undefined;
	}

	#enforceRewindBeforeYield(): boolean {
		if (!this.#checkpointState || this.#pendingRewindReport) {
			return false;
		}
		const reminder = [
			"<system-warning>",
			"You are in an active checkpoint. You MUST call rewind with your investigation findings before yielding. Do NOT yield without completing the checkpoint.",
			"</system-warning>",
		].join("\n");
		this.agent.appendMessage({
			role: "developer",
			content: [{ type: "text", text: reminder }],
			attribution: "agent",
			timestamp: Date.now(),
		});
		this.#scheduleAgentContinue({
			source: "checkpoint-rewind-reminder",
			generation: this.#promptGeneration,
		});
		return true;
	}

	#extractRewindReport(messages: AgentMessage[]): string | undefined {
		const checkpointState = this.#checkpointState;
		if (!checkpointState) return undefined;
		if (this.#pendingRewindReport) return this.#pendingRewindReport;
		for (let i = messages.length - 1; i >= checkpointState.checkpointMessageCount; i--) {
			const message = messages[i];
			if (message?.role !== "toolResult" || message.isError) continue;
			const semanticResult = semanticToolResult(message.toolName, message);
			if (semanticResult?.toolName !== "rewind") continue;
			const details = semanticResult.details;
			const detailReport =
				details && typeof details === "object" && "report" in details && typeof details.report === "string"
					? details.report.trim()
					: "";
			const textReport = message.content.find(part => part.type === "text")?.text.trim() ?? "";
			const report = detailReport || textReport;
			return report.length > 0 ? report : undefined;
		}
		return undefined;
	}

	async #applyRewind(report: string, activeMessages?: AgentMessage[], turn?: AgentTurnEndContext): Promise<void> {
		const checkpointState = this.#checkpointState;
		if (!checkpointState) {
			return;
		}
		this.#bash.withBranchTransition(() => {
			try {
				this.sessionManager.branchWithSummary(checkpointState.checkpointEntryId, report, {
					startedAt: checkpointState.startedAt,
				});
			} catch (error) {
				logger.warn("Rewind branch checkpoint missing, falling back to root", {
					error: error instanceof Error ? error.message : String(error),
				});
				this.sessionManager.branchWithSummary(null, report, { startedAt: checkpointState.startedAt });
			}
		});

		const rewoundAt = new Date().toISOString();
		const details = { report, startedAt: checkpointState.startedAt, rewoundAt };
		this.sessionManager.appendCustomMessageEntry(
			"rewind-report",
			prompt.render(rewindReportTemplate, { report }),
			false,
			details,
			"agent",
		);
		// Rewind cuts the exploration branch, but sibling calls in this tool batch
		// have already run. Reparent their calls and results together so the next
		// provider turn (and a resumed session) can see their completed work.
		if (turn?.message.role === "assistant") {
			const siblingResults = turn.toolResults.filter(
				result => semanticToolResult(result.toolName, result)?.toolName !== "rewind",
			);
			if (siblingResults.length > 0) {
				const siblingIds = new Set(siblingResults.map(result => result.toolCallId));
				const calls = turn.message.content.filter(
					(block): block is ToolCall => block.type === "toolCall" && siblingIds.has(block.id),
				);
				if (calls.length > 0) {
					const callIds = new Set(calls.map(call => call.id));
					this.sessionManager.appendMessage(
						sanitizeAssistantForReparentedHistory({ ...turn.message, content: calls }),
					);
					for (const result of siblingResults) {
						if (callIds.has(result.toolCallId)) this.sessionManager.appendMessage(result);
					}
				}
			}
		}
		this.#lastCompletedRewind = { report, startedAt: checkpointState.startedAt, rewoundAt };

		if (activeMessages) {
			for (const message of activeMessages) {
				if (message.role === "toolResult" && semanticToolResult(message.toolName, message)?.toolName === "rewind") {
					this.#rewoundToolResultIds.add(message.toolCallId);
				}
			}
		}
		const sessionContext = this.buildDisplaySessionContext();
		if (activeMessages) {
			activeMessages.splice(0, activeMessages.length, ...sessionContext.messages);
		}
		this.agent.replaceMessages(activeMessages ?? sessionContext.messages);
		this.#advisors.resetSessionState({ preserveCost: true });
		this.#todo.syncFromBranch();
		this.#modelMentions.syncFromBranch();
		this.#closeCodexProviderSessionsForHistoryRewrite();
		this.#checkpointState = undefined;
		this.#pendingRewindReport = undefined;
	}
	/** Plan-mode decision affordances: `ask`, or plan approval via `write xd://propose`. */
	#isPlanDecisionTool(toolCall: { name: string; arguments?: Record<string, unknown> }): boolean {
		return toolCall.name === "ask" || isProposeToolCall(toolCall);
	}

	async #enforcePlanModeDecisionAtSettle(): Promise<boolean> {
		if (!this.#planModeState?.enabled) {
			return false;
		}
		const assistantMessage = this.#findLastAssistantMessage();
		if (!assistantMessage) {
			return false;
		}
		if (assistantMessage.stopReason === "error" || assistantMessage.stopReason === "aborted") {
			return false;
		}

		const calledDecisionTool = assistantMessage.content.some(
			content => content.type === "toolCall" && this.#isPlanDecisionTool(content),
		);
		if (calledDecisionTool) {
			this.#planModeReminderCount = 0;
			this.#planModeReminderAwaitingProgress = false;
			return false;
		}

		const hasToolCall = assistantMessage.content.some(content => content.type === "toolCall");
		if (hasToolCall) {
			return false;
		}
		if (this.#planModeReminderAwaitingProgress) {
			return false;
		}
		if (this.#planModeReminderCount >= PLAN_MODE_REMINDER_MAX) {
			logger.debug("Plan mode convergence: reminder cap reached; yielding to user");
			return false;
		}
		const hasRequiredTools = this.#tools.registry.has("ask") && this.#tools.registry.has("write");
		if (!hasRequiredTools) {
			logger.warn("Plan mode enforcement skipped because ask/write tools are unavailable", {
				activeToolNames: this.agent.state.tools.map(tool => tool.name),
			});
			return false;
		}

		this.#planModeReminderCount++;
		this.#planModeReminderAwaitingProgress = true;
		this.#toolChoiceQueue.pushOnce("required", { label: "plan-mode-decision" });
		const reminder = prompt.render(planModeToolDecisionReminderPrompt, {
			askToolName: "ask",
		});
		const reminderMessage: Message = {
			role: "developer",
			content: [{ type: "text", text: reminder }],
			attribution: "agent",
			timestamp: Date.now(),
		};

		this.agent.appendMessage(reminderMessage);
		this.sessionManager.appendMessage(reminderMessage);
		this.#scheduleAgentContinue({
			source: "plan-mode-reminder",
			generation: this.#promptGeneration,
			// If the continuation never runs (new prompt, dispose, compaction,
			// handoff), the forced choice must not leak onto an unrelated turn.
			onSkip: () => this.#toolChoiceQueue.removeByLabel("plan-mode-decision"),
		});
		return true;
	}

	/**
	 * Rebuild the model catalog after an `extendedContext` toggle and rebind the
	 * active model when its effective context window changed. Same-model rebinds
	 * skip provider-session resets (`modelsAreEqual` sees no change), so this
	 * only refreshes metadata consumers (compaction thresholds, context display).
	 */
	async #reapplyExtendedContextPolicy(): Promise<void> {
		try {
			await this.#modelRegistry.reapplyModelPolicies();
			const currentModel = this.model;
			if (!currentModel || this.#isDisposed) return;
			const updated = this.#modelRegistry.find(currentModel.provider, currentModel.id);
			if (updated && updated.contextWindow !== currentModel.contextWindow) {
				await this.#setModelWithProviderSessionReset(updated);
			}
		} catch (error) {
			logger.warn("extended-context policy reapply failed", { error: String(error) });
		}
	}

	async #setModelWithProviderSessionReset(model: Model): Promise<void> {
		const currentModel = this.model;
		const isChanging = !currentModel || !modelsAreEqual(currentModel, model);
		if (currentModel) {
			this.#closeProviderSessionsForModelSwitch(currentModel, model);
			if (isChanging) {
				this.#clearInheritedProviderPromptCacheKey();
			}
		}
		this.agent.setModel(model);
		// Model mutations driven through ModelControls (explicit /model, prewalk
		// hand-offs, retry-fallback, model cycling) funnel through this method,
		// so this is the single point that notifies subscribers (ACP config
		// sync, RPC, TUI status line) — callers that bypass ModelControls never
		// need to remember to notify separately. `switchSession`'s rollback
		// restores via `agent.setModel` directly and emits its own corrective
		// event.
		//
		// Fan-out uses the synchronous `#emit`, matching `thinking_level_changed`:
		// `model_changed` has no extension-facing hook (`#emitExtensionEvent`
		// never maps it), so routing it through `#emitSessionEvent` would only
		// add an extension-delivery await inside every model switch — including
		// retry-fallback on the error path.
		if (isChanging) {
			this.#emit({ type: "model_changed" });
		}

		await this.#reconcileModelDependentState(currentModel, model);
	}

	async #reconcileModelDependentState(previousModel: Model | undefined, model: Model): Promise<void> {
		// Re-evaluate append-only context mode — provider or setting may have changed
		this.#syncAppendOnlyContext(model);

		if (this.#tools.codeModeChangesBetween(previousModel, model) || this.#tools.codeModeDirectWireMetadataChanged()) {
			try {
				await this.#tools.reconcileCodeMode();
			} catch (error) {
				logger.warn("Code Mode reconcile after model change failed", { error: String(error) });
			}
		}

		try {
			await this.#tools.reconcileThinkTool();
		} catch (error) {
			logger.warn("think tool reconcile after model change failed", { error: String(error) });
		}
	}

	#closeCodexProviderSessionsForHistoryRewrite(): void {
		const currentModel = this.model;
		if (currentModel?.api !== "openai-codex-responses") return;
		this.#closeProviderSessionsForModelSwitch(currentModel, currentModel);
	}

	#resetCodexProviderAfterCompaction(compaction: CodexCompactionContext): void {
		resetOpenAICodexHistoryAfterCompaction({
			providerSessionState: this.#providerSessionState,
			sessionId: this.sessionId,
			compaction,
		});
	}

	#resetCurrentResponsesProviderSession(reason: string): void {
		const currentModel = this.model;
		if (currentModel?.api !== "openai-responses" && currentModel?.api !== "openai-codex-responses") {
			return;
		}

		this.#closeProviderSessionsForModelSwitch(currentModel, currentModel);
		this.agent.appendOnlyContext?.invalidateForModelChange();
		logger.debug("Reset Responses provider session after stale replay error", {
			provider: currentModel.provider,
			model: currentModel.id,
			api: currentModel.api,
			reason,
		});
	}

	/**
	 * Re-evaluate append-only context mode, creating or destroying the
	 * manager as needed. Called on model switch AND setting change.
	 */
	#syncAppendOnlyContext(model: Model | null | undefined): void {
		const setting = cfgProviderAppendOnlyContext.get(this.settings);
		const enable = shouldEnableAppendOnlyContext(setting, model);
		const providerId = model?.provider;
		const prev = this.#lastAppendOnlyResolution;
		if (prev && prev.enable === enable && prev.providerId === providerId) return;
		this.#lastAppendOnlyResolution = { enable, providerId };

		if (enable && !this.agent.appendOnlyContext) {
			this.agent.setAppendOnlyContext(new AppendOnlyContextManager());
		} else if (enable && this.agent.appendOnlyContext) {
			// Already active — invalidate prefix + log so the next turn
			// rebuilds for the current model's normalization.
			this.agent.appendOnlyContext.invalidateForModelChange();
		} else if (!enable && this.agent.appendOnlyContext) {
			this.agent.setAppendOnlyContext(undefined);
		}
	}

	#closeProviderSessionsForModelSwitch(currentModel: Model, nextModel: Model): void {
		const providerKeys = new Set<string>();
		if (currentModel.api === "openai-codex-responses" || nextModel.api === "openai-codex-responses") {
			providerKeys.add("openai-codex-responses");
		}
		if (currentModel.api === "openai-responses") {
			providerKeys.add(`openai-responses:${currentModel.provider}`);
		}
		if (nextModel.api === "openai-responses") {
			providerKeys.add(`openai-responses:${nextModel.provider}`);
		}

		// `openai-completions` sessions are keyed `openai-completions:<provider>:<resolvedBaseUrl>:<modelId>`
		// and cache backend-specific decisions (strict-tools disable scopes, reasoning-effort
		// fallbacks). The resolved request base URL can differ from the catalog `model.baseUrl`
		// (Moonshot env override, Alibaba Coding Plan enterprise URL, Azure deployment URL),
		// so evict by provider prefix when the user moves away from that completions backend.
		let completionsPrefixToEvict: string | undefined;
		if (currentModel.api === "openai-completions") {
			const currentScope = `${currentModel.provider}:${currentModel.baseUrl ?? ""}`;
			const nextScope =
				nextModel.api === "openai-completions" ? `${nextModel.provider}:${nextModel.baseUrl ?? ""}` : undefined;
			if (currentScope !== nextScope) {
				completionsPrefixToEvict = `openai-completions:${currentModel.provider}:`;
			}
		}

		for (const providerKey of providerKeys) {
			const state = this.#providerSessionState.get(providerKey);
			if (!state) continue;

			try {
				state.close();
			} catch (error) {
				logger.warn("Failed to close provider session state during model switch", {
					providerKey,
					error: String(error),
				});
			}

			this.#providerSessionState.delete(providerKey);
		}

		if (completionsPrefixToEvict !== undefined) {
			for (const [key, state] of this.#providerSessionState) {
				if (!key.startsWith(completionsPrefixToEvict)) continue;
				try {
					state.close();
				} catch (error) {
					logger.warn("Failed to close provider session state during model switch", {
						providerKey: key,
						error: String(error),
					});
				}
				this.#providerSessionState.delete(key);
			}
		}
	}

	// =========================================================================
	// Auto-Retry
	// =========================================================================

	/** Cancel an in-progress retry. */
	abortRetry(): void {
		this.#recovery.abortRetry();
	}

	/** Whether auto-retry is currently in progress. */
	get isRetrying(): boolean {
		return this.#recovery.isRetrying;
	}

	/** Whether auto-retry is enabled. */
	get autoRetryEnabled(): boolean {
		return this.#recovery.autoRetryEnabled;
	}

	/** Toggle the auto-retry setting. `persist` saves it to global config; the default applies a session-scoped override. */
	setAutoRetryEnabled(enabled: boolean, persist = false): void {
		this.#recovery.setAutoRetryEnabled(enabled, persist);
	}

	/** Whether the last turn ended aborted/failed on a tool call, so {@link retry} would re-attempt it. */
	get hasAbortedToolCallTail(): boolean {
		return this.#recovery.hasAbortedToolCallTail;
	}

	/** Retry the last failed assistant turn when the session is idle. */
	retry(): Promise<boolean> {
		return this.#recovery.retry();
	}

	// =========================================================================
	// Bash Execution
	// =========================================================================

	/**
	 * Execute a bash command and retain the session/branch that owned its start.
	 * @param command The bash command to execute
	 * @param onChunk Optional streaming callback for output
	 * @param options.excludeFromContext If true, command output won't be sent to LLM (!! prefix)
	 * @param options.useUserShell If true, allow caller to request configured user-shell routing
	 */
	executeBash(
		command: string,
		onChunk?: (chunk: string) => void,
		options?: { excludeFromContext?: boolean; useUserShell?: boolean; pty?: BashPtyOptions },
	): Promise<BashResult> {
		return this.#bash.executeBash(command, onChunk, options);
	}

	/** Record a bash result supplied outside executeBash in the current ownership scope. */
	recordBashResult(command: string, result: BashResult, options?: { excludeFromContext?: boolean }): void {
		this.#bash.recordBashResult(command, result, options);
	}

	/** Cancel running bash commands. */
	abortBash(): void {
		this.#bash.abort();
	}

	/** Whether a bash command is currently running */
	get isBashRunning(): boolean {
		return this.#bash.isRunning;
	}

	/** Whether there are pending bash messages waiting to be flushed */
	get hasPendingBashMessages(): boolean {
		return this.#bash.hasPendingMessages;
	}

	// =========================================================================
	// User-Initiated Python Execution
	// =========================================================================

	/**
	 * Execute Python code in the shared kernel.
	 * Uses the same kernel session as eval's Python backend, allowing collaborative editing.
	 * @param code The Python code to execute
	 * @param onChunk Optional streaming callback for output
	 * @param options.excludeFromContext If true, execution won't be sent to LLM ($$ prefix)
	 */
	executePython(
		code: string,
		onChunk?: (chunk: string) => void,
		options?: { excludeFromContext?: boolean },
	): Promise<PythonResult> {
		return this.#eval.executePython(code, onChunk, options);
	}

	assertEvalExecutionAllowed(): void {
		this.#eval.assertExecutionAllowed();
	}

	/**
	 * Track Python work started outside AgentSession.executePython so dispose can await and abort it too.
	 */
	trackEvalExecution<T>(execution: Promise<T>, abortController: AbortController): Promise<T> {
		return this.#eval.trackExecution(execution, abortController);
	}

	/**
	 * Record a Python execution result in session history.
	 */
	recordPythonResult(code: string, result: PythonResult, options?: { excludeFromContext?: boolean }): void {
		this.#eval.recordPythonResult(code, result, options);
	}

	/**
	 * Cancel running Python execution.
	 */
	abortEval(): void {
		this.#eval.abort();
	}

	/** Whether a Python execution is currently running */
	get isEvalRunning(): boolean {
		return this.#eval.isRunning;
	}

	/** Whether there are pending Python messages waiting to be flushed */
	get hasPendingPythonMessages(): boolean {
		return this.#eval.hasPendingMessages;
	}

	/**
	 * Flush pending Python messages to agent state and session.
	 */

	// =========================================================================
	// IRC Delivery
	// =========================================================================

	/** Surfaces and consumes pending IRC records before automatic injection. */
	drainPendingIrcInboxMessages(agentId: string, opts?: { from?: string; limit?: number }): IrcMessage[] {
		return this.#irc.drainInboxMessages(agentId, opts);
	}

	/** Delivers an IRC message into this recipient session. */
	deliverIrcMessage(msg: IrcMessage): Promise<"injected" | "woken"> {
		if (this.#childTaskRecovery) this.#revokeTaskRecovery("IRC input conflicts with bound task recovery");
		return this.#irc.deliver(msg);
	}

	/** Waits for any in-flight IRC wake-turn relays. */
	waitForIrcReplies(): Promise<void> {
		return this.#irc.waitForReplies();
	}

	/** Registers an in-flight IRC wake-turn relay. */
	trackIrcReply(pending: Promise<void>): void {
		this.#irc.trackReply(pending);
	}

	/** Installs task-executor monitoring around autonomous IRC wake turns. */
	setIrcWakeTurnObserver(
		observer: ((records: AgentMessage[]) => ((error?: unknown) => void | Promise<void>) | undefined) | undefined,
	): void {
		this.#ircWakeTurnObserver = observer;
	}

	/** Emits an IRC relay observation for UI rendering without persisting it. */
	emitIrcRelayObservation(record: CustomMessage): void {
		this.#irc.emitRelayObservation(record);
	}

	/**
	 * Run a single ephemeral side-channel turn against this session's current
	 * model + system prompt + history. The main turn's tool catalog is sent
	 * to preserve the prompt cache unless `tools: false` is requested. The
	 * model is reminded not to call tools and any tool calls are discarded. The side request
	 * does not block on, or interfere with, any in-flight main turn. The
	 * session's history and persisted state are NOT modified by this call.
	 *
	 * Used by `BtwController` (`/btw`) and `OmfgController` (`/omfg`) to share
	 * the snapshot + stream pipeline. The snapshot includes any in-flight
	 * streaming assistant text so the model sees the half-finished response
	 * rather than missing context.
	 */
	async runEphemeralTurn(args: EphemeralTurnOptions): Promise<EphemeralTurnResult> {
		if (this.#childTaskRecovery) this.#revokeTaskRecovery("Foreign side-channel turn conflicts with task recovery");
		const model = this.model;
		if (!model) {
			throw new Error("No active model on session");
		}
		const modelDescription = `${model.provider}/${model.id} (${model.api})`;
		const sessionGeneration = this.#sessionGeneration;
		const assertEphemeralTurnReady = () => {
			args.signal?.throwIfAborted();
			// The side request must use the exact model snapshot captured above.
			// `modelsAreEqual` intentionally compares only provider/id, while a
			// replacement with that same identity can still change routing and wire
			// behavior (baseUrl, requestModelId, compatibility settings, etc.).
			if (this.model !== model) throw new Error("Active model changed during ephemeral turn; retry.");
			if (this.#sessionGeneration !== sessionGeneration) {
				throw new Error("Active session changed during ephemeral turn; retry.");
			}
		};
		for (const field of ["maxTokens", "maxContextBytes"] as const) {
			const cap = args[field];
			if (cap !== undefined && (!Number.isSafeInteger(cap) || cap <= 0)) {
				throw new Error(`${field} must be a positive safe integer.`);
			}
		}
		const cappedBudgetThinking =
			args.maxTokens !== undefined &&
			(model.thinking?.mode === "budget" || model.thinking?.mode === "anthropic-budget-effort");
		if (cappedBudgetThinking && model.thinking?.requiresEffort && !model.thinking.suppressWhenOff) {
			throw new Error(
				`Model ${modelDescription} requires budget thinking and cannot preserve maxTokens for ephemeral turns. Omit the cap or use a model that supports output limits.`,
			);
		}
		if (args.tools === false && requiresNativeTools(model)) {
			throw new Error(
				`Model ${modelDescription} does not support tools: false for ephemeral turns because its transport requires native tools.`,
			);
		}
		// Do not silently start an unbounded request when discovery or transport
		// policy says the output limit will be omitted or overwritten.
		if (args.maxTokens !== undefined && !supportsOutputTokenLimit(model)) {
			throw new Error(
				`Model ${modelDescription} does not support maxTokens for ephemeral turns. Omit the cap or use a model that supports output limits.`,
			);
		}
		assertEphemeralTurnReady();
		const cacheSessionId = this.sessionId;
		const snapshot = this.#buildEphemeralSnapshot(args.promptText, args.history);
		const llmMessages = await this.convertMessagesToLlm(snapshot, args.signal);
		assertEphemeralTurnReady();
		const sideContext = await this.agent.buildSideRequestContext(llmMessages);
		const toolHistory = sideContext.messages.some(
			message =>
				message.role === "toolResult" ||
				(message.role === "assistant" &&
					Array.isArray(message.content) &&
					message.content.some(block => block.type === "toolCall")),
		);
		if (args.tools === false && requiresToolFreeHistoryForToolOptOut(model) && toolHistory) {
			throw new Error(
				`Model ${modelDescription} cannot support tools: false with historical tool calls. Omit tools: false or start from tool-free history.`,
			);
		}
		// Apply after context transforms, without mutating a potentially shared context.
		const context = obfuscateProviderContext(
			this.#obfuscator,
			args.tools === false ? { ...sideContext, tools: [] } : sideContext,
		);
		if (
			args.maxContextBytes !== undefined &&
			Buffer.byteLength(JSON.stringify(context), "utf8") > args.maxContextBytes
		) {
			throw new Error(`Ephemeral turn context exceeds the configured ${args.maxContextBytes}-byte limit.`);
		}
		// `AssistantMessageEventStream` has no iterator-return cancellation hook, so
		// throwing out of the consumer loop below (a rejected `onTextDelta` delivery,
		// an `error` event) would leave the transport streaming: still burning
		// inference and queueing output nobody reads. Abort the request ourselves when
		// we stop consuming it, without touching the caller's signal.
		const streamAbort = new AbortController();
		const options = this.prepareSimpleStreamOptions(
			{
				apiKey: this.#modelRegistry.resolver(model, cacheSessionId),
				// Side-channel turns must not share OpenAI/Codex append-only
				// conversation state with the main agent turn: IRC and /btw can run
				// while the main turn is mid-tool-call. Keep the prompt-cache key
				// stable, but isolate provider routing from the main conversation.
				// Serialized BTW follow-ups reuse a topic-specific lineage; standalone
				// side requests retain their unique request lineage.
				sessionId: args.conversationKey
					? `${cacheSessionId}:side:conversation:${args.conversationKey}`
					: `${cacheSessionId}:side:${Snowflake.next()}`,
				promptCacheKey: this.agent.promptCacheKey ?? this.agent.sessionId,
				preferWebsockets: this.preferWebsockets,
				providerSessionState: this.#providerSessionState,
				reasoning: toReasoningEffort(this.thinkingLevel),
				// Budget-thinking transports can raise explicit caps to make room for their
				// default thinking budget. A side turn's cap is a hard resource boundary.
				disableReasoning: shouldDisableReasoning(this.thinkingLevel) || cappedBudgetThinking,
				hideThinkingSummary: this.agent.hideThinkingSummary,
				serviceTier: this.#models.effectiveServiceTier(model),
				maxTokens: args.maxTokens,
				signal: args.signal ? AbortSignal.any([args.signal, streamAbort.signal]) : streamAbort.signal,
			},
			model.provider,
		);

		if (args.tools === false) options.toolChoice = "none";

		let providerReplyText = "";
		let emittedReplyText = "";
		let assistantMessage: AssistantMessage | undefined;
		assertEphemeralTurnReady();
		const stream = await this.#sideStreamFn(model, context, options);
		try {
			for await (const event of stream) {
				if (event.type === "text_delta") {
					providerReplyText += event.delta;
					if (args.onTextDelta) {
						const readyText = this.#deobfuscatedProviderTextReadyForDelta(providerReplyText);
						if (readyText.length > emittedReplyText.length) {
							const delta = readyText.slice(emittedReplyText.length);
							emittedReplyText = readyText;
							await args.onTextDelta(delta);
						}
					}
					continue;
				}
				if (event.type === "done") {
					// A well-formed provider "done" event carries `content: AssistantContentBlock[]`,
					// but a proxy/wrapper (custom extension providers, gateway-wrapped OAuth streams,
					// see #4323) can hand back a message whose `content` was dropped or replaced with
					// `undefined`. Downstream `.content.filter` at the sanitize step below would then
					// crash the recap turn with `TypeError: undefined is not an object (evaluating
					// 'H.content.filter')`. Normalize to `[]` so the recap surfaces an empty reply
					// instead of turning a malformed side-channel response into a session-mute crash.
					const rawContent = Array.isArray(event.message.content) ? event.message.content : [];
					assistantMessage = this.#obfuscator?.hasSecrets()
						? { ...event.message, content: deobfuscateAssistantContent(this.#obfuscator, rawContent) }
						: { ...event.message, content: rawContent };
					break;
				}
				if (event.type === "error") {
					throw new Error(event.error.errorMessage || "Ephemeral turn failed");
				}
			}
		} catch (error) {
			streamAbort.abort();
			throw error;
		}

		if (!assistantMessage) {
			throw new Error("Ephemeral turn ended without a final message");
		}
		const replyText = this.#deobfuscateFromProvider(providerReplyText);
		if (args.onTextDelta && replyText.length > emittedReplyText.length) {
			await args.onTextDelta(replyText.slice(emittedReplyText.length));
		}
		const sanitizedMessage: AssistantMessage = {
			...assistantMessage,
			content: assistantMessage.content.filter(block => block.type !== "toolCall"),
		};
		return {
			replyText: args.dedupeReply === false ? replyText.trim() : dedupeEphemeralReply(replyText.trim()),
			assistantMessage: sanitizedMessage,
		};
	}

	/**
	 * Build a message snapshot for an ephemeral side-channel turn.  Includes
	 * the in-flight streaming assistant message (if any) so the model sees
	 * the partial response in context, then appends detached side-channel history
	 * and the current prompt after the no-tools reminder.
	 */
	#buildEphemeralSnapshot(promptText: string, history?: readonly Message[]): AgentMessage[] {
		const messages = [...this.messages];
		const streaming = this.agent.state.streamMessage;
		if (streaming && streaming.role === "assistant" && Array.isArray(streaming.content)) {
			const preservedBlocks: AssistantMessage["content"] = [];
			// Preserve thinking blocks: DeepSeek-class encoders replay them as
			// `reasoning_content` and reject the request (HTTP 400) when the field
			// goes missing on a turn that previously emitted thinking.
			for (const c of streaming.content) {
				if (c.type === "thinking") preservedBlocks.push(c);
			}
			const streamingText = streaming.content
				.filter((c): c is TextContent => c.type === "text")
				.map(c => c.text)
				.join("");
			if (streamingText) {
				preservedBlocks.push({ type: "text", text: streamingText });
			}
			if (preservedBlocks.length > 0) {
				const normalized: AssistantMessage = {
					...streaming,
					content: preservedBlocks,
				};
				const lastMessage = messages.at(-1);
				if (lastMessage?.role === "assistant") {
					messages[messages.length - 1] = normalized;
				} else {
					messages.push(normalized);
				}
			}
		}
		messages.push({
			role: "developer",
			content: [{ type: "text", text: sideChannelNoToolsReminder }],
			attribution: "agent",
			timestamp: Date.now(),
		});
		if (history?.length) {
			// Detach before the conversion pipeline can await or mutate caller-owned messages.
			messages.push(...structuredClone(history));
		}
		messages.push({
			role: "user",
			content: [{ type: "text", text: promptText }],
			attribution: "agent",
			timestamp: Date.now(),
		});
		return messages;
	}

	// =========================================================================
	// Session Management
	// =========================================================================

	/**
	 * Reload the current session from disk.
	 *
	 * Intended for extension commands and headless modes to re-read the current session
	 * file and re-emit session_switch hooks.
	 */
	async reload(): Promise<void> {
		const sessionFile = this.sessionFile;
		if (!sessionFile) return;
		const switched = await this.switchSession(sessionFile);
		if (!switched) throw new Error("Session reload cancelled");
	}
	/**
	 * Switch to a different session file.
	 * Aborts current operation, loads messages, restores model/thinking.
	 * Listeners are preserved and will continue receiving events.
	 * @returns true if switch completed, false if cancelled by hook or cwd change
	 */
	async switchSession(
		sessionPath: string,
		options?: {
			onCwdChange?: (newCwd: string, previousCwd: string) => Promise<boolean>;
			/** Collab snapshot adoption keeps the guest's process cwd and marks the replica runtime-only. */
			preserveLocalCwd?: boolean;
		},
	): Promise<boolean> {
		this.#assertTaskRecoveryInput();
		using _transition = this.#beginSessionTransition();
		const previousSessionFile = this.sessionManager.getSessionFile();
		const switchingToDifferentSession = previousSessionFile
			? path.resolve(previousSessionFile) !== path.resolve(sessionPath)
			: true;
		// Emit session_before_switch event (can be cancelled)
		if (this.#extensionRunner?.hasHandlers("session_before_switch")) {
			const result = (await this.#extensionRunner.emit({
				type: "session_before_switch",
				reason: "resume",
				targetSessionFile: sessionPath,
			})) as SessionBeforeSwitchResult | undefined;

			if (result?.cancel) {
				return false;
			}
		}

		this.#disconnectFromAgent();
		await this.abort({ goalReason: "internal" });
		await this.#sessionBeforeSwitchReconciler?.();

		await this.#bash.flushPending();
		// Flush pending writes before switching so restore snapshots reflect committed state.
		await this.sessionManager.flush();
		const previousSessionState = this.sessionManager.captureState();
		const bashTransition = this.#bash.beginSessionTransition();
		// Only same-session reloads compare against the prior context to detect
		// rollback edits (`#didSessionMessagesChange` below). Building it for a
		// different-session switch is a pure waste — and on huge pre-fix sessions
		// it materializes every persisted snapcompact frame plus the
		// `openaiRemoteCompaction.replacementHistory` payload into messages,
		// blowing the heap before the new session even loads (issue #3846). The
		// error-recovery path rebuilds the context on demand from the restored
		// state instead.
		const previousSessionContext = switchingToDifferentSession ? undefined : this.buildDisplaySessionContext();
		// switchSession replaces these arrays wholesale during load/rollback, so retaining
		// the existing message objects is sufficient and avoids structured-clone failures for
		// extension/custom metadata that is valid to persist but not cloneable.
		const previousAgentMessages = [...this.agent.state.messages];
		const previousSteeringMessages = [...this.agent.peekSteeringQueue()];
		const previousFollowUpMessages = [...this.agent.peekFollowUpQueue()];
		const previousPendingNextTurnMessages = [...this.#pendingNextTurnMessages];
		const previousScheduledHiddenNextTurnGeneration = this.#scheduledHiddenNextTurnGeneration;
		const previousQueuedMessageDrainBlocked = this.#queuedMessageDrainBlocked;
		const previousUsagePreflightReadyForNextModelCall = this.#usagePreflightReadyForNextModelCall;
		const previousUsagePreflightReadyModel = this.#usagePreflightReadyModel;
		const previousModel = this.model;
		const previousThinkingLevel = this.thinkingLevel;
		const previousAutoThinking = this.isAutoThinking;
		const previousAutoResolvedLevel = this.autoResolvedThinkingLevel();
		const previousServiceTierByFamily = this.serviceTierByFamily;
		const previousTools = [...this.agent.state.tools];
		const previousBaseSystemPrompt = this.#tools.baseSystemPrompt;
		const previousSystemPrompt = this.agent.state.systemPrompt;
		const previousBaseSystemPromptBeforeMemoryPromotion = this.#memory.promotionSnapshot;
		const previousFreshProviderSessionId = this.#freshProviderSessionId;
		const previousInheritedProviderPromptCacheKey = this.#inheritedProviderPromptCacheKey;

		// Snapshot the full checkpoint runtime state: the success path calls
		// #rehydrateCheckpointRewindState(), which clears and rebuilds all four
		// fields from the target branch. On rollback every one must be restored,
		// or a failed switch leaks the target session's checkpoint state.
		const previousCheckpointState = this.#checkpointState;
		const previousPendingRewindReport = this.#pendingRewindReport;
		const previousLastCompletedRewind = this.#lastCompletedRewind;
		const previousRewoundToolResultIds = new Set(this.#rewoundToolResultIds);

		this.agent.clearAllQueues();
		// Same rationale as newSession: an aborted turn can skip its final aside poll,
		// stranding IRC/extension asides meant for the outgoing transcript. Snapshot so a
		// rolled-back switch (catch block below) restores them for the still-live session.
		// #sessionGeneration bumps in the same breath (and rolls back with it) so an
		// aside-queueing call still awaiting normalization when the switch started drops its
		// record on success but stays valid if the switch is rolled back to this same session.
		const previousIrcPending = this.#irc.clearPending();
		const previousSessionGeneration = this.#sessionGeneration++;
		const generationSettled = Promise.withResolvers<void>();
		const previousSessionGenerationSettled = this.#sessionGenerationSettled;
		this.#sessionGenerationSettled = generationSettled.promise;
		this.#pendingNextTurnMessages = [];
		this.#scheduledHiddenNextTurnGeneration = undefined;
		this.#queuedMessageDrainBlocked = false;
		this.#usagePreflightReadyForNextModelCall = false;
		this.#usagePreflightReadyModel = undefined;

		let cwdChangeTarget: string | undefined;
		try {
			if (switchingToDifferentSession) {
				// Stop and settle in-flight advisors while the old-session feeds can
				// still observe message_end, then mute before swapping files.
				await this.#advisors.drainAndDetachRecorders();
			}
			await this.sessionManager.setSessionFile(sessionPath);
			this.#bash.markSessionTransition(bashTransition);
			const newCwd = this.sessionManager.getCwd();
			const recordedCwd = this.sessionManager.getRecordedCwd() ?? previousSessionState.cwd;
			if (options?.preserveLocalCwd) {
				this.sessionManager.setCwdWithoutRelocation(previousSessionState.cwd);
			} else {
				if (!options?.onCwdChange && path.resolve(recordedCwd) !== path.resolve(previousSessionState.cwd)) {
					throw SESSION_CWD_CHANGE_REJECTED;
				}
				if (options?.onCwdChange) {
					if (path.resolve(newCwd) !== path.resolve(previousSessionState.cwd)) {
						cwdChangeTarget = newCwd;
						if (!(await options.onCwdChange(newCwd, previousSessionState.cwd))) {
							throw SESSION_CWD_CHANGE_REJECTED;
						}
					} else if (path.resolve(recordedCwd) !== path.resolve(previousSessionState.cwd)) {
						throw SESSION_CWD_CHANGE_REJECTED;
					}
				}
			}
			if (switchingToDifferentSession) {
				this.#freshProviderSessionId = undefined;
				this.#clearInheritedProviderPromptCacheKey();
				this.#adoptInheritedProviderPromptCacheKey();
			}
			this.#syncAgentSessionId(undefined, false);
			this.#memory.rekeyForCurrentSessionId();

			let sessionContext = this.buildDisplaySessionContext();
			const didReloadConversationChange =
				previousSessionContext !== undefined &&
				didSessionMessagesChange(previousSessionContext.messages, sessionContext.messages);
			this.#rehydrateCheckpointRewindState();

			// Emit session_switch event to hooks
			if (this.#extensionRunner) {
				await this.#extensionRunner.emit({
					type: "session_switch",
					reason: "resume",
					previousSessionFile,
				});
			}

			this.agent.replaceMessages(sessionContext.messages);
			this.#reseedTokenRate();
			this.#advisors.resetSessionState({ preserveCost: true });
			this.#todo.syncFromBranch();
			this.#modelMentions.syncFromBranch();
			if (switchingToDifferentSession) {
				this.#closeAllProviderSessions("session switch");
			} else if (didReloadConversationChange) {
				this.#closeAllProviderSessions("session reload");
			}

			// Restore model if saved
			const targetModelStrings = getRestorableSessionModels(
				sessionContext.models,
				this.sessionManager.getLastModelChangeRole(),
			);
			if (targetModelStrings.length > 0) {
				const availableModels = this.#modelRegistry.getAvailable();
				let match: Model | undefined;
				for (const targetModelStr of targetModelStrings) {
					const slashIdx = targetModelStr.indexOf("/");
					if (slashIdx <= 0) continue;
					const provider = targetModelStr.slice(0, slashIdx);
					const modelId = targetModelStr.slice(slashIdx + 1);
					match = availableModels.find(m => m.provider === provider && m.id === modelId);
					if (match) break;
				}
				if (match) {
					const currentModel = this.model;
					const shouldResetProviderState =
						switchingToDifferentSession ||
						(currentModel !== undefined &&
							(currentModel.provider !== match.provider ||
								currentModel.id !== match.id ||
								currentModel.api !== match.api));
					if (shouldResetProviderState) {
						await this.#setModelWithProviderSessionReset(match);
					} else {
						this.agent.setModel(match);
					}
				}
			}

			const model = this.model;
			if (model) {
				const interruptedTurnAbort = createInterruptedTurnAbortMessage(this.sessionManager.getBranch(), {
					api: model.api,
					provider: model.provider,
					model: model.id,
				});
				if (interruptedTurnAbort) {
					this.sessionManager.appendMessage(interruptedTurnAbort);
					sessionContext = this.buildDisplaySessionContext();
					this.agent.replaceMessages(sessionContext.messages);
				}
			}

			const hasThinkingEntry = this.sessionManager.getBranch().some(entry => entry.type === "thinking_level_change");
			const hasServiceTierEntry = this.sessionManager
				.getBranch()
				.some(entry => entry.type === "service_tier_change");
			const defaultThinkingLevel = parseConfiguredThinkingLevel(cfgDefaultThinkingLevel.get(this.settings));
			const configuredServiceTierByFamily = buildServiceTierByFamily(
				cfgTierOpenai.get(this.settings),
				cfgTierAnthropic.get(this.settings),
				cfgTierGoogle.get(this.settings),
			);
			// Restore the thinking selector. Each change persists the configured
			// selector (`auto` or a concrete level), so prefer it: an `auto` session
			// resumes in auto mode (reclassifying the next turn) instead of freezing at
			// the last resolved level. Entries written before the `configured` field
			// existed fall back to the concrete level (legacy pin-on-resume behavior).
			// With no thinking entry, fall back to the global default so fresh sessions
			// still classify their first turn.
			const restoredConfigured = sessionContext.configuredThinkingLevel;
			const restoredThinkingLevel: ConfiguredThinkingLevel | undefined =
				hasThinkingEntry || (defaultThinkingLevel === AUTO_THINKING && sessionContext.thinkingLevel !== "off")
					? restoredConfigured === AUTO_THINKING
						? AUTO_THINKING
						: (sessionContext.thinkingLevel as ThinkingLevel | undefined)
					: defaultThinkingLevel;
			this.#models.restoreThinkingLevel(restoredThinkingLevel);
			this.#models.restoreServiceTiers(
				hasServiceTierEntry ? (sessionContext.serviceTier ?? {}) : configuredServiceTierByFamily,
			);

			if (switchingToDifferentSession) {
				await this.#memory.resetContextForNewTranscript();
			}
			if (switchingToDifferentSession || didReloadConversationChange) {
				this.#clearSessionScopedToolState();
			}
			this.#reconnectToAgent();
			try {
				await this.#sessionSwitchReconciler?.();
			} catch (error) {
				logger.warn("Failed to reconcile session mode after switch", {
					targetSessionFile: sessionPath,
					error: String(error),
				});
			}
			// Refresh the workspace-roots block to match the resumed session's directory set.
			// Wrapped so a rebuild failure (e.g. a gate that intentionally fails in tests)
			// doesn't roll back an otherwise-successful session switch.
			try {
				await this.refreshBaseSystemPrompt();
			} catch (refreshErr) {
				logger.warn("Failed to refresh system prompt after session switch", {
					targetSessionFile: sessionPath,
					error: String(refreshErr),
				});
			}
			// Hand the ledger over to the session that just took over, and only once the
			// switch has committed: an earlier swap would be lost work if any step above
			// rolled it back. The target's own advisor transcripts are the record of what
			// it already spent, so a session with history resumes with its total instead
			// of restarting at zero.
			if (switchingToDifferentSession) {
				const providersBySlug = new Map<string, Set<string>>();
				const costs = await loadAdvisorTranscriptCosts(this.sessionFile, { providersBySlug });
				this.#advisors.restoreCost(costs, providersBySlug);
			}
			this.#bash.finishSessionTransition(bashTransition, true);
			// Keep the old reservations during rollback; the target is committed now,
			// so the snapshotted old queues can no longer be restored.
			this.#releaseTtsrReservations(previousSteeringMessages);
			this.#releaseTtsrReservations(previousFollowUpMessages);
			if (previousSessionState.sessionId !== this.sessionManager.getSessionId()) {
				this.#notifySessionChangeCallbacks();
			}
			generationSettled.resolve();
			this.#sessionGenerationSettled = previousSessionGenerationSettled;
			return true;
		} catch (error) {
			this.sessionManager.restoreState(previousSessionState);
			this.#freshProviderSessionId = previousFreshProviderSessionId;
			this.#syncAgentSessionId(previousSessionState.sessionId, false);
			this.#memory.rekeyForCurrentSessionId();
			this.agent.setTools(previousTools);
			this.#tools.setBaseSystemPrompt(previousBaseSystemPrompt);
			this.#memory.restorePromotionSnapshot(previousBaseSystemPromptBeforeMemoryPromotion);
			this.agent.setSystemPrompt(previousSystemPrompt);
			this.agent.replaceMessages(previousAgentMessages);
			this.agent.replaceQueues(previousSteeringMessages, previousFollowUpMessages);
			this.#irc.restorePending(previousIrcPending);
			this.#sessionGeneration = previousSessionGeneration;
			generationSettled.resolve();
			this.#sessionGenerationSettled = previousSessionGenerationSettled;
			this.#pendingNextTurnMessages = previousPendingNextTurnMessages;
			this.#scheduledHiddenNextTurnGeneration = previousScheduledHiddenNextTurnGeneration;
			this.#queuedMessageDrainBlocked = previousQueuedMessageDrainBlocked;
			this.#usagePreflightReadyForNextModelCall = previousUsagePreflightReadyForNextModelCall;
			this.#usagePreflightReadyModel = previousUsagePreflightReadyModel;
			this.#inheritedProviderPromptCacheKey = previousInheritedProviderPromptCacheKey;
			this.#checkpointState = previousCheckpointState;
			this.#pendingRewindReport = previousPendingRewindReport;
			this.#lastCompletedRewind = previousLastCompletedRewind;
			this.#rewoundToolResultIds = previousRewoundToolResultIds;
			// The try block may have already reached #setModelWithProviderSessionReset
			// for the target session's model, which emits `model_changed` for it.
			// Restoring here bypasses that method (it also resets provider-session
			// state we're already unwinding above), so if the rollback actually
			// changes the model back, emit the corrective event ourselves —
			// otherwise ACP/RPC/TUI keep advertising the never-committed target.
			// Deferred until after restoreThinkingSnapshot below: #emit's listeners
			// (ACP's #handleLifetimeEvent -> #pushConfigOptionUpdate) read
			// session state synchronously before their first await, so emitting
			// here — before the target session's thinking level is unwound —
			// would push a { previousModel, target-session-thinking } config that
			// was never a real session state.
			let modelRolledBack = false;
			if (previousModel) {
				const rolledBackModel = this.model;
				this.agent.setModel(previousModel);
				modelRolledBack = !modelsAreEqual(rolledBackModel, previousModel);
			}
			this.#models.restoreThinkingSnapshot(previousThinkingLevel, previousAutoThinking, previousAutoResolvedLevel);
			this.#models.restoreServiceTiers(previousServiceTierByFamily);
			if (modelRolledBack) {
				this.#emit({ type: "model_changed" });
			}
			this.#todo.syncFromBranch();
			this.#modelMentions.syncFromBranch();
			this.#advisors.resetAllRuntimes();
			this.#advisors.reattachRecorderFeeds();
			this.#reconnectToAgent();
			try {
				await this.#sessionSwitchReconciler?.();
			} catch (reconcileError) {
				logger.warn("Failed to reconcile session mode after switch rollback", {
					targetSessionFile: sessionPath,
					error: String(reconcileError),
				});
			}
			if (cwdChangeTarget && error !== SESSION_CWD_CHANGE_REJECTED && options?.onCwdChange) {
				let rollbackFailure: string | undefined;
				try {
					if (!(await options.onCwdChange(previousSessionState.cwd, cwdChangeTarget))) {
						rollbackFailure = "cwd rollback was rejected";
					}
				} catch (rollbackError) {
					rollbackFailure = `cwd rollback failed: ${rollbackError instanceof Error ? rollbackError.message : String(rollbackError)}`;
				}
				if (rollbackFailure) {
					this.beginDispose();
					this.#bash.finishSessionTransition(bashTransition, false);
					logger.warn("Failed to restore cwd after session switch", { cwd: previousSessionState.cwd });
					const original = error instanceof Error ? error.message : String(error);
					throw new Error(`${original} (${rollbackFailure}; the process may remain in ${cwdChangeTarget})`);
				}
			}
			this.#bash.finishSessionTransition(bashTransition, false);
			if (error === SESSION_CWD_CHANGE_REJECTED) return false;
			throw error;
		}
	}

	/**
	 * Create a branch from a specific entry.
	 * Emits before_branch/branch session events to hooks.
	 *
	 * @param entryId ID of the entry to branch from
	 * @returns Object with:
	 *   - selectedText: The text of the selected user message (for editor pre-fill)
	 *   - selectedImages: Image attachments of the selected user message (for editor draft restore)
	 *   - cancelled: True if a hook cancelled the branch
	 */
	async branch(entryId: string): Promise<{
		selectedText: string;
		selectedImages: ImageContent[];
		cancelled: boolean;
	}> {
		this.#assertTaskRecoveryInput();
		using _transition = this.#beginSessionTransition();
		const previousSessionFile = this.sessionFile;
		const selectedEntry = this.sessionManager.getEntry(entryId);

		if (selectedEntry?.type !== "message" || selectedEntry.message.role !== "user") {
			throw new Error("Invalid entry ID for branching");
		}

		const selectedText = this.#extractUserMessageText(selectedEntry.message.content);
		const selectedImages = this.#extractUserMessageImages(selectedEntry.message.content);

		let skipConversationRestore = false;

		// Emit session_before_branch event (can be cancelled)
		if (this.#extensionRunner?.hasHandlers("session_before_branch")) {
			const result = (await this.#extensionRunner.emit({
				type: "session_before_branch",
				entryId,
			})) as SessionBeforeBranchResult | undefined;

			if (result?.cancel) {
				return { selectedText, selectedImages, cancelled: true };
			}
			skipConversationRestore = result?.skipConversationRestore ?? false;
		}

		// Clear pending messages (bound to old session state)
		this.#pendingNextTurnMessages = [];
		this.#scheduledHiddenNextTurnGeneration = undefined;
		this.#queuedMessageDrainBlocked = false;
		this.#usagePreflightReadyForNextModelCall = false;

		await this.#bash.flushPending();
		// Flush pending writes before branching
		await this.sessionManager.flush();
		const bashTransition = this.#bash.beginSessionTransition();
		this.#cancelOwnAsyncJobs();
		this.#abortAutolearnCapture();
		await this.#drainAutolearnCapture();

		let sessionTransitioned = false;
		let advisorRecordersDetached = false;
		try {
			advisorRecordersDetached = true;
			await this.#advisors.drainAndDetachRecorders();
			try {
				// Pending prompt setup belongs to the history being replaced.
				this.#promptGeneration++;
				if (!selectedEntry.parentId) {
					const title = this.sessionManager.getSessionName();
					const titleSource = this.sessionManager.titleSource;
					await this.sessionManager.newSession({ parentSession: previousSessionFile });
					if (title) await this.sessionManager.setSessionName(title, titleSource);
				} else {
					this.sessionManager.createBranchedSession(selectedEntry.parentId);
				}
				this.#bash.markSessionTransition(bashTransition);
				this.#advisors.clearCost();
				sessionTransitioned = true;
			} finally {
				this.#bash.finishSessionTransition(bashTransition, sessionTransitioned);
			}
			this.#clearSessionScopedToolState();
			this.#rehydrateCheckpointRewindState();
			this.#todo.syncFromBranch();
			this.#modelMentions.syncFromBranch();
			this.#freshProviderSessionId = undefined;
			this.#clearInheritedProviderPromptCacheKey();
			this.#syncAgentSessionId();
			this.#memory.rekeyForCurrentSessionId();
			await this.#memory.resetContextForNewTranscript();

			// Reload messages from entries (works for both file and in-memory mode)
			const sessionContext = this.buildDisplaySessionContext();

			// Emit session_branch event to hooks (after branch completes)
			if (this.#extensionRunner) {
				await this.#extensionRunner.emit({
					type: "session_branch",
					previousSessionFile,
				});
			}

			if (!skipConversationRestore) {
				this.agent.replaceMessages(sessionContext.messages);
				this.#advisors.resetSessionState();
				this.#closeCodexProviderSessionsForHistoryRewrite();
			}

			this.#advisors.reattachRecorderFeeds();
			advisorRecordersDetached = false;
			await this.#reconcileModeAfterBranch();
			return { selectedText, selectedImages, cancelled: false };
		} finally {
			if (advisorRecordersDetached) {
				if (sessionTransitioned) this.#advisors.resetSessionState();
				else this.#advisors.reattachRecorderFeeds();
			}
		}
	}

	/** Promotes a completed /btw answer from the explicitly authorized session and leaf. */
	async branchFromBtw(
		question: string,
		assistantMessage: AssistantMessage,
		leafId: string,
		sessionId: string,
	): Promise<{ cancelled: boolean; sessionFile: string | undefined }> {
		using _transition = this.#beginSessionTransition();
		const previousSessionFile = this.sessionFile;
		if (!this.sessionManager.getSessionFile()) {
			throw new Error("Cannot branch /btw: session is not persisted");
		}

		if (!leafId || this.sessionManager.getSessionId() !== sessionId || this.sessionManager.getLeafId() !== leafId) {
			throw new Error("Cannot branch /btw: session changed since /btw started");
		}

		if (
			this.isStreaming ||
			this.isBashRunning ||
			this.isEvalRunning ||
			this.isCompacting ||
			this.isGeneratingHandoff ||
			this.isRetrying
		) {
			throw new Error("Cannot branch /btw while session maintenance or user work is still running");
		}

		if (this.#extensionRunner?.hasHandlers("session_before_branch")) {
			const result = (await this.#extensionRunner.emit({
				type: "session_before_branch",
				entryId: leafId,
			})) as SessionBeforeBranchResult | undefined;

			if (result?.cancel) {
				return { cancelled: true, sessionFile: previousSessionFile };
			}
		}

		if (this.sessionManager.getSessionId() !== sessionId || this.sessionManager.getLeafId() !== leafId) {
			throw new Error("Cannot branch /btw: session changed since /btw started");
		}

		await withTimeout(
			this.#cancelPostPromptTasks(),
			POST_PROMPT_DRAIN_TIMEOUT_MS,
			"Timed out draining post-prompt tasks before /btw branch",
		);
		if (
			this.isStreaming ||
			this.isBashRunning ||
			this.isEvalRunning ||
			this.isCompacting ||
			this.isGeneratingHandoff ||
			this.isRetrying
		) {
			throw new Error("Cannot branch /btw while session maintenance or user work is still running");
		}

		this.#pendingNextTurnMessages = [];
		this.#scheduledHiddenNextTurnGeneration = undefined;
		this.#releaseQueuedTtsrReservations();
		this.agent.replaceQueues([], []);
		this.#queuedMessageDrainBlocked = false;
		this.#usagePreflightReadyForNextModelCall = false;
		await this.#bash.flushPending();
		await this.sessionManager.flush();
		const bashTransition = this.#bash.beginSessionTransition();
		this.#cancelOwnAsyncJobs();
		this.#abortAutolearnCapture();
		await this.#drainAutolearnCapture();

		let sessionTransitioned = false;
		let advisorRecordersDetached = false;
		try {
			advisorRecordersDetached = true;
			await this.#advisors.drainAndDetachRecorders();
			try {
				if (this.sessionManager.getSessionId() !== sessionId || this.sessionManager.getLeafId() !== leafId) {
					throw new Error("Cannot branch /btw: session changed since /btw started");
				}
				// A prompt may have been admitted during the flush/drain awaits
				// after the idle check. It still belongs to the pre-branch context.
				this.#promptGeneration++;
				this.sessionManager.createBranchedSession(leafId);
				this.#bash.markSessionTransition(bashTransition);
				this.#advisors.clearCost();
				sessionTransitioned = true;
			} finally {
				this.#bash.finishSessionTransition(bashTransition, sessionTransitioned);
			}

			this.#clearSessionScopedToolState();

			this.#rehydrateCheckpointRewindState();
			this.sessionManager.appendMessage({
				role: "user",
				content: [{ type: "text", text: question }],
				attribution: "user",
				timestamp: Date.now(),
			});
			this.sessionManager.appendMessage(sanitizeAssistantForReparentedHistory(assistantMessage));
			this.#todo.syncFromBranch();
			this.#modelMentions.syncFromBranch();
			this.#freshProviderSessionId = undefined;
			this.#syncAgentSessionId();
			this.#memory.rekeyForCurrentSessionId();
			await this.#memory.resetContextForNewTranscript();

			const sessionContext = this.buildDisplaySessionContext();

			if (this.#extensionRunner) {
				await this.#extensionRunner.emit({
					type: "session_branch",
					previousSessionFile,
				});
			}

			this.agent.replaceMessages(sessionContext.messages);
			this.#advisors.resetSessionState();
			this.#closeCodexProviderSessionsForHistoryRewrite();
			advisorRecordersDetached = false;
			await this.#reconcileModeAfterBranch();

			return { cancelled: false, sessionFile: this.sessionFile };
		} finally {
			if (advisorRecordersDetached) {
				if (sessionTransitioned) this.#advisors.resetSessionState();
				else this.#advisors.reattachRecorderFeeds();
			}
		}
	}

	// =========================================================================
	// Tree Navigation
	// =========================================================================

	/**
	 * Navigate to a different node in the session tree.
	 * Unlike branch() which creates a new session file, this stays in the same file.
	 *
	 * @param targetId The entry ID to navigate to
	 * @param options.summarize Whether user wants to summarize abandoned branch
	 * @param options.customInstructions Custom instructions for summarizer
	 * @returns Result with editorText/editorImages (if user message) and cancelled status
	 */
	async navigateTree(
		targetId: string,
		options: {
			summarize?: boolean;
			customInstructions?: string;
			/**
			 * Opts into the two-phase `ask` toolResult re-answer protocol
			 * (issue #5642): set only by the interactive `/tree` selector, which
			 * knows how to re-open the picker on `reopenAsk` and complete the
			 * navigation with `reanswerAskResult`. Every other public caller
			 * (extensions, hooks, ACP, session-extension actions) leaves this
			 * unset and gets the pre-#5642 plain leaf move onto `ask`
			 * toolResults instead — they have no picker to re-open and would
			 * otherwise report a successful no-op navigation (roboomp review on
			 * #5895).
			 */
			allowAskReopen?: boolean;
			/**
			 * Completes an in-progress `ask` re-answer (issue #5642): the caller
			 * already received `reopenAsk` from a prior call on the same
			 * `targetId`, re-opened the picker, and is handing back the fresh
			 * answer. Branches a new toolResult sibling instead of landing on
			 * the original one.
			 */
			reanswerAskResult?: AgentToolResult<AskToolDetails>;
		} = {},
	): Promise<{
		editorText?: string;
		/** Image attachments of the target user message, parallel to the positional `[Image #N]` markers in {@link editorText}. */
		editorImages?: ImageContent[];
		cancelled: boolean;
		aborted?: boolean;
		summaryEntry?: BranchSummaryEntry;
		/** Raw session context built during navigation — pass to renderInitialMessages to skip a second O(N) walk. */
		sessionContext?: SessionContext;
		/**
		 * Set when `targetId` is an `ask` toolResult, `options.allowAskReopen`
		 * was set, and `options.reanswerAskResult` was not supplied: nothing was
		 * mutated. The caller must re-open the ask picker with these
		 * `questions`, then call `navigateTree(targetId, { ...options,
		 * reanswerAskResult })` with the produced result to actually branch
		 * (issue #5642).
		 */
		reopenAsk?: { toolCallId: string; questions: AskToolInput["questions"] };
		/**
		 * `true` when this call committed a new sibling answer for an `ask`
		 * re-answer (`reanswerAskResult` was applied). The interactive caller
		 * resumes the agent via {@link resumeAfterAskReanswer} *after* rebuilding
		 * its transcript, so the resumed turn never renders against the stale
		 * pre-rebuild UI (issue #6483).
		 */
		askReanswerCommitted?: boolean;
	}> {
		this.#assertTaskRecoveryInput();
		using _transition = this.#beginSessionTransition();
		await this.#bash.flushPending();
		const oldLeafId = this.sessionManager.getLeafId();

		const targetEntry = this.sessionManager.getEntry(targetId);
		if (!targetEntry) {
			throw new Error(`Entry ${targetId} not found`);
		}
		const targetIsAskResult =
			targetEntry.type === "message" &&
			targetEntry.message.role === "toolResult" &&
			targetEntry.message.toolName === "ask";
		const targetIsUserMessage = targetEntry.type === "message" && targetEntry.message.role === "user";

		// No-op if already at target — except for a user message, which always
		// rewinds PAST itself (leaf → parent, text → editor), so a leaf user
		// prompt (turn aborted before any assistant reply) is still a real move
		// — and except mid-flight through the `ask` re-answer protocol (issue
		// #5642): a probe or completion call can legitimately target the
		// *current* leaf (e.g. the user interrupted right after answering
		// `ask`, before a follow-up assistant message landed, or another caller
		// navigated straight onto the ask result), and must still return
		// `reopenAsk` / branch the new answer instead of silently reporting a
		// no-op (chatgpt-codex review on #5895).
		if (targetId === oldLeafId && !targetIsUserMessage && !(options.allowAskReopen && targetIsAskResult)) {
			return { cancelled: false };
		}

		// Model required for summarization
		if (options.summarize && !this.model) {
			throw new Error("No model available for summarization");
		}

		// `ask` toolResult, first pass: hand control back to the caller to
		// re-open the picker instead of landing on the stale answer in place.
		// Nothing is mutated here — see the `reanswerAskResult` branch below for
		// the actual sibling-branch construction once the caller has an answer.
		// Gated on `allowAskReopen` — callers that don't understand `reopenAsk`
		// fall straight through to the plain leaf move below instead of
		// reporting a successful no-op (roboomp review on #5895).
		if (
			options.allowAskReopen &&
			!options.reanswerAskResult &&
			targetEntry.type === "message" &&
			targetEntry.message.role === "toolResult" &&
			targetEntry.message.toolName === "ask"
		) {
			const toolCallId = targetEntry.message.toolCallId;
			const questions = this.#recoverAskReanswerQuestions(targetEntry.parentId, toolCallId);
			if (questions) {
				return { cancelled: false, reopenAsk: { toolCallId, questions } };
			}
			// Original arguments couldn't be recovered (corrupted/legacy session
			// data) — fall through to a plain leaf move so navigation still works.
		}

		// Collect entries to summarize (from old leaf to common ancestor). For an
		// `ask` re-answer completion, the branch point is `targetEntry.parentId`
		// (the new sibling toolResult lands there, not on `targetId`) — anchor
		// the collection there too, or the old answer entry is neither on the
		// new branch nor included in the summary (chatgpt-codex review on
		// #5895).
		const summaryAnchorId =
			options.reanswerAskResult !== undefined &&
			targetEntry.type === "message" &&
			targetEntry.message.role === "toolResult" &&
			targetEntry.message.toolName === "ask" &&
			targetEntry.parentId !== null
				? targetEntry.parentId
				: targetId;
		const { entries: entriesToSummarize, commonAncestorId } = collectEntriesForBranchSummary(
			this.sessionManager,
			oldLeafId,
			summaryAnchorId,
		);

		// Prepare event data
		const preparation: TreePreparation = {
			targetId,
			oldLeafId,
			commonAncestorId,
			entriesToSummarize,
			userWantsSummary: options.summarize ?? false,
		};

		// Set up abort controller for summarization
		this.#branchSummaryAbortController = new AbortController();
		let hookSummary: { summary: string; details?: unknown } | undefined;
		let fromExtension = false;

		// Emit session_before_tree event
		if (this.#extensionRunner?.hasHandlers("session_before_tree")) {
			const result = (await this.#extensionRunner.emit({
				type: "session_before_tree",
				preparation,
				signal: this.#branchSummaryAbortController.signal,
			})) as SessionBeforeTreeResult | undefined;

			if (result?.cancel) {
				return { cancelled: true };
			}

			if (result?.summary && options.summarize) {
				hookSummary = result.summary;
				fromExtension = true;
			}
		}

		// Run default summarizer if needed
		let summaryText: string | undefined;
		let summaryDetails: unknown;
		if (options.summarize && entriesToSummarize.length > 0 && !hookSummary) {
			const model = this.model!;
			const apiKey = await this.#modelRegistry.getApiKey(model, this.sessionId);
			if (!apiKey) {
				throw new Error(`No API key for ${model.provider}`);
			}
			const result = await generateBranchSummary(entriesToSummarize, {
				model,
				apiKey: this.#modelRegistry.resolver(model, this.sessionId),
				signal: this.#branchSummaryAbortController.signal,
				customInstructions: this.#obfuscateTextForProvider(options.customInstructions),
				reserveTokens: cfgBranchSummaryReserveTokens.get(this.settings),
				metadata: this.agent.metadataForProvider(model.provider),
				convertToLlm: messages => this.#convertToLlmForSideRequest(messages),
				telemetry: resolveTelemetry(this.agent.telemetry, this.sessionId),
				// Same per-provider concurrency cap rationale as the compaction
				// path above (chatgpt-codex review on #3751).
				completeImpl: async (requestModel, requestContext, requestOptions) => {
					const stream = await this.#sideStreamFn(requestModel, requestContext, requestOptions);
					return stream.result();
				},
			});
			this.#branchSummaryAbortController = undefined;
			if (result.aborted) {
				return { cancelled: true, aborted: true };
			}
			if (result.error) {
				throw new Error(result.error);
			}
			summaryText = result.summary;
			summaryDetails = {
				readFiles: result.readFiles || [],
				modifiedFiles: result.modifiedFiles || [],
			};
		} else if (hookSummary) {
			summaryText = hookSummary.summary;
			summaryDetails = hookSummary.details;
		}

		// All cancellation/no-op exits are behind us. Invalidate prompt setup
		// admitted on the abandoned branch before committing any tree changes.
		this.#promptGeneration++;

		// Determine the new leaf position based on target type
		let newLeafId: string | null;
		let editorText: string | undefined;
		let editorImages: ImageContent[] | undefined;
		// Set when the second-pass `ask` re-answer branch below actually commits a
		// new sibling answer — the trigger for resuming the agent afterwards so the
		// model consumes it, mirroring a live `ask` completion (issue #6483).
		let isAskReanswerCompletion = false;

		if (isTranscriptEntry(targetEntry) && isUserRequestEntry(targetEntry)) {
			// User request (plain prompt, or a user-invoked skill/collab prompt): leaf = parent
			// (null if root), the draft the user typed goes back to the editor with its images.
			newLeafId = targetEntry.parentId;
			editorText = userTurnDraft(targetEntry);
			const request = transcriptEntryMessage(targetEntry);
			const targetImages =
				request && (request.role === "user" || request.role === "custom")
					? this.#extractUserMessageImages(request.content)
					: [];
			if (targetImages.length > 0) editorImages = targetImages;
		} else if (targetEntry.type === "custom_message" && targetEntry.customType !== SKILL_PROMPT_MESSAGE_TYPE) {
			// Other custom message: leaf = parent (null if root), text goes to editor
			newLeafId = targetEntry.parentId;
			editorText =
				typeof targetEntry.content === "string"
					? targetEntry.content
					: targetEntry.content
							.filter((c): c is { type: "text"; text: string } => c.type === "text")
							.map(c => c.text)
							.join("");
		} else if (
			targetEntry.type === "message" &&
			targetEntry.message.role === "toolResult" &&
			targetEntry.message.toolName === "ask" &&
			options.reanswerAskResult
		) {
			// `ask` toolResult, second pass: the caller re-opened the picker and
			// is handing back a fresh answer. Branch a *new* sibling toolResult
			// off the same `ask` toolCall instead of reusing `targetId` — the
			// original answer's branch stays reachable (issue #5642).
			const reanswer = options.reanswerAskResult;
			const toolResultMessage: ToolResultMessage = {
				role: "toolResult",
				toolCallId: targetEntry.message.toolCallId,
				toolName: "ask",
				content: reanswer.content,
				details: reanswer.details,
				isError: reanswer.isError === true,
				timestamp: Date.now(),
			};
			newLeafId = this.sessionManager.appendMessageToBranch(toolResultMessage, targetEntry.parentId);
			isAskReanswerCompletion = true;
		} else {
			// Non-user message (or an agent/autoload skill-prompt injection): land the
			// leaf on the selected node so it stays on the active branch. Injected skill
			// prompts must not be re-editable — their content is a large expanded body,
			// not a user turn (issue #5374).
			newLeafId = targetId;
		}

		// Switch leaf (with or without summary)
		// Summary is attached at the navigation target position (newLeafId), not the old branch
		const bashTransition = this.#bash.beginSessionTransition();
		let summaryEntry: BranchSummaryEntry | undefined;
		let branchTransitioned = false;
		try {
			if (summaryText) {
				// Create summary at target position (can be null for root)
				const summaryId = this.sessionManager.branchWithSummary(
					newLeafId,
					summaryText,
					summaryDetails,
					fromExtension,
				);
				summaryEntry = this.sessionManager.getEntry(summaryId) as BranchSummaryEntry;
			} else if (newLeafId === null) {
				this.sessionManager.resetLeaf();
			} else {
				this.sessionManager.branch(newLeafId);
			}
			this.#bash.markSessionTransition(bashTransition);
			branchTransitioned = true;
		} finally {
			this.#bash.finishSessionTransition(bashTransition, branchTransitioned);
		}

		// Update agent state — build display context to populate agent messages.
		const stateContext = this.sessionManager.buildSessionContext();
		const displayContext = this.#withEvalStateContext(deobfuscateSessionContext(stateContext, this.#obfuscator));
		this.agent.replaceMessages(displayContext.messages);
		this.#rehydrateCheckpointRewindState();
		this.#advisors.resetSessionState({ preserveCost: true });
		this.#todo.syncFromBranch();
		this.#modelMentions.syncFromBranch();
		this.#closeCodexProviderSessionsForHistoryRewrite();

		this.#branchSummaryAbortController = undefined;

		// Report a committed `ask` re-answer so the interactive caller can resume
		// the agent via `resumeAfterAskReanswer()` *after* rebuilding its
		// transcript. Scheduling the continue here instead would start a fresh
		// streaming turn whose `agent_start`/`turn_start` events could render
		// against the stale pre-rebuild UI and then be clobbered by the caller's
		// `renderInitialMessages(...)` (issue #6483). Plain leaf moves and the
		// read-only `reopenAsk` probe leave the flag unset.

		// Emit session_tree event; only handlers can mutate session entries, so skip
		// the emit and the context rebuild when no handlers are registered (mirrors
		// the session_before_tree guard above).
		if (this.#extensionRunner?.hasHandlers("session_tree")) {
			await this.#extensionRunner.emit({
				type: "session_tree",
				newLeafId: this.sessionManager.getLeafId(),
				oldLeafId,
				summaryEntry,
				fromExtension: summaryText ? fromExtension : undefined,
			});
			const rawContext = this.sessionManager.buildSessionContext();
			return {
				editorText,
				editorImages,
				cancelled: false,
				summaryEntry,
				sessionContext: rawContext,
				askReanswerCommitted: isAskReanswerCompletion,
			};
		}
		return {
			editorText,
			editorImages,
			cancelled: false,
			summaryEntry,
			sessionContext: stateContext,
			askReanswerCommitted: isAskReanswerCompletion,
		};
	}

	/**
	 * Resume the agent after the interactive `/tree` caller has committed an
	 * `ask` re-answer (`navigateTree` returned `askReanswerCommitted`) and
	 * rebuilt its transcript. Mirrors how a live `ask` completion drives a
	 * follow-up turn, but is deferred to the caller so the resumed turn renders
	 * against the rebuilt UI rather than the stale pre-navigation transcript
	 * (issue #6483). The scheduled continue honors the same disposed/compacting
	 * guards as every other post-prompt continuation.
	 */
	resumeAfterAskReanswer(): void {
		this.#scheduleAgentContinue({ source: "ask-reanswer" });
	}

	/**
	 * Look up the `ask` toolCall's persisted `arguments` and validate them
	 * back into `questions`, for `/tree` `ask` re-answer (issue #5642). Walks
	 * up from the toolResult's parent past any interleaved ancestor entries
	 * — sibling toolResults from other tool calls in the same turn (`ask`
	 * runs `exclusive`, which only serializes *execution*, not persistence
	 * order — roboomp review on #5895), and bookkeeping entries such as the
	 * `tool_execution_start` custom entry `#recordToolExecutionStart()`
	 * appends before every toolResult in real persisted sessions (chatgpt-codex
	 * review on #5895) — until it finds the assistant entry that actually
	 * emitted `toolCallId`. Stops at a `user` message (turn boundary) or a
	 * dead end. Returns `undefined` when no ancestor entry holds a matching
	 * `ask` toolCall, or the arguments can't be resolved — the caller falls
	 * back to a plain leaf move rather than opening a picker with bad data.
	 */
	#recoverAskReanswerQuestions(parentId: string | null, toolCallId: string): AskToolInput["questions"] | undefined {
		let current = parentId;
		while (current !== null) {
			const entry = this.sessionManager.getEntry(current);
			if (!entry) return undefined;
			if (entry.type === "message") {
				if (entry.message.role === "assistant") {
					const toolCall = entry.message.content.find(
						(block): block is AgentToolCall => block.type === "toolCall" && block.id === toolCallId,
					);
					if (!toolCall) return undefined;
					if (toolCall.name !== "ask") return undefined;
					const args = this.#obfuscator?.hasSecrets()
						? deobfuscateToolArguments(this.#obfuscator, toolCall.arguments)
						: toolCall.arguments;
					return recoverAskQuestions(args);
				}
				if (entry.message.role === "user") return undefined;
			}
			current = entry.parentId;
		}
		return undefined;
	}

	/**
	 * Build a standalone `AgentToolContext` for running `AskTool.execute()`
	 * outside a normal agent turn, for `/tree` `ask` re-answer (issue #5642).
	 * `SelectorController` has no reachable `ToolContextStore` (that store is
	 * built inside `sdk.ts` and never threaded through to mode controllers),
	 * so this mirrors `refreshMCPTools()`'s `getCustomToolContext` factory
	 * with real session state instead of a `{ ... } as unknown as
	 * AgentToolContext` cast that could silently compile with an incomplete
	 * context (roboomp review on #5895) — every `CustomToolContext` field is
	 * backed by live session state, so a future required field fails to
	 * compile here instead of surfacing as `undefined` at runtime.
	 */
	buildAskReanswerContext(uiContext: ExtensionUIContext): AgentToolContext {
		return {
			sessionManager: this.sessionManager,
			modelRegistry: this.#modelRegistry,
			model: this.model,
			isIdle: () => !this.isStreaming,
			hasQueuedMessages: () => this.queuedMessageCount > 0,
			abort: () => {
				this.agent.abort();
			},
			settings: this.settings,
			ui: uiContext,
			hasUI: true,
		};
	}

	/**
	 * Get all user messages from session for branch selector.
	 */
	getUserMessagesForBranching(): Array<{ entryId: string; text: string }> {
		const entries = this.sessionManager.getEntries();
		const result: Array<{ entryId: string; text: string }> = [];

		for (const entry of entries) {
			if (entry.type !== "message") continue;
			if (entry.message.role !== "user") continue;

			const text = this.#extractUserMessageText(entry.message.content);
			if (text) {
				result.push({ entryId: entry.id, text });
			}
		}

		return result;
	}

	#extractUserMessageText(content: string | Array<{ type: string; text?: string }>): string {
		if (typeof content === "string") return content;
		if (Array.isArray(content)) {
			return content
				.filter((c): c is { type: "text"; text: string } => c.type === "text")
				.map(c => c.text)
				.join("");
		}
		return "";
	}

	/** Image parts of a stored user request, in submission order — index N-1 backs the
	 *  `[Image #N]` marker in the message text, so restoring them alongside the text keeps
	 *  positional markers resolvable on resubmit. */
	#extractUserMessageImages(content: UserMessage["content"] | CustomMessage["content"]): ImageContent[] {
		if (!Array.isArray(content)) return [];
		return content.filter((c): c is ImageContent => c.type === "image");
	}

	/**
	 * Get session statistics.
	 */
	getSessionStats(): SessionStats {
		return this.#stats.getSessionStats();
	}

	/**
	 * Get current context usage statistics.
	 * Uses the last assistant message's usage data when available,
	 * otherwise estimates tokens for all messages.
	 */
	getContextBreakdown(options?: {
		contextWindow?: number;
		pendingMessages?: AgentMessage[];
	}): ContextUsageBreakdown | undefined {
		return this.#stats.getContextBreakdown(options);
	}

	getContextUsage(options?: { contextWindow?: number }): ContextUsage | undefined {
		return this.#stats.getContextUsage(options);
	}

	/**
	 * Monotonic counter that changes whenever the in-flight pending context
	 * snapshot is set or cleared. Status-line context memoization keys on this so
	 * a value computed mid-turn cannot persist after the turn ends/aborts.
	 */
	get contextUsageRevision(): number {
		return this.#stats.revision;
	}

	async fetchUsageReports(signal?: AbortSignal): Promise<UsageReport[] | null> {
		const authStorage = this.#modelRegistry.authStorage;
		if (!authStorage.usage.reports) return null;
		const reports = await authStorage.usage.reports({
			baseUrlResolver: provider => {
				if (provider === "google-antigravity") {
					const mode = cfgProvidersAntigravityEndpoint.get(this.settings);
					if (mode === "sandbox") {
						return "https://daily-cloudcode-pa.sandbox.googleapis.com";
					} else if (mode === "production") {
						return "https://daily-cloudcode-pa.googleapis.com";
					}
				}
				return this.#modelRegistry.getProviderBaseUrl?.(provider);
			},
			signal,
		});
		// Every fresh usage snapshot doubles as the salvage-sweep heartbeat: the
		// status line calls this every 5 minutes while the TUI is open.
		if (reports) this.#maybeScheduleResetSweep(reports);
		return reports;
	}

	/** Models whose live `/usage` reports map to a quantitative provider scope. */
	getUsageReportingModelSelectors(reports: readonly UsageReport[]): string[] {
		const modelsByProvider = new Map<string, Model[]>();
		for (const model of this.#modelRegistry.getAvailable()) {
			const models = modelsByProvider.get(model.provider) ?? [];
			models.push(model);
			modelsByProvider.set(model.provider, models);
		}
		const selectors = new Set<string>();
		for (const [provider, models] of modelsByProvider) {
			const modelIds = this.#modelRegistry.authStorage.usage.reportingModelIds(
				provider,
				models.map(model => model.id),
				reports,
			);
			for (const modelId of modelIds) selectors.add(`${provider}/${modelId}`);
		}
		return [...selectors].sort((left, right) => left.localeCompare(right));
	}

	/** List stored OAuth accounts for the current model provider and mark this session's active account. */
	async listCurrentProviderOAuthAccounts(): Promise<SessionOAuthAccountList | undefined> {
		const provider = this.model?.provider;
		if (!provider) return undefined;
		const authStorage = this.#modelRegistry.authStorage;
		await authStorage.credentials.reload();
		return {
			provider,
			accounts: authStorage.oauth.accounts(provider, this.sessionId),
		};
	}

	/**
	 * Pin a stored OAuth account to the current model provider for this session.
	 * Returns false while streaming or when the credential is no longer available.
	 */
	pinCurrentProviderOAuthAccount(credentialId: number): boolean {
		const provider = this.model?.provider;
		if (!provider || this.isStreaming) return false;
		return this.#modelRegistry.authStorage.sessions.pin(provider, this.sessionId, credentialId);
	}

	/**
	 * Redeem one provider-selected saved rate-limit reset for an exact stored
	 * credential. Never throws for business outcomes — inspect `code`.
	 */
	async redeemResetCredit(target: ResetCreditTarget, signal?: AbortSignal): Promise<ResetCreditRedeemOutcome> {
		return this.#modelRegistry.authStorage.resets.redeem({
			target,
			baseUrlResolver: provider => this.#modelRegistry.getProviderBaseUrl?.(provider),
			signal,
		});
	}

	/**
	 * List live saved-reset eligibility. An explicit provider lists only that
	 * provider; the public default aggregates Codex and Claude independently.
	 */
	async listResetCredits(signal?: AbortSignal, provider?: string): Promise<ResetCreditAccountStatus[]> {
		const options = {
			sessionId: this.sessionId,
			baseUrlResolver: (candidate: string) => this.#modelRegistry.getProviderBaseUrl?.(candidate),
			signal,
		};
		if (provider) {
			return this.#modelRegistry.authStorage.resets.list({ ...options, provider });
		}
		const [codex, claude] = await Promise.all([
			this.#modelRegistry.authStorage.resets.list({ ...options, provider: "openai-codex" }),
			this.#modelRegistry.authStorage.resets.list({ ...options, provider: "anthropic" }),
		]);
		return [...codex, ...claude];
	}
	/**
	 * Ask before a provider's first automatic spend. Consent is persisted in
	 * that provider's independent settings group; headless hosts only receive a
	 * one-shot notice and never spend while the mode is unset.
	 */
	async #confirmAutoRedeem(
		provider: "openai-codex" | "anthropic",
		actions: (CodexResetAction | ClaudeResetAction)[],
		coordinator: CodexAutoRedeemCoordinator,
	): Promise<boolean> {
		const first = actions[0];
		if (!first) return false;
		const providerLabel = provider === "anthropic" ? "Claude" : "Codex";
		const settingsKey = provider === "anthropic" ? "claudeResets.autoRedeem" : "codexResets.autoRedeem";
		const source = provider === "anthropic" ? "claude-auto-reset" : "codex-auto-reset";
		const runner = this.#extensionRunner;
		if (!runner?.hasUI()) {
			if (!coordinator.notifiedKeys.has(first.attemptKey)) {
				coordinator.notifiedKeys.add(first.attemptKey);
				this.emitNotice(
					"warning",
					`Saved ${providerLabel} resets are eligible to spend, but auto-redeem is unset and no prompt UI is available. Run \`/usage reset\` or set ${settingsKey}.`,
					source,
				);
			}
			return false;
		}

		const lines = actions.map(action => {
			if (!("program" in action)) {
				const codex = action;
				return codex.reason === "blocked-account"
					? `${codex.label} is blocked by the Codex ${(codex.blockedWindows ?? []).join(" + ") || "usage"} limit for about ${formatDuration(codex.remainingMs ?? 0)}.`
					: `${codex.label}: a saved reset expires in ${formatDuration(codex.expiresInMs ?? 0)} (${codex.salvageWindow ?? "weekly"} window ${Math.round((codex.salvageUsedFraction ?? codex.weeklyUsedFraction ?? 0) * 100)}% used).`;
			}
			const claude = action;
			const grant = claude.program === "juniper_tide" ? "5h session-only reset" : (claude.title ?? "saved reset");
			const early = claude.requiresLimit
				? ""
				: " This grant permits early use before the covered window is fully blocked.";
			return claude.reason === "blocked-account"
				? `${claude.label}: ${grant} covers ${(claude.blockedWindows ?? []).map(formatUsageResetWindow).join(" + ")} with about ${formatDuration(claude.remainingMs ?? 0)} left.${early}`
				: `${claude.label}: ${grant} expires in ${formatDuration(claude.expiresInMs ?? 0)}; ${formatUsageResetWindow(claude.salvageWindow ?? "")} is ${Math.round((claude.salvageUsedFraction ?? 0) * 100)}% used.${early}`;
		});
		const question =
			actions.length === 1
				? `Spend a saved ${providerLabel} rate-limit reset?\n${lines[0]}`
				: `Spend ${actions.length} saved ${providerLabel} rate-limit resets?\n${lines.join("\n")}`;
		try {
			const choice = await runner.getUIContext().select(question, [
				{
					label: "Yes",
					description: `Redeem now and remember yes for future eligible ${providerLabel} resets.`,
				},
				{
					label: "No",
					description: `Do not auto-redeem saved ${providerLabel} resets.`,
				},
			]);
			if (choice === "Yes") {
				if (provider === "anthropic") cfgClaudeResetsAutoRedeem.set(this.settings, "yes");
				else cfgCodexResetsAutoRedeem.set(this.settings, "yes");
				return true;
			}
			if (choice === "No") {
				if (provider === "anthropic") cfgClaudeResetsAutoRedeem.set(this.settings, "no");
				else cfgCodexResetsAutoRedeem.set(this.settings, "no");
			}
		} catch (error) {
			logger.warn(`${source} prompt failed`, { error: String(error) });
		}
		return false;
	}

	#planCodexResets(
		trigger: CodexResetTrigger,
		reports: UsageReport[] | null,
		identity: OAuthAccountIdentity | undefined,
		coordinator: CodexAutoRedeemCoordinator,
		activeBlockUnblockAtMs?: number,
	): CodexResetPlan {
		const cfg = cfgCodexResets.get(this.settings);
		const model = this.model;
		const plan = planCodexResetRedemptions({
			nowMs: Date.now(),
			trigger,
			provider: model?.provider ?? "",
			modelId: model?.id ?? "",
			settings: {
				enabled: shouldEvaluateCodexAutoRedeem(cfg.autoRedeem),
				minBlockedMinutes: Math.max(0, cfg.minBlockedMinutes),
				keepCredits: Math.max(0, Math.trunc(cfg.keepCredits)),
				salvageHorizonMs: Math.max(0, cfg.salvageHorizonHours) * 3_600_000,
			},
			identity,
			reports,
			attemptedKeys: coordinator.attemptedKeys,
			deferredUntilByKey: coordinator.deferredUntilByKey,
			lastAttemptAtByAccount: coordinator.lastAttemptAtByAccount,
			activeBlockUnblockAtMs,
		});
		if (plan.skipped.length > 0) {
			logger.debug("codex-auto-reset: plan", { trigger, actions: plan.actions.length, skipped: plan.skipped });
		}
		return plan;
	}

	#planClaudeResets(
		trigger: CodexResetTrigger,
		reports: UsageReport[] | null,
		statuses: readonly ResetCreditAccountStatus[],
		coordinator: CodexAutoRedeemCoordinator,
		activeBlockUnblockAtMs?: number,
	): ClaudeResetPlan {
		const cfg = cfgClaudeResets.get(this.settings);
		const model = this.model;
		const plan = planClaudeResetRedemptions({
			nowMs: Date.now(),
			trigger,
			provider: model?.provider ?? "",
			modelId: model?.provider === "anthropic" ? model.id : "",
			settings: {
				enabled: shouldEvaluateCodexAutoRedeem(cfg.autoRedeem),
				minBlockedMinutes: Math.max(0, cfg.minBlockedMinutes),
				keepCredits: Math.max(0, Math.trunc(cfg.keepCredits)),
				salvageHorizonMs: Math.max(0, cfg.salvageHorizonHours) * 3_600_000,
			},
			reports,
			statuses,
			attemptedKeys: coordinator.attemptedKeys,
			deferredUntilByKey: coordinator.deferredUntilByKey,
			lastAttemptAtByAccount: coordinator.lastAttemptAtByAccount,
			activeBlockUnblockAtMs,
		});
		if (plan.skipped.length > 0) {
			logger.debug("claude-auto-reset: plan", { trigger, actions: plan.actions.length, skipped: plan.skipped });
		}
		return plan;
	}

	#resetLockPath(lockKey: string, coordinator: CodexAutoRedeemCoordinator): string {
		return `${coordinator.resetLockPath ?? getAgentDbPath()}.reset-${Bun.hash(lockKey).toString(16)}`;
	}

	async #readResetMarker(lockPath: string): Promise<{ state: string; atMs: number }> {
		let text: string;
		try {
			text = await Bun.file(lockPath).text();
		} catch (error) {
			if (!isEnoent(error)) throw error;
			text = "";
		}
		const [state, timestamp] = text.split(":");
		return { state, atMs: Number(timestamp) };
	}

	#adoptResetMarker(lockKey: string, marker: { state: string; atMs: number }): boolean {
		if (
			marker.state !== "reset" ||
			!Number.isFinite(marker.atMs) ||
			Date.now() - marker.atMs >= ATTEMPT_COOLDOWN_MS ||
			marker.atMs <= (this.#adoptedResetMarkers.get(lockKey) ?? 0)
		) {
			return false;
		}
		this.#adoptedResetMarkers.set(lockKey, marker.atMs);
		return true;
	}

	async #adoptRecentReset(
		statuses: readonly ResetCreditAccountStatus[],
		coordinator: CodexAutoRedeemCoordinator,
	): Promise<boolean> {
		for (const status of statuses) {
			if (status.provider !== this.model?.provider) continue;
			const lockKey = resetAccountLockKey(status);
			if (!lockKey) continue;
			const lockPath = this.#resetLockPath(lockKey, coordinator);
			await fs.promises.mkdir(path.dirname(lockPath), { recursive: true });
			const adopted = await withFileLock(
				lockPath,
				async () => this.#adoptResetMarker(lockKey, await this.#readResetMarker(lockPath)),
				{ retries: 300, retryDelayMs: 100 },
			);
			if (adopted) {
				await this.#modelRegistry.authStorage.credentials.revalidate();
				return true;
			}
		}
		return false;
	}

	/**
	 * Shared consume executor for Codex and Claude plans. Attempt keys enter the
	 * process-wide set before mutation, while nonterminal outcomes release and
	 * defer the episode so a still-banked grant is not buried permanently.
	 */
	async #executeResetActions(
		provider: "openai-codex" | "anthropic",
		actions: (CodexResetAction | ClaudeResetAction)[],
		coordinator: CodexAutoRedeemCoordinator,
	): Promise<number> {
		const authStorage = this.#modelRegistry.authStorage;
		const providerLabel = provider === "anthropic" ? "Claude" : "Codex";
		const source = provider === "anthropic" ? "claude-auto-reset" : "codex-auto-reset";
		let redeemed = 0;
		for (const action of actions) {
			if (coordinator.attemptedKeys.has(action.attemptKey)) continue;
			coordinator.attemptedKeys.add(action.attemptKey);
			coordinator.lastAttemptAtByAccount.set(action.accountKey, Date.now());
			let outcome: ResetCreditRedeemOutcome | undefined;
			let sharedReset = false;
			try {
				const redeemOptions = {
					target: action.target,
					baseUrlResolver: (candidate: string) => this.#modelRegistry.getProviderBaseUrl?.(candidate),
					// Caller cancellation must not leave an ambiguous consume in flight.
					signal: AbortSignal.timeout(15_000),
				};
				const lockKey = resetAccountLockKey(action.target);
				if (!lockKey) {
					// An account without an upstream identity cannot share a cross-process fence.
					outcome = await authStorage.resets.redeem(redeemOptions);
				} else {
					// The coordinator is process-local. Fence concurrent processes and
					// remember a recent attempt so a late 429 cannot spend again.
					const lockPath = this.#resetLockPath(lockKey, coordinator);
					await fs.promises.mkdir(path.dirname(lockPath), { recursive: true });
					outcome = await withFileLock(
						lockPath,
						async () => {
							const marker = await this.#readResetMarker(lockPath);
							if (Date.now() - marker.atMs < ATTEMPT_COOLDOWN_MS) {
								sharedReset = this.#adoptResetMarker(lockKey, marker);
								if (sharedReset) await authStorage.credentials.revalidate();
								return undefined;
							}
							// Claude's redeem revalidates its exact offer. Codex needs its
							// balance rechecked after acquiring the cross-process fence.
							if (provider === "openai-codex") {
								const statuses = await this.listResetCredits(AbortSignal.timeout(10_000), provider);
								const live = statuses.find(
									status => status.credentialId === action.target.credentialId && !status.error,
								);
								if (!live) {
									return {
										ok: false,
										code: "credit_list_failed",
										provider,
									} satisfies ResetCreditRedeemOutcome;
								}
								if (action.availableCount !== undefined && live.availableCount < action.availableCount) {
									return undefined;
								}
								if (live.availableCount < 1) {
									return { ok: false, code: "no_credit", provider } satisfies ResetCreditRedeemOutcome;
								}
							}
							const attemptedAt = Date.now();
							await Bun.write(lockPath, `pending:${attemptedAt}`);
							const result = await authStorage.resets.redeem(redeemOptions);
							if (result.code === "reset") {
								await Bun.write(lockPath, `reset:${attemptedAt}`);
								this.#adoptedResetMarkers.set(lockKey, attemptedAt);
							} else if (result.code === "no_credit" || result.code === "nothing_to_reset") {
								await Bun.write(lockPath, "");
							}
							return result;
						},
						{ retries: 300, retryDelayMs: 100 },
					);
				}
			} catch (error) {
				coordinator.attemptedKeys.delete(action.attemptKey);
				coordinator.deferredUntilByKey.set(action.attemptKey, Date.now() + REDEEM_RETRY_DEFER_MS);
				logger.warn(`${source}: redeem threw, deferred`, {
					account: action.accountKey,
					error: String(error),
				});
				continue;
			}
			if (!outcome) {
				if (sharedReset) redeemed++;
				continue;
			}
			if (!isTerminalRedeemOutcome(outcome.code)) {
				coordinator.attemptedKeys.delete(action.attemptKey);
				coordinator.deferredUntilByKey.set(action.attemptKey, Date.now() + REDEEM_RETRY_DEFER_MS);
			}
			switch (outcome.code) {
				case "reset": {
					redeemed++;
					const left =
						action.availableCount === undefined ? undefined : ` (${Math.max(0, action.availableCount - 1)} left)`;
					const detail =
						action.reason === "expiring-credit"
							? `it was set to expire in ${formatDuration(action.expiresInMs ?? 0)}`
							: outcome.cleared?.length
								? `cleared ${outcome.cleared.map(formatUsageResetWindow).join(" + ")}; retrying now`
								: "retrying now";
					this.emitNotice(
						"info",
						`Auto-redeemed a saved ${providerLabel} rate-limit reset for ${action.label}${left ?? ""}; ${detail}.`,
						source,
					);
					break;
				}
				case "already_redeemed":
					this.emitNotice(
						"warning",
						`A saved ${providerLabel} reset for ${action.label} was already redeemed elsewhere.`,
						source,
					);
					break;
				case "no_credit":
					logger.debug(`${source}: no_credit (snapshot/live mismatch)`, { account: action.accountKey });
					break;
				case "nothing_to_reset":
					if (action.reason === "blocked-account") {
						this.emitNotice(
							"warning",
							`${providerLabel} reset for ${action.label} reported nothing to reset; will retry later.`,
							source,
						);
					} else {
						logger.debug(`${source}: nothing_to_reset deferred`, { account: action.accountKey });
					}
					break;
				default:
					if (action.reason === "blocked-account") {
						this.emitNotice(
							"warning",
							`${providerLabel} auto-redeem for ${action.label} failed (${outcome.code}); will retry later.`,
							source,
						);
					} else {
						logger.warn(`${source}: consume failed, deferred`, {
							account: action.accountKey,
							code: outcome.code,
						});
					}
					break;
			}
		}
		if (redeemed > 0) void this.fetchUsageReports();
		return redeemed;
	}

	async #maybeAutoRedeemReset(activeBlockUnblockAtMs?: number): Promise<ResetRecoveryResult> {
		const provider = this.model?.provider;
		if (provider !== "anthropic" && provider !== "openai-codex") return { restored: false };
		const cfg = (provider === "anthropic" ? cfgClaudeResets : cfgCodexResets).get(this.settings);
		if (!shouldEvaluateCodexAutoRedeem(cfg.autoRedeem)) return { restored: false };
		const coordinator = this.#resetCoordinator;
		const authStorage = this.#modelRegistry.authStorage;
		const identity = authStorage.oauth.identity(provider, this.sessionId);
		const identityValue = (identity?.accountId ?? identity?.email ?? identity?.orgId)?.trim().toLowerCase();
		if (!identityValue) return { restored: false };
		const accountKey = `${provider}|${identity?.orgId?.trim().toLowerCase() ?? "-"}|${identityValue}`;
		const existing = coordinator.inFlightByAccount.get(accountKey);
		if (existing) return existing;

		const run = (async (): Promise<ResetRecoveryResult> => {
			let reports: UsageReport[] | null = null;
			if (provider === "openai-codex") {
				await authStorage.usage.invalidate(provider);
				reports = await this.fetchUsageReports();
			}
			// Claude's live reset listing includes the same response's quota
			// windows; a second broker usage poll adds no evidence and can 429.
			const statuses = await this.listResetCredits(AbortSignal.timeout(10_000), provider);
			const plan =
				provider === "anthropic"
					? this.#planClaudeResets("blocked", reports, statuses, coordinator, activeBlockUnblockAtMs)
					: this.#planCodexResets(
							"blocked",
							overlayLiveResetCredits(reports, statuses, { synthesizeActive: true, nowMs: Date.now() }),
							identity,
							coordinator,
							activeBlockUnblockAtMs,
						);
			if (plan.actions.length === 0) {
				if (await this.#adoptRecentReset(statuses, coordinator)) return { restored: true };
				let retryAfterMs: number | undefined;
				if (provider === "anthropic" && cfg.autoRedeem === "yes") {
					for (const status of statuses) {
						if (!status.error || status.retryAfterMs === undefined || !Number.isFinite(status.retryAfterMs))
							continue;
						const delay = Math.max(0, status.retryAfterMs);
						retryAfterMs = retryAfterMs === undefined ? delay : Math.min(retryAfterMs, delay);
					}
				}
				return { restored: false, retryAfterMs };
			}
			if (
				shouldPromptCodexAutoRedeem(cfg.autoRedeem) &&
				!(await this.#confirmAutoRedeem(provider, plan.actions, coordinator))
			) {
				return { restored: false };
			}
			return { restored: (await this.#executeResetActions(provider, plan.actions, coordinator)) > 0 };
		})()
			.catch((error): ResetRecoveryResult => {
				logger.warn("auto-reset: blocked pass failed", { provider, account: accountKey, error: String(error) });
				return { restored: false };
			})
			.finally(() => coordinator.inFlightByAccount.delete(accountKey));
		coordinator.inFlightByAccount.set(accountKey, run);
		return run;
	}

	/**
	 * One process-wide salvage sweep handles both providers, but plans and asks
	 * consent independently. Every candidate is refreshed through its live
	 * listing before spend; a failed listing cannot fall back to stale usage.
	 */
	#maybeScheduleResetSweep(reports: UsageReport[]): void {
		const coordinator = this.#resetCoordinator;
		const codexCfg = cfgCodexResets.get(this.settings);
		const claudeCfg = cfgClaudeResets.get(this.settings);
		const codexEnabled =
			shouldEvaluateCodexAutoRedeem(codexCfg.autoRedeem) &&
			codexCfg.salvageHorizonHours > 0 &&
			reports.some(report => report.provider === "openai-codex");
		const claudeEnabled =
			shouldEvaluateCodexAutoRedeem(claudeCfg.autoRedeem) &&
			claudeCfg.salvageHorizonHours > 0 &&
			reports.some(report => report.provider === "anthropic");
		if (!codexEnabled && !claudeEnabled) return;
		if (coordinator.sweepInFlight || coordinator.inFlightByAccount.size > 0) return;
		const now = Date.now();
		if (now - coordinator.lastSweepAt < SWEEP_MIN_INTERVAL_MS) return;
		coordinator.sweepInFlight = true;
		coordinator.lastSweepAt = now;
		coordinator.sweepPromise = (async () => {
			if (codexEnabled) {
				try {
					const statuses = await this.listResetCredits(AbortSignal.timeout(10_000), "openai-codex");
					const effectiveReports = overlayLiveResetCredits(reports, statuses);
					const identity = this.#modelRegistry.authStorage.oauth.identity("openai-codex", this.sessionId);
					const plan = this.#planCodexResets("sweep", effectiveReports, identity, coordinator);
					if (
						plan.actions.length > 0 &&
						(!shouldPromptCodexAutoRedeem(codexCfg.autoRedeem) ||
							(await this.#confirmAutoRedeem("openai-codex", plan.actions, coordinator)))
					) {
						await this.#executeResetActions("openai-codex", plan.actions, coordinator);
					}
				} catch (error) {
					logger.warn("codex-auto-reset: salvage listing failed", { error: String(error) });
				}
			}
			if (claudeEnabled) {
				try {
					const statuses = await this.listResetCredits(AbortSignal.timeout(10_000), "anthropic");
					const plan = this.#planClaudeResets("sweep", reports, statuses, coordinator);
					if (
						plan.actions.length > 0 &&
						(!shouldPromptCodexAutoRedeem(claudeCfg.autoRedeem) ||
							(await this.#confirmAutoRedeem("anthropic", plan.actions, coordinator)))
					) {
						await this.#executeResetActions("anthropic", plan.actions, coordinator);
					}
				} catch (error) {
					logger.warn("claude-auto-reset: salvage listing failed", { error: String(error) });
				}
			}
		})()
			.catch(error => logger.warn("reset salvage sweep failed", { error: String(error) }))
			.finally(() => {
				coordinator.sweepInFlight = false;
			});
	}

	/**
	 * Export session to HTML.
	 * @param outputPath Optional output path
	 * @param useUserThemes Bundle the dark and light TUI themes selected in settings
	 */
	async exportToHtml(outputPath?: string, useUserThemes = false): Promise<string> {
		// Lazy import: the export module embeds the HTML template and pre-built
		// tool renderers as text; only `/export` should pay that load.
		const { exportSessionToHtml } = await import("../export/html");
		return exportSessionToHtml(this.sessionManager, this.state, {
			outputPath,
			palette: useUserThemes ? "theme" : "web",
			themeNames: useUserThemes
				? {
						dark: cfgThemeDark.get(this.settings),
						light: cfgThemeLight.get(this.settings),
					}
				: undefined,
		});
	}

	// =========================================================================
	// Utilities
	// =========================================================================

	/**
	 * Get text content of last assistant message.
	 * Consumed by the `/copy` command and by the yield tool's empty-last-turn
	 * guard (a data-less `useLastTurn` finalize is rejected when this is
	 * undefined, so a thinking-only turn cannot become a null-data run failure).
	 * @returns Trimmed text content, or undefined if no assistant message has text
	 */
	getLastAssistantText(): string | undefined {
		const lastAssistant = this.#getLastCopyCandidateAssistantMessage();
		if (!lastAssistant) return undefined;

		let text = "";
		for (const content of lastAssistant.content) {
			if (content.type === "text") {
				text += content.text;
			}
		}

		return text.trim() || undefined;
	}

	hasCopyCandidateAssistantMessage(): boolean {
		return this.#getLastCopyCandidateAssistantMessage() !== undefined;
	}

	#getLastCopyCandidateAssistantMessage(): AssistantMessage | undefined {
		for (let i = this.messages.length - 1; i >= 0; i--) {
			const message = this.messages[i];
			if (message.role !== "assistant") continue;

			const assistantMessage = message as AssistantMessage;
			// Skip aborted messages with no content
			if (assistantMessage.stopReason === "aborted" && assistantMessage.content.length === 0) continue;

			return assistantMessage;
		}

		return undefined;
	}
	/**
	 * Get text content of the most recent visible handoff message.
	 * Sessions created by older versions injected the handoff document as a
	 * custom message at the top of a fresh session; callers that copy the
	 * "last" message use this as a fallback while no assistant response exists.
	 */
	getLastVisibleHandoffText(): string | undefined {
		for (let i = this.messages.length - 1; i >= 0; i--) {
			const message = this.messages[i];
			if (message.role !== "custom") continue;

			const customMessage = message as CustomMessage;
			if (customMessage.customType !== "handoff" || !customMessage.display) continue;

			if (typeof customMessage.content === "string") {
				return customMessage.content.trim() || undefined;
			}

			let text = "";
			for (const content of customMessage.content) {
				if (content.type === "text") {
					text += content.text;
				}
			}
			return text.trim() || undefined;
		}

		return undefined;
	}

	/**
	 * Format the entire session as plain text for clipboard export: system
	 * prompt, model/thinking config, tool inventory, and the full transcript
	 * rendered with markdown role headings (`## User`, `## Assistant`,
	 * `### Tool Call`/`### Tool Result`).
	 */
	formatSessionAsText(): string {
		return formatSessionDumpText({
			messages: this.messages,
			systemPrompt: this.agent.state.systemPrompt,
			model: this.agent.state.model,
			thinkingLevel: this.thinkingLevel,
			tools: this.agent.state.tools,
			inlineToolDescriptors: this.agent.pruneToolDescriptions,
		});
	}

	/**
	 * Dump the current session's LLM-facing request context as JSON to a
	 * auto-named file in `os.tmpdir()`. This is the synchronous
	 * `convertToLlm`-boundary snapshot — system prompt, tools (wire schemas),
	 * thinking/service tier, and converted messages — with no network round-trip
	 * and no arming flag, so advisor/side requests cannot intercept it.
	 *
	 * The file persists on disk and may contain the same raw context/secrets
	 * as `/dump`; treat the path accordingly.
	 *
	 * @returns the written file path, or `undefined` when there are no messages.
	 */
	async dumpLlmRequestToTmpDir(): Promise<string | undefined> {
		const messages = this.messages;
		if (messages.length === 0) return undefined;
		const llmMessages = await this.convertMessagesToLlm(messages);
		const payload = {
			model: this.agent.state.model ?? null,
			thinkingLevel: this.thinkingLevel ?? null,
			serviceTier: this.#models.serviceTierEntry(),
			systemPrompt: this.agent.state.systemPrompt,
			tools: this.agent.state.tools.map(tool => ({
				name: tool.name,
				description: tool.description,
				parameters: toolWireSchema(tool),
				...(tool.strict !== undefined ? { strict: tool.strict } : {}),
				...(tool.customWireName ? { customWireName: tool.customWireName } : {}),
			})),
			messages: llmMessages,
		};
		const filePath = path.join(os.tmpdir(), `omp-llm-request-${Snowflake.next()}.json`);
		await Bun.write(filePath, `${JSON.stringify(payload, null, 2)}\n`);
		return filePath;
	}

	/**
	 * Enable or disable the advisor for this session. The setting is overridden for the session,
	 * and the runtime is started or stopped to match.
	 *
	 * @returns true when the advisor is actively running after the call.
	 */
	setAdvisorEnabled(enabled: boolean): boolean {
		return this.#advisors.setAdvisorEnabled(enabled);
	}

	/**
	 * Reactivate an advisor that resolved to `no_model` at construction because a
	 * discovery-backed provider had not populated the model registry yet. Awaits
	 * the initial background refresh, then rebuilds the advisor and emits
	 * `model_changed` so the status line reflects the now-active advisor. See #9010.
	 */
	async #retryInactiveAdvisorAfterModelDiscovery(): Promise<void> {
		if (this.#isDisposed || !this.#advisors.hasInactiveNoModelAdvisor()) return;
		await this.#modelRegistry.awaitBackgroundRefresh();
		if (this.#isDisposed) return;
		if (this.#advisors.retryAfterModelDiscovery()) this.#emit({ type: "model_changed" });
	}

	/**
	 * Run the retry.fallbackChains validation a `deferRetryFallbackValidation`
	 * session skipped at construction. Validation composes the catalog slice of
	 * every provider a chain names, so interactive startup runs it after the
	 * first frame; the header picks the warnings up via `config_warnings_changed`.
	 */
	validateRetryFallbackChains(): void {
		if (this.#isDisposed || !this.#fallbackChainValidationDeferred) return;
		this.#fallbackChainValidationDeferred = false;
		const warningCount = this.configWarnings.length;
		this.#recovery.validateRetryFallbackChains();
		if (this.configWarnings.length !== warningCount) this.#emit({ type: "config_warnings_changed" });
		void this.#revalidateFallbackChainsAfterModelDiscovery();
	}

	/**
	 * Re-run retry.fallbackChains validation once the initial background discovery
	 * settles. Startup validation suppresses "unknown model" warnings for
	 * config-declared discovery providers whose cold cache left the registry empty
	 * (#10048); this retracts the ones discovery resolved and surfaces any that
	 * stayed unknown. Uses {@link ModelRegistry.awaitInitialBackgroundRefresh}
	 * because the CLI starts that refresh right after the session is built, so an
	 * in-flight snapshot taken in the constructor would always miss it.
	 */
	async #revalidateFallbackChainsAfterModelDiscovery(): Promise<void> {
		if (this.#isDisposed || !this.#recovery.hasPendingDiscoveryDeferredFallbackValidation()) return;
		await this.#modelRegistry.awaitInitialBackgroundRefresh(this.#modelDiscoveryAbortController.signal);
		if (this.#isDisposed) return;
		if (this.#recovery.revalidateRetryFallbackChainsAfterDiscovery()) {
			this.#emit({ type: "config_warnings_changed" });
		}
	}

	/**
	 * Rebind the active model to its refreshed registry entry once the initial
	 * background discovery settles.
	 *
	 * Startup resolves the active model from the pre-discovery catalog snapshot
	 * (`main.ts` fires `refreshInBackground` only after the session is built), so
	 * a discovery-backed provider that re-clamps or splits a selector after the
	 * fact leaves the live model holding stale metadata. GitHub Copilot caps a
	 * tiered base selector (e.g. `github-copilot/gpt-5.6-sol`) to its default-tier
	 * context window and synthesizes a separate `-1m` sibling only during live
	 * discovery; the bundled base entry still carries the full long-context
	 * window, so a fresh session runs with the 1.05M window that contradicts the
	 * 400K catalog value until the user re-selects the same model. Re-look-up the
	 * active selector post-discovery and, when its context window changed, fold
	 * the refreshed spec into the live model. Same selector, so this is a metadata
	 * refresh with no provider-session reset; reconcile model-dependent tools and
	 * append-only state before `model_changed` notifies the status line and RPC
	 * subscribers. Issue #10488.
	 */
	async #rebindActiveModelAfterModelDiscovery(): Promise<void> {
		const boundAtStartup = this.model;
		if (this.#isDisposed || !boundAtStartup) return;
		if (typeof this.#modelRegistry.awaitInitialBackgroundRefresh !== "function") return;
		await this.#modelRegistry.awaitInitialBackgroundRefresh(this.#modelDiscoveryAbortController.signal);
		if (this.#isDisposed) return;
		// Only silently re-metadata the startup-bound selector: bail if the user
		// switched models while discovery was in flight.
		const current = this.model;
		if (!current || !modelsAreEqual(current, boundAtStartup)) return;
		const refreshed = this.#modelRegistry.find(current.provider, current.id);
		if (!refreshed || refreshed.contextWindow === current.contextWindow) return;
		this.agent.setModel(refreshed);
		await this.#reconcileModelDependentState(current, refreshed);
		if (this.#isDisposed) return;
		this.#emit({ type: "model_changed" });
	}

	/**
	 * Toggle the advisor setting and start/stop the runtime accordingly.
	 *
	 * @returns true when the advisor is actively running after the call.
	 */
	toggleAdvisorEnabled(): boolean {
		return this.#advisors.toggleAdvisorEnabled();
	}

	/**
	 * Replace the live advisor roster from an edited `WATCHDOG.yml` (the `/advisor
	 * configure` save path). Swaps the configs + shared baseline, then rebuilds the
	 * runtimes in place so the change applies without a restart. When the advisor is
	 * disabled the new configs are simply stored for the next enable.
	 *
	 * @returns the number of advisors active after the rebuild.
	 */
	applyAdvisorConfigs(
		advisors: AdvisorConfig[],
		sharedInstructions: string | undefined,
		sharedMaxNotesPerUpdate?: number,
	): number {
		return this.#advisors.applyAdvisorConfigs(advisors, sharedInstructions, sharedMaxNotesPerUpdate);
	}

	/**
	 * Refresh the project context prompt advisor sessions run against after
	 * context files change on `/reload-plugins`. Rebuilds live advisor runtimes so
	 * they stop evaluating turns against stale `AGENTS.md` instructions.
	 */
	setAdvisorContextPrompt(contextPrompt: string | undefined): void {
		this.#advisors.setContextPrompt(contextPrompt);
	}

	/**
	 * Refresh the memory backend instructions advisor sessions run against.
	 * Store-only: live advisors pick the new value up at their next runtime
	 * build (compaction, reset, toggle) — see `SessionAdvisors#setMemoryPrompt`.
	 */
	setAdvisorMemoryPrompt(memoryPrompt: string | undefined): void {
		this.#advisors.setMemoryPrompt(memoryPrompt);
	}

	/**
	 * Whether the advisor setting is enabled for this session.
	 */
	isAdvisorEnabled(): boolean {
		return this.#advisors.isAdvisorEnabled();
	}

	/**
	 * Whether a live advisor agent is attached to this session. True only when
	 * `advisor.enabled` is set for this session (subagents opt in per agent via
	 * frontmatter `advisor` / `task.agentAdvisor`) AND a model resolved for the
	 * `advisor` role — i.e. the actual runtime exists, not merely the setting.
	 * Drives the status-line badge and `/dump advisor`.
	 */
	isAdvisorActive(): boolean {
		return this.#advisors.isAdvisorActive();
	}

	/**
	 * The names of the tools available to advisors this session (the pool a
	 * `/advisor configure` editor lists). The advisor is a full agent, so this is the
	 * full built tool set; a tool whose optional factory returns null (e.g. lsp with
	 * no servers) is absent.
	 */
	getAdvisorAvailableToolNames(): string[] {
		return this.#advisors.getAdvisorAvailableToolNames();
	}

	/**
	 * The live advisor `Agent`, or `undefined` when no advisor runtime is
	 * attached. Surfaced for diagnostics (`/dump advisor` already serializes
	 * its transcript via {@link formatAdvisorHistoryAsText}) and so callers can
	 * verify the advisor inherits the session's provider-shaping options
	 * (`streamFn`, `promptCacheKey`, `providerSessionState`, ...).
	 */
	getAdvisorAgent(): Agent | undefined {
		return this.#advisors.getAdvisorAgent();
	}

	/** WATCHDOG.yml problems from startup discovery; shown by the UI once it is ready. */
	getAdvisorConfigWarnings(): readonly string[] {
		return this.#advisors.configWarnings;
	}

	/**
	 * Lightweight advisor status for the status line: returns just the configured
	 * flag and per-advisor name/status without computing token/cost breakdowns.
	 * Avoids re-tokenizing the advisor transcript on every render frame.
	 */
	getAdvisorStatusOverview(): { configured: boolean; advisors: AdvisorStatusOverviewEntry[] } {
		return this.#advisors.getAdvisorStatusOverview();
	}

	/** Return cumulative cost recorded for the current session's advisor activity. */
	getAdvisorCost(): number {
		return this.#advisors.getAdvisorCost();
	}

	/**
	 * Begin backfilling advisor spend recorded before this resume, off the
	 * critical path. A large transcript would otherwise block startup while
	 * the file is streamed; the status-line total hydrates once the scan
	 * settles.
	 */
	beginInitialAdvisorCostRestore(): void {
		let stale = false;
		const unregisterSessionChange = this.registerSessionChangeCallback(() => {
			stale = true;
		});
		const snapshot = this.#advisors.beginCostRestoreSnapshot();
		const providersBySlug = new Map<string, Set<string>>();
		this.#advisorCostRestore = loadAdvisorTranscriptCosts(this.sessionFile, {
			beforeSnapshot: snapshot.ready,
			onSnapshot: snapshot.release,
			shouldContinue: () => !stale && !this.isDisposed,
			providersBySlug,
		})
			.then(costs => {
				if (stale || this.isDisposed) return;
				this.restoreInitialAdvisorCosts(costs, snapshot.costsAtSnapshot, providersBySlug);
				this.#emit({ type: "advisor_cost_changed" });
			})
			.catch(err => logger.debug("advisor cost restore failed", { err: String(err) }))
			.finally(() => {
				snapshot.release();
				unregisterSessionChange();
			});
	}

	/** Resolves once {@link beginInitialAdvisorCostRestore}'s scan has settled. */
	get advisorCostRestore(): Promise<void> {
		return this.#advisorCostRestore;
	}

	/**
	 * Restore persisted advisor spend plus the process-local delta billed after
	 * `costsAtSnapshot`. The recorder barrier fixes every transcript's byte length
	 * after capturing that baseline, so a turn completed while the scan runs is added
	 * exactly once.
	 */
	restoreInitialAdvisorCosts(
		costs: ReadonlyMap<string, number>,
		costsAtSnapshot: ReadonlyMap<string, number> = new Map(),
		providersBySlug?: ReadonlyMap<string, ReadonlySet<string>>,
	): void {
		this.#advisors.restoreInitialCost(costs, costsAtSnapshot, providersBySlug);
	}
	/** Return whether any active or configured advisor is running on an OAuth/subscription model. */
	isAdvisorUsingSubscription(): boolean {
		return this.#advisors.isUsingSubscription();
	}
	/**
	 * Return structured advisor stats for the status command and TUI panel.
	 */
	getAdvisorStats(): AdvisorStats {
		return this.#advisors.getAdvisorStats();
	}

	/** Per-advisor supervision path, authority, and arm counts for the live roster. */
	getAdvisorSupervisionReport(): { name: string; report: AdvisorSupervisionPipelineReport }[] {
		return this.#advisors.getAdvisorSupervisionReport();
	}

	/**
	 * Format a concise advisor status line for ACP/text output.
	 */
	formatAdvisorStatus(): string {
		return this.#advisors.formatAdvisorStatus();
	}

	/**
	 * Format the advisor agent's own transcript (its system prompt, config,
	 * tools, and the markdown deltas it received plus its thinking/advise/read
	 * calls) as plain text — the advisor-side equivalent of
	 * {@link formatSessionAsText}. Returns null when no advisor is active.
	 */
	formatAdvisorHistoryAsText(options?: { compact?: boolean }): string | null {
		return this.#advisors.formatAdvisorHistoryAsText(options);
	}

	// =========================================================================
	// Extension System
	// =========================================================================

	/**
	 * Check if extensions have handlers for a specific event type.
	 */
	hasExtensionHandlers(eventType: string): boolean {
		return this.#extensionRunner?.hasHandlers(eventType) ?? false;
	}

	/**
	 * Get the extension runner (for setting UI context and error handlers).
	 */
	get extensionRunner(): ExtensionRunner | undefined {
		return this.#extensionRunner;
	}

	/**
	 * Consume any pending Anthropic fallback credit handle for the next retry turn.
	 */
	consumeActiveFallbackCreditRedemption(targetModel?: Model): AnthropicFallbackCreditHandle | undefined {
		return this.#recovery.consumeActiveFallbackCreditRedemption(targetModel);
	}
}
