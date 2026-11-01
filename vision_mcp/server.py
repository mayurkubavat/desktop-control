"""Vision Control Model Context Protocol (MCP) Server.

Exposes tools for autonomous Linux and cross-platform desktop UI navigation,
perception with Set-of-Marks, pluggable GroundingEngine (ensemble, semantic, cv, template),
input injection, compound autonomous actions, and closed-loop verification.
"""

import os
import sys
import tempfile
import subprocess
import time
from typing import Optional, List, Dict, Any

try:
    from mcp.server.mcpserver import MCPServer
    from mcp.server.mcpserver.exceptions import ToolError
except ImportError:
    from mcp.server.fastmcp import FastMCP as MCPServer

    class ToolError(RuntimeError):
        pass

from vision_mcp.hal.factory import get_desktop_hal
from vision_mcp.agent_loop.controller import FeedbackLoopController
from vision_mcp.agent_loop.trajectory import TrajectoryEngine
from vision_mcp.types import FindElementResult, DiagnosticsResult
from vision_mcp.config import CONFIG
from vision_mcp.toolset import ToolSetManager, ToolDefinition, OutputMode

_TOOL_LIST_NOTIFICATIONS: List[str] = []


def _notify_tools_changed() -> None:
    """Records notifications/tools/list_changed and forwards it when a session exists."""
    _TOOL_LIST_NOTIFICATIONS.append("notifications/tools/list_changed")
    session = getattr(mcp_server, "active_session", None)
    if session is None or not hasattr(session, "send_tool_list_changed"):
        return None
    loop = getattr(mcp_server, "active_loop", None)
    # Sync tools run in a worker thread. The session's streams belong to the server's
    # event loop, so the notification must be scheduled there, not in a new loop.
    if loop is not None and loop.is_running():
        import asyncio

        try:
            if asyncio.get_running_loop() is loop:
                loop.create_task(session.send_tool_list_changed())
                return None
        except RuntimeError:
            pass
        asyncio.run_coroutine_threadsafe(session.send_tool_list_changed(), loop)
        return None
    return session.send_tool_list_changed()


class DesktopControlServer(MCPServer):
    """MCP server whose tools/list follows the active domain profile."""

    active_session: Any = None
    active_loop: Any = None

    async def list_tools(self):
        tools = await super().list_tools()
        active = {schema["name"] for schema in toolset_manager.get_active_mcp_schemas()}
        return [tool for tool in tools if tool.name in active]

    async def call_tool(self, name, arguments, context=None):
        if context is not None and getattr(context, "session", None) is not None:
            self.active_session = context.session
            import asyncio

            self.active_loop = asyncio.get_running_loop()
        if not toolset_manager.is_tool_active(name):
            raise ToolError(f"Tool '{name}' is outside the active tool profile. Call manage_toolsets to enable it.")
        return await super().call_tool(name, arguments, context)


mcp_server = DesktopControlServer("desktop-control")
hal = get_desktop_hal()
controller = FeedbackLoopController(hal)
trajectory_engine = TrajectoryEngine(controller)

toolset_manager = ToolSetManager(
    initial_profile=CONFIG.toolset_profile,
    output_mode=OutputMode(CONFIG.output_mode),
    max_inline_tokens=CONFIG.output_file_threshold_tokens,
    state_dir=CONFIG.state_dir,
    notify_tools_changed_cb=_notify_tools_changed,
)

# Register tools with ToolSetManager for dynamic capability gating
_TOOL_DOMAINS: Dict[str, tuple[str, str]] = {
    # Core tools. The cheap perception tiers (AX tree, OCR, local yes/no) stay in core so
    # the minimal profile can avoid screenshots.
    "take_screenshot": ("core", "Captures desktop screen with visual perception"),
    "click": ("core", "Emulates mouse clicks"),
    "type_text": ("core", "Types text"),
    "press_key": ("core", "Presses single key"),
    "hotkey": ("core", "Presses hotkey combo"),
    "scroll": ("core", "Scrolls mouse wheel"),
    "manage_toolsets": ("core", "Manages active tool domains and out-of-band output mode"),
    # Window management
    "list_windows": ("window_mgmt", "Lists active top-level windows"),
    "get_active_window": ("window_mgmt", "Gets currently active window"),
    "focus_window": ("window_mgmt", "Focuses target window"),
    "capture_window": ("window_mgmt", "Captures target or active window"),
    "wait_for_ui_change": ("window_mgmt", "Waits for visual quiescence"),
    # Developer tools
    "get_accessibility_tree": ("core", "Queries OS accessibility bus"),
    "find_element": ("core", "Finds element in accessibility tree"),
    "click_and_type": ("developer", "Compound click then type"),
    "find_and_click": ("core", "Finds accessibility element and clicks"),
    "move_cursor": ("developer", "Moves mouse cursor"),
    "drag_and_drop": ("developer", "Performs mouse drag and drop"),
    "scroll_until_visible": ("developer", "Scrolls until element is visible"),
    "run_terminal_command": ("developer", "Executes shell command"),
    "dismiss_obstructions": ("developer", "Detects and dismisses modals"),
    "resolve_modal_dialog": ("developer", "Clicks button on modal dialog"),
    "manage_cache": ("developer", "Manages self-healing action cache"),
    "execute_trajectory": ("developer", "Executes compound deterministic trajectory"),
    "compact_history": ("developer", "Compacts trajectory history into an 8-part checkpoint"),
    # Advanced vision
    "configure_vision": ("advanced_vision", "Configures runtime vision parameters"),
    "get_vision_diagnostics": ("advanced_vision", "Returns perception system health"),
    "ask_screen": ("core", "Answers visual questions via OCR/Gemma"),
    "read_screen_text": ("core", "Extracts screen text via local OCR"),
    "find_visual_element": ("advanced_vision", "Finds visual elements without accessibility names"),
    # Plugins
    "list_plugins": ("plugins", "Lists discovered application plugins"),
    "list_plugin_features": ("plugins", "Lists application features"),
    "invoke_plugin_feature": ("plugins", "Executes high-level plugin action"),
    "capture_pane": ("plugins", "Captures named application sub-pane"),
    # Skills
    "start_skill_recording": ("skills", "Begins recording trajectory"),
    "stop_skill_recording": ("skills", "Stops recording and returns session journal"),
    "crystallize_skill": ("skills", "Crystallizes recorded session into reusable macro"),
    "execute_crystallized_skill": ("skills", "Executes crystallized skill with parameter substitution"),
    "list_crystallized_skills": ("skills", "Lists all crystallized skills"),
    "delete_crystallized_skill": ("skills", "Deletes crystallized skill"),
    "start_cassette_recording": ("skills", "Records live actions and screen state as a replayable cassette"),
    "stop_cassette_recording": ("skills", "Stops cassette recording and writes index.json"),
    # VDOM
    "capture_vdom": ("vdom", "Captures unified Virtual DOM snapshot"),
    "query_vdom": ("vdom", "Zero-token spatial and semantic query on VDOM"),
}

