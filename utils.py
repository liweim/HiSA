#!/usr/bin/env python3
"""
Common utilities for handling context construction including RAG and verbose instruction.
"""

import os
from typing import Any, Dict, List, Optional, Tuple, Union
import json
import numpy as np
import datetime
import logging
import sys
from PIL import Image
import cv2
import re
import math
import base64
import io
import pandas as pd
from plotnine import *

def get_change_roi(
    image1: Union[Image.Image, np.ndarray, str],
    image2: Union[Image.Image, np.ndarray, str],
    margin: int = 50,
) -> Union[Tuple[int, int, int, int], Tuple[Tuple[int, int, int, int], Image.Image]]:
    # Load image
    def load_image(img):
        if isinstance(img, str):
            # File path
            return cv2.imread(img)
        elif isinstance(img, Image.Image):
            # PIL Image
            return cv2.cvtColor(np.array(img), cv2.COLOR_RGB2BGR)
        elif isinstance(img, np.ndarray):
            # numpy array
            return img
        else:
            raise ValueError(f"Unsupported image type: {type(img)}")

    img1 = load_image(image1)
    img2 = load_image(image2)

    # Ensure both images have the same dimensions
    if img1.shape != img2.shape:
        raise ValueError(
            f"Images must have the same dimensions. "
            f"Got {img1.shape} and {img2.shape}"
        )

    # Convert to grayscale
    gray1 = cv2.cvtColor(img1, cv2.COLOR_BGR2GRAY) if len(img1.shape) == 3 else img1
    gray2 = cv2.cvtColor(img2, cv2.COLOR_BGR2GRAY) if len(img2.shape) == 3 else img2

    # Calculate pixel differences
    diff = cv2.absdiff(gray1, gray2)

    # Apply threshold to get binary difference map
    _, binary = cv2.threshold(diff, 0, 255, cv2.THRESH_BINARY)

    # Find all changed pixels
    coords = cv2.findNonZero(binary)

    if coords is None:
        return None, None

    # Get bounding box of changed region
    x, y, w, h = cv2.boundingRect(coords)

    # Add margin
    height, width = img1.shape[:2]
    x1 = max(0, x - margin)
    y1 = max(0, y - margin)
    x2 = min(width, x + w + margin)
    y2 = min(height, y + h + margin)

    # Crop original image (return ROI from second image)
    if isinstance(image2, Image.Image):
        cropped1 = image1.crop((x1, y1, x2, y2))
        cropped2 = image2.crop((x1, y1, x2, y2))
    else:
        # Crop from numpy array and convert to PIL Image
        img1_rgb = cv2.cvtColor(img1, cv2.COLOR_BGR2RGB) if len(img1.shape) == 3 else img1
        img2_rgb = cv2.cvtColor(img2, cv2.COLOR_BGR2RGB) if len(img2.shape) == 3 else img2
        cropped1 = Image.fromarray(img1_rgb[y1:y2, x1:x2])
        cropped2 = Image.fromarray(img2_rgb[y1:y2, x1:x2])

    # print(f"cropped size from {Image.fromarray(img1).size} to {cropped1.size}")
    # timestamp = datetime.datetime.now().strftime("%Y%m%d%H%M%S")
    # cropped1.save(f"results/tmp/cropped1_{timestamp}.png")
    # cropped2.save(f"results/tmp/cropped2_{timestamp}.png")
    return cropped1, cropped2


# ==================== Computer Use Preview (CUA) Utilities ====================
CUA_SYSTEM_PROMPT = """You are an agent that performs desktop computer tasks as instructed.
You will receive a screenshot and predict the action based on the image.

Use `pyautogui` to perform actions. DO NOT use `pyautogui.locateCenterOnScreen` or `pyautogui.screenshot()`.
Return Python code to perform ONE action at a time.
You must specify coordinates yourself based on the screenshot - be careful to ensure accuracy.

Return code in a code block:
```python
# your code here
```

Analyze the screenshot carefully and return the code."""


def count_images_in_messages(messages: list) -> int:
    """Count the number of images in message list"""
    count = 0
    for message in messages:
        if isinstance(message.get("content"), list):
            for content in message["content"]:
                if content.get("type") in ["image_url", "image", "input_image"]:
                    count += 1
    return count


