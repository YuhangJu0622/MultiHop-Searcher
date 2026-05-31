import datetime
import json
import os
import re
import time
from typing import Optional

import json5
import tiktoken
from openai import AsyncOpenAI

from logger_config import get_logger
from prompts import SYSTEM_PROMPT, USER_PROMPT_TEMPLATE_NORMAL, USER_PROMPT_TEMPLATE_THINKING
from tools_search import batch_search
from tools_visit import visit_pages

logger = get_logger()


DASHSCOPE_API_KEY = os.getenv("DASHSCOPE_API_KEY", "")
NODESK_GATEWAY_KEY = os.getenv("NODESK_GATEWAY_KEY", "")
AGENT_MODEL = os.getenv("AGENT_MODEL", "qwen3.5-plus")

THINKING_MODELS = {
    "qwen3.5-plus",
}

IS_THINKING_MODEL = AGENT_MODEL.lower() in THINKING_MODELS
MAX_ROUNDS = 100
TIMEOUT_SECONDS = 540  # 9 minutes (leave 1 min buffer for 10 min limit)
MAX_TOKENS_ESTIMATE = 500000  # Upgraded from 80K - qwen-plus supports 128K, leave buffer
MAX_TOOL_RESULT_CHARS = 15000  # Max chars per tool result to keep context manageable

_client = AsyncOpenAI(
    base_url="https://llm-gateway-api.nodesk.tech/default/passthrough?",
    api_key=NODESK_GATEWAY_KEY,
)

# Initialize tiktoken encoder for accurate token counting
try:
    _tokenizer = tiktoken.get_encoding("cl100k_base")
    logger.debug("Using tiktoken for accurate token counting")
except Exception as e:
    logger.warning("Failed to load tiktoken encoder: %s", e)
    _tokenizer = None


def _today_date() -> str:
    return datetime.date.today().strftime("%Y-%m-%d")


def _extract_between(text: str, start_tag: str, end_tag: str) -> str:
    """Extract content between two tags."""
    start_idx = text.find(start_tag)
    if start_idx == -1:
        return ""
    start_idx += len(start_tag)
    end_idx = text.find(end_tag, start_idx)
    if end_idx == -1:
        return text[start_idx:].strip()
    return text[start_idx:end_idx].strip()


def _estimate_tokens(messages: list) -> int:
    """Accurate token counting using tiktoken (fallback to rough estimation)."""
    if _tokenizer is not None:
        try:
            total_tokens = 0
            for msg in messages:
                content = msg.get("content", "")
                total_tokens += len(_tokenizer.encode(content))
            return total_tokens
        except Exception as e:
            logger.warning("Tokenizer error: %s, falling back to char estimation", e)

    # Fallback: rough estimation
    total_chars = sum(len(m.get("content", "")) for m in messages)
    return int(total_chars / 1.5)


def _truncate_tool_result(result: str) -> str:
    """Truncate tool results to keep context manageable."""
    if len(result) > MAX_TOOL_RESULT_CHARS:
        return result[:MAX_TOOL_RESULT_CHARS] + "\n\n[... result truncated due to length ...]"
    return result


def _normalize_answer(answer: str) -> str:
    """Clean up answer format: remove common prefixes, trailing punctuation, and quote wrapping."""
    text = answer.strip()
    # Remove common prefixes
    for prefix in [
        "The answer is ", "the answer is ",
        "Answer: ", "answer: ",
        "答案是", "答案：",
    ]:
        if text.startswith(prefix):
            text = text[len(prefix):].strip()
    # Remove wrapping quotes (Chinese and English)
    if len(text) >= 2:
        if (text[0] == '"' and text[-1] == '"') or (text[0] == "'" and text[-1] == "'"):
            text = text[1:-1].strip()
        if (text[0] == '\u201c' and text[-1] == '\u201d') or (text[0] == '\u2018' and text[-1] == '\u2019'):
            text = text[1:-1].strip()
        if (text[0] == '\u300c' and text[-1] == '\u300d'):
            text = text[1:-1].strip()
    return text