for _name, (_dom, _desc) in _TOOL_DOMAINS.items():
    toolset_manager.register_tool(ToolDefinition(name=_name, domain=_dom, description=_desc))


@mcp_server.tool()
def take_screenshot(
    mode: str = "annotated_som",
    app_filter: Optional[str] = None,
    region: Optional[List[int]] = None,
    window_id: Optional[str] = None,
    clip_to_active_window: bool = False,
    strategy_override: Optional[str] = None,
    zoom_factor: float = 1.0,
    include_image: bool = False,
) -> Dict[str, Any]:
    """
    Captures the desktop screen with visual perception and Set-of-Marks.

    The default payload is the mark list (id, role, name, center) and a resource
    URI for the image. Pass include_image=True to inline image_base64.

    Args:
        mode: 'annotated_som', 'annotated_cv', 'cursor_only', or 'raw'.
        app_filter: Optional application title or process filter.
        region: Optional [x, y, width, height] bounding box.
        window_id: Optional window identifier to clip perception to.
        clip_to_active_window: Crop to the focused window.
        strategy_override: 'ensemble', 'semantic', 'cv', or 'template'.
        zoom_factor: Magnification for a coarse-to-fine crop.
        include_image: When true, include image_base64 in the tool result.
    """
    reg_tuple = tuple(region) if region and len(region) == 4 else None
    result = controller.capture_state(
        mode=mode,
        app_filter=app_filter,
        region=reg_tuple,
        window_id=window_id,
        clip_to_active_window=clip_to_active_window,
        strategy_override=strategy_override,
        zoom_factor=zoom_factor,
    )
    return _screenshot_summary(result.model_dump(), include_image)


def _screenshot_summary(payload: Dict[str, Any], include_image: bool) -> Dict[str, Any]:
    """Marks header by default. The image bytes are a resource unless inlined."""
    marks = []
    for mark in payload.get("marks") or []:
        bbox = mark.get("bbox") or {}
        cx = int(bbox.get("x", 0)) + int(bbox.get("width", 0)) // 2
        cy = int(bbox.get("y", 0)) + int(bbox.get("height", 0)) // 2
        marks.append({
            "id": mark.get("id"),
            "role": mark.get("role"),
            "name": mark.get("name"),
            "center": [cx, cy],
        })
    summary: Dict[str, Any] = {
        "ok": True,
        "kind": "screenshot",
        "width": payload["width"],
        "height": payload["height"],
        "scale_factor": payload["scale_factor"],
        "marks": marks,
        "marks_count": len(marks),
        "mime_type": payload.get("mime_type", "image/jpeg"),
    }
    image_body = {
        "image_base64": payload.get("image_base64", ""),
        "mime_type": payload.get("mime_type", "image/jpeg"),
        "width": payload["width"],
        "height": payload["height"],
    }
    if include_image:
        summary["image_base64"] = payload.get("image_base64", "")
    else:
        offloaded = toolset_manager.format_output(
            "take_screenshot",
            image_body,
            output_mode_override=OutputMode.RESOURCE,
            force_offload=True,
        )
        summary["uri"] = offloaded.get("uri") or offloaded.get("resource_uri")
        summary["image_offloaded"] = bool(offloaded.get("offloaded"))
        if not offloaded.get("offloaded"):
            summary["image_base64"] = payload.get("image_base64", "")
    return summary


@mcp_server.tool()
def capture_window(
    window_id: Optional[str] = None,
    title_filter: Optional[str] = None,
    mode: str = "annotated_som",
) -> Dict[str, Any]:
    """
    High-efficiency perception tool that captures strictly the target or active window.
    Slashes multimodal token consumption by 60-80% compared to capturing a full 4K display.

    Args:
        window_id: Hex or integer window identifier. If None, uses title_filter or active window.
        title_filter: Substring to match window title (e.g. 'Chrome', 'Terminal', 'Verdi').
        mode: 'annotated_som', 'annotated_cv', or 'raw'.
    """
    target_win = controller.window_clipper.resolve_target_window(window_id=window_id, title_filter=title_filter)
    win_id = target_win.window_id if target_win else None
    result = controller.capture_state(
        mode=mode,
        window_id=win_id,
        clip_to_active_window=(target_win is None),
    )
    return result.model_dump()


@mcp_server.tool()
def dismiss_obstructions(
    max_attempts: int = 2,
) -> Dict[str, Any]:
    """
    Autonomous defense & modal triage: Detects and classifies blocking modal popups.
    Safely auto-dismisses benign popups and acknowledges informative completion notices,
    while halting and returning an escalation payload for workflow-branching or destructive dialogs.

    Args:
        max_attempts: Number of dismissal iterations.
    """
    triage = controller.obstruction_interceptor.triage_and_resolve()
    res = triage.model_dump()
    res["obstruction_cleared"] = triage.auto_dismissed
    res["actions_taken"] = [triage.action_taken] if triage.action_taken else []
    return res


@mcp_server.tool()
def resolve_modal_dialog(
    button_id: Optional[str] = None,
    button_label: Optional[str] = None,
) -> Dict[str, Any]:
    """
    Resolves an escalated modal dialog by clicking the specified button option.
    Allows the orchestrator to safely make decisions on branching or destructive modals (0 visual tokens).

    Args:
        button_id: Target button identifier from ModalEscalationPayload (e.g. 'btn_0', 'btn_1').
        button_label: Target button label text (e.g. 'Cancel', 'Save', 'Overwrite').
    """
    return controller.obstruction_interceptor.resolve_pending_modal(
        button_id=button_id,
        button_label=button_label,
    )