def smart_resize(
    height: int,
    width: int,
    factor: int,
    min_pixels: int,
    max_pixels: int,
    max_ratio=200,
) -> tuple[int, int]:
    """
    Rescales the image so that the following conditions are met:

    1. Both dimensions (height and width) are divisible by 'factor'.

    2. The total number of pixels is within the range ['min_pixels', 'max_pixels'].

    3. The aspect ratio of the image is maintained as closely as possible.
    """
    if max(height, width) / min(height, width) > max_ratio:
        raise ValueError(
            f"absolute aspect ratio must be smaller than {max_ratio}, got {max(height, width) / min(height, width)}"
        )
    h_bar = max(factor, round_by_factor(height, factor))
    w_bar = max(factor, round_by_factor(width, factor))
    if h_bar * w_bar > max_pixels:
        beta = math.sqrt((height * width) / max_pixels)
        h_bar = floor_by_factor(height / beta, factor)
        w_bar = floor_by_factor(width / beta, factor)
    elif h_bar * w_bar < min_pixels:
        beta = math.sqrt(min_pixels / (height * width))
        h_bar = ceil_by_factor(height * beta, factor)
        w_bar = ceil_by_factor(width * beta, factor)
    return h_bar, w_bar


def round_by_factor(number: int, factor: int) -> int:
    """Returns the closest integer to 'number' that is divisible by 'factor'."""
    return round(number / factor) * factor


def ceil_by_factor(number: int, factor: int) -> int:
    """Returns the smallest integer greater than or equal to 'number' that is divisible by 'factor'."""
    return math.ceil(number / factor) * factor


def floor_by_factor(number: int, factor: int) -> int:
    """Returns the largest integer less than or equal to 'number' that is divisible by 'factor'."""
    return math.floor(number / factor) * factor


# ==================== Other Utilities ====================


def get_price(model: str) -> Tuple[float, float]:
    from llm import MODEL_CONFIGS

    # Handle unknown models gracefully
    if model not in MODEL_CONFIGS:
        import logging

        logging.warning(
            f"Model '{model}' not found in MODEL_CONFIGS, using default price (0, 0)"
        )
        return 0, 0

    llm_config = MODEL_CONFIGS[model]
    prompt_price, completion_price = (
        llm_config.prompt_price,
        llm_config.completion_price,
    )
    return prompt_price / 1000000, completion_price / 1000000


def serialize_json(obj):
    """Convert objects to JSON serializable format"""
    if hasattr(obj, "__dict__"):
        # For objects with __dict__, convert to dict but exclude non-serializable items
        result = {}
        for key, value in obj.__dict__.items():
            try:
                json.dumps(value)  # Test if value is serializable
                result[key] = value
            except (TypeError, ValueError):
                result[key] = str(value)  # Convert to string if not serializable
        return result
    elif isinstance(obj, dict):
        result = {}
        for key, value in obj.items():
            try:
                json.dumps(value)  # Test if value is serializable
                result[key] = value
            except (TypeError, ValueError):
                result[key] = str(value)  # Convert to string if not serializable
        return result
    elif isinstance(obj, (list, tuple)):
        return [serialize_json(item) for item in obj]
    else:
        try:
            json.dumps(obj)  # Test if obj is serializable
            return obj
        except (TypeError, ValueError):
            return str(obj)  # Convert to string if not serializable


def get_retrieved_context(
    config_path: str,
    topk: int = 4,
    file_name: str = "retrieved_chunk_size_512_chunk_overlap_20_topk_4_embed_bge-large-en-v1.5.txt",
) -> Optional[str]:
    """Get retrieved context from RAG file."""
    context_path = os.path.join(os.path.dirname(config_path), file_name)
    if os.path.exists(context_path):
        with open(context_path, "r", encoding="utf-8") as f:
            context = f.read().strip()
        if context.strip() == "":
            return ""
        splits = context.split("Documentation Source:")
        if len(splits) > topk + 1:  # First split is empty
            return "Documentation Source:".join(splits[: topk + 1])
        return context
    return ""


def build_additional_contexts(
    example_dir: str,
    summarize_rag: bool = False,
    use_rag: bool = False,
    rag_topk: int = 4,
    rag_filename: str = "retrieved_chunk_size_512_chunk_overlap_20_topk_4_embed_bge-large-en-v1.5.txt",
) -> Tuple[Optional[str], Optional[str]]:
    """
    Build separate RAG context and verbose instruction content based on task config tags.
    This function is for frameworks that handle RAG and verbose instruction separately.
    """
    rag_context = ""

    if use_rag:
        if summarize_rag:
            rag_path = os.path.join(example_dir, "retrieved_instruction.txt")
            if os.path.exists(rag_path):
                rag_context = open(rag_path, "r", encoding="utf-8").read()

            # json_path = os.path.join(example_dir, f"{os.path.basename(example_dir)}.json")
            # retrieved_path = os.path.join(example_dir, rag_filename)
            # with open(json_path, 'r', encoding='utf-8') as f:
            #     task_data = json.load(f)
            #     instruction = task_data.get("instruction", "")
            # retrieved_content = get_retrieved_context(retrieved_path)
            # rag_context = generate_retrieved_instruction(llm, instruction, retrieved_content)
        else:
            config_file_path = os.path.join(
                example_dir, f"{os.path.basename(example_dir)}.json"
            )
            rag_context = get_retrieved_context(
                config_file_path, rag_topk, rag_filename
            )

        if rag_context != "":
            rag_context = f"\n\nWe also retrieve relevant documentation from the web for reference (you should decide what to do based on the current environment):\n{rag_context}"

    return rag_context


