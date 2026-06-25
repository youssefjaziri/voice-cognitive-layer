"""High-level orchestration service that coordinates the intelligent response generation pipeline."""
import logging
import random
import time
from typing import Optional
from ..schemas.metadata import SpeechMetadata
from ..schemas.orchestration import OrchestrationResponse
from ..schemas.intent import IntentCategory
from ..intent.detector import IntentDetector
from ..quality.analyzer import SpeechQualityAnalyzer
from ..prompts.builder import PromptBuilder
from ..validation.validator import ResponseValidator, FallbackHandler
from ..orchestration.context.manager import ContextManager
from ..intent.categories import RECOMMENDED_TEMPERATURES
from .llm_service import LLMService
from ..routing.model_router import ModelRouter
from ..knowledge.retriever import KnowledgeRetriever
from ..navigation.location_mapper import extract_navigation_goal


logger = logging.getLogger(__name__)

# Predefined responses for fast-tier intents. TinyLlama (1.1B) cannot
# reliably follow system prompt constraints and generates roleplay scripts.
# These categories need short, predictable answers — not LLM reasoning.
_CANNED = {
    IntentCategory.GREETING: [
        "Hello! How can I help you today?",
        "Hi there! What can I do for you?",
        "Good day! How may I assist you?",
        "Welcome to ISR! How can I help?",
    ],
    IntentCategory.ACKNOWLEDGEMENT: [
        "You're welcome! Let me know if you need anything else.",
        "Happy to help! Is there anything else I can do for you?",
        "Of course! Feel free to ask if you need further assistance.",
        "Glad I could help! Have a great day.",
    ],
}


