import copy
import asyncio
import hashlib
import json
import os
from anthropic import AsyncAnthropic
try:
    from openai import AsyncOpenAI
except Exception:
    AsyncOpenAI = None

try:
    import tiktoken
except Exception:
    tiktoken = None
try:
    from transformers import AutoTokenizer
except Exception:
    AutoTokenizer = None

class MemoryCompactor:
    """
    Acts as the 'Snip' layer. 
    It evaluates old conversations and uses a cheaper, faster LLM
    to generate an extremely dense summary block to replace them.
    """
    def __init__(
        self,
        model="claude-3-5-haiku-latest",
        *,
        provider: str = None,
        api_base_url: str = None,
        local_tokenizer_path: str = None,
    ):
        self.provider = self._resolve_provider(provider, model)
        self.model = self._resolve_model_name(model)
        self.api_base_url = api_base_url or os.environ.get("OPENAI_BASE_URL", "")
        self.local_tokenizer_path = (
            local_tokenizer_path
            or os.environ.get("CODECLAW_LOCAL_TOKENIZER_PATH", "")
            or os.environ.get("CODECLAW_LOCAL_TOKENIZER_MODEL", "")
        )
        self.client = self._build_client()
        self.token_encoding_name = "cl100k_base"
        self.local_tokenizer = self._resolve_local_tokenizer()
        self.token_encoder = self._resolve_token_encoder()
        self.token_count_cache = {}
        self.token_count_cache_limit = 24

    def _resolve_provider(self, provider: str, model: str) -> str:
        resolved = str(
            provider
            or os.environ.get("CODECLAW_MODEL_PROVIDER", "")
            or ""
        ).strip().lower()
        if resolved in {"openai", "anthropic"}:
            return resolved
        model_name = str(model or "").strip().lower()
        if model_name.startswith(("gpt-", "o1", "o3", "o4")):
            return "openai"
        return "anthropic"

    def _resolve_model_name(self, model: str) -> str:
        candidate = str(model or "").strip()
        if self.provider == "openai":
            if not candidate or candidate.startswith("claude-"):
                return os.environ.get("CODECLAW_OPENAI_COMPACTOR_MODEL", "") or os.environ.get("OPENAI_MODEL", "") or "gpt-4o-mini"
            return candidate
        if not candidate:
            return "claude-3-5-haiku-latest"
        return candidate

    def _build_client(self):
        if self.provider == "openai":
            if AsyncOpenAI is None:
                return None
            kwargs = {}
            if self.api_base_url:
                kwargs["base_url"] = self.api_base_url
            return AsyncOpenAI(**kwargs)
        return AsyncAnthropic()

    def _resolve_local_tokenizer(self):
        if AutoTokenizer is None or not self.local_tokenizer_path:
            return None
        try:
            return AutoTokenizer.from_pretrained(
                self.local_tokenizer_path,
                local_files_only=True,
                use_fast=True,
            )
        except Exception:
            return None

    def _resolve_token_encoder(self):
        if tiktoken is None:
            return None
        try:
            return tiktoken.get_encoding(self.token_encoding_name)
        except Exception:
            try:
                return tiktoken.get_encoding("cl100k_base")
            except Exception:
                return None

    def token_estimator_mode(self) -> str:
        local_mode = self._local_estimator_mode()
        if self.provider == "anthropic":
            return f"anthropic_api -> {local_mode}"
        return local_mode

    def _estimate_text_tokens(self, text: str) -> int:
        if not text:
            return 0
        if self.local_tokenizer is not None:
            try:
                return len(self.local_tokenizer.encode(text, add_special_tokens=False))
            except Exception:
                pass
        if self.token_encoder is not None:
            try:
                return len(self.token_encoder.encode(text, disallowed_special=()))
            except Exception:
                pass
        return max(1, len(text) // 4)

    def _normalize_block_for_estimation(self, block):
        if isinstance(block, dict):
            return block
        block_type = getattr(block, "type", None)
        if block_type == "text":
            return {"type": "text", "text": getattr(block, "text", "")}
        if block_type == "tool_use":
            return {
                "type": "tool_use",
                "name": getattr(block, "name", "unknown"),
                "input": copy.deepcopy(getattr(block, "input", {}) or {}),
            }
        if block_type == "tool_result":
            return {
                "type": "tool_result",
                "content": getattr(block, "content", ""),
            }
        if block_type == "thinking":
            return {
                "type": "thinking",
                "thinking": getattr(block, "thinking", ""),
            }
        if block_type == "redacted_thinking":
            return {
                "type": "redacted_thinking",
                "data": getattr(block, "data", ""),
            }
        return {"type": "unknown", "text": str(block)}

    def _stringify_message_for_estimation(self, message: dict) -> str:
        role = message.get("role", "unknown")
        content = message.get("content", "")
        if isinstance(content, str):
            return f"[{role}] {content}"

        if not isinstance(content, list):
            return f"[{role}] {str(content)}"

        rendered = []
        for raw_block in content:
            block = self._normalize_block_for_estimation(raw_block)

            block_type = block.get("type", "unknown")
            if block_type == "text":
                rendered.append(block.get("text", ""))
            elif block_type == "tool_use":
                rendered.append(
                    f"[tool_use:{block.get('name', 'unknown')} input={block.get('input', {})}]"
                )
            elif block_type == "tool_result":
                rendered.append(f"[tool_result:{block.get('content', '')}]")
            elif block_type == "thinking":
                rendered.append(f"[thinking:{block.get('thinking', '')}]")
            elif block_type == "redacted_thinking":
                rendered.append("[redacted_thinking]")
            elif block_type in {"image", "document"}:
                rendered.append(f"[{block_type} attached]")
            else:
                rendered.append(str(block.get("text", block)))

        return f"[{role}] " + " ".join(rendered)

    def estimate_tokens(self, messages: list) -> int:
        return self.estimate_request_tokens(messages)

    def estimate_request_tokens(
        self,
        messages: list,
        *,
        system: str = "",
        tools: list = None,
        thinking: dict = None,
    ) -> int:
        if not messages:
            base = 0
        else:
            base = sum(
                self._estimate_text_tokens(self._stringify_message_for_estimation(message)) + 3
                for message in messages
                if isinstance(message, dict)
            )

        total_tokens = base
        if system:
            total_tokens += self._estimate_text_tokens(f"[system] {system}") + 3
        if tools:
            try:
                total_tokens += self._estimate_text_tokens(json.dumps(tools, ensure_ascii=False, sort_keys=True))
            except Exception:
                total_tokens += self._estimate_text_tokens(str(tools))
        if thinking:
            try:
                total_tokens += self._estimate_text_tokens(json.dumps(thinking, ensure_ascii=False, sort_keys=True))
            except Exception:
                total_tokens += self._estimate_text_tokens(str(thinking))
        return max(1, total_tokens)

    def estimate_content_tokens(self, role: str, content) -> int:
        return self._estimate_text_tokens(
            self._stringify_message_for_estimation({"role": role, "content": content})
        )

    def _local_estimator_mode(self) -> str:
        if self.local_tokenizer is not None:
            return "local_tokenizer -> tiktoken -> heuristic"
        return "tiktoken" if self.token_encoder is not None else "heuristic"

    def _build_token_count_cache_key(self, payload: dict) -> str:
        raw = json.dumps(payload, ensure_ascii=False, sort_keys=True)
        return hashlib.sha256(raw.encode("utf-8")).hexdigest()[:24]

    def _remember_token_count(self, cache_key: str, tokens: int):
        self.token_count_cache[cache_key] = int(tokens)
        if len(self.token_count_cache) > self.token_count_cache_limit:
            for key in list(self.token_count_cache.keys())[:-self.token_count_cache_limit]:
                self.token_count_cache.pop(key, None)

    async def estimate_tokens_precise(
        self,
        messages: list,
        *,
        model: str,
        system: str = "",
        tools: list = None,
        thinking: dict = None,
    ) -> tuple[int, str]:
        request_payload = {
            "model": model,
            "system": system or "",
            "messages": copy.deepcopy(messages or []),
            "tools": copy.deepcopy(tools or []),
            "thinking": copy.deepcopy(thinking or {}),
        }
        cache_key = self._build_token_count_cache_key(request_payload)
        if cache_key in self.token_count_cache:
            return int(self.token_count_cache[cache_key]), "anthropic_api_cache"

        if self.provider == "anthropic" and self.client is not None:
            try:
                kwargs = {
                    "model": model,
                    "messages": request_payload["messages"],
                }
                if system:
                    kwargs["system"] = system
                if tools:
                    kwargs["tools"] = request_payload["tools"]
                if thinking:
                    kwargs["thinking"] = request_payload["thinking"]
                response = await self.client.beta.messages.count_tokens(**kwargs)
                input_tokens = int(getattr(response, "input_tokens", 0) or 0)
                if input_tokens > 0:
                    self._remember_token_count(cache_key, input_tokens)
                    return input_tokens, "anthropic_api"
            except Exception:
                pass

        return self.estimate_request_tokens(
            messages,
            system=system,
            tools=tools,
            thinking=thinking,
        ), self._local_estimator_mode()

    def should_compact(
        self,
        messages: list,
        *,
        token_budget: int = 60000,
        reserve_tokens: int = 12000,
        hard_message_count: int = 30,
        cache_read_input_tokens: int = 0,
        cache_creation_input_tokens: int = 0,
        max_cache_penalty_tokens: int = 12000,
    ) -> tuple[bool, int]:
        estimated_tokens = self.estimate_tokens(messages)
        cache_pressure_tokens = max(
            0,
            int(cache_creation_input_tokens or 0) - int(cache_read_input_tokens or 0),
        )
        cache_penalty = min(max_cache_penalty_tokens, cache_pressure_tokens // 2)
        budget_threshold = max(0, token_budget - reserve_tokens - cache_penalty)
        should_compact = (
            len(messages) > hard_message_count
            or estimated_tokens >= budget_threshold
        )
        return should_compact, estimated_tokens

    async def should_compact_precise(
        self,
        messages: list,
        *,
        model: str,
        system: str = "",
        tools: list = None,
        thinking: dict = None,
        token_budget: int = 60000,
        reserve_tokens: int = 12000,
        hard_message_count: int = 30,
        cache_read_input_tokens: int = 0,
        cache_creation_input_tokens: int = 0,
        max_cache_penalty_tokens: int = 12000,
    ) -> tuple[bool, int, str]:
        estimated_tokens, source = await self.estimate_tokens_precise(
            messages,
            model=model,
            system=system,
            tools=tools,
            thinking=thinking,
        )
        cache_pressure_tokens = max(
            0,
            int(cache_creation_input_tokens or 0) - int(cache_read_input_tokens or 0),
        )
        cache_penalty = min(max_cache_penalty_tokens, cache_pressure_tokens // 2)
        budget_threshold = max(0, token_budget - reserve_tokens - cache_penalty)
        should_compact = (
            len(messages) > hard_message_count
            or estimated_tokens >= budget_threshold
        )
        return should_compact, estimated_tokens, source

    def _is_compaction_boundary(self, message: dict) -> bool:
        if not isinstance(message, dict):
            return False
        content = message.get("content")
        if not isinstance(content, str):
            return False
        lowered = content.lower()
        return (
            "[compactionboundary:" in lowered
            or "layered history summary:" in lowered
            or "compaction summary:" in lowered
        )

    def micro_compact_tool_results(
        self,
        messages: list,
        preserve_last_messages: int = 12,
        max_tool_result_chars: int = 450,
        preview_chars: int = 160,
    ) -> tuple[list, int]:
        if not messages:
            return messages, 0

        cloned = copy.deepcopy(messages)
        compacted_count = 0
        cutoff = max(0, len(cloned) - preserve_last_messages)

        for msg in cloned[:cutoff]:
            content = msg.get("content")
            if not isinstance(content, list):
                continue

            for block in content:
                if not isinstance(block, dict) or block.get("type") != "tool_result":
                    continue

                block_content = block.get("content")
                if not isinstance(block_content, str):
                    continue
                if len(block_content) <= max_tool_result_chars:
                    continue

                compacted_count += 1
                prefix = block_content[:preview_chars]
                suffix = block_content[-preview_chars:] if len(block_content) > preview_chars else ""
                block["content"] = (
                    prefix
                    + f"\n...[micro-compacted historical tool result: {len(block_content) - len(prefix) - len(suffix)} chars omitted]...\n"
                    + suffix
                )

        return cloned, compacted_count

    def snip_old_compaction_boundaries(
        self,
        messages: list,
        preserve_last_messages: int = 12,
        keep_recent_boundaries: int = 1,
    ) -> tuple[list, int]:
        if not messages:
            return messages, 0

        cutoff = max(0, len(messages) - preserve_last_messages)
        boundary_indices = [
            index
            for index, message in enumerate(messages[:cutoff])
            if self._is_compaction_boundary(message)
        ]
        if len(boundary_indices) <= keep_recent_boundaries:
            return copy.deepcopy(messages), 0

        keep_indices = set(boundary_indices[-keep_recent_boundaries:])
        snipped = []
        removed_count = 0
        for index, message in enumerate(messages):
            if index in boundary_indices and index not in keep_indices:
                removed_count += 1
                continue
            snipped.append(copy.deepcopy(message))

        return snipped, removed_count

    def prune_large_tool_results(
        self,
        messages: list,
        preserve_last_messages: int = 12,
        max_tool_result_chars: int = 1200,
    ) -> tuple[list, int]:
        """
        Trim oversized historical tool results while preserving the most recent
        message window intact.
        """
        if not messages:
            return messages, 0

        cloned = copy.deepcopy(messages)
        trimmed_count = 0
        cutoff = max(0, len(cloned) - preserve_last_messages)

        for msg in cloned[:cutoff]:
            content = msg.get("content")
            if not isinstance(content, list):
                continue

            for block in content:
                if not isinstance(block, dict):
                    continue
                if block.get("type") != "tool_result":
                    continue

                block_content = block.get("content")
                if isinstance(block_content, str) and len(block_content) > max_tool_result_chars:
                    trimmed_count += 1
                    preserved_prefix = block_content[:700]
                    preserved_suffix = block_content[-300:]
                    block["content"] = (
                        preserved_prefix
                        + f"\n\n...[historical tool result truncated: {len(block_content) - 1000} chars removed]...\n\n"
                        + preserved_suffix
                    )

        return cloned, trimmed_count

    def _project_message_for_collapse(
        self,
        message: dict,
        *,
        text_chars: int = 180,
    ) -> str:
        role = str(message.get("role", "unknown")).upper()
        content = message.get("content", "")

        if isinstance(content, str):
            collapsed = " ".join(content.split())
            return f"{role}: {collapsed[:text_chars]}"

        if not isinstance(content, list):
            collapsed = " ".join(str(content).split())
            return f"{role}: {collapsed[:text_chars]}"

        parts = []
        for block in content:
            if not isinstance(block, dict):
                continue
            block_type = block.get("type")
            if block_type == "text":
                text = " ".join(str(block.get("text", "")).split())
                if text:
                    parts.append(text[:text_chars])
            elif block_type == "tool_use":
                parts.append(
                    f"[tool_use:{block.get('name', 'unknown')}]"
                )
            elif block_type == "tool_result":
                text = " ".join(str(block.get("content", "")).split())
                parts.append(f"[tool_result:{text[:100]}]")
            elif block_type in {"image", "document"}:
                parts.append(f"[{block_type}]")
        rendered = " ".join(parts).strip()
        return f"{role}: {rendered[:text_chars]}"

    def context_collapse(
        self,
        messages: list,
        *,
        preserve_first_messages: int = 1,
        preserve_last_messages: int = 8,
        max_projection_items: int = 10,
        text_chars: int = 180,
    ) -> tuple[list, dict]:
        if len(messages) <= preserve_first_messages + preserve_last_messages + 1:
            return copy.deepcopy(messages), {"collapsed": False}

        head, middle, tail = self.split_for_layered_compaction(
            messages,
            preserve_first_messages=preserve_first_messages,
            preserve_last_messages=preserve_last_messages,
        )
        if not middle:
            return copy.deepcopy(messages), {"collapsed": False}

        selected_messages = []
        if len(middle) <= max_projection_items:
            selected_messages = middle
        else:
            stride = max(1, len(middle) // max_projection_items)
            selected_messages = middle[::stride][:max_projection_items - 1]
            selected_messages.append(middle[-1])

        tool_names = []
        user_count = 0
        assistant_count = 0
        tool_result_count = 0
        for message in middle:
            role = message.get("role")
            if role == "user":
                user_count += 1
            elif role == "assistant":
                assistant_count += 1

            content = message.get("content", [])
            if not isinstance(content, list):
                continue
            for block in content:
                if not isinstance(block, dict):
                    continue
                if block.get("type") == "tool_use":
                    tool_names.append(str(block.get("name", "unknown")))
                elif block.get("type") == "tool_result":
                    tool_result_count += 1

        tool_summary = ", ".join(tool_names[:8]) if tool_names else "none"
        projection_lines = [
            "<system-reminder>",
            "[CompactionBoundary:context_collapse]",
            f"collapsed_messages: {len(middle)}",
            f"preserved_first_messages: {preserve_first_messages}",
            f"preserved_last_messages: {preserve_last_messages}",
            f"user_messages: {user_count}",
            f"assistant_messages: {assistant_count}",
            f"tool_results: {tool_result_count}",
            f"tool_trace: {tool_summary}",
            "Context collapse projection:",
        ]

        for item in selected_messages:
            projection_lines.append(
                f"- {self._project_message_for_collapse(item, text_chars=text_chars)}"
            )

        projection_lines.append("</system-reminder>")
        reminder = {
            "role": "user",
            "content": "\n".join(projection_lines),
        }
        return head + [reminder] + tail, {
            "collapsed": True,
            "collapsed_messages": len(middle),
            "projection_items": len(selected_messages),
            "tool_trace_count": len(tool_names),
        }

    def split_for_layered_compaction(
        self,
        messages: list,
        preserve_first_messages: int = 1,
        preserve_last_messages: int = 12,
    ) -> tuple[list, list, list]:
        if len(messages) <= preserve_first_messages + preserve_last_messages:
            return messages[:preserve_first_messages], [], messages[preserve_first_messages:]

        head = messages[:preserve_first_messages]
        tail = messages[-preserve_last_messages:]
        middle = messages[preserve_first_messages:-preserve_last_messages]
        return head, middle, tail
        
    async def compact_history(self, old_messages: list) -> str:
        """
        Takes an array of old Anthropic-formatted messages and returns a dense summary.
        """
        prompt = """CRITICAL: Respond with TEXT ONLY. Do NOT call any tools.

Your task is to create a detailed summary of the conversation so far, paying close attention to the user's explicit requests and your previous actions.
This summary should be thorough in capturing technical details, code patterns, and architectural decisions that would be essential for continuing development work without losing context.

First, in an <analysis> tag, analyze the conversation and identify the key information needed for each section. Then write the summary.

Your summary should include the following sections:

1. Primary Request and Intent: Capture all of the user's explicit requests and intents in detail.
2. Key Technical Concepts: List all important technical concepts, technologies, and frameworks discussed.
3. Files and Code Sections: Enumerate specific files and code sections examined, modified, or created. Pay special attention to the most recent messages and include full code snippets where applicable.
4. Errors and Fixes: List all errors that were encountered, and how they were fixed.
5. Problem Solving: Document problems solved and any ongoing troubleshooting efforts.
6. All User Messages: List ALL user messages that are not tool results.
7. Pending Tasks: Outline any pending tasks that have explicitly been asked to work on.
8. Current Work: Describe in detail precisely what was being worked on immediately before this summary request.
9. Optional Next Step: List the next step that will be taken related to the most recent work. IMPORTANT: ensure that this step is DIRECTLY in line with the user's most recent explicit requests. If the most recent request has been completed, do NOT include a next step. If there is a next step, include direct quotes from the most recent conversation showing exactly what task was being worked on.

Conversation to summarize:

"""
        
        # Stringify the old messages safely without destroying token limits with raw image B64
        for idx, m in enumerate(old_messages):
            role = m.get("role", "unknown")
            content = m.get("content", "")
            
            if isinstance(content, list):
                # Filter out raw base64 strings so the summarizer doesn't choke on tokens
                safe_blocks = []
                for block in content:
                    if block.get("type") in ["image", "document"]:
                        safe_blocks.append(f"[{block.get('type')} attached]")
                    elif block.get("type") == "text":
                        safe_blocks.append(block.get("text", ""))
                    elif block.get("type") == "tool_use":
                        safe_blocks.append(f"[tool_use: {block.get('name')}]")
                    elif block.get("type") == "tool_result":
                        text_slice = str(block.get('content', ''))[:200]
                        safe_blocks.append(f"[tool_result: {text_slice}...]")
                safe_str = " ".join(safe_blocks)
                prompt += f"[{role}]: {safe_str}\n"
            else:
                prompt += f"[{role}]: {content}\n"
                
        try:
            from codeclaw.core.config import COMPACT_MAX_OUTPUT_TOKENS, safe_llm_call
            result = await safe_llm_call(
                self.client, self.model, self.provider,
                [{"role": "user", "content": prompt}],
                COMPACT_MAX_OUTPUT_TOKENS,
            )
            return result or "[System: Compaction response contained no text blocks]"
        except Exception as e:
            return f"[System: Context summarization bypass failed due to API Error - {str(e)}]"
