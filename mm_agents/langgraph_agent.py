#!/usr/bin/env python3
"""
LangGraph-based Dual Agent Framework with Direct GUI Feedback
Simplified version: directly tell operator what failed
"""

import base64
import json
import os
import logging
import traceback
from typing import TypedDict, Annotated, Literal, Optional, Tuple, List, Any, Dict
import operator as op
from langgraph.graph import StateGraph, END
from desktop_env.desktop_env import DesktopEnv
from llm import AbstractLLM
from utils import serialize_json
from json_repair import repair_json


# ==================== PROMPTS ====================

COORDINATOR_SYSTEM_MESSAGE = """# Your Role
You are an expert in graphical user interfaces and bash code. You are responsible for executing the task step-by-step. Carefully read the task instruction and keep it in mind.

# GUIDELINES

## General Instructions
1. You are provided with:
    - A screenshot of the current time step.
    - The history of your previous interactions with the UI.
2. Check screenshots carefully to verify task completion
3. Do not modify user requirements (file names, paths, etc.)

## Agent Usage Guidelines
You have access to both GUI and code agents. Choose the appropriate agent based on the task requirements:

### GUI Agent
Delegate GUI tasks to an operator.
- **Use for**: clicking, typing, navigation, file operations, tasks requiring specific application features, visual elements, interactive features, application UI, complex formatting, print/export settings, multi-step workflows, pivot tables, charts, chrome browser
- Issue ONE clear and complete action per call
- Operator can click and type but positioning may be inaccurate

**When GUI operations fail (check screenshot for expected result)**:
- Consider using Ctrl+Z to undo the failed operation if it made unwanted changes
- Provide HIGH-LEVEL guidance in "gui_feedback" (NO coordinates/positions)
- Suggest alternatives: keyboard shortcuts (including Ctrl+Z for undo), different elements, scrolling, etc.
- Describe visual landmarks: "button with save icon", "menu bar at top", etc.

### Code Agent
Execute bash commands in ```bash...``` blocks for complex tasks. Note: We ONLY use bash to execute Python code.
- **Use for**: data processing (especially excel), bulk operations, file content modification, and tasks requiring programming logic that can be solved by code rather than UI interactions

**Available Commands**:
- Use sudo: "echo {CLIENT_PASSWORD} | sudo -S [COMMAND]"
- For Python: `python3 -c "code"` or install packages: `pip install numpy && python3 -c "import numpy"`
- Verify results before saving changes

**Core Guidelines**:
- Execute Python code via bash step-by-step to progress toward the goal
- Username: "user"
- Print results and handle errors appropriately
- Code execution may not show immediately on screen

**CRITICAL: Incremental Step-by-Step Approach**:
- Break down complex tasks into small, self-contained steps
- Each step should contain a single, focused code snippet that advances toward the goal
- Code from each step does NOT persist to the next step - write complete, standalone snippets
- Example workflow:
  * Step 1: Write code to locate/find the target file
  * Step 2: Write code to THOROUGHLY inspect/read the file contents
  * Step 3: Write code to modify the file based on findings
  * Step 4: Write code to verify the changes
- If verification fails (the modification did not work as intended), return to Step 3 and rewrite the modification code. Repeat until verification succeeds.
- Do NOT write entire scripts in one step - focus on one small task per step

**CRITICAL: File Modification Strategy**:
- ALWAYS prioritize modifying existing open files IN PLACE rather than creating new files
- The screenshot context shows which file is currently open and should be modified
- For open documents (LibreOffice .docx/.xlsx, text editors, etc.), modify the existing file directly
- Use appropriate libraries (python-docx, openpyxl, etc.) to modify files in place
- CRITICAL: When modifying files, perform COMPLETE OVERWRITES, not appends
- For documents: replace all paragraphs/sheets with new content
- For text files: write the complete new content, overwriting the old
- Only create new files when explicitly required by the task
- Verify your reasoning aligns with the user's intent for the open file

**CRITICAL: Thorough File Inspection Guidelines**:
- ALWAYS inspect file contents AND data types before and after modifications
- Check cell values, formats, data types, number formats, decimal separators, and formatting properties
- For spreadsheets: inspect cell values, number formats, date formats, currency formats, and cell properties
- For documents: inspect text content, formatting, styles, and structural elements
- Verify that modifications actually changed the intended properties (not just values)
- Compare before/after states to ensure changes were applied correctly

**CRITICAL: Code-Based Task Solving**:
- You are responsible for writing EXECUTABLE CODE to solve the task programmatically
- Write bash commands that execute Python scripts to process, filter, transform, or manipulate the data as required

**CRITICAL: Preserve Document Structure and Formatting**:
- When modifying documents/spreadsheets, PRESERVE the original structure, headers, and formatting
- NEVER modify column headers, row headers, document titles, or sheet names unless explicitly requested
- Maintain fonts, colors, borders, cell formatting, paragraph styles, etc.
- Only change the content/data, not the structure or visual presentation
- Use libraries that support formatting preservation (python-docx, openpyxl, etc.)
- The goal is to keep the document looking exactly the same, just with different content
- For column reordering: Preserve table position - reorder columns within the table without shifting the table itself

**CRITICAL: Final Step Requirement**:
- At the final step before completing the task (the step before you return DONE), you MUST print out the contents of any files you modified
- Use appropriate commands to display the final state of modified files:
  * For text files: `cat filename` or `head -n 50 filename` for large files
  * For Python files: `cat filename.py`
  * For configuration files: `cat filename.conf`
  * For any other file type: use appropriate viewing commands
- This ensures the user can see exactly what changes were made to the files

**CRITICAL: Verification Instructions**:
- When you complete a task that modifies files, you MUST provide clear verification instructions
- Include specific details about what the GUI agent should check:
  * Which files were modified and their expected final state
  * What the content should look like (number of lines, key data points, etc.)
  * How to verify the changes are correct (e.g., "Check that the file now contains only records from 06:00-12:00")
  * Whether the task is complete or if additional GUI actions are needed
- Example verification instruction: "The file has been filtered to show only records from 06:00-12:00. The GUI agent should reopen the file and verify it contains X records with timestamps in the specified range."
- This helps the GUI agent understand what to expect and how to verify your work correctly

**Technical Notes**:
- All code is executed via bash - wrap code in ONE bash code block
- For Python: use `python3 -c "code"` within bash commands
- Install missing packages as needed: `pip install package_name`
- Ignore "sudo: /etc/sudoers.d is world writable" error

### Code Agent Verification
- After the code agent modifies files, your job is to find and verify these files via GUI actions (e.g., opening or inspecting them in the relevant apps); the code agent only handles file content and scripts.
- ALWAYS verify code agent results with GUI actions before terminating; NEVER trust code agent output alone. If verification or the code agent fails, use GUI actions to finish the task and only terminate if results match expectations.
- **CRITICAL**: Files modified by code agent may not show changes in currently open applications - you MUST close and reopen the entire application. Reloading the page/file is insufficient.

Never assume a task is done based on appearances - always ensure the specific requested action has been performed and verify the modification. If you haven't executed any actions, the task is not complete.

### END OF GUIDELINES

# Response JSON in the following format or "INFEASIBLE" if the task is impossible:
{
    "thought": "Your reasoning about current situation and next action",
    "action": "code|gui|terminate",
    "content": "Bash commands OR ONE atomic GUI task description",
    "gui_feedback": "Optional: high-level guidance if previous GUI failed (no coordinates)"
}"""