@mcp_server.tool()
def manage_cache(
    action: str = "stats",
    app_key: Optional[str] = None,
    query: Optional[str] = None,
) -> Dict[str, Any]:
    """
    Manages the Self-Healing Action & Locator Cache.

    Args:
        action: 'stats' (view telemetry), 'verify' (proactive health check against live screen),
                'heal' (proactively re-anchor drifting entries), 'invalidate' (clear specific entry),
                or 'clear' (empty cache).
        app_key: Application identifier (used for invalidate, verify, heal).
        query: Query string (used for invalidate).
    """
    act = action.strip().lower()
    if act == "stats":
        return controller.action_cache.get_stats()
    elif act == "clear":
        controller.action_cache.clear()
        return {"success": True, "message": "Locator cache cleared."}
    elif act == "invalidate":
        if not app_key or not query:
            return {"success": False, "error": "Must provide 'app_key' and 'query' to invalidate."}
        ok = controller.action_cache.invalidate(app_key=app_key, query=query)
        return {"success": ok, "message": f"Entry for '{app_key}::{query}' invalidated."}
    elif act in ("verify", "heal"):
        target_app = app_key or controller._get_active_app_key()
        try:
            screen = hal.capture_screen()
            win = hal.get_active_window()
            return controller.action_cache.proactive_verify_all(app_key=target_app, live_screen=screen, current_window=win)
        except Exception as e:
            return {"success": False, "error": f"Failed to execute proactive {act}: {e}"}
    return {"success": False, "error": f"Unknown action: '{action}'"}


@mcp_server.tool()
def manage_toolsets(
    action: str = "list_domains",
    domains: Optional[List[str]] = None,
    output_mode: Optional[str] = None,
) -> Dict[str, Any]:
    """
    Manages MCP tool domains and out-of-band payload offloading to save AI prompt tokens.

    Args:
        action: 'list_domains', 'enable', 'disable', or 'set_output_mode'.
        domains: Optional list of domains to enable/disable (e.g. ['window_mgmt', 'vdom', 'eda_vivado']).
        output_mode: Optional target output mode: 'inline', 'file', or 'resource'.

    Returns:
        Status dictionary with active domains, tool count, and output mode.
    """
    return toolset_manager.manage_toolsets(action=action, domains=domains, output_mode=output_mode)


@mcp_server.tool()
def get_accessibility_tree(
    app_name_filter: Optional[str] = None,
    max_depth: int = 16,
    filter_interactable: bool = True,
    diff_only: bool = False,
    output_mode: Optional[str] = None,
) -> Any:
    """
    Directly queries OS accessibility bus (AXUIElement on macOS, AT-SPI2 on Linux)
    for the live semantic UI tree. Provides ground-truth element names, roles, and
    physical bounding boxes without visual hallucination.

    Args:
        app_name_filter: Filter to target a specific app (e.g. 'terminal', 'chrome', 'calc').
        max_depth: Maximum hierarchy recursion depth.
        filter_interactable: If True, only returns clickable or typable elements.
        diff_only: If True, returns diff-only payload (added, removed, modified) relative
                   to prior inspection, reducing context tokens by 80-90% on multi-turn workflows.
        output_mode: Optional override ('inline', 'file', 'resource') for out-of-band offloading.

    Returns:
        List of UIElement objects, diff dictionary, or out-of-band file offload payload.
    """
    res = controller.get_accessibility_tree(
        app_name_filter=app_name_filter,
        max_depth=max_depth,
        filter_interactable=filter_interactable,
        diff_only=diff_only,
    )
    if isinstance(res, dict):
        return toolset_manager.format_output("get_accessibility_tree", res, output_mode_override=output_mode)
    elif isinstance(res, list):
        payload = {"count": len(res), "nodes": [n.model_dump() if hasattr(n, "model_dump") else n for n in res]}
        formatted = toolset_manager.format_output("get_accessibility_tree", payload, output_mode_override=output_mode)
        if formatted.get("offloaded", False):
            return formatted
        return res
    return res


@mcp_server.tool()
def find_element(
    query: str,
    role: Optional[str] = None,
    fuzzy: bool = True,
    strategy: Optional[str] = None,
) -> Dict[str, Any]:
    """
    Autonomously searches for a UI element by text, accessible name, or role.
    Extremely token-efficient: resolves physical (x, y) coordinates with ZERO screenshot tokens.

    Args:
        query: Target text or label (e.g. '4 Argon', 'Ask Gemini', 'Block', 'Submit').
        role: Optional role constraint (e.g. 'button', 'text', 'menu_item').
        fuzzy: Whether to perform substring fuzzy matching.
        strategy: Grounding backend to use ('ensemble', 'semantic', 'cv', 'template').

    Returns:
        FindElementResult detailing match status, element bounds, and exact physical center coordinates.
    """
    res = controller.find_element(
        query=query,
        role=role,
        fuzzy=fuzzy,
        strategy_override=strategy,
    )
    return res.model_dump()


@mcp_server.tool()
def click(
    mark_id: Optional[int] = None,
    x: Optional[int] = None,
    y: Optional[int] = None,
    query: Optional[str] = None,
    button: str = "left",
    click_count: int = 1,
    verify_delta: bool = True,
    expected_outcome: Optional[Dict[str, Any]] = None,
) -> Dict[str, Any]:
    """
    Clicks on a UI element either by Set-of-Marks ID, text query, or physical (x, y) coordinates.

    Args:
        mark_id: Numeric badge ID from last screenshot.
        x, y: Physical pixel coordinates (used if mark_id is not specified).
        query: Optional text label to find and click automatically.
        button: 'left', 'right', or 'middle'.
        click_count: 1 for single click, 2 for double click, 3 for triple click.
        verify_delta: Whether to automatically check if screen visually reacted post-click.
        expected_outcome: When set, verify with the local bicameral shield instead of returning pixels.

    Returns:
        Verification result detailing success, delta detected, and visual change ratio.
    """
    target_x, target_y = controller.resolve_target_coordinates(query=query, mark_id=mark_id, x=x, y=y)

    if expected_outcome:
        verdict = controller.bicameral.execute_step(
            "mouse_click",
            {"x": target_x, "y": target_y, "button": button, "click_count": click_count},
            expected_outcome,
        )
        controller.note_turn("user", f"click {button} at ({target_x}, {target_y})")
        controller.note_turn("assistant", verdict.reason)
        return verdict.model_dump()

    def _do_click():
        hal.mouse_click(target_x, target_y, button=button, click_count=click_count)

    res = controller.execute_with_verification(
        action_name=f"click({button}, count={click_count}) at ({target_x}, {target_y})",
        action_func=_do_click,
        verify_delta=verify_delta,
    )
    return res.model_dump()