def save_args_to_settings(args):
    """Save args to settings.txt in the result subdirectory"""
    os.makedirs(args.result_dir, exist_ok=True)
    settings_file = os.path.join(args.result_dir, "settings.txt")

    with open(settings_file, "w", encoding="utf-8") as f:
        args_dict = vars(args)
        for key, value in sorted(args_dict.items()):
            f.write(f"{key} = {value}\n")

def setup_logger(result_name, log_level):
    datetime_str: str = datetime.datetime.now().strftime("%Y%m%d@%H%M%S")

    logger = logging.getLogger()

    log_level = getattr(logging, log_level.upper())
    logger.setLevel(log_level)

    datetime_str: str = datetime.datetime.now().strftime("%Y%m%d@%H%M%S")

    log_folder = f"logs/{result_name}"
    os.makedirs(log_folder, exist_ok=True)
    error_handler = logging.FileHandler(
        os.path.join(log_folder, "{:}-error-{:}.log".format(result_name, datetime_str)),
        encoding="utf-8",
    )
    debug_handler = logging.FileHandler(
        os.path.join(log_folder, "{:}-debug-{:}.log".format(result_name, datetime_str)),
        encoding="utf-8",
    )
    stdout_handler = logging.StreamHandler(sys.stdout)

    error_handler.setLevel(logging.ERROR)
    debug_handler.setLevel(logging.DEBUG)
    stdout_handler.setLevel(log_level)

    formatter = logging.Formatter(
        fmt="\x1b[1;33m[%(asctime)s \x1b[31m%(levelname)s \x1b[32m%(module)s/%(lineno)d-%(processName)s\x1b[1;33m] \x1b[0m%(message)s"
    )
    error_handler.setFormatter(formatter)
    debug_handler.setFormatter(formatter)
    stdout_handler.setFormatter(formatter)

    stdout_handler.addFilter(logging.Filter("desktopenv"))

    logger.addHandler(error_handler)
    logger.addHandler(debug_handler)
    logger.addHandler(stdout_handler)

    logger = logging.getLogger("desktopenv")
    return logger

def postprocess_action(action):
    new_action = ""
    if "pyautogui.scroll" in action:
        match = re.findall(r"pyautogui\.scroll\((.*?)\)", action)
        if len(match) > 0:
            scroll_amount = match[0].split(",")[0].strip()
            if float(scroll_amount) > 5:
                new_action = action.replace(scroll_amount, "5")
            elif float(scroll_amount) < -5:
                new_action = action.replace(scroll_amount, "-5")
    if "pyautogui.sleep" in action:
        match = re.findall(r"pyautogui\.sleep\((.*?)\)", action)
        for sleep_amount in match:
            if float(sleep_amount) < 0.5:
                new_action = action.replace(sleep_amount, "0.5")
    if "time.sleep" in action:
        match = re.findall(r"time\.sleep\((.*?)\)", action)
        for sleep_amount in match:
            if float(sleep_amount) < 0.5:
                new_action = action.replace(sleep_amount, "0.5")

    if new_action:
        return new_action
    else:
        return action


def convert_to_cua_format(messages: List[Dict]) -> List[Dict]:
    """
    Convert standard message format to OpenAI Computer Use API format.

    Args:
        messages: List of messages in standard format

    Returns:
        List of messages in CUA format
    """
    formatted = []
    for msg in messages:
        formatted_msg = {"role": msg["role"]}

        if isinstance(msg["content"], list):
            # Convert content items to responses API format
            content_list = []
            for item in msg["content"]:
                if item.get("type") == "text":
                    # Convert old "text" format to new "input_text" format
                    content_list.append({"type": "input_text", "text": item["text"]})
                elif item.get("type") == "image_url":
                    # Convert old "image_url" format to new "input_image" format
                    image_url = item.get("image_url", {})
                    if isinstance(image_url, dict):
                        url = image_url.get("url", "")
                    else:
                        url = image_url
                    content_list.append({"type": "input_image", "image_url": url})
                elif item.get("type") == "input_text":
                    # Already in correct format
                    content_list.append(item)
                elif item.get("type") == "input_image":
                    # Already in correct format
                    content_list.append(item)
                else:
                    # Keep other types as-is (fallback)
                    content_list.append(item)

            formatted_msg["content"] = content_list
        else:
            # Simple text message - convert to input_text format
            formatted_msg["content"] = [{"type": "input_text", "text": msg["content"]}]

        formatted.append(formatted_msg)

    return formatted