OPERATOR_SYSTEM_MESSAGE = """You are an agent that performs desktop computer tasks as instructed.
You will receive a screenshot and predict the action based on the image.

Use `pyautogui` to perform actions. DO NOT use `pyautogui.locateCenterOnScreen` or `pyautogui.screenshot()`.
Return Python code to perform ONE action at a time.
You must specify coordinates yourself based on the screenshot - be careful to ensure accuracy.

Return code in a code block:
```python
# your code here
```

My computer's password is '{CLIENT_PASSWORD}'.

{previous_attempt_info}

Analyze the screenshot carefully and return the code."""


# ==================== STATE DEFINITION ====================

class AgentState(TypedDict):
    """LangGraph state for the dual agent workflow."""
    # Task information
    task_instruction: str
    additional_context: str
    task_config: dict
    
    # Current state
    current_screenshot: bytes
    operation_count: int
    
    # Coordinator decision
    coordinator_thought: str
    coordinator_action: str
    coordinator_content: str
    
    # GUI tracking
    last_gui_task: str
    last_gui_command: str
    last_gui_success: Optional[bool]
    last_gui_result_check: str
    
    # Execution results
    last_execution_result: str
    last_execution_success: bool
    
    # History and logs - remove op.add, use regular fields
    action_logs: List[dict]
    conversation_history: List[dict]
    
    # Tracking
    last_history_summary_at: int
    history_summary: str
    history_summary_interval: int
    
    # Control flow
    next_node: str
    task_completed: bool
    
    # Environment reference
    env: Optional[DesktopEnv]
    operations_dir: str
    
    # Configuration
    coordinator_model: str
    operator_model: str
    client_password: str
    screen_width: int
    screen_height: int
    sleep_after_execution: float
    max_steps: int
    
    # LLM clients (removed model_usage)
    coordinator_llm: AbstractLLM
    operator_llm: AbstractLLM


# ==================== NODE FUNCTIONS ====================
def print_messages(messages: List[dict], logger: logging.Logger):
    # Debug print messages without base64 images
    logger.info("="*80)
    logger.info("[Messages]")
    debug_text = []
    for i, msg in enumerate(messages):
        debug_text.append(f"\n[Message {i}] Role: {msg['role']}")
        if isinstance(msg['content'], str):
            debug_text.append(f"Content: {msg['content'][:500]}")
        elif isinstance(msg['content'], list):
            for item in msg['content']:
                if item['type'] == 'input_text':
                    debug_text.append(f"Text: {item['text'][:500]}")
                elif item['type'] == 'input_image':
                    debug_text.append(f"Image: [base64 data omitted]")
    logger.info("\n".join(debug_text))
    logger.info("="*80)