def _extract_tool_call(content: str) -> Optional[str]:
    """Extract tool call JSON from content, supporting multiple formats."""
    # Format 1: <tool_call>...</tool_call>
    if "<tool_call>" in content and "</tool_call>" in content:
        return _extract_between(content, "<tool_call>", "</tool_call>")
    if "<tool_call>" in content:
        return content[content.find("<tool_call>") + len("<tool_call>"):].strip()

    # Format 2: <function=name>\n<parameter=key>\nvalue\n</parameter>\n</function>
    func_match = re.search(r'<function=(search|visit)>', content)
    if func_match:
        tool_name = func_match.group(1)
        func_start = func_match.start()
        func_end_tag = content.find("</function>", func_start)
        if func_end_tag == -1:
            func_block = content[func_start:]
        else:
            func_block = content[func_start:func_end_tag]
        args = {}
        for param_match in re.finditer(r'<parameter=(\w+)>\s*(.*?)\s*</parameter>', func_block, re.DOTALL):
            param_name = param_match.group(1)
            param_value = param_match.group(2).strip()
            try:
                args[param_name] = json5.loads(param_value)
            except Exception:
                args[param_name] = param_value
        result = json.dumps({"name": tool_name, "arguments": args})
        logger.debug("Converted <function=%s> to JSON: %s", tool_name, result[:200])
        return result

    # Format 3: bare JSON tool call (no tags)
    bare_match = re.search(r'\{"name":\s*"(search|visit)"', content)
    if bare_match:
        json_start = bare_match.start()
        brace_depth = 0
        json_end = json_start
        for i in range(json_start, len(content)):
            if content[i] == '{':
                brace_depth += 1
            elif content[i] == '}':
                brace_depth -= 1
                if brace_depth == 0:
                    json_end = i + 1
                    break
        return content[json_start:json_end]
    return None


CONTENT_FILTER_MARKER = "__CONTENT_FILTERED__"


async def _call_llm(
    messages: list,
    stop: Optional[list] = None,
    temperature: float = 0.4,
    max_tokens: int = 8192,
) -> str:
    """Call LLM via DashScope OpenAI-compatible API with retries."""
    extra_body = {
        "channel": "DMX",
        "channel_url": "https://www.dmxapi.cn/v1/chat/completions"
    }
    if IS_THINKING_MODEL:
        extra_body["enable_thinking"] = True

    for attempt in range(3):
        try:
            resp = await _client.chat.completions.create(
                model=AGENT_MODEL,
                messages=messages,
                stop=stop or ["<tool_response>"],
                temperature=temperature,
                max_tokens=max_tokens,
                extra_body=extra_body,
            )
            msg = resp.choices[0].message
            # qwen3.5 with thinking mode: reasoning is in reasoning_content field
            reasoning = getattr(msg, "reasoning_content", None) or ""
            content = msg.content or ""
            # Clean up garbled tag fragments at start of content (e.g. "ynchroneg>")
            content = re.sub(r'^[a-z]*>', '', content.lstrip())
            # Reassemble: wrap reasoning in <think> tags + content
            if IS_THINKING_MODEL and reasoning:
                full = f"<think>\n{reasoning}\n</think>\n{content}"
            else:
                full = content
            if full and full.strip():
                return full.strip()
            logger.warning("Empty response on attempt %d", attempt + 1)
        except Exception as e:
            err_str = str(e)
            logger.warning("LLM call attempt %d failed: %s", attempt + 1, e)
            # Content safety filter - no point retrying the same prompt
            if "data_inspection_failed" in err_str:
                logger.warning("Content filter triggered, signaling redirect")
                return CONTENT_FILTER_MARKER
            if attempt < 2:
                await _async_sleep(2 ** attempt)

    return "I was unable to process this request due to an API error."


async def _async_sleep(seconds: float):
    import asyncio
    await asyncio.sleep(seconds)