@mcp_server.tool()
def click_and_type(
    text: str,
    query: Optional[str] = None,
    mark_id: Optional[int] = None,
    x: Optional[int] = None,
    y: Optional[int] = None,
    clear_first: bool = False,
    press_enter: bool = False,
    delay_ms: float = CONFIG.typing_delay_ms,
    verify_delta: bool = True,
) -> Dict[str, Any]:
    """
    High-level atomic compound action: Focuses an element (by query, mark_id, or x,y),
    optionally clears existing text (Ctrl+A -> Backspace), types string with natural cadence,
    and optionally presses Enter.

    Args:
        text: Text to type into target.
        query: Optional label to find the target element autonomously.
        mark_id: Optional Set-of-Marks badge ID.
        x, y: Optional physical coordinates.
        clear_first: Whether to select all and delete existing text before typing.
        press_enter: Whether to press Enter after typing.
        delay_ms: Milliseconds delay between keystrokes.
        verify_delta: Whether to verify visual change post-execution.
    """
    res = controller.click_and_type(
        text=text,
        query=query,
        mark_id=mark_id,
        x=x,
        y=y,
        clear_first=clear_first,
        press_enter=press_enter,
        delay_ms=delay_ms,
        verify_delta=verify_delta,
    )
    return res.model_dump()


@mcp_server.tool()
def find_and_click(
    query: str,
    button: str = "left",
    click_count: int = 1,
    verify_delta: bool = True,
) -> Dict[str, Any]:
    """
    Autonomous one-shot action: Finds an element by text query and clicks it with verified delta.

    Args:
        query: Target text or label (e.g. 'Flash-Lite', 'Argon', 'Send').
        button: 'left', 'right', or 'middle'.
        click_count: 1 for single click, 2 for double click.
        verify_delta: Whether to verify visual reaction.
    """
    res = controller.find_and_click(
        query=query,
        button=button,
        click_count=click_count,
        verify_delta=verify_delta,
    )
    return res.model_dump()


@mcp_server.tool()
def move_cursor(x: int, y: int) -> Dict[str, Any]:
    """
    Moves the mouse pointer to absolute coordinates (x, y) without clicking.
    """
    hal.mouse_move(x, y)
    return {"success": True, "cursor_position": [x, y]}


@mcp_server.tool()
def drag_and_drop(
    start_x: int,
    start_y: int,
    end_x: int,
    end_y: int,
    duration_sec: float = 0.3,
    verify_delta: bool = True,
) -> Dict[str, Any]:
    """
    Smoothly drags mouse pointer from start coordinates to end coordinates.
    """
    def _do_drag():
        hal.mouse_drag(start_x, start_y, end_x, end_y, duration_sec=duration_sec)

    res = controller.execute_with_verification(
        action_name=f"drag from ({start_x}, {start_y}) to ({end_x}, {end_y})",
        action_func=_do_drag,
        verify_delta=verify_delta,
    )
    return res.model_dump()


@mcp_server.tool()
def scroll(
    direction: str = "down",
    amount: int = 3,
    verify_delta: bool = True,
) -> Dict[str, Any]:
    """
    Emulates mouse wheel scroll at current cursor location.
    """
    dx, dy = 0, 0
    if direction == "up":
        dy = amount
    elif direction == "down":
        dy = -amount
    elif direction == "left":
        dx = -amount
    elif direction == "right":
        dx = amount

    def _do_scroll():
        hal.mouse_scroll(dx=dx, dy=dy)

    res = controller.execute_with_verification(
        action_name=f"scroll({direction}, amount={amount})",
        action_func=_do_scroll,
        verify_delta=verify_delta,
    )
    return res.model_dump()


@mcp_server.tool()
def scroll_until_visible(
    query: str,
    direction: str = "down",
    max_scrolls: int = 6,
    scroll_amount: int = 6,
    verify_delta: bool = True,
) -> Dict[str, Any]:
    """
    Autonomous scroll loop: Iteratively scrolls the viewport until the query element is found.

    Args:
        query: Text or label to find.
        direction: 'down' or 'up'.
        max_scrolls: Max scroll attempts.
        scroll_amount: Wheel increments per scroll step.
    """
    res = controller.scroll_until_visible(
        query=query,
        direction=direction,
        max_scrolls=max_scrolls,
        scroll_amount=scroll_amount,
        verify_delta=verify_delta,
    )
    return res.model_dump()


@mcp_server.tool()
def type_text(
    text: str,
    press_enter: bool = False,
    delay_ms: float = CONFIG.typing_delay_ms,
    verify_delta: bool = True,
) -> Dict[str, Any]:
    """
    Types text into the currently focused desktop element.
    """
    def _do_type():
        hal.keyboard_type(text, delay_ms=delay_ms)
        if press_enter:
            hal.keyboard_press_key("enter")

    res = controller.execute_with_verification(
        action_name=f"type_text(len={len(text)}, enter={press_enter})",
        action_func=_do_type,
        verify_delta=verify_delta,
    )
    return res.model_dump()


@mcp_server.tool()
def press_key(key: str, verify_delta: bool = True) -> Dict[str, Any]:
    """
    Presses and releases a single key.
    """
    def _do_press():
        hal.keyboard_press_key(key)

    res = controller.execute_with_verification(
        action_name=f"press_key({key})",
        action_func=_do_press,
        verify_delta=verify_delta,
    )
    return res.model_dump()


@mcp_server.tool()
def hotkey(combo: str, verify_delta: bool = True) -> Dict[str, Any]:
    """
    Sends a keyboard chord shortcut (e.g. 'ctrl+c', 'alt+tab', 'ctrl+a').
    """
    keys = [k.strip() for k in combo.split("+")]

    def _do_hotkey():
        hal.keyboard_hotkey(keys)

    res = controller.execute_with_verification(
        action_name=f"hotkey({combo})",
        action_func=_do_hotkey,
        verify_delta=verify_delta,
    )
    return res.model_dump()


@mcp_server.tool()
def list_windows() -> List[Dict[str, Any]]:
    """
    Lists open desktop windows, titles, geometry bounds, and active focus status.
    """
    windows = hal.list_windows()
    return [win.model_dump() for win in windows]


@mcp_server.tool()
def get_active_window() -> Optional[Dict[str, Any]]:
    """
    Returns the currently active / focused window metadata.
    """
    win = hal.get_active_window()
    return win.model_dump() if win else None


@mcp_server.tool()
def focus_window(window_id: str) -> Dict[str, Any]:
    """
    Brings target window to the foreground and grants it focus.
    """
    ok = hal.focus_window(window_id)
    _enable_plugin_domain()
    return {"success": ok, "window_id": window_id}


def _enable_plugin_domain() -> None:
    """Enables the focused application's tool domain and notifies the client."""
    try:
        win = hal.get_active_window()
    except Exception:
        return
    if win is None:
        return
    plugin = controller.plugin_registry.detect(win.title, getattr(win, "app_name", None))
    if plugin is None:
        return
    domain = {"vivado": "eda_vivado", "chrome": "plugins"}.get(plugin.app_id)
    if domain:
        toolset_manager.manage_toolsets(action="enable", domains=[domain])


