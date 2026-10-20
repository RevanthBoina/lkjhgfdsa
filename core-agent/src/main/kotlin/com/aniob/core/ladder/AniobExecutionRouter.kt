package com.aniob.core.ladder

import com.aniob.core.domain.AniobAction
import com.aniob.core.domain.AniobScreenState
import com.aniob.core.domain.SemanticTarget
import com.aniob.core.router.AniobAutoRouter
import com.aniob.core.router.RouteDecision
import com.aniob.core.router.RouteTarget
import com.aniob.core.embedding.AniobEmbeddingStore
import com.aniob.core.skills.AniobSemanticSkillMatcher
import com.aniob.core.skills.AniobSkill
import com.aniob.core.skills.AniobSkillMatcher
import com.aniob.core.tools.AniobReplayEngine
import com.aniob.core.tools.DevicePowerState

/**
 * Execution Ladder Coordinator.
 * Sequentially queries:
 * INTENT -> FASTPATH -> SKILL -> LOCAL_SLM -> OMNIROUTE_CLOUD
 */
class AniobExecutionRouter(
    private val replayEngine: AniobReplayEngine = AniobReplayEngine(),
    private val skillMatcher: AniobSkillMatcher = AniobSkillMatcher(),
    private val semanticSkillMatcher: AniobSemanticSkillMatcher? = null,
    private val planningAgent: AniobPlanningAgent? = null,
    private val memoryStore: AniobEmbeddingStore? = null
) {
    /** Shared with the learning pipeline so hydration and replay hit the same store. */
    val fastPathEngine: AniobReplayEngine get() = replayEngine

    /**
     * UX-4: the Trust Center's FastPath switch is REAL — when off, the replay lookup is skipped
     * entirely, so a disabled toggle provably yields zero replay hits.
     */
    var fastPathEnabled: Boolean = true

    /**
     * Research ablation switch for the step-0 intent-shortcut lookup. Off means the ladder never
     * resolves `AniobIntentResolver` and every step goes through the model/skill rungs — the
     * BASELINE condition. Defaults to on, which is the shipping behaviour.
     */
    var intentShortcutsEnabled: Boolean = true

    /**
     * Remember-replay switch (the FULL_HUMAN_SPEED condition). On means the zero-LLM cache is
     * consulted right after the intent shortcut and before any model rung.
     */
    var rememberReplayEnabled: Boolean = false

    /**
     * Cache lookup supplied by the app layer: (goal, live screen) -> replayable actions, or null
     * when this exact transition was never solved. Kept as a callback so the ladder stays pure.
     */
    var rememberLookup: ((String, AniobScreenState) -> List<AniobAction>?)? = null

    /**
     * App-name resolver supplied by the app layer: (goal) -> the app the task names, resolved
     * against the installed-app catalog. Turns "open Clock and set an alarm" into a direct launch
     * instead of a model round trip. Gated by [intentShortcutsEnabled]: it is the same class of
     * zero-model pre-resolution as the system-intent shortcut.
     */
    var appLaunchResolver: ((String) -> AppLaunchTarget?)? = null

    /** UX-5: skills the user disabled are skipped by both matchers. */
    private var disabledSkills: Set<String> = emptySet()

    fun setDisabledSkills(names: Set<String>) {
        disabledSkills = names.toSet()
    }

    fun isSkillDisabled(name: String): Boolean = disabledSkills.contains(name)

    /** Wires a FastPath lookup callback for use outside the ladder (tracker/learning tests). */
    fun lookup(taskSignature: String): AniobReplayEngine.ReplayTrajectory? =
        if (fastPathEnabled) replayEngine.findTrajectory(taskSignature) else null

    sealed class ExecutionPlanResult {
        data class DirectIntent(val shortcut: ResolvedIntentShortcut, val reason: String) : ExecutionPlanResult()
        /**
         * Step 0 opens a named app directly. The package came from the installed-app catalog, so
         * the step costs no model call; the next step plans on the app's own screen.
         */
        data class AppLaunch(val packageName: String, val appName: String, val reason: String) : ExecutionPlanResult()
        /**
         * A verified transition replayed from the remember cache. The list is dispatched in order
         * without any model call, so it costs 0 LLM requests.
         */
        data class RememberReplay(val actions: List<AniobAction>, val reason: String) : ExecutionPlanResult()
        data class FastPathStep(val action: AniobAction, val reason: String) : ExecutionPlanResult()
        data class SkillStepExecution(val action: AniobAction, val skill: AniobSkill, val reason: String) : ExecutionPlanResult()
        data class ModelDispatch(
            val decision: RouteDecision,
            val progressSummary: String? = null,
            val progress: TaskProgress? = null
        ) : ExecutionPlanResult()
        data class CannotProceed(val reason: String) : ExecutionPlanResult()
    }

    fun planStep(
        taskPrompt: String,
        screenState: AniobScreenState,
        stepIndex: Int,
        taskSignature: String,
        powerState: DevicePowerState,
        installedModelId: String? = null,
        lastLocalFailCount: Int = 0,
        isModelFileMissing: Boolean = false,
        previousProgress: TaskProgress? = null,
        userRoutingMode: String = "auto",
        lastObservedResult: String? = null
    ): ExecutionPlanResult {
        // Step 0: Direct Intent Shortcut (0ms LLM). The ablation switch gates the lookup itself.
        if (stepIndex == 0 && intentShortcutsEnabled) {
            val intentShortcut = AniobIntentResolver.resolve(taskPrompt)
            if (intentShortcut != null) {
                return ExecutionPlanResult.DirectIntent(
                    shortcut = intentShortcut,
                    reason = "Direct intent shortcut resolved in <15ms"
                )
            }
        }

        // Step 0.25: App launch (0 LLM). The task names an app the catalog already knows, so the
        // first action is a single OpenApp intent instead of a model round trip that would have to
        // decide the same thing from a screen full of icons.
        if (stepIndex == 0 && intentShortcutsEnabled) {
            val launch = runCatching { appLaunchResolver?.invoke(taskPrompt) }.getOrNull()
            if (launch != null) {
                return ExecutionPlanResult.AppLaunch(
                    packageName = launch.packageName,
                    appName = launch.appName,
                    reason = "App shortcut: '${launch.appName}' is installed (0 LLM calls)"
                )
            }
        }

        // Step 0.5: Remember replay (0 LLM). Sits after the intent shortcut and before every
        // model rung, exactly where the ablation condition expects the cache to be consulted.
        if (rememberReplayEnabled) {
            val replay = rememberLookup?.invoke(taskPrompt, screenState)
            if (!replay.isNullOrEmpty()) {
                return ExecutionPlanResult.RememberReplay(
                    actions = replay,
                    reason = "Remember cache hit for ${screenState.packageName} (0 LLM calls)"
                )
            }
        }

        // Step 1: FastPath trajectory replay with fingerprint verification (0ms LLM, 0 tokens)
        // UX-4: the FastPath switch isn't decorative — OFF skips the lookup entirely.
        val trajectory = if (fastPathEnabled) replayEngine.findTrajectory(taskSignature) else null
        if (trajectory != null) {
            val cachedAction = replayEngine.nextAction(trajectory, stepIndex, screenState)
            if (cachedAction != null) {
                // If the action names an element not currently on screen, self-heal via semantic token overlap or scroll
                val target = cachedAction.semanticTarget()
                if (target is SemanticTarget.SomIndex && screenState.findNodeById(target.index) == null) {
                    val fallbackNode = findSemanticFallbackNode(taskPrompt, screenState)
                    if (fallbackNode != null) {
                        return ExecutionPlanResult.FastPathStep(
                            action = AniobAction.Tap(SemanticTarget.SomIndex(fallbackNode.id)),
                            reason = "FastPath fallback matched node ${fallbackNode.id} by semantic token overlap"
                        )
                    }
                    if (screenState.nodes.any { it.isScrollable }) {
                        return ExecutionPlanResult.FastPathStep(
                            action = AniobAction.Swipe(
                                direction = com.aniob.core.domain.SwipeDirection.DOWN,
                                distancePx = 600,
                                thought = "Scroll down to reveal off-screen FastPath target ${target.index}"
                            ),
                            reason = "FastPath target ${target.index} off-screen; scrolling to reveal"
                        )
                    }
                }
                return ExecutionPlanResult.FastPathStep(
                    action = cachedAction,
                    reason = "FastPath verified replay step $stepIndex"
                )
            }
        }

        // Step 2: Tier 1.5 YAML or Semantic Skill Match
        val skillMatch = semanticSkillMatcher?.findBestSkill(taskPrompt, disabledSkills) ?: skillMatcher.match(taskPrompt, disabledSkills)
        // UX-5: a disabled or draft skill never participates, so user routing and quality switches are real.
        val skillUsable = skillMatch.skill != null &&
            skillMatch.skill.status == com.aniob.core.skills.SkillStatus.ACTIVE &&
            !skillMatch.skill.isDraft &&
            !disabledSkills.contains(skillMatch.skill.name)
        if (skillMatch.matched && skillUsable) {
            val skill = skillMatch.skill!!
            val step = skill.steps.getOrNull(stepIndex)
            if (step != null) {
                val action = step.toAniobAction()
                val target = action.semanticTarget()
                if (target is SemanticTarget.SomIndex && screenState.findNodeById(target.index) == null) {
                    val fallbackNode = findSemanticFallbackNode(taskPrompt, screenState)
                    if (fallbackNode != null) {
                        return ExecutionPlanResult.SkillStepExecution(
                            action = AniobAction.Tap(SemanticTarget.SomIndex(fallbackNode.id)),
                            skill = skill,
                            reason = "Skill fallback matched node ${fallbackNode.id} by semantic token overlap"
                        )
                    }
                    if (screenState.nodes.any { it.isScrollable }) {
                        return ExecutionPlanResult.SkillStepExecution(
                            action = AniobAction.Swipe(
                                direction = com.aniob.core.domain.SwipeDirection.DOWN,
                                distancePx = 600,
                                thought = "Scroll down to reveal off-screen skill target ${target.index}"
                            ),
                            skill = skill,
                            reason = "Skill target ${target.index} off-screen; scrolling to reveal"
                        )
                    }
                }
                return ExecutionPlanResult.SkillStepExecution(
                    action = action,
                    skill = skill,
                    reason = skillMatch.reason
                )
            }
        }

        // Context Retrieval via Memory Store RAG
        var retrievedContext: String? = null
        if (memoryStore != null) {
            val qVec = AniobEmbeddingStore.generatePseudoEmbedding(taskPrompt)
            val memories = memoryStore.search(qVec, topK = 1, threshold = 0.5f)
            if (memories.isNotEmpty()) {
                retrievedContext = memories.first().text
            }
        }

        // Planning Progress condensation: prefrontal-cortex summary replaces the full
        // interleaved observation history in the LLM prompt (~80% token reduction).
        val previousOp = lastObservedResult ?: if (stepIndex > 0) "Step ${stepIndex - 1} executed" else null
        val progress = planningAgent?.updateProgress(
            userInstruction = taskPrompt,
            previousOperation = previousOp,
            previousProgress = previousProgress,
            focusContent = retrievedContext
        )

        // Step 3 & 4: AutoRouter decides between Local SLM and Omniroute Cloud
        val decision = AniobAutoRouter.decideRoute(
            taskPrompt = taskPrompt,
            screenState = screenState,
            powerState = powerState,
            hasFastPathHit = false,
            isIntentShortcut = false,
            installedModelId = installedModelId,
            lastLocalFailCount = lastLocalFailCount,
            isModelFileMissing = isModelFileMissing,
            userRoutingMode = userRoutingMode
        )

        if (decision.target == RouteTarget.CANNOT_PROCEED) {
            return ExecutionPlanResult.CannotProceed(decision.reason)
        }

        return ExecutionPlanResult.ModelDispatch(
            decision = decision,
            progressSummary = progress?.summary,
            progress = progress
        )
    }

    /**
     * Stopword-filtered token-salience fallback resolver.
     * Prevents false-positive substring matches on short stop-words ("on", "in", "to", "a")
     * and requires the candidate node to be visible, enabled, and interactive.
     */
    internal fun findSemanticFallbackNode(
        taskPrompt: String,
        screenState: AniobScreenState
    ): com.aniob.core.domain.AniobNode? {
        val promptTokens = extractSalientTokens(taskPrompt)
        if (promptTokens.isEmpty()) return null

        var bestNode: com.aniob.core.domain.AniobNode? = null
        var bestScore = 0.0

        for (node in screenState.nodes) {
            if (!node.isVisibleToUser || !node.isEnabled || (!node.isClickable && !node.isEditable)) continue
            val label = node.text.ifBlank { node.contentDescription }
            if (label.isBlank()) continue
            val nodeTokens = extractSalientTokens(label)
            if (nodeTokens.isEmpty()) continue

            val intersection = nodeTokens.count { it in promptTokens }
            if (intersection == 0) continue

            val recall = intersection.toDouble() / nodeTokens.size.toDouble()
            val precision = intersection.toDouble() / promptTokens.size.toDouble()
            val f1 = (2.0 * precision * recall) / (precision + recall)
            if (recall >= 0.5 && f1 > bestScore) {
                bestScore = f1
                bestNode = node
            }
        }
        return bestNode
    }

    private fun extractSalientTokens(text: String): Set<String> =
        text.lowercase()
            .split(TOKEN_SPLIT_REGEX)
            .filter { it.length >= 3 && it !in STOPWORDS }
            .toSet()

    companion object {
        private val TOKEN_SPLIT_REGEX = Regex("\\W+")
        private val STOPWORDS = setOf(
            "the", "and", "for", "with", "from", "into", "onto", "tap", "click",
            "open", "press", "button", "app", "please", "can", "you"
        )
    }
}