async def _force_answer(messages: list) -> str:
    """Force the LLM to generate a final answer based on gathered info."""
    force_msg = (
        "You have reached the limit. Based on ALL information gathered, provide your final answer.\n"
        "IMPORTANT: Use <think> tags to:\n"
        "1. Re-read the original question\n"
        "2. List ALL constraints from the question\n"
        "3. Choose the candidate that best satisfies ALL constraints\n"
        "Then answer:\n<think>your final reasoning</think>\n<answer>your answer</answer>"
    )
    messages.append({"role": "user", "content": force_msg})

    content = await _call_llm(messages, stop=["</answer>"], temperature=0.3)
    messages.append({"role": "assistant", "content": content})

    if "<answer>" in content:
        answer = _extract_between(content, "<answer>", "</answer>")
        if answer:
            return _normalize_answer(answer)
        # If </answer> was the stop token, the content after <answer> is the answer
        idx = content.find("<answer>")
        answer = content[idx + len("<answer>"):].strip()
        if answer:
            return _normalize_answer(answer)

    # Last resort: return the raw content
    return content


async def _execute_tool(tool_name: str, tool_args: dict) -> str:
    """Execute a tool call and return the result string."""
    try:
        if tool_name == "search":
            queries = tool_args.get("query", [])
            if isinstance(queries, str):
                queries = [queries]
            engines = tool_args.get("engine", None)
            if isinstance(engines, str):
                engines = [engines]
            result = batch_search(queries, engines=engines)
            return _truncate_tool_result(result)
        elif tool_name == "visit":
            urls = tool_args.get("url", [])
            goal = tool_args.get("goal", "Extract relevant information")
            result = await visit_pages(urls, goal)
            return _truncate_tool_result(result)
        else:
            return f"Error: Unknown tool '{tool_name}'"
    except Exception as e:
        return f"Error executing tool '{tool_name}': {str(e)}"