def cua_to_pyautogui(action) -> str:
    """
    Convert OpenAI CUA action to pyautogui command.

    Args:
        action: CUA action object or dict

    Returns:
        String containing pyautogui command
    """

    def fld(key: str, default: Any = None) -> Any:
        return (
            action.get(key, default)
            if isinstance(action, dict)
            else getattr(action, key, default)
        )

    act_type = fld("type")
    if not isinstance(act_type, str):
        act_type = str(act_type).split(".")[-1]
    act_type = act_type.lower()

    if act_type in ["click", "double_click"]:
        button = fld("button", "left")
        if button in [1, "left"]:
            button = "left"
        elif button in [2, "middle"]:
            button = "middle"
        elif button in [3, "right"]:
            button = "right"

        if act_type == "click":
            return f"pyautogui.click({fld('x')}, {fld('y')}, button='{button}')"
        if act_type == "double_click":
            return f"pyautogui.doubleClick({fld('x')}, {fld('y')}, button='{button}')"

    if act_type == "scroll":
        if fld("scroll_y", 0) != 0:
            return f"pyautogui.scroll({-fld('scroll_y', 0) / 100}, x={fld('x', 0)}, y={fld('y', 0)})"
        return ""

    if act_type == "drag":
        path = fld("path", [{"x": 0, "y": 0}, {"x": 0, "y": 0}])
        cmd = f"pyautogui.moveTo({path[0]['x']}, {path[0]['y']}, _pause=False); "
        cmd += f"pyautogui.dragTo({path[1]['x']}, {path[1]['y']}, duration=0.5, button='left')"
        return cmd

    if act_type == "move":
        return f"pyautogui.moveTo({fld('x')}, {fld('y')})"

    if act_type == "keypress":
        keys = fld("keys", []) or [fld("key")]
        if len(keys) == 1:
            return f"pyautogui.press('{keys[0].lower()}')"
        else:
            return "pyautogui.hotkey('{}')".format("', '".join(keys)).lower()

    if act_type == "type":
        text = str(fld("text", ""))
        return "pyautogui.typewrite({:})".format(repr(text))

    return "WAIT"


def parse_cua_response(response) -> Tuple[str, str, str]:
    """
    Parse OpenAI Computer Use API response.

    Args:
        response: Response object from OpenAI CUA API

    Returns:
        Tuple of (py_cmd, reasoning, message_text)
    """
    reasoning = ""
    py_cmd = ""
    message_text = ""

    for output_item in response.output:
        output_type = (
            output_item.get("type", "")
            if isinstance(output_item, dict)
            else getattr(output_item, "type", "")
        )

        if "computer_call" in str(output_type):
            action_call = (
                output_item
                if isinstance(output_item, dict)
                else output_item.model_dump()
            )
            py_cmd = cua_to_pyautogui(action_call["action"])

        elif (
            "reasoning" in str(output_type)
            and hasattr(output_item, "summary")
            and len(output_item.summary) > 0
        ):
            reasoning = output_item.summary[0].text

        elif "message" in str(output_type) or "output_text" in str(output_type):
            if hasattr(output_item, "content") and len(output_item.content) > 0:
                message_text = (
                    output_item.content[0].text
                    if hasattr(output_item.content[0], "text")
                    else str(output_item.content[0])
                )
            else:
                message_text = str(output_item)

    unify_output = ""
    if py_cmd:
        unify_output = py_cmd
    elif message_text:
        unify_output = message_text
    elif reasoning:
        unify_output = reasoning
    return unify_output, py_cmd, reasoning, message_text


