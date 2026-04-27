import json
import logging
from typing import AsyncGenerator, Iterable, List, Optional

from openai import AsyncOpenAI
from core.config import get_settings
from services.retrieval import RetrievedChunk

logger = logging.getLogger(__name__)

SYSTEM_PROMPT = """You are 'Contract AI', a precise Legal AI Assistant specialized in contract analysis and RFI responses.

STRICT GROUNDING RULES:
1.  **Context-Only**: Your answer must be based EXCLUSIVELY on the provided "CONTEXT FROM DOCUMENTS". 
2.  **Refusal Mode**: If the answer is not present in the context, or the evidence is insufficient, explicitly state: "I am sorry, but the provided documents do not contain enough information to answer [query]."
3.  **Citations**: Cite every factual claim using: [Document: Filename, Page: X]. Place citations next to the specific detail.
4.  **Extractive Accuracy**: For legal clauses, stay very close to the source wording.
5.  **General Mode**: If no documents are linked yet, greet the user naturally and explain your specific capabilities (Contract Analysis, Risk Detection, RFI Support). Use your general legal knowledge to explain concepts, but state that you need a contract to provide specific analysis.

RESPONSE STRUCTURE:
You must follow this EXACT structure for every response:
1.  **Thinking Block**: Open with `<thinking>`. Inside, perform your internal "Critique" and plan your answer. Match facts to sources. 
    - **CRITICAL**: The thinking block is for YOUR INTERNAL LOGIC ONLY. Do NOT write your final greeting or final answer here.
2.  **Final Answer**: Close the thinking block with `</thinking>`. Then, on a new line, provide your direct, professional response to the user in Markdown format.

SELF-VERIFICATION PROTOCOL (Inside <thinking>):
- List factual claims.
- Match each to a specific SOURCE in the context.
- If no direct support exists, remove the claim or trigger Refusal Mode.
"""

USER_PROMPT_TEMPLATE = """USER NAME: {user_name}

CONTEXT FROM DOCUMENTS:
{context_text}

USER QUERY: 
{query}
"""

# ── LLM Service ──────────────────────────────────────────────────────────────

class LLMService:
    def __init__(self):
        settings = get_settings()
        self.client = AsyncOpenAI(
            base_url=settings.SGLANG_BASE_URL,
            api_key=settings.SGLANG_API_KEY,
        )
        self.model = settings.SGLANG_INTENT_MODEL

    def _format_context(self, chunks: List[RetrievedChunk]) -> str:
        """Combine multiple chunks into context string with clear source markers."""
        if not chunks:
            return "GENERAL MODE: No documents linked yet. Answer greetings or general legal questions using your internal knowledge, but do not hallucinate details about specific user projects."
            
        context_parts = []
        for i, chunk in enumerate(chunks, 1):
            part = (
                f"SOURCE [{i}]:\n"
                f"Filename: {chunk.filename}\n"
                f"Section: {chunk.section or 'N/A'}\n"
                f"Page: {chunk.page}\n"
                f"Content: {chunk.text}\n"
                f"--------------------------"
            )
            context_parts.append(part)
        return "\n".join(context_parts)

    async def generate_response_stream(
        self,
        query: str,
        chunks: List[RetrievedChunk],
        user_name: str = "User"
    ) -> AsyncGenerator[str, None]:
        """
        Generate a token-by-token streaming response.
        """
        context_text = self._format_context(chunks)
        user_content = USER_PROMPT_TEMPLATE.format(
            user_name=user_name,
            context_text=context_text,
            query=query
        )

        try:
            stream = await self.client.chat.completions.create(
                model=self.model,
                messages=[
                    {"role": "system", "content": SYSTEM_PROMPT},
                    {"role": "user", "content": user_content},
                ],
                stream=True,
                temperature=0.4, # Improved variance for natural flow
                max_tokens=2048,
            )

            async for chunk in stream:
                token = chunk.choices[0].delta.content
                if token:
                    yield token

        except Exception as e:
            logger.error(f"Error calling LLM: {e}")
            yield f"\n\n[System Error: Connection to GPU server failed - {str(e)}]"

    async def generate_thought_and_answer(
        self,
        query: str,
        chunks: List[RetrievedChunk],
        user_name: str = "User"
    ) -> dict:
        """
        Non-streaming legacy version (kept for sync operations).
        Parses reasoning out of <thinking> tags.
        """
        context_text = self._format_context(chunks)
        user_content = USER_PROMPT_TEMPLATE.format(
            user_name=user_name,
            context_text=context_text,
            query=query
        )

        try:
            response = await self.client.chat.completions.create(
                model=self.model,
                messages=[
                    {"role": "system", "content": SYSTEM_PROMPT},
                    {"role": "user", "content": user_content},
                ],
                temperature=0.2,
                max_tokens=2048,
            )
            
            full_text = response.choices[0].message.content or ""
            
            # Simple Tag Parser
            thinking = ""
            answer = full_text
            
            if "<thinking>" in full_text and "</thinking>" in full_text:
                parts = full_text.split("</thinking>", 1)
                thinking = parts[0].replace("<thinking>", "").strip()
                answer = parts[1].strip()
            
            return {"thinking": thinking, "answer": answer}

        except Exception as e:
            logger.error(f"Error calling LLM: {e}")
            return {"thinking": "", "answer": "I'm sorry, I'm having trouble connecting to my engine."}