@mcp_server.tool()
def configure_vision(
    setting: str,
    value: Any,
) -> Dict[str, Any]:
    """
    Dynamically hotswaps runtime settings for grounding, tokens, and safety.

    Args:
        setting: Parameter name:
                 - 'grounding_strategy' ('ensemble', 'semantic', 'cv', 'template')
                 - 'max_image_dimension' (int, e.g. 1200, 1600)
                 - 'image_quality' (int, e.g. 70, 85)
                 - 'token_optimization_mode' ('standard', 'delta_patch')
                 - 'enable_nms_fusion' (bool)
                 - 'typing_delay_ms' (float)
        value: New value to apply.
    """
    setting_clean = setting.strip().lower()

    if setting_clean == "grounding_strategy":
        ok = controller.grounding_engine.set_strategy(str(value))
        return {"success": ok, "setting": setting_clean, "value": controller.grounding_engine.active_strategy}

    if hasattr(CONFIG, setting_clean):
        setattr(CONFIG, setting_clean, value)
        return {"success": True, "setting": setting_clean, "value": getattr(CONFIG, setting_clean)}

    return {"success": False, "error": f"Unknown configuration setting: '{setting}'"}


@mcp_server.tool()
def get_vision_diagnostics() -> Dict[str, Any]:
    """
    Returns diagnostic health check of the Vision MCP server, active display,
    available perception backends, and current configuration.
    """
    screen_w, screen_h = hal.get_screen_size()
    active_win = hal.get_active_window()

    diag = DiagnosticsResult(
        platform=sys.platform,
        display_server=getattr(controller.hal, "display_server", None)
        or ("Wayland" if getattr(controller.hal, "_is_wayland", False) else "X11"),
        primary_screen_size=(screen_w, screen_h),
        active_grounding_strategy=controller.grounding_engine.active_strategy,
        atspi_available=controller.atspi_inspector.is_available,
        opencv_available=True,
        supported_grounding_providers=controller.grounding_engine.list_strategies(),
        active_window=active_win.title if active_win else None,
        config_summary=CONFIG.model_dump(),
        gemma=_gemma_diagnostics(),
        ocr=controller.ocr.diagnostics() if getattr(controller, "ocr", None) else None,
    )
    return diag.model_dump()


def _gemma_diagnostics() -> Optional[Dict[str, Any]]:
    grounder = getattr(getattr(controller, "neural_grounder", None), "gemma3_grounder", None)
    if grounder is None:
        return None
    try:
        return grounder.diagnostics()
    except Exception as e:  # diagnostics must never fail the health check
        return {"error": str(e)}


@mcp_server.tool()
def ask_screen(
    question: str = "",
    region: Optional[List[int]] = None,
    expected_text: Optional[str] = None,
) -> Dict[str, Any]:
    """
    Answers a yes/no question about the screen using the local Gemma model, without
    sending an image back to the client (zero image tokens).

    Use it to verify an action ("Did the Save dialog close?", "Is the simulation
    status 'Running'?"). If ``answer`` is null or confidence is low, fall back to
    take_screenshot.

    Args:
        question: A yes/no question about what is visible (answered by Gemma, ~seconds).
        region: Optional [x, y, width, height]; defaults to the active window.
        expected_text: Optional text that proves "yes" (e.g. "Saved", "Simulation finished").
            Checked first with local OCR (~0.3 s); Gemma runs only if the text is absent
            and a question is given. Prefer this whenever the outcome shows as text.

    Returns:
        {answer: bool|null, confidence: 0..1, evidence: str, source: 'ocr'|'gemma'|'fallback', region}
    """
    reg_tuple = tuple(region) if region and len(region) == 4 else None
    return controller.ask_screen(question, region=reg_tuple, expected_text=expected_text)


@mcp_server.tool()
def read_screen_text(
    region: Optional[List[int]] = None,
    contains: Optional[str] = None,
    regex: bool = False,
    output_mode: Optional[str] = None,
) -> Dict[str, Any]:
    """
    Reads text on screen with local OCR (Apple Vision on macOS, RapidOCR on Linux/Windows)
    and returns lines with boxes and click points. No image is returned, so this costs a
    few hundred text tokens instead of a screenshot.

    Args:
        region: Optional [x, y, width, height]; defaults to the active window.
        contains: Optional filter. Matching ignores case, spaces and underscores.
        regex: Treat ``contains`` as a regular expression.
        output_mode: Optional override ('inline', 'file', 'resource') for out-of-band offloading.

    Returns:
        {available, engine, count, lines: [{text, bbox, click_point, confidence}]} or offloaded payload.
    """
    reg_tuple = tuple(region) if region and len(region) == 4 else None
    res = controller.read_screen_text(region=reg_tuple, contains=contains, regex=regex)
    return toolset_manager.format_output("read_screen_text", res, output_mode_override=output_mode)


@mcp_server.tool()
def find_visual_element(description: str, region: Optional[List[int]] = None) -> Dict[str, Any]:
    """
    Finds an element by description where accessibility gives no names (canvases,
    custom Qt/Tk widgets, EDA toolbars). Tries local OCR for a visible-text match
    first; otherwise the local detector proposes boxes, local Gemma picks one by
    number, and the click point comes from the detector box, never from the model.
    No image is returned.

    Args:
        description: What to find, e.g. "Run Simulation button" or "zoom fit icon".
        region: Optional [x, y, width, height]; defaults to the active window.

    Returns:
        {found, bbox, click_point, candidates, confidence, reason, source}
    """
    reg_tuple = tuple(region) if region and len(region) == 4 else None
    return controller.find_with_gemma(description, region=reg_tuple)


@mcp_server.tool()
def run_terminal_command(
    command: str,
    timeout_seconds: int = CONFIG.command_timeout_seconds,
) -> Dict[str, Any]:
    """
    Executes a shell command in the background for hybrid CLI navigation.
    """
    if not CONFIG.allow_terminal_commands:
        return {"success": False, "error": "Terminal commands are disabled in configuration."}

    start = time.perf_counter()
    try:
        proc = subprocess.run(
            command,
            shell=True,
            capture_output=True,
            text=True,
            timeout=timeout_seconds,
        )
        elapsed = time.perf_counter() - start
        return {
            "success": proc.returncode == 0,
            "exit_code": proc.returncode,
            "stdout": proc.stdout,
            "stderr": proc.stderr,
            "execution_time_sec": round(elapsed, 3),
        }
    except subprocess.TimeoutExpired:
        return {
            "success": False,
            "exit_code": -1,
            "error": f"Command timed out after {timeout_seconds} seconds",
            "execution_time_sec": timeout_seconds,
        }
    except Exception as e:
        return {
            "success": False,
            "exit_code": -1,
            "error": str(e),
        }