def build_coordinator_messages(state: AgentState, logger) -> Tuple[List[dict], dict]:
    """
    Build message list for coordinator with efficient history management.
    Strategy: Keep first message (task instruction) + summary of middle turns + recent turns
    
    Returns:
        Tuple of (messages, state_updates) - returns message list and state updates
    """
    history = state.get("conversation_history", [])
    messages = [{"role": "system", "content": COORDINATOR_SYSTEM_MESSAGE}]
    
    summary_interval = state.get("history_summary_interval", 5)
    state_updates = {
        "conversation_history": history,
        "history_summary": state.get("history_summary", ""),
        "last_history_summary_at": state.get("last_history_summary_at", 0),
    }
    
    # If history is short (less than interval + 2 recent turns), keep everything
    # Calculation: 1 (first message) + summary_interval * 2 (turns as message pairs) + 4 (last 2 turns)
    min_messages_for_summary = 1 + summary_interval * 2 + 4
    
    if len(history) < min_messages_for_summary:
        messages.extend(history)
        return messages, state_updates
    
    # Check if we need to create/update summary
    last_summary_at = state.get("last_history_summary_at", 0)
    current_turn = (len(history) - 1) // 2  # Subtract first message, then divide by 2
    
    # Summarize based on configured interval
    if current_turn - last_summary_at >= summary_interval:
        # Messages to summarize: everything except first message and last 2 turns
        summary_start = 1  # After first message (task instruction)
        summary_end = len(history) - 4  # Before last 2 turns
        to_summarize = history[summary_start:summary_end]
        
        if to_summarize:
            logger.info(f"Summarizing {len(to_summarize)} messages (from message {summary_start} to {summary_end-1})...")
            logger.info(f"Summary triggered: current_turn={current_turn}, last_summary_at={last_summary_at}, interval={summary_interval}")
            
            # Build summary request messages
            summary_messages = [
                {
                    "role": "system",
                    "content": "You create concise summaries of agent conversation history."
                },
                {
                    "role": "user",
                    "content": f"""Summarize this conversation history between a coordinator and execution results.

Focus on:
1. Actions attempted (bash commands, GUI operations)
2. Success/failure patterns
3. Important discoveries or issues
4. Progress toward task goal

Keep it concise (max 200 words) but include critical information.

History to summarize:
{format_history_for_summary(to_summarize)}"""
                }
            ]
            
            # Use coordinator LLM from state for summarization
            summary = state["coordinator_llm"](summary_messages)
            
            # Create summary messages to replace the middle section
            summary_messages_pair = [
                {
                    "role": "user",
                    "content": f"[Summary of {len(to_summarize)//2} previous operations]\n{summary}"
                },
                {
                    "role": "assistant",
                    "content": "Understood. Continuing from this context."
                }
            ]
            
            # REPLACE the middle section in conversation_history
            # New history = first message + summary + last 2 turns
            compressed_history = (
                history[:1] +  # First message (task instruction)
                summary_messages_pair +  # Summary replacement
                history[-4:]  # Last 2 turns
            )
            
            logger.info(f"Created summary at turn {current_turn} ({len(summary)} chars)")
            logger.info(f"Summarized {len(to_summarize)} messages ({len(to_summarize)//2} turns)")
            logger.info(f"History compressed: {len(history)} -> {len(compressed_history)} messages")
            
            # Update state
            state_updates["conversation_history"] = compressed_history
            state_updates["history_summary"] = summary
            state_updates["last_history_summary_at"] = current_turn
            
            # Build messages from compressed history
            messages.extend(compressed_history)
            logger.info(f"Built messages: {len(messages)} total (including system prompt)")
            
            return messages, state_updates
                
    # Build messages from original history (no compression needed)
    messages.extend(history)
    logger.info(f"Built messages: {len(messages)} total (including system prompt)")
    
    return messages, state_updates


def format_history_for_summary(messages: List[dict]) -> str:
    """Format message history into readable text for summarization."""
    formatted = []
    for msg in messages:
        role = msg["role"].upper()
        content = msg["content"]
        
        if isinstance(content, str):
            formatted.append(f"{role}: {content[:500]}")
        elif isinstance(content, list):
            text_parts = [
                item.get("text", "")
                for item in content
                if item.get("type") == "input_text"
            ]
            if text_parts:
                formatted.append(f"{role}: {' '.join(text_parts)[:500]}")
    
    return "\n\n".join(formatted)


def filter_base64_images_from_messages(messages: List[dict]) -> List[dict]:
    """Remove base64 images from messages for logging purposes."""
    filtered_messages = []
    for msg in messages:
        filtered_msg = {"role": msg["role"]}
        content = msg["content"]
        
        if isinstance(content, str):
            # String content - keep as is
            filtered_msg["content"] = content
        elif isinstance(content, list):
            # List content - filter out images
            filtered_content = []
            for item in content:
                if item.get("type") == "input_text":
                    filtered_content.append(item)
                elif item.get("type") == "input_image":
                    # Replace image with placeholder
                    filtered_content.append({
                        "type": "input_image",
                    })
            filtered_msg["content"] = filtered_content
        else:
            filtered_msg["content"] = content
        
        filtered_messages.append(filtered_msg)
    
    return filtered_messages


def merge_conversation_and_actions(conversation_history: List[dict], action_logs: List[dict]) -> List[dict]:
    """Merge conversation messages and action logs into a unified timeline."""
    timeline = []
    
    # Filter conversation messages to remove base64 images
    filtered_messages = filter_base64_images_from_messages(conversation_history)
    
    # Group messages into pairs (user + assistant)
    message_pairs = []
    i = 0
    while i < len(filtered_messages):
        if filtered_messages[i]["role"] == "user":
            user_msg = filtered_messages[i]
            assistant_msg = filtered_messages[i + 1] if i + 1 < len(filtered_messages) else None
            message_pairs.append({"user": user_msg, "assistant": assistant_msg})
            i += 2
        else:
            i += 1
    
    # Match conversation pairs with action logs
    # First pair is initial task instruction (step 0)
    if message_pairs:
        first_pair = message_pairs[0]
        timeline.append({
            "step": 0,
            "type": "task_instruction",
            "user_message": first_pair["user"]["content"],
            "assistant_response": first_pair["assistant"]["content"] if first_pair["assistant"] else None
        })
    
    # Process remaining pairs with corresponding actions
    for idx, pair in enumerate(message_pairs[1:], start=1):
        # Add action log if available
        if idx - 1 < len(action_logs):
            action = action_logs[idx - 1].copy()
            # Add conversation context to action
            action["coordinator_decision"] = pair["assistant"]["content"] if pair["assistant"] else None
            action["execution_result"] = pair["user"]["content"] if idx < len(message_pairs) else None
            timeline.append(action)
        else:
            # No action log, just record the conversation
            timeline.append({
                "step": idx,
                "type": "conversation_only",
                "user_message": pair["user"]["content"],
                "assistant_response": pair["assistant"]["content"] if pair["assistant"] else None
            })
    
    # Add any remaining action logs that don't have conversation pairs
    for idx in range(len(message_pairs) - 1, len(action_logs)):
        timeline.append(action_logs[idx])
    
    return timeline