def call_computer_use_api(
    llm_client,
    messages: List[Dict],
    model: str = "computer-use-preview",
    environment: str = "linux",
    usage_stats=None,
):
    """
    Call OpenAI Computer Use Preview API and handle the complete workflow.

    Args:
        llm_client: OpenAI client instance
        messages: List of messages in standard format
        model: Model name (default: "computer-use-preview")
        environment: Operating system environment
        usage_stats: Optional UsageStats object to update token usage
        return_details: If True, return (py_cmd, reasoning, message_text) tuple;
                       If False, return single string result

    Returns:
        If return_details=True: Tuple of (py_cmd, reasoning, message_text)
        If return_details=False: String containing the result (py_cmd, message_text, or reasoning)
    """
    # Convert messages to CUA format
    formatted = convert_to_cua_format(messages)
    screenshot = Image.open(
        io.BytesIO(
            base64.b64decode(
                messages[1]["content"][1]["image_url"].replace(
                    "data:image/png;base64,", ""
                )
            )
        )
    )
    screen_width, screen_height = screenshot.size

    # Call the API
    response = llm_client.responses.create(
        model=model,
        tools=[
            {
                "type": "computer_use_preview",
                "display_width": screen_width,
                "display_height": screen_height,
                "environment": environment,
            }
        ],
        input=formatted,
        reasoning={"summary": "concise"},
        tool_choice="required",
        truncation="auto",
    )

    # Update token usage statistics if provided
    if usage_stats is not None and hasattr(response, "usage"):
        usage_stats.prompt_tokens += response.usage.input_tokens
        usage_stats.completion_tokens += response.usage.output_tokens
        usage_stats.image_count += count_images_in_messages(formatted)

    return parse_cua_response(response)

def add_results(root, result_name, select_example=False):
    result_path = "result_human.xlsx"
    df = pd.read_excel(result_path)
    df[result_name] = 0
    selected = {}
    count = 0
    config = json.load(
        open(f"{root}/evaluation_examples/test_abstract.json", "r", encoding="utf-8")
    )
    for i, (domain, lines) in enumerate(config.items()):
        # if domain != 'snowflake':
        #     continue
        for id in lines:
            idx = df[df["id"] == id].index[0]
            js = json.load(
                open(
                    f"{root}/evaluation_examples/examples/{domain}/{id}/{id}.json",
                    "r",
                    encoding="utf-8",
                )
            )
            action_number = js["action_number"]
            if action_number <= 5:
                level = "easy"
            elif action_number <= 15:
                level = "medium"
            else:
                level = "hard"
            df.loc[idx, "action_number"] = action_number
            df.loc[idx, "level"] = level
            path = f"{root}/results/{result_name}/{domain}/{id}/result.txt"
            if os.path.exists(path):
                r = eval(open(path, "r", encoding="utf-8").read())
            else:
                r = 0
            if df.loc[idx, "type"] == "abstract" and (
                r > 0 or df.loc[idx, "agents3_gpt5_uitars1.5_50"] > 0
            ):
                # if pd.isna(df.loc[idx, 'score']):
                if domain not in selected:
                    selected[domain] = []
                selected[domain].append(id)
                count += 1
            df.loc[idx, result_name] = r
    df.to_excel(result_path, index=False)

    print(count)

    if select_example:
        with open(
            f"{root}/evaluation_examples/select2.json", "w", encoding="utf-8"
        ) as f:
            json.dump(selected, f, indent=2, ensure_ascii=False)


def calculate_resolution_token_increase(result_dir: str) -> Dict[str, float]:
    """
    Calculate the token increase if image resolution is increased.

    Token increase per image for different models:
    - gpt-5: 0 tokens/image (no increase)
    - gpt-5-mini: 705 tokens/image
    - gta1-7b: 1495 tokens/image

    Args:
        result_dir: Path to the result directory

    Returns:
        Dictionary with statistics:
        - average_tokens_per_task: Average token increase per task
        - total_tokens: Total token increase across all tasks
        - num_tasks: Number of tasks processed
        - model_breakdown: Per-model token increase details
    """
    # Token increase per image for each model
    TOKEN_INCREASE_PER_IMAGE = {
        "gpt-5": 0,
        "gpt-5-mini": 705,
        "gta1-7b": 1495,
    }

    # Statistics containers
    total_token_increase = 0
    num_tasks = 0
    model_stats = {}
    task_token_increases = []

    # Traverse all execution_log.json files
    for domain_dir in os.listdir(result_dir):
        domain_path = os.path.join(result_dir, domain_dir)
        if not os.path.isdir(domain_path):
            continue

        for task_id in os.listdir(domain_path):
            task_path = os.path.join(domain_path, task_id)
            if not os.path.isdir(task_path):
                continue

            execution_log_file = os.path.join(task_path, "execution_log.json")
            if not os.path.exists(execution_log_file):
                continue

            try:
                with open(execution_log_file, "r", encoding="utf-8") as f:
                    execution_log = json.load(f)

                stats = execution_log.get("statistics", {})
                model_usage = stats.get("model_usage", {})

                task_token_increase = 0

                # Calculate token increase for each model used in this task
                for role, usage in model_usage.items():
                    model_name = usage.get("model_name", "")
                    image_count = usage.get("image_count", 0)

                    # Get token increase per image for this model
                    token_increase_per_img = TOKEN_INCREASE_PER_IMAGE.get(model_name, 0)

                    # Calculate total token increase for this model in this task
                    model_token_increase = image_count * token_increase_per_img
                    task_token_increase += model_token_increase

                    # Track per-model statistics
                    if model_name not in model_stats:
                        model_stats[model_name] = {
                            "total_images": 0,
                            "total_token_increase": 0,
                            "token_per_image": token_increase_per_img
                        }

                    model_stats[model_name]["total_images"] += image_count
                    model_stats[model_name]["total_token_increase"] += model_token_increase

                task_token_increases.append(task_token_increase)
                total_token_increase += task_token_increase
                num_tasks += 1

            except Exception as e:
                print(f"Warning: Could not process {execution_log_file}: {e}")
                continue

    # Calculate averages
    avg_tokens_per_task = total_token_increase / num_tasks if num_tasks > 0 else 0

    # Print summary
    print(f"\n{'='*60}")
    print(f"Resolution Increase Token Analysis")
    print(f"{'='*60}")
    print(f"Total tasks analyzed: {num_tasks}")
    print(f"Total token increase: {total_token_increase/1e3}")
    print(f"Average tokens per task: {avg_tokens_per_task/1e3:,.2f}")