@mcp_server.tool()
def wait_for_ui_change(
    timeout_seconds: float = 5.0,
    poll_interval_sec: float = 0.2,
    min_delta_ratio: float = 0.005,
) -> Dict[str, Any]:
    """
    Blocks until a visual change occurs on the desktop.
    """
    initial_img, _, _, _ = controller.pipeline.capture(draw_cursor=False, scale_down=True)
    start_time = time.perf_counter()

    while time.perf_counter() - start_time < timeout_seconds:
        time.sleep(poll_interval_sec)
        current_img, _, _, _ = controller.pipeline.capture(draw_cursor=False, scale_down=True)
        delta = controller.pipeline.compute_image_delta(initial_img, current_img)
        if delta >= min_delta_ratio:
            return {
                "change_detected": True,
                "delta_ratio": round(delta, 4),
                "elapsed_sec": round(time.perf_counter() - start_time, 3),
            }

    return {
        "change_detected": False,
        "delta_ratio": 0.0,
        "elapsed_sec": timeout_seconds,
        "message": "Timed out waiting for visual change.",
    }


@mcp_server.tool()
def list_plugins() -> List[Dict[str, Any]]:
    """
    Lists all registered UI Application Plugins and reports which is currently active.
    
    Returns:
        List of plugin summaries including app_id, name, is_active, and supported sub-panes.
    """
    act_win = hal.get_active_window()
    active_title = act_win.title if act_win else None
    summaries = controller.plugin_registry.list_all(active_window_title=active_title)
    return [s.model_dump() for s in summaries]


@mcp_server.tool()
def list_plugin_features(
    plugin_id: Optional[str] = None,
) -> Dict[str, Any]:
    """
    Returns the declarative feature catalog and hotkeys for an application plugin.
    
    Args:
        plugin_id: Target plugin identifier ('chrome', 'verdi', etc.). If None, detects active window.
        
    Returns:
        Dictionary containing plugin metadata and list of feature descriptors.
    """
    plugin = None
    if plugin_id:
        plugin = controller.plugin_registry.get(plugin_id)
    else:
        plugin = controller.get_active_plugin() or controller.plugin_registry.get("chrome")

    if not plugin:
        return {"error": f"Plugin '{plugin_id}' not found.", "features": []}

    features = [f.model_dump() for f in plugin.list_features()]
    return {
        "app_id": plugin.app_id,
        "name": plugin.name,
        "supported_panes": list(plugin.sub_panes.keys()),
        "features": features,
    }


@mcp_server.tool()
def invoke_plugin_feature(
    feature_id: str,
    plugin_id: Optional[str] = None,
    args: Optional[Dict[str, Any]] = None,
) -> Dict[str, Any]:
    """
    Executes a high-level application capability natively with closed-loop delta verification.
    
    Args:
        feature_id: Identifier of the capability (e.g. 'browser.navigate', 'browser.new_tab', 'browser.reload').
        plugin_id: Target plugin identifier. If omitted, routes to the active window's plugin.
        args: Optional parameter dictionary (e.g. {'url': 'https://gemini.google.com'}).
        
    Returns:
        Action outcome with success flag, visual delta, and status message.
    """
    plugin = None
    if plugin_id:
        plugin = controller.plugin_registry.get(plugin_id)
    else:
        plugin = controller.get_active_plugin() or controller.plugin_registry.get("chrome")

    if not plugin:
        return {
            "success": False,
            "feature_id": feature_id,
            "message": f"Could not resolve an application plugin for feature '{feature_id}'.",
        }

    return plugin.execute_feature(feature_id=feature_id, controller=controller, args=args)


@mcp_server.tool()
def capture_pane(
    pane_name: str,
    window_id: Optional[str] = None,
    title_filter: Optional[str] = None,
    mode: str = "raw",
) -> Dict[str, Any]:
    """
    Ultra-efficient sub-pane perception tool. Captures strictly a named functional
    zone of the target or active window (e.g. 'address_bar', 'tab_strip', 'content_area').
    Slashes multimodal token consumption by up to 90% compared to capturing a whole display.
    
    Args:
        pane_name: Identifier of sub-pane ('address_bar', 'tab_strip', 'content_area', etc.).
        window_id: Optional target window ID.
        title_filter: Optional title substring filter (e.g. 'Chrome').
        mode: Grounding mode ('raw', 'cursor_only', 'annotated_som').
        
    Returns:
        ScreenshotResult dictionary with image_base64 and scaled dimensions.
    """
    result = controller.capture_pane(
        pane_name=pane_name,
        window_id=window_id,
        title_filter=title_filter,
        mode=mode,
    )
    return result.model_dump()


@mcp_server.tool()
def start_skill_recording(
    journal_path: Optional[str] = None,
) -> Dict[str, Any]:
    """
    GUI-to-Script Crystallization: Starts recording physical GUI actions and correlations
    with application command journal streams (e.g. vivado.jou, novas.cmd).
    
    Args:
        journal_path: Path to application journal file. If omitted, uses default or existing path.
    """
    if journal_path:
        controller.journal_correlator.set_journal_path(journal_path)
    elif not controller.journal_correlator.journal_path:
        candidates = [
            "/home/mk/DV/vivado_fifo/vivado.jou",
            os.path.abspath("vivado.jou"),
        ]
        for c in candidates:
            if os.path.exists(c):
                controller.journal_correlator.set_journal_path(c)
                break

    controller.journal_correlator.start_recording()
    return {
        "success": True,
        "recording": True,
        "journal_path": controller.journal_correlator.journal_path,
        "message": f"Skill recording started. Tracking commands from '{controller.journal_correlator.journal_path}'.",
    }


@mcp_server.tool()
def stop_skill_recording() -> Dict[str, Any]:
    """
    Stops active skill recording and returns summary of captured action steps.
    """
    steps = controller.journal_correlator.stop_recording()
    return {
        "success": True,
        "recording": False,
        "recorded_steps_count": len(steps),
        "steps": [s.model_dump() for s in steps],
        "message": f"Skill recording stopped. Captured {len(steps)} correlated GUI action steps.",
    }