def coordinator_node(state: AgentState) -> dict:
    """Coordinator makes decisions about next action."""
    logger = logging.getLogger("desktopenv")
    
    screenshot = state["current_screenshot"]
    screenshot_b64 = base64.b64encode(screenshot).decode("utf-8")

    # Get coordinator LLM from state
    coordinator_llm = state["coordinator_llm"]
    
    # Prepare current message
    if state["operation_count"] == 0:
        user_message = f"""Task instruction:\n{state['task_instruction']}{state['additional_context']}

Check my computer screenshot and describe it first. If this task is possible to complete, please complete it on my computer. If not, reply with "INFEASIBLE" to end the conversation.

Current screenshot attached below."""
    else:
        user_message = f"""Previous action result:
{state['last_execution_result']}

Continue with the task or verify if completed. Current screenshot attached below."""
    
    # Build messages with efficient history management
    messages, state_updates = build_coordinator_messages(state, logger)
    
    # Add current message
    messages.append({
        "role": "user",
        "content": [
            {"type": "input_text", "text": user_message},
            {"type": "input_image", "image_url": f"data:image/png;base64,{screenshot_b64}"}
        ]
    })
    
    logger.info(f"\n{'='*80}")
    logger.info(f"[Coordinator] Operation count: {state['operation_count']}")
    logger.info(f"[Coordinator] Message count: {len(messages)}")
    
    try:
        response_text = coordinator_llm(messages)
        
        # Parse JSON response or handle direct bash execution
        try:
            if response_text.lower() == "infeasible":
                decision = {
                    "thought": "INFEASIBLE",
                    "action": "terminate",
                    "content": "INFEASIBLE"
                }
            elif "```json" in response_text:
                json_start = response_text.find("```json") + 7
                json_end = response_text.find("```", json_start)
                response_text = response_text[json_start:json_end].strip()
                decision = json.loads(repair_json(response_text))
            # Check if response contains bash code block - execute directly
            elif "```bash" in response_text:
                logger.info("Detected bash code block, executing directly")
                code_start = response_text.find("```bash") + 7
                code_end = response_text.find("```", code_start)
                bash_code = response_text[code_start:code_end].strip()
                
                # Execute bash code immediately
                operation_count = state["operation_count"] + 1
                logger.info(f"\n{'='*80}")
                logger.info(f"[Direct Bash Execution] Operation #{operation_count}")
                logger.info(f"Code:\n{bash_code}")
                logger.info("="*80)
                
                exitcode = 1
                logs = ""
                try:
                    output_dict = state["env"].controller.run_bash_script(bash_code, timeout=300)
                    exitcode = 0 if output_dict["status"] == "success" else 1
                    logs = output_dict["output"]
                except Exception as e:
                    exitcode = 1
                    logs = f"Execution error: {str(e)}"
                    logger.error(traceback.format_exc())
                
                success = (exitcode == 0)
                
                # Take screenshot after execution
                screenshot = state["env"].controller.get_screenshot()
                screenshot_filename = f"step_{operation_count}_bash_direct.png"
                
                with open(os.path.join(state["operations_dir"], screenshot_filename), "wb") as f:
                    f.write(screenshot)
                
                # Log the action
                action_log = {
                    "step": operation_count,
                    "type": "bash_execution_direct",
                    "code": bash_code,
                    "exitcode": exitcode,
                    "output": logs,
                    "screenshot": screenshot_filename
                }
                
                result_message = f"Bash execution {'succeeded' if success else 'failed'}.\nOutput:\n{logs}"
                logger.info(f"Exit code: {exitcode}")
                logger.info(f"Output: {logs[:500]}")
                
                # Explicitly manage conversation history: use compressed history, add new messages
                compressed_history = state_updates.get("conversation_history", state.get("conversation_history", []))
                new_history = compressed_history + [
                    {"role": "user", "content": user_message},
                    {"role": "assistant", "content": response_text}
                ]
                
                # Explicitly manage action logs: read existing logs, add new log
                current_action_logs = state.get("action_logs", [])
                new_action_logs = current_action_logs + [action_log]
                
                # Return state update to continue workflow
                return {
                    "operation_count": operation_count,
                    "current_screenshot": screenshot,
                    "last_execution_result": result_message,
                    "last_execution_success": success,
                    "conversation_history": new_history,  # complete replacement
                    "action_logs": new_action_logs,  # complete replacement
                    "history_summary": state_updates.get("history_summary", ""),
                    "last_history_summary_at": state_updates.get("last_history_summary_at", 0),
                    "next_node": "coordinator",
                    "task_completed": False
                }
            
            else:
                decision = json.loads(repair_json(response_text))
        except json.JSONDecodeError:
            # If JSON parsing fails, try to infer intent from response
            logger.error(f"Failed to parse JSON from response: {response_text}")
            decision = {
                "thought": response_text,
                "action": "terminate",
                "content": response_text
            }
        
        logger.info(f"Thought: {decision.get('thought', 'N/A')[:200]}")
        logger.info(f"Action: {decision.get('action', 'N/A')}")
        logger.info(f"Content preview: {str(decision.get('content', ''))[:100]}")
        
        # Check GUI result if this is feedback after a GUI operation
        gui_success = decision.get('gui_success')
        gui_result_check = decision.get('gui_result_check', '')
        
        if gui_success is False:
            logger.info(f"GUI Result Check: {gui_result_check[:150]}")
        
        # Explicitly manage conversation history: use compressed history, add new messages
        compressed_history = state_updates.get("conversation_history", state.get("conversation_history", []))
        new_history = compressed_history + [
            {"role": "user", "content": user_message},
            {"role": "assistant", "content": response_text}
        ]
        
        # Determine next node
        action = decision.get("action", "terminate").lower()
        
        # Base return dict with explicit history management
        base_return = {
            "coordinator_thought": decision.get("thought", ""),
            "coordinator_action": action,
            "coordinator_content": decision.get("content", ""),
            "conversation_history": new_history,  # complete replacement
            "history_summary": state_updates.get("history_summary", ""),
            "last_history_summary_at": state_updates.get("last_history_summary_at", 0),
        }
        
        if action == "terminate":
            is_infeasible = "infeasible" in decision.get("thought", "").lower()
            logger.info(f"Task {'INFEASIBLE' if is_infeasible else 'COMPLETED'}")
            return {
                **base_return,
                "next_node": "evaluator",
                "task_completed": True
            }
        elif action == "code":
            logger.info("Next: Code Execution (Bash)")
            return {
                **base_return,
                "next_node": "code_executor",
                "task_completed": False
            }
        elif action == "gui":
            logger.info("Next: GUI Operation")
            return {
                **base_return,
                "last_gui_success": gui_success,
                "last_gui_result_check": gui_result_check,
                "next_node": "gui_operator",
                "task_completed": False
            }
        else:
            logger.warning(f"Unknown action: {action}, terminating")
            return {
                **base_return,
                "next_node": "evaluator",
                "task_completed": True
            }
        
    except Exception as e:
        logger.error(f"Coordinator error: {e}")
        logger.error(traceback.format_exc())
        
        # Explicitly manage conversation history: use compressed history, add error message
        compressed_history = state_updates.get("conversation_history", state.get("conversation_history", []))
        new_history = compressed_history + [
            {"role": "user", "content": user_message},
            {"role": "assistant", "content": f"Error: {str(e)}"}
        ]
        
        return {
            "coordinator_thought": f"Error: {str(e)}",
            "coordinator_action": "terminate",
            "coordinator_content": "",
            "conversation_history": new_history,  # complete replacement
            "history_summary": state_updates.get("history_summary", ""),
            "last_history_summary_at": state_updates.get("last_history_summary_at", 0),
            "next_node": "evaluator",
            "task_completed": True
        }