def summary(result_dir, test_all_meta):
    """
    Generate summary from test results.
    
    Args:
        result_dir: Path to results directory
        test_all_meta: Can be:
            - str: Path to JSON file
            - dict: {domain: [example_id, ...]}
            - list: [(domain, example_id), ...]
    """
    # Handle different input types
    if type(test_all_meta) == str:
        with open(test_all_meta, "r", encoding="utf-8") as f:
            test_all_meta = json.load(f)
    elif type(test_all_meta) == list:
        # Convert list of tuples to dict
        meta_dict = {}
        for domain, example_id in test_all_meta:
            if domain not in meta_dict:
                meta_dict[domain] = []
            meta_dict[domain].append(example_id)
        test_all_meta = meta_dict

    all_scores = []
    all_scores_50 = []
    all_costs = []
    all_prompt_tokens = []
    all_completion_tokens = []
    all_image_counts = []
    all_execution_times = []
    stats = {}
    global_model_usage = {}  # Track usage across all models
    count_remain = 0  # Tasks without result.txt
    count_errors = 0  # Tasks with err_reason.txt

    for domain in test_all_meta:
        stats[domain] = {
            "score": [],
            "cost": [],
            "gui_steps": [],
            "code_steps": [],
            "total_steps": [],
            "execution_time": [],
            "prompt_tokens": [],
            "completion_tokens": [],
            "image_counts": [],
        }

        for ex_id in test_all_meta[domain]:
            score_file = os.path.join(result_dir, f"{domain}/{ex_id}/result.txt")
            execution_log_file = os.path.join(result_dir, f"{domain}/{ex_id}/execution_log.json")
            error_file = os.path.join(result_dir, f"{domain}/{ex_id}/err_reason.txt")

            # --- 1. Get Score ---
            has_completed_score = os.path.exists(score_file)
            if has_completed_score:
                with open(score_file, "r") as f:
                    try:
                        score = eval(f.read()) * 100
                    except:
                        score = 0
            else:
                # Missing result file means the task has not completed yet.
                score = 0
            if score > 0 and os.path.exists(error_file):
                os.remove(error_file)
            if not os.path.exists(score_file) or os.path.exists(error_file):
                count_remain += 1

            score_50 = 0
            if has_completed_score:
                all_scores.append(score)
                stats[domain]["score"].append(score)

            # --- 2. Check for Errors ---
            # If an error file exists, skip statistics and fail logging after recording the score.
            # This ensures we don't record cost/tokens or add it to 'fails'.
            if os.path.exists(error_file):
                print(f"Error file exists: {error_file}")
                assert score == 0, f"Score is not 0 when error file exists: {error_file}"
                count_errors += 1
                all_scores_50.append(score_50)
                continue 

            # --- 3. Process Execution Log ---
            # Logic reaches here only if err_reason.txt does not exist.
            
            if os.path.exists(execution_log_file):
                try:
                    with open(execution_log_file, "r", encoding="utf-8") as f:
                        execution_log = json.load(f)

                    execution_stats = execution_log.get("statistics", {})
                    
                    # Extract basic data
                    cost = execution_stats.get("total_cost", 0)
                    prompt_tokens = execution_stats.get("prompt_tokens", 0) / 1e3
                    completion_tokens = execution_stats.get("completion_tokens", 0) / 1e3
                    image_count = execution_stats.get("image_count", 0)
                    execution_time = execution_stats.get("execution_time", 0)
                    
                    # Extract step data
                    if "cua_steps" in execution_stats:
                        gui_steps = execution_stats.get("cua_steps", 0)
                        code_steps = execution_stats.get("coding_steps", 0)
                    else:
                        gui_steps = execution_stats.get("total_steps", 0)
                        code_steps = 0

                    # Accumulate Model Usage
                    local_model_usage = execution_stats.get("model_usage", {})
                    for model, usage in local_model_usage.items():
                        if model not in global_model_usage:
                            global_model_usage[model] = {
                                "model_name": usage.get("model_name", "unknown"),
                                "cost": 0, "prompt_tokens": 0, "completion_tokens": 0
                            }
                        global_model_usage[model]["cost"] += usage.get("cost", 0)
                        global_model_usage[model]["prompt_tokens"] += usage.get("prompt_tokens", 0) / 1e3
                        global_model_usage[model]["completion_tokens"] += usage.get("completion_tokens", 0) / 1e3
                    
                    # --- 4. Record Statistics ---
                    # Only record these if no error occurred and execution_log exists
                    all_costs.append(cost)
                    all_prompt_tokens.append(prompt_tokens)
                    all_completion_tokens.append(completion_tokens)
                    all_image_counts.append(image_count)
                    all_execution_times.append(execution_time)
                    
                    stats[domain]["cost"].append(cost)
                    stats[domain]["gui_steps"].append(gui_steps)
                    stats[domain]["code_steps"].append(code_steps)
                    stats[domain]["total_steps"].append(gui_steps + code_steps)
                    stats[domain]["execution_time"].append(execution_time)
                    stats[domain]["prompt_tokens"].append(prompt_tokens)
                    stats[domain]["completion_tokens"].append(completion_tokens)
                    stats[domain]["image_counts"].append(image_count)
                    total_task_steps = gui_steps + code_steps
                    if total_task_steps <= 50:
                        score_50 = score
                    all_scores_50.append(score_50)
                except:
                    print(f"error loading execution_log_file: {execution_log_file}")
                    if has_completed_score:
                        all_scores_50.append(score_50)
                    continue
            else:
                if os.path.exists(score_file):
                    print(f"not found: {execution_log_file}")
                if has_completed_score:
                    all_scores_50.append(score_50)
                continue

    num_tasks = sum(len(example_ids) for example_ids in test_all_meta.values())
    num_completed_scores = len(all_scores)
    num_tasks_with_log = len(all_costs)  # Number of tasks with execution_log
    avg_score = np.mean(all_scores) if num_completed_scores > 0 else 0
    avg_score_50 = np.mean(all_scores_50) if num_completed_scores > 0 else 0
    total_cost = sum(all_costs)

    # Calculate total operations and tokens
    total_gui_steps = sum(
        sum(stats[domain]["gui_steps"]) for domain in stats
    )
    total_code_steps = sum(
        sum(stats[domain]["code_steps"]) for domain in stats
    )
    total_steps = total_gui_steps + total_code_steps
    total_prompt_tokens = sum(all_prompt_tokens)
    total_completion_tokens = sum(all_completion_tokens)
    total_tokens = total_prompt_tokens + total_completion_tokens
    total_image_counts = sum(all_image_counts)
    total_execution_times = sum(all_execution_times)
    
    # Use number of tasks with execution_log to calculate averages
    avg_cost = total_cost / num_tasks_with_log if num_tasks_with_log > 0 else 0
    avg_steps = total_steps / num_tasks_with_log if num_tasks_with_log > 0 else 0
    avg_gui_steps = total_gui_steps / num_tasks_with_log if num_tasks_with_log > 0 else 0
    avg_code_steps = total_code_steps / num_tasks_with_log if num_tasks_with_log > 0 else 0
    avg_prompt_tokens = total_prompt_tokens / num_tasks_with_log if num_tasks_with_log > 0 else 0
    avg_completion_tokens = total_completion_tokens / num_tasks_with_log if num_tasks_with_log > 0 else 0
    avg_total_tokens = total_tokens / num_tasks_with_log if num_tasks_with_log > 0 else 0
    avg_image_counts = total_image_counts / num_tasks_with_log if num_tasks_with_log > 0 else 0
    avg_execution_time = total_execution_times / num_tasks_with_log if num_tasks_with_log > 0 else 0

    # Save detailed statistics as JSON
    detailed_stats = {
        "summary": {
            "score": avg_score,
            "score_50": avg_score_50,
            "total_tasks": num_tasks,
            "completed_tasks": num_completed_scores,
            "left_tasks": count_remain,  # All incomplete tasks
            "error_tasks": count_errors,  # Only tasks with err_reason.txt
            "total": {
                "cost": total_cost,
                "tokens": total_tokens,
                "prompt_tokens": total_prompt_tokens,
                "completion_tokens": total_completion_tokens,
                "image_counts": total_image_counts,
                "steps": total_steps,
                "cua_steps": total_gui_steps,
                "code_steps": total_code_steps,
                "execution_time": total_execution_times,
            },
            "average": {
                "score": avg_score,
                "score_50": avg_score_50,
                "cost": avg_cost,
                "tokens": avg_total_tokens,
                "prompt_tokens": avg_prompt_tokens,
                "completion_tokens": avg_completion_tokens,
                "image_counts": avg_image_counts,
                "steps": avg_steps,
                "cua_steps": avg_gui_steps,
                "code_steps": avg_code_steps,
                "execution_time": avg_execution_time,
            },
            "domain_score": {
                domain: np.mean(stats[domain]["score"]) if len(stats[domain]["score"]) > 0 else 0
                for domain in test_all_meta
            },
            "model_usage": global_model_usage,
        },
        "domain_breakdown": {
            domain: {
                "score": np.mean(stats[domain]["score"]) if len(stats[domain]["score"]) > 0 else 0,
                "cost": np.mean(stats[domain]["cost"]) if len(stats[domain]["cost"]) > 0 else 0,
                "tokens": (
                    np.mean(stats[domain]["prompt_tokens"])
                    + np.mean(stats[domain]["completion_tokens"])
                ) if len(stats[domain]["prompt_tokens"]) > 0 and len(stats[domain]["completion_tokens"]) > 0 else 0,
                "prompt_tokens": np.mean(stats[domain]["prompt_tokens"]) if len(stats[domain]["prompt_tokens"]) > 0 else 0,
                "completion_tokens": np.mean(
                    stats[domain]["completion_tokens"]
                ) if len(stats[domain]["completion_tokens"]) > 0 else 0,
                "image_counts": np.mean(stats[domain]["image_counts"]) if len(stats[domain]["image_counts"]) > 0 else 0,
                "steps": np.mean(stats[domain]["total_steps"]) if len(stats[domain]["total_steps"]) > 0 else 0,
                "cua_steps": np.mean(stats[domain]["gui_steps"]) if len(stats[domain]["gui_steps"]) > 0 else 0,
                "code_steps": np.mean(stats[domain]["code_steps"]) if len(stats[domain]["code_steps"]) > 0 else 0,
                "execution_time": np.mean(stats[domain]["execution_time"]) if len(stats[domain]["execution_time"]) > 0 else 0,
            }
            for domain in test_all_meta
        },
    }

    with open(os.path.join(result_dir, "summary.json"), "w", encoding="utf-8") as f:
        json.dump(detailed_stats, f, indent=2, ensure_ascii=False)

    summary_stats = detailed_stats['summary']
    # print(json.dumps(summary_stats, indent=2, ensure_ascii=False))

    total_tasks = summary_stats['total_tasks']
    left_tasks = summary_stats['left_tasks']
    error_tasks = summary_stats['error_tasks']
    avg_score = summary_stats['score']
    avg_score_50 = summary_stats['score_50']
    avg_cost = summary_stats['average']['cost']
    avg_total_tokens = summary_stats['average']['tokens']
    avg_prompt_tokens = summary_stats['average']['prompt_tokens']
    avg_completion_tokens = summary_stats['average']['completion_tokens']
    avg_steps = summary_stats['average']['steps']
    avg_execution_time = summary_stats['average']['execution_time']
    
    print(f"Total tasks: {total_tasks}, Left tasks: {left_tasks}, Error tasks: {error_tasks}")
    print(f"method, score, score_50, cost, tokens, prompt_tokens, completion_tokens, steps, execution_time:\n{os.path.basename(result_dir)},{avg_score:.2f},{avg_score_50:.2f},{avg_cost:.2f},{avg_total_tokens:.2f},{avg_prompt_tokens:.2f},{avg_completion_tokens:.2f},{avg_steps:.2f},{avg_execution_time:.2f}")
    print('*'*100)
    return detailed_stats

if __name__ == "__main__":
    summary('results/hisa2_qwen3.5-9b_wo_pattern', 'benchmarks/OSWorld/evaluation_examples/debug.json')
    summary('results/hisa2_qwen3.5-9b_wo_pattern_old', 'benchmarks/OSWorld/evaluation_examples/debug.json')