class OrchestrationService:
    """Main orchestration service for intelligent response generation."""

    def __init__(self,
                 context_manager: Optional[ContextManager] = None,
                 intent_detector: Optional[IntentDetector] = None,
                 quality_analyzer: Optional[SpeechQualityAnalyzer] = None,
                 prompt_builder: Optional[PromptBuilder] = None,
                 response_validator: Optional[ResponseValidator] = None,
                 llm_service: Optional[LLMService] = None):

        self.context_manager = context_manager or ContextManager()
        self.intent_detector = intent_detector or IntentDetector()
        self.quality_analyzer = quality_analyzer or SpeechQualityAnalyzer()
        self.response_validator = response_validator or ResponseValidator()
        self.llm_service = llm_service or LLMService()
        self.model_router = ModelRouter()

        # RAG retriever — initialised once at startup; gracefully disabled if
        # Ollama is unreachable or the knowledge base file is missing.
        _rag = KnowledgeRetriever()
        self.prompt_builder = prompt_builder or PromptBuilder(knowledge_retriever=_rag)

    async def process_transcription(self,
                                    user_id: str,
                                    transcription: str,
                                    metadata: SpeechMetadata,
                                    user_system_prompt: Optional[str] = None) -> OrchestrationResponse:
        """Process a transcription through the full orchestration pipeline."""

        pipeline_times = {}
        start_time = time.time()

        try:
            # Stage 1: Intent Detection
            stage_start = time.time()
            intent = await self.intent_detector.detect(transcription, metadata)
            pipeline_times["intent_detection"] = (time.time() - stage_start) * 1000

            # Stage 2: Context Retrieval
            stage_start = time.time()
            context = self.context_manager.get_context(user_id)
            pipeline_times["context_retrieval"] = (time.time() - stage_start) * 1000

            # Stage 3: Quality Analysis
            stage_start = time.time()
            quality = self.quality_analyzer.analyze(metadata)
            pipeline_times["quality_analysis"] = (time.time() - stage_start) * 1000

            # Stage 4: Prompt Building (includes RAG retrieval)
            stage_start = time.time()
            system_prompt, user_prompt, rag_context = self.prompt_builder.build_full_prompt(
                transcription, intent, metadata, context, quality
            )

            # Override with user-provided system prompt if given
            if user_system_prompt:
                system_prompt = user_system_prompt

            pipeline_times["prompt_building"] = (time.time() - stage_start) * 1000

            # Stage 5: LLM Generation (model router selects model + optional temp override)
            stage_start = time.time()

            # Fast-tier shortcut: return a predefined response for greeting and
            # acknowledgement without any LLM call. TinyLlama cannot follow
            # system prompt constraints reliably for these simple intents.
            if intent.category in _CANNED and not user_system_prompt:
                llm_response = random.choice(_CANNED[intent.category])
                pipeline_times["llm_generation"] = (time.time() - stage_start) * 1000
                pipeline_times["response_validation"] = 0.0
                self.context_manager.add_turn(
                    user_id, transcription, llm_response,
                    intent=intent.category.value, quality_score=quality.overall_score
                )
                total_time = (time.time() - start_time) * 1000
                return OrchestrationResponse(
                    user_text=transcription,
                    llm_response=llm_response,
                    intent=intent.category,
                    intent_confidence=intent.confidence,
                    speech_quality_score=quality.overall_score,
                    speech_quality_level=quality.quality_level,
                    metadata=metadata,
                    routed_model="canned",
                    rag_used=False,
                    processing_time_ms=total_time,
                    pipeline_stages=pipeline_times,
                )

            temperature = self._select_temperature(intent, quality)
            routed_model, temp_override = self.model_router.select(intent, quality)
            if temp_override is not None:
                temperature = temp_override
            logger.info(
                f"[MODEL_ROUTER] intent={intent.category.value} "
                f"quality={quality.quality_level} → model={routed_model}"
            )

            llm_response = await self._call_llm(user_prompt, system_prompt, temperature, routed_model)
            pipeline_times["llm_generation"] = (time.time() - stage_start) * 1000

            # Stage 6: Response Validation
            stage_start = time.time()
            validation = self.response_validator.validate(llm_response, intent)

            if not validation.is_valid:
                llm_response = self._apply_fallback(validation, intent)

            pipeline_times["response_validation"] = (time.time() - stage_start) * 1000

            # Update context
            self.context_manager.add_turn(
                user_id,
                transcription,
                llm_response,
                intent=intent.category.value,
                quality_score=quality.overall_score
            )

            total_time = (time.time() - start_time) * 1000

            nav_goal = None
            if intent.category == IntentCategory.NAVIGATION:
                nav_goal = extract_navigation_goal(transcription)

            return OrchestrationResponse(
                user_text=transcription,
                llm_response=llm_response,
                intent=intent.category,
                intent_confidence=intent.confidence,
                speech_quality_score=quality.overall_score,
                speech_quality_level=quality.quality_level,
                metadata=metadata,
                routed_model=routed_model,
                rag_used=bool(rag_context),
                rag_context=rag_context or None,
                navigation_goal=nav_goal,
                processing_time_ms=total_time,
                pipeline_stages=pipeline_times
            )

        except Exception as e:
            logger.error(f"Error in orchestration pipeline: {e}", exc_info=True)

            # Return graceful fallback
            return OrchestrationResponse(
                user_text=transcription,
                llm_response=FallbackHandler.get_fallback("generic"),
                intent=IntentCategory.CONVERSATIONAL,
                intent_confidence=0.0,
                speech_quality_score=0.0,
                metadata=metadata,
                processing_time_ms=(time.time() - start_time) * 1000,
                pipeline_stages=pipeline_times
            )

    async def process_message(self,
                             user_id: str,
                             user_text: str,
                             user_system_prompt: Optional[str] = None) -> OrchestrationResponse:
        """Process a text message (no speech metadata)."""

        # Create minimal metadata for text-only input
        metadata = SpeechMetadata(
            vad_confidence=1.0,
            speech_duration=1.0,
            silence_duration=0.0,
            prebuffer_duration=0.0,
            transcription_confidence=1.0
        )

        return await self.process_transcription(user_id, user_text, metadata, user_system_prompt)

    def _select_temperature(self, intent, quality) -> float:
        """Select appropriate temperature based on intent and quality."""

        base_temp = RECOMMENDED_TEMPERATURES.get(intent.category, 0.2)

        # Reduce temperature for low-quality speech
        if quality.quality_level in ["poor", "unintelligible"]:
            base_temp = min(base_temp, 0.1)

        # Low confidence intent → be more conservative
        if intent.confidence < 0.5:
            base_temp = min(base_temp, 0.15)

        return base_temp

    async def _call_llm(self, prompt: str, system: str, temperature: float,
                        model: str = None) -> str:
        """Call LLM with given parameters and optional model override."""
        return await self._run_async(
            self.llm_service.message_to_llm_text,
            prompt,
            system,
            temperature,
            model,
        )

    async def _run_async(self, func, *args, **kwargs):
        """Run synchronous function asynchronously."""
        import asyncio
        return await asyncio.to_thread(func, *args, **kwargs)

    def _apply_fallback(self, validation, intent) -> str:
        """Apply fallback response based on validation results."""

        if not validation.issues:
            return FallbackHandler.get_fallback("generic")

        primary_issue = validation.issues[0]

        if "too short" in primary_issue.lower():
            return FallbackHandler.get_fallback("too_short")
        elif "too long" in primary_issue.lower():
            return FallbackHandler.get_fallback("too_long")
        elif "incoherent" in primary_issue.lower():
            return FallbackHandler.get_fallback("incoherent")
        elif "hallucination" in primary_issue.lower():
            return FallbackHandler.get_fallback("hallucination")
        elif "format" in primary_issue.lower():
            return FallbackHandler.get_fallback("format_issue")
        else:
            return FallbackHandler.get_fallback("generic")