def code_executor_node(state: AgentState) -> dict:
    """Execute bash commands in the desktop environment."""
    logger = logging.getLogger("desktopenv")
    
    bash_code = state["coordinator_content"]
    env = state["env"]
    operation_count = state["operation_count"] + 1
    
    logger.info(f"\n{'='*80}")
    logger.info(f"[Bash Execution] Operation #{operation_count}")
    logger.info(f"Code:\n{bash_code}")
    logger.info("="*80)
    
    exitcode = 1
    logs = ""
    
    try:
        output_dict = env.controller.run_bash_script(bash_code, timeout=300)
        exitcode = 0 if output_dict["status"] == "success" else 1
        logs = output_dict["output"]
    except Exception as e:
        exitcode = 1
        logs = f"Execution error: {str(e)}"
        logger.error(traceback.format_exc())
    
    success = (exitcode == 0)
    
    # Take screenshot after execution
    screenshot = env.controller.get_screenshot()
    screenshot_filename = f"step_{operation_count}_bash.png"
    
    with open(os.path.join(state["operations_dir"], screenshot_filename), "wb") as f:
        f.write(screenshot)
    
    # Log the action
    action_log = {
        "step": operation_count,
        "type": "bash_execution",
        "code": bash_code,
        "exitcode": exitcode,
        "output": logs,
        "cost": 0.0,
        "screenshot": screenshot_filename
    }
    
    result_message = f"Bash execution {'succeeded' if success else 'failed'}.\nOutput:\n{logs}"
    logger.info(f"Exit code: {exitcode}")
    logger.info(f"Output: {logs[:500]}")
    
    # Explicitly manage action logs: read existing logs, add new log
    current_action_logs = state.get("action_logs", [])
    new_action_logs = current_action_logs + [action_log]
    
    return {
        "operation_count": operation_count,
        "current_screenshot": screenshot,
        "last_execution_result": result_message,
        "last_execution_success": success,
        "action_logs": new_action_logs,  # complete replacement
        "next_node": "coordinator"
    }