@mcp_server.tool()
def start_cassette_recording(
    name: str,
    capture_images: bool = False,
    capture_ocr: bool = True,
    settle_ms: int = 400,
) -> Dict[str, Any]:
    """
    Starts recording a cassette from this live session. After every input action
    (click, type, key, hotkey, drag, scroll, focus) the server waits settle_ms and
    saves AX nodes, OCR lines, windows and cursor. stop_cassette_recording writes
    the cassette, which replays offline with DESKTOP_HAL=replay, `pytest -m replay`,
    or crystallize_skill(cassette_path=...).

    Typed text is stored verbatim, so do not record while typing secrets.

    Args:
        name: Cassette name; becomes the folder name ([a-z0-9_-]).
        capture_images: Also save a JPEG of the screen per frame (larger, but replays visual tools).
        capture_ocr: Run local OCR per frame (default true; turn off for speed).
        settle_ms: Wait after each action before the snapshot.
    """
    from vision_mcp.hal.cassette_recorder import LiveCassetteRecorder

    current = getattr(hal, "recorder", None)
    if current is not None and current.active:
        return {"success": False, "message": f"Already recording '{current.name}'. Call stop_cassette_recording first."}
    recorder = LiveCassetteRecorder(
        name=name,
        out_dir=CONFIG.cassette_dir,
        snapshot_fn=lambda: controller.cassette_snapshot(capture_ocr=capture_ocr),
        capture_images=capture_images,
        settle_ms=settle_ms,
    )
    try:
        info = recorder.start()
    except FileExistsError as exc:
        return {"success": False, "message": str(exc)}
    hal.recorder = recorder
    return {"success": True, "recording": True, **info}


@mcp_server.tool()
def stop_cassette_recording() -> Dict[str, Any]:
    """
    Stops the cassette recording and writes <cassette_dir>/<name>/index.json
    (plus frames/*.jpg when images were captured). Returns the path and counts.
    """
    recorder = getattr(hal, "recorder", None)
    if recorder is None or not recorder.active:
        return {"success": False, "message": "No cassette recording is active."}
    summary = recorder.stop()
    hal.recorder = None
    return {"success": True, "recording": False, **summary}


@mcp_server.tool()
def crystallize_skill(
    skill_name: str,
    task_prompt: str,
    app_target: str = "vivado_2025.1",
    extracted_entities: Optional[Dict[str, Any]] = None,
    verification_cmd: Optional[str] = None,
    description: Optional[str] = None,
    cassette_path: Optional[str] = None,
) -> Dict[str, Any]:
    """
    Compiles recorded GUI trajectory into a parameterized, deterministic Tcl/CLI skill,
    lifting entity literals into Jinja2 parameters and saving to dynamic skill registry.
    
    Args:
        skill_name: Identifier for the new skill (e.g. 'run_sim_fifo').
        task_prompt: Natural language description of the demonstrated task.
        app_target: Target application suite (default 'vivado_2025.1').
        extracted_entities: Dictionary of literal parameters to lift into variables (e.g. {'runtime': '10us', 'radix': 'hex'}).
        verification_cmd: Tcl assertion command for post-execution verification.
        description: Detailed summary of what this crystallized skill accomplishes.
    """
    steps = controller.journal_correlator.recorded_steps
    if not steps:
        return {
            "success": False,
            "message": "No recorded trajectory steps found. Run start_skill_recording() and perform GUI actions first.",
        }

    spec = controller.trajectory_compiler.compile_trajectory(
        steps=steps,
        task_prompt=task_prompt,
        extracted_entities=extracted_entities,
        skill_name=skill_name,
        app_target=app_target,
        description=description,
        verification_cmd=verification_cmd,
    )
    macro = controller.trace_compiler.compile_steps(
        steps=steps,
        name=skill_name,
        app_id=app_target,
        description=spec.description,
        entities=extracted_entities,
        native_template=spec.tcl_template,
        native_kind="tcl" if spec.tcl_template.strip() else "none",
    )
    replay_hal = None
    if cassette_path:
        from vision_mcp.hal.mock_replay import load_cassette

        replay_hal = load_cassette(cassette_path)
    try:
        controller.skill_registry.register_macro(macro, hal=replay_hal)
    except Exception as exc:
        return {
            "success": False,
            "message": f"Macro did not replay on the cassette: {exc}",
        }
    controller.skill_registry.register_skill(spec)
    return {
        "success": True,
        "skill": spec.model_dump(),
        "macro": macro.model_dump(),
        "message": f"Successfully crystallized skill '{skill_name}' with {len(spec.parameters)} parameters.",
    }


@mcp_server.tool()
def execute_crystallized_skill(
    skill_name: str,
    arguments: Optional[Dict[str, Any]] = None,
) -> Dict[str, Any]:
    """
    Executes a crystallized parameterized skill with 0 visual tokens by compiling
    the template and executing deterministically via application CLI/Tcl bridge.
    
    Args:
        skill_name: Identifier of the crystallized skill to execute.
        arguments: Dynamic arguments overriding default parameters.
    """
    spec = controller.skill_registry.get_skill(skill_name)
    if not spec:
        return {
            "success": False,
            "skill_name": skill_name,
            "message": f"Skill '{skill_name}' not found in dynamic skill registry.",
        }

    t_start = time.monotonic()
    try:
        rendered_script = controller.skill_registry.render_script(skill_name, arguments)
    except Exception as e:
        return {
            "success": False,
            "skill_name": skill_name,
            "message": f"Failed to render skill template: {e}",
        }

    plugin = controller.get_active_plugin()
    exec_msg = ""
    success = True
    macro = controller.skill_registry.get_macro(skill_name)

    if plugin and "vivado" in plugin.app_id and spec.tcl_template.strip():
        with tempfile.NamedTemporaryFile("w", suffix=".tcl", delete=False) as f:
            f.write(rendered_script + "\n")
            temp_path = f.name

        try:
            res = plugin.execute_feature(
                "vivado.tcl_exec",
                controller,
                {"command": f"source {temp_path}"},
            )
            success = res.get("success", True)
            exec_msg = f"Sourced {temp_path} into Vivado Tcl Console"
        finally:
            try:
                os.unlink(temp_path)
            except Exception:
                pass
    elif macro is not None and macro.steps:
        trajectory = {
            "trajectory_name": macro.name,
            "variables": arguments or {},
            "steps": [
                {
                    "step_id": f"s{index}",
                    "action": step.action,
                    "parameters": step.args,
                    "verify_delta": False,
                }
                for index, step in enumerate(macro.steps)
            ],
        }
        ran = trajectory_engine.execute_trajectory(trajectory)
        success = bool(ran.success)
        exec_msg = ran.message or f"Ran {ran.successful_steps} macro steps"
    else:
        success = False
        exec_msg = "Rendered script was not dispatched; no native bridge and no macro steps"

    elapsed_ms = (time.monotonic() - t_start) * 1000.0
    return {
        "success": success,
        "skill_name": skill_name,
        "rendered_tcl": rendered_script,
        "execution_time_ms": round(elapsed_ms, 2),
        "message": f"Skill '{skill_name}' executed in {elapsed_ms:.1f}ms: {exec_msg}",
    }