async def react_agent(question: str) -> str:
    """
    Main ReAct agent loop.

    Follows the DeepResearch pattern:
    - System prompt with behavioral principles
    - User prompt with tool definitions and format examples
    - Iterative think → tool_call → tool_response → ... → answer
    - Timeout and token limit management
    """
    if IS_THINKING_MODEL:
        user_prompt = USER_PROMPT_TEMPLATE_THINKING + question
    else:
        user_prompt = USER_PROMPT_TEMPLATE_NORMAL + question

    messages = [
        {"role": "system", "content": SYSTEM_PROMPT + _today_date()},
        {"role": "user", "content": user_prompt},
    ]

    start_time = time.time()
    early_answer_blocked = False  # only block early answer once
    content_filter_count = 0  # track consecutive content filter hits

    for round_idx in range(MAX_ROUNDS):
        # Timeout check
        elapsed = time.time() - start_time
        if elapsed > TIMEOUT_SECONDS:
            logger.warning("Timeout after %.0fs at round %d", elapsed, round_idx + 1)
            return await _force_answer(messages)

        # Call LLM
        current_tokens = _estimate_tokens(messages)
        logger.info("Round %d, elapsed %.0fs, tokens %d", round_idx + 1, elapsed, current_tokens)
        content = await _call_llm(messages)

        # Handle content filter: redirect or force a neutral search
        if content == CONTENT_FILTER_MARKER:
            content_filter_count += 1
            logger.warning("Content filter hit #%d at round %d", content_filter_count, round_idx + 1)
            if content_filter_count <= 2:
                redirect_msg = (
                    "The previous response was blocked by content filters. "
                    "Please try a different approach: rephrase your search using more neutral, "
                    "academic, or indirect terms. Focus on factual and historical aspects. "
                    "Use <think> to plan a new search angle, then make a tool call."
                )
                messages.append({"role": "assistant", "content": "<think>My previous response was filtered. I need to rephrase my approach using more neutral terms.</think>"})
                messages.append({"role": "user", "content": redirect_msg})
            else:
                # After 2 redirects, context itself is toxic — force answer with sanitized context
                logger.warning("Too many content filters, forcing answer with sanitized context")
                # Keep only system prompt, original question, and a summary of findings
                sanitized_messages = [messages[0], messages[1]]  # system + user question
                # Check if model already found an answer in earlier rounds
                for msg in messages:
                    if msg["role"] == "assistant":
                        c = msg["content"]
                        if "<answer>" in c:
                            answer_text = _extract_between(c, "<answer>", "</answer>")
                            if answer_text:
                                return _normalize_answer(answer_text)
                # Extract key findings from assistant messages (avoid sensitive details)
                findings = []
                for msg in messages:
                    if msg["role"] == "assistant":
                        for line in msg["content"].split("\n"):
                            if any(kw in line for kw in ["答案", "answer", "结论", "确认", "因此", "全名", "全称"]):
                                findings.append(line[:200])
                if findings:
                    sanitized_messages.append({
                        "role": "user",
                        "content": "Based on your earlier research, you found:\n" + "\n".join(findings[-5:]) + "\nNow give your final answer."
                    })
                return await _force_answer(sanitized_messages)
            continue

        # Clean up: remove any hallucinated <tool_response> tags
        if "<tool_response>" in content:
            content = content[: content.find("<tool_response>")]

        # Detect stalled output (very short meaningless content like "<" or empty)
        if len(content.strip()) < 5 and "<answer>" not in content:
            logger.warning("Stalled output detected: '%s', retrying", content.strip())
            continue

        messages.append({"role": "assistant", "content": content})

        logger.debug("Output preview: %s", content[:500])
        # Check for <think> usage and prepare reminder
        think_reminder = not IS_THINKING_MODEL and "<think>" not in content and round_idx > 0

        # Check for final answer (with or without closing tag)
        if "<answer>" in content:
            if "</answer>" in content:
                answer_text = _extract_between(content, "<answer>", "</answer>")
            else:
                # No closing tag — extract everything after <answer>
                answer_text = content[content.find("<answer>") + len("<answer>"):].strip()
                # Take only the first line to avoid grabbing trailing content
                if "\n" in answer_text:
                    answer_text = answer_text.split("\n")[0].strip()
                logger.debug("Detected <answer> without </answer>, extracted: %s", answer_text[:100])

            if answer_text:
                # Early answer gating: if answered too quickly, inject verification prompt
                elapsed = time.time() - start_time
                if round_idx < 3 and elapsed < 120 and not early_answer_blocked:
                    early_answer_blocked = True
                    verify_msg = (
                        "You answered very quickly. For complex multi-hop questions, "
                        "this often leads to errors. Please verify:\n"
                        "1. Re-read the original question\n"
                        "2. Check EVERY constraint\n"
                        "3. Search for one more confirming source\n"
                        "If correct, repeat your answer. If not, search more."
                    )
                    messages.append({"role": "user", "content": verify_msg})
                    logger.info("Early answer blocked at round %d, requesting verification", round_idx + 1)
                    continue

                logger.info("Got answer at round %d: %s", round_idx + 1, answer_text[:100])
                return _normalize_answer(answer_text)

        # Check for tool call — support both <tool_call> tags and bare JSON
        tool_call_str = _extract_tool_call(content)

        if tool_call_str:
            try:
                tool_data = json5.loads(tool_call_str)
                tool_name = tool_data.get("name", "")
                tool_args = tool_data.get("arguments", {})
                logger.info("Calling tool: %s", tool_name)

                result = await _execute_tool(tool_name, tool_args)

                prefix = ""
                if think_reminder:
                    prefix = "Reminder: Use <think> tags to reason before every tool call or answer.\n\n"

                messages.append({
                    "role": "user",
                    "content": f"{prefix}<tool_response>\n{result}\n</tool_response>",
                })
            except Exception as e:
                error_msg = (
                    f'Error: Tool call is not valid JSON. '
                    f'Tool call must contain a valid "name" and "arguments" field. '
                    f'Error: {str(e)}'
                )
                messages.append({
                    "role": "user",
                    "content": f"<tool_response>\n{error_msg}\n</tool_response>",
                })
        else:
            # No tool call and no answer — nudge the LLM
            nudge_msg = (
                "You did not make a tool call or provide an answer. "
                "Please use <think> to reason, then either make a tool call or provide your answer."
            )
            messages.append({"role": "user", "content": nudge_msg})

        # Token limit check
        if _estimate_tokens(messages) > MAX_TOKENS_ESTIMATE:
            logger.warning("Token limit reached at round %d", round_idx + 1)
            return await _force_answer(messages)

    # Exhausted all rounds
    logger.warning("Max rounds (%d) exhausted", MAX_ROUNDS)
    return await _force_answer(messages)