def gui_operator_node(state: AgentState) -> dict:
    """Execute GUI operation using computer use API."""
    logger = logging.getLogger("desktopenv")
    
    task = state["coordinator_content"]
    env = state["env"]
    operation_count = state["operation_count"] + 1
    
    # Get operator LLM from state
    operator_llm = state["operator_llm"]
    
    # Check if this is a retry with failure info
    last_gui_success = state.get("last_gui_success")
    last_gui_result_check = state.get("last_gui_result_check", "")
    last_gui_task = state.get("last_gui_task", "")
    last_gui_command = state.get("last_gui_command", "")
    
    logger.info(f"\n{'='*80}")
    logger.info(f"[GUI Operation] Operation #{operation_count}")
    logger.info(f"Task: {task}")
    
    # Build previous attempt info
    previous_attempt_info = ""
    if last_gui_success is False and last_gui_result_check:
        previous_attempt_info = f"""
# IMPORTANT - Previous Attempt Failed
Task: {last_gui_task}
Your previous command: {last_gui_command}
Result: FAILED - {last_gui_result_check}

The coordinator verified from the screenshot that your previous action did not achieve the expected result.
Please re-analyze the current screenshot carefully and adjust your coordinates/approach.
"""
        logger.info(f"Previous attempt failed: {last_gui_result_check[:150]}")
    
    logger.info("="*80)
    
    screenshot = state["current_screenshot"]
    screenshot_b64 = base64.b64encode(screenshot).decode("utf-8")
    
    # Save screenshot before operation
    screenshot_filename = f"step_{operation_count}_gui.png"
    with open(os.path.join(state["operations_dir"], screenshot_filename), "wb") as f:
        f.write(screenshot)
    
    # Prepare operator prompt
    system_prompt = OPERATOR_SYSTEM_MESSAGE.format(
        CLIENT_PASSWORD=state.get("client_password", "password"),
        previous_attempt_info=previous_attempt_info
    )
    
    history_inputs = [{
        "role": "system",
        "content": [
            {"type": "input_text", "text": system_prompt},
        ],
    },
    {
        "role": "user",
        "content": [
            {"type": "input_text", "text": f"Task: {task}"},
            {"type": "input_image", "image_url": f"data:image/png;base64,{screenshot_b64}"},
        ],
    }]
    
    try:
        py_cmd, reasoning = operator_llm.call_cua(history_inputs, screen_width=state.get("screen_width", 1920), screen_height=state.get("screen_height", 1080), environment="linux")

        executed_action = False
        execution_error = None
        if py_cmd:
            try:
                logger.info(f"[GUI command] {py_cmd}")
                obs, *_ = env.step(py_cmd, state.get("sleep_after_execution", 0.5))
                executed_action = True
            except Exception as e:
                logger.error(f"GUI operation error: {e}")
                logger.error(traceback.format_exc())
                execution_error = str(e)
        
        if not reasoning:
            reasoning = "Executed GUI action" if executed_action else "No action executed"

        # Get updated screenshot
        screenshot = env.controller.get_screenshot()
        
        action_log = {
            "step": operation_count,
            "type": "gui_operator",
            "task": task,
            "command": py_cmd if py_cmd else "None",
            "result": reasoning,
            "execution_success": executed_action,
            "had_previous_failure": last_gui_success is False,
            "model": state.get("operator_model", "computer-use-preview"),
            "screenshot": screenshot_filename
        }
        
        result_message = f"GUI operation executed: {reasoning}\nCommand: {py_cmd if py_cmd else 'None'}"
        
        if not executed_action and execution_error:
            result_message += f"\n\nExecution error occurred: {execution_error}"
        
        logger.info(f"Execution status: {executed_action}")
        
        # Explicitly manage action logs: read existing logs, add new log
        current_action_logs = state.get("action_logs", [])
        new_action_logs = current_action_logs + [action_log]
        
        return {
            "operation_count": operation_count,
            "current_screenshot": screenshot,
            "last_execution_result": result_message,
            "last_execution_success": executed_action,
            "last_gui_task": task,
            "last_gui_command": py_cmd if py_cmd else "None",
            "action_logs": new_action_logs,  # complete replacement
            "next_node": "coordinator"
        }
        
    except Exception as e:
        logger.error(f"GUI operation error: {e}")
        logger.error(traceback.format_exc())
        
        action_log = {
            "step": operation_count,
            "type": "gui_operator",
            "task": task,
            "command": "Error",
            "result": f"Error: {str(e)}",
            "execution_success": False,
            "had_previous_failure": last_gui_success is False,
            "cost": 0.0,
            "screenshot": screenshot_filename
        }
        
        # Explicitly manage action logs: read existing logs, add new log
        current_action_logs = state.get("action_logs", [])
        new_action_logs = current_action_logs + [action_log]
        
        return {
            "operation_count": operation_count,
            "last_execution_result": f"GUI operation failed with exception: {str(e)}",
            "last_execution_success": False,
            "last_gui_task": task,
            "last_gui_command": "Error",
            "action_logs": new_action_logs,  # complete replacement
            "next_node": "coordinator"
        }