@mcp_server.tool()
def list_crystallized_skills() -> Dict[str, Any]:
    """
    Lists all registered crystallized skills available for zero-visual-token deterministic execution.
    """
    skills = controller.skill_registry.list_skills()
    return {
        "count": len(skills),
        "skills": [s.model_dump() for s in skills],
    }


@mcp_server.tool()
def delete_crystallized_skill(
    skill_name: str,
) -> Dict[str, Any]:
    """
    Deletes a crystallized skill from the registry.
    """
    deleted = controller.skill_registry.delete_skill(skill_name)
    return {
        "success": deleted,
        "skill_name": skill_name,
        "message": f"Skill '{skill_name}' deleted." if deleted else f"Skill '{skill_name}' not found.",
    }


@mcp_server.tool()
def capture_vdom(
    window_id: Optional[str] = None,
    title_filter: Optional[str] = None,
    label_with_gemma: Optional[bool] = None,
    output_mode: Optional[str] = None,
) -> Dict[str, Any]:
    """
    Unified Virtual DOM (vDOM): Captures and indexes UI state by fusing AT-SPI2
    accessibility semantics with local neural/CV proposals in < 30ms (0 cloud tokens).
    
    Args:
        window_id: Optional target window ID to localize capture.
        title_filter: Optional window title substring filter.
        label_with_gemma: Name unlabeled visual-only nodes with local Gemma (Set-of-Marks;
            cached per app). Defaults to the gemma3_label_vdom setting.
        output_mode: Optional override ('inline', 'file', 'resource') for out-of-band offloading.

    Returns:
        VirtualDOMSnapshot dictionary or out-of-band file offload payload.
    """
    snapshot = controller.capture_vdom(
        window_id=window_id, title_filter=title_filter, label_with_gemma=label_with_gemma
    )
    return toolset_manager.format_output("capture_vdom", snapshot.model_dump(), output_mode_override=output_mode)


@mcp_server.tool()
def query_vdom(
    selector: str,
    window_id: Optional[str] = None,
    refresh: bool = False,
    limit: int = 10,
    output_mode: Optional[str] = None,
) -> Dict[str, Any]:
    """
    Zero-Token Spatial & Semantic Query: Searches the in-memory Virtual DOM using CSS-like
    selectors and spatial constraints without sending screenshots to multimodal LLMs.
    
    Supported selector syntax:
      - 'push_button[name*="Run Simulation"]'
      - 'text_input:right_of("Period (ns):")'
      - 'waveform_signal:inside("waveform_canvas")'
      - 'push_button:below("Summary"):enabled'
      - ':sash_divider'
      - '#vdom_0142'
      
    Args:
        selector: CSS spatial selector string.
        window_id: Optional target window ID if refresh is needed.
        refresh: Whether to capture a fresh snapshot before querying.
        limit: Maximum number of matched nodes to return.
        output_mode: Optional override ('inline', 'file', 'resource') for out-of-band offloading.
        
    Returns:
        Dictionary with count and list of matched VDOMNode models, or out-of-band file offload payload.
    """
    nodes = controller.query_vdom(selector=selector, window_id=window_id, refresh=refresh, limit=limit)
    payload = {
        "count": len(nodes),
        "selector": selector,
        "nodes": [n.model_dump() for n in nodes],
    }
    return toolset_manager.format_output("query_vdom", payload, output_mode_override=output_mode)


@mcp_server.tool()
def execute_trajectory(
    trajectory_spec: Dict[str, Any],
) -> Dict[str, Any]:
    """
    Local Macro & Trajectory Dispatcher: Executes a structured multi-step declarative trajectory locally
    at native OS speeds, eliminating dozens of intermediate round-trips to multimodal LLMs.

    Supported action primitives:
      - 'focus_window': {"title": "..."} or {"window_id": "..."}
      - 'find_and_click': {"query": "...", "button": "left", "verify_delta": true}
      - 'click': {"x": 100, "y": 200} or {"query": "..."}
      - 'click_and_type': {"query": "...", "text": "...", "press_enter": true}
      - 'type_text': {"text": "...", "press_enter": true}
      - 'hotkey': {"keys": ["ctrl", "s"]}
      - 'press_key': {"key": "enter"}
      - 'scroll': {"dx": 0, "dy": -5}
      - 'wait': {"duration_sec": 1.5}
      - 'wait_for_ui_change': {"timeout": 5.0}
      - 'capture_pane': {"pane_name": "waveform_canvas"}
      - 'capture_vdom': {"query_selector": "push_button[name*='Run']"}
      - 'query_vdom': {"selector": "push_button"}
      - 'execute_crystallized_skill': {"skill_name": "...", "parameters": {...}}
      - 'run_terminal_command': {"command": "..."}
      - 'dismiss_obstructions': {}

    Args:
        trajectory_spec: Structured dictionary specifying trajectory_name, variables, and steps.

    Returns:
        TrajectoryExecutionResult dictionary detailing per-step timing, success, assertions,
        and estimated multimodal tokens saved.
    """
    res = trajectory_engine.execute_trajectory(trajectory_spec)
    return res.model_dump()


def _warmup_gemma() -> None:
    grounder = getattr(getattr(controller, "neural_grounder", None), "gemma3_grounder", None)
    if grounder is not None:
        grounder.client.warmup(grounder.vision_model)


def main():
    """Starts the FastMCP server in standard I/O mode."""
    if CONFIG.gemma3_warmup_on_start:
        import threading

        threading.Thread(target=_warmup_gemma, name="gemma-warmup", daemon=True).start()
    mcp_server.run()


@mcp_server.resource("mcp://desktop-control/state/{name}")
def read_state_resource(name: str) -> str:
    """Reads an offloaded state artifact. Names cannot escape the state directory."""
    return toolset_manager.resolve_state_file(name).read_text(encoding="utf-8")


@mcp_server.tool()
def compact_history(max_tokens: int = 12000, keep_last_n: int = 2) -> Dict[str, Any]:
    """Compacts the server-side trajectory log into the 8-part state checkpoint."""
    compacted = controller.compact_history(max_tokens=max_tokens, keep_last_n=keep_last_n)
    return {"messages": compacted, "count": len(compacted)}


def _capture_tool_schemas() -> None:
    try:
        infos = mcp_server._tool_manager.list_tools()
    except Exception:
        return
    for info in infos:
        tool = toolset_manager._registry.get(getattr(info, "name", ""))
        if tool is None:
            continue
        schema = getattr(info, "parameters", None) or getattr(info, "input_schema", None) or {}
        tool.input_schema = schema or {}


_capture_tool_schemas()


if __name__ == "__main__":
    main()