def evaluator_node(state: AgentState) -> dict:
    """Evaluate task completion and calculate final score."""
    logger = logging.getLogger("desktopenv")
    env = state["env"]
    
    logger.info(f"\n{'='*80}")
    logger.info("Task Evaluation")
    logger.info("="*80)
    
    try:
        logger.info("Task completed, press Esc to close the temporary window")
        esc_cmd = "pyautogui.press('esc')"
        obs, *_ = env.step(esc_cmd, 0.5)

        score = env.evaluate()
    except Exception as e:
        logger.error(f"Evaluation error: {e}")
        score = 0.0
    
    # Calculate statistics
    cua_steps = len([log for log in state["action_logs"] if log["type"] == "gui_operator"])
    coding_steps = len([log for log in state["action_logs"] if log["type"] == "bash_execution"])
    gui_execution_failures = len([log for log in state["action_logs"] if log["type"] == "gui_operator" and not log.get("execution_success", True)])
    gui_retries = len([log for log in state["action_logs"] if log["type"] == "gui_operator" and log.get("had_previous_failure", False)])
    
    # Get usage from LLM clients
    coordinator_llm = state["coordinator_llm"]
    operator_llm = state["operator_llm"]
    
    coordinator_cost, coordinator_prompt, coordinator_completion, coordinator_images = coordinator_llm.get_usage()
    operator_cost, operator_prompt, operator_completion, operator_images = operator_llm.get_usage()
    
    total_cost = coordinator_cost + operator_cost
    prompt_tokens = coordinator_prompt + operator_prompt
    completion_tokens = coordinator_completion + operator_completion
    
    model_usage = {
        "coordinator": {
            "cost": coordinator_cost,
            "prompt_tokens": coordinator_prompt,
            "completion_tokens": coordinator_completion,
            "image_count": coordinator_images
        },
        "operator": {
            "cost": operator_cost,
            "prompt_tokens": operator_prompt,
            "completion_tokens": operator_completion,
            "image_count": operator_images
        }
    }
    
    logger.info(f"Score: {score}")
    logger.info(f"Total operations: {state['operation_count']} (GUI: {cua_steps}, Bash: {coding_steps})")
    logger.info(f"GUI execution failures: {gui_execution_failures}/{cua_steps}")
    logger.info(f"GUI retries after coordinator feedback: {gui_retries}")
    logger.info(f"Total cost: ${total_cost:.4f}")
    logger.info(f"Tokens: {prompt_tokens} prompt + {completion_tokens} completion")
    
    # Create execution log
    # Merge conversation history and action logs into unified timeline
    conversation_history = state.get("conversation_history", [])
    action_logs = state.get("action_logs", [])
    unified_timeline = merge_conversation_and_actions(conversation_history, action_logs)
    
    execution_log = {
        "statistics": {
            "score": score,
            "total_steps": state["operation_count"],
            "cua_steps": cua_steps,
            "coding_steps": coding_steps,
            "gui_execution_failures": gui_execution_failures,
            "gui_retries": gui_retries,
            "total_cost": total_cost,
            "prompt_tokens": prompt_tokens,
            "completion_tokens": completion_tokens,
            "model_usage": model_usage
        },
        "task_config": state["task_config"],
        "additional_context": state["additional_context"],
        "action_logs": unified_timeline,
        "final_thought": state.get("coordinator_thought", "")
    }
    
    # Save execution log
    history_save_dir = os.path.dirname(state["operations_dir"])
    with open(os.path.join(history_save_dir, "execution_log.json"), "w") as f:
        json.dump(serialize_json(execution_log), f, indent=2)
    
    # Save score
    with open(os.path.join(history_save_dir, "result.txt"), "w") as f:
        f.write(str(score))
    
    logger.info("="*80 + "\n")
    
    return {
        "next_node": "done",
        "task_completed": True
    }


# ==================== ROUTING ====================

def route_next(state: AgentState) -> Literal["coordinator", "code_executor", "gui_operator", "evaluator", "done"]:
    """Route to next node based on current state."""
    
    # Check max steps
    if state["operation_count"] >= state.get("max_steps", 15):
        return "evaluator"
    
    # Check task completion
    if state.get("task_completed", False):
        return "done" if state["next_node"] == "done" else "evaluator"
    
    # Route based on next_node
    return state.get("next_node", "coordinator")


# ==================== WORKFLOW ====================

def create_workflow() -> StateGraph:
    """Create the LangGraph workflow."""
    workflow = StateGraph(AgentState)
    
    workflow.add_node("coordinator", coordinator_node)
    workflow.add_node("code_executor", code_executor_node)
    workflow.add_node("gui_operator", gui_operator_node)
    workflow.add_node("evaluator", evaluator_node)
    
    workflow.set_entry_point("coordinator")
    
    workflow.add_conditional_edges(
        "coordinator",
        route_next,
        {
            "coordinator": "coordinator",
            "code_executor": "code_executor",
            "gui_operator": "gui_operator",
            "evaluator": "evaluator",
            "done": END
        }
    )
    
    workflow.add_conditional_edges(
        "code_executor",
        route_next,
        {"coordinator": "coordinator", "evaluator": "evaluator"}
    )
    
    workflow.add_conditional_edges(
        "gui_operator",
        route_next,
        {"coordinator": "coordinator", "evaluator": "evaluator"}
    )
    
    workflow.add_edge("evaluator", END)
    
    return workflow.compile()


# ==================== FRAMEWORK ====================

class MyAgentFramework:
    """LangGraph-based dual agent framework with direct GUI feedback."""
    
    def __init__(
        self,
        coordinator_model: str = "gpt-o4-mini",
        operator_model: str = "computer-use-preview",
        operator_client_password: str = "",
        screen_width: int = 1920,
        screen_height: int = 1080,
        sleep_after_execution: float = 0.5,
        llm_config_path: str = None,
        max_steps: int = 15,
        history_save_dir: str = "",
        max_gui_subtask_attempts: int = 5,
        history_summary_interval: int = 8
    ):
        self.coordinator_model = coordinator_model
        self.operator_model = operator_model
        self.client_password = operator_client_password
        self.screen_width = screen_width
        self.screen_height = screen_height
        self.sleep_after_execution = sleep_after_execution
        self.max_steps = max_steps
        self.history_save_dir = history_save_dir
        self.max_gui_subtask_attempts = max_gui_subtask_attempts
        self.history_summary_interval = history_summary_interval
        
        self.workflow = create_workflow()
        self.env = None
        
        # Initialize LLM clients
        logger = logging.getLogger("desktopenv")
        self.coordinator_llm = AbstractLLM(coordinator_model, logger=logger)
        self.operator_llm = AbstractLLM(operator_model, logger=logger)
    
    def setup_environment(
        self, 
        path_to_vm: str,
        snapshot_name: str = "init_state",
        headless: bool = False
    ):
        """Initialize the desktop environment."""
        self.env = DesktopEnv(
            path_to_vm=path_to_vm,
            action_space="pyautogui",
            snapshot_name=snapshot_name,
            headless=headless,
            require_a11y_tree=False
        )
    
    def execute_task(
        self,
        task_config: dict,
        additional_context: Optional[str] = None
    ) -> float:
        """Execute a task using the LangGraph workflow."""
        if not self.env:
            raise ValueError("Environment not initialized. Call setup_environment() first.")
        
        logger = logging.getLogger("desktopenv")
        
        # Reset LLM usage stats before each task
        self.coordinator_llm.reset_stats()
        self.operator_llm.reset_stats()
        
        # Reset environment
        self.env.reset(task_config=task_config)
        
        # Create operations directory
        operations_dir = os.path.join(self.history_save_dir, "operations")
        os.makedirs(operations_dir, exist_ok=True)
        
        # Get initial screenshot
        screenshot = self.env.controller.get_screenshot()
        
        # Initialize state with LLM clients
        initial_state = {
            "task_instruction": task_config["instruction"],
            "additional_context": additional_context or "",
            "task_config": task_config,
            "current_screenshot": screenshot,
            "operation_count": 0,
            "coordinator_thought": "",
            "coordinator_action": "",
            "coordinator_content": "",
            "coordinator_gui_feedback": "",
            "last_execution_result": "",
            "last_execution_success": True,
            "current_gui_subtask": "",
            "gui_subtask_attempts": 0,
            "gui_error_history": [],
            "consecutive_gui_failures": 0,
            "action_logs": [],
            "conversation_history": [],
            "next_node": "coordinator",
            "task_completed": False,
            "env": self.env,
            "operations_dir": operations_dir,
            "coordinator_model": self.coordinator_model,
            "operator_model": self.operator_model,
            "client_password": self.client_password,
            "screen_width": self.screen_width,
            "screen_height": self.screen_height,
            "sleep_after_execution": self.sleep_after_execution,
            "max_steps": self.max_steps,
            "max_gui_subtask_attempts": self.max_gui_subtask_attempts,
            "history_summary_interval": self.history_summary_interval,
            "coordinator_llm": self.coordinator_llm,
            "operator_llm": self.operator_llm,
        }
        
        logger.info("\n" + "="*80)
        logger.info("Starting LangGraph Workflow (Smart GUI Feedback)")
        logger.info("="*80)
        logger.info(f"Task: {task_config['instruction'][:100]}...")
        logger.info(f"Coordinator model: {self.coordinator_model}")
        logger.info(f"Operator model: {self.operator_model}")
        logger.info(f"Max steps: {self.max_steps}")
        logger.info(f"Max GUI subtask attempts: {self.max_gui_subtask_attempts}")
        logger.info("="*80 + "\n")
        
        # Execute workflow with detailed logging
        try:
            iteration = 0
            for state_update in self.workflow.stream(initial_state, config={"recursion_limit": self.max_steps*2}):
                iteration += 1
                node_name = list(state_update.keys())[0]
                node_state = state_update[node_name]
                
                logger.debug(f"\n{'#'*80}")
                logger.debug(f"Iteration {iteration}: Node '{node_name}' completed")
                logger.debug(f"  Operation count: {node_state.get('operation_count', 0)}")
                logger.debug(f"  Next node: {node_state.get('next_node', 'N/A')}")
                logger.debug(f"  Task completed: {node_state.get('task_completed', False)}")
                logger.debug(f"  Coordinator action: {node_state.get('coordinator_action', 'N/A')}")
                logger.debug(f"  Consecutive GUI failures: {node_state.get('consecutive_gui_failures', 0)}")
                logger.debug(f"  GUI subtask attempts: {node_state.get('gui_subtask_attempts', 0)}")
                logger.debug(f"{'#'*80}\n")
                
                # Stop if we've reached the end
                if node_name == "evaluator":
                    final_state = node_state
                    break
            else:
                # If loop completes without break, get final state
                final_state = node_state
            
        except Exception as e:
            logger.error(f"Workflow execution error: {e}")
            logger.error(traceback.format_exc())
            
            # Create emergency execution log
            execution_log = {
                "statistics": {
                    "score": 0.0,
                    "total_steps": 0,
                    "cua_steps": 0,
                    "coding_steps": 0,
                    "gui_execution_failures": 0,
                    "total_cost": 0.0,
                    "prompt_tokens": 0,
                    "completion_tokens": 0,
                    "model_usage": {},
                    "error": str(e)
                },
                "task_config": task_config,
                "additional_context": additional_context or "",
                "action_logs": [],
                "final_thought": f"Workflow error: {str(e)}"
            }
            
            with open(os.path.join(self.history_save_dir, "execution_log.json"), "w") as f:
                json.dump(serialize_json(execution_log), f, indent=2)
            
            with open(os.path.join(self.history_save_dir, "result.txt"), "w") as f:
                f.write("0.0")
            
            return 0.0
        
        # Extract score from execution log
        execution_log_path = os.path.join(self.history_save_dir, "execution_log.json")
        if os.path.exists(execution_log_path):
            with open(execution_log_path, "r") as f:
                execution_log = json.load(f)
                score = execution_log["statistics"]["score"]
        else:
            logger.warning("Execution log not found, returning score 0.0")
            score = 0.0
        
        return score
    
    def cleanup(self):
        """Clean up resources."""
        if self.env:
            print("Closing environment...")
            self.env.close()
            self.env = None
            print("Environment closed")