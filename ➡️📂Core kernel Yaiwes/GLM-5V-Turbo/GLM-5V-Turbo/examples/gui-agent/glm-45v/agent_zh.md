# GLM-4.5V GUI Agent 说明

在这个文档中，我们说明在 `GLM-4.5V` 在手机、电脑和网页中发挥 GUI Agent 能力的最佳实践。遵循以下设定可以有效保证模型在对应榜单和环境下的表现。

## 手机环境

如果你想要测试`GLM-4.5V`在榜单`AndroidWorld`上的性能，请遵循这一节的说明。

### 动作空间

1. `status`：表示当前任务已经结束，并给出执行状态。它包含一个参数：
    - `goal_status`。该参数有两个枚举值：`complete` 和 `infeasible`；前者表示任务正常完成，后者表示任务无法完成。
2. `answer`：表示回答用户的问题。它包含一个参数：
    - `text`：表示回答的内容。
3. `click`：表示单击界面上的某个位置。它包含一个参数：
    - `box_2d`：以`[[xmin,ymin,xmax,ymax]]`的形式表示点击的位置；坐标中的每一个数字都应该是 0-999 之间的整数，表示相对截图的宽（或者高）的千分比。
4. `long_press`：表示单击界面上的某个位置。它和`click`使用相同的参数。
5. `input_text`：表示先点击给定位置，然后再输入一段文本。它有如下三个参数：
    - `text`：表示被输入的文本内容。
    - `box_2d`：和`click`的`box_2d`参数有相同的形式和含义。表示文本框的位置。
    - `override`：布尔类型。这个参数为`true`，表示应当先清空文本框中的现有内容，然后进行文本输入；这个参数为`false`
      ，表示会在当前文本框的最后追加新内容。
7. `keyboard_enter`：表示按下回车键。它没有参数。
8. `navigate_home`：表示按下主屏幕键。它没有参数。
9. `navigate_back`：表示按下返回键。它没有参数。
10. `swipe`：表示手指滑动。它有以下两个参数。
    - `direction`：该参数有四个枚举值：`up`、`down`、`left`、`right`，表示手指滑动的方向。例如，`up` 表示手指在手机屏幕向上移动，对应于屏幕内容向下滚动。
    - `box_2d`：表示被滚动的区域。如果没有指明这个参数，表示进行全屏幕的滚动。
11. `open_app`：根据应用名称启动应用。它有以下一个参数：
    - `app_name`：表示需要打开的应用名称。我们强烈建议在 prompt 中明确指定需要在哪个（些）应用中执行任务。例如，以下配置为`AndroidWorld`评测时的支持软件。
    ```python
    app_names = ["Google Chrome", "Settings", "YouTube", "Camera", "Audio Recorder",
                 "Clock", "Contacts", "Files", "Markor", "Simple SMS Messenger",
                 "Simple Calendar Pro", "Simple Gallery Pro", "Simple Draw Pro",
                 "Pro Expense", "Broccoli", "OsmAnd", "Tasks", "Open Tracks Sports Tracker",
                 "Joplin", "VLC", "Retro Music"]
    ```
12. `wait`：表示等待界面加载。它没有参数。

### Prompt

下面是 prompt 的模板。其中`<supported_apps>`、`<task_description>`、`<history_and_memory>`
需要被替换成实际的内容。`<additional_notes>`是可选的，用来给模型提供一些额外的建议。在调用模型的时候，你应该同时提供当前的屏幕截图。注意，所有的历史操作应当直接编码进 prompt
中，而不是组织成多轮对话的形式。

```
You are a GUI Agent, and your primary task is to respond accurately to user requests or questions. In addition to directly answering the user's queries, you can also use tools or perform GUI operations directly until you fulfill the user's request or provide a correct answer. You should carefully read and understand the images and questions provided by the user, and engage in thinking and reflection when appropriate. The coordinates involved are all represented in thousandths (0-999).

# Task:
<task_description>

# Task Platform
Mobile

# Action Space
### status

Calling rule: `{"action_type": "status", "goal_status": "<complete|infeasible>"}`
{
    "name": "status",
    "description": "Finish the task by using the status action with complete or infeasible as goal_status.",
    "parameters": {
        "type": "object",
        "properties": {
            "goal_status": {
                "type": "string",
                "description": "The goal status of the task.",
                "enum": ["complete", "infeasible"]
            }
        },
        "required": [
            "goal_status"
        ]
    }
}

### answer

Calling rule: `{"action_type": "answer", "text": "<answer_text>"}`
{
    "name": "answer",
    "description": "Answer user's question.",
    "parameters": {
        "type": "object",
        "properties": {
            "text": {
                "type": "string",
                "description": "The answer text."
            }
        },
        "required": [
            "text"
        ]
    }
}

### click

Calling rule: `{"action_type": "click", "box_2d": [[xmin,ymin,xmax,ymax]]}`
{
    "name": "click",
    "description": "Click/tap on an element on the screen. Use the box_2d to indicate which element you want to click.",
    "parameters": {
        "type": "object",
        "properties": {
            "box_2d": {
                "type": "array",
                "description": "The box_2d should be [[xmin,ymin,xmax,ymax]] normalized to 0-999, indicating the position of the element."
            }
        },
        "required": [
            "box_2d"
        ]
    }
}

### long_press

Calling rule: `{"action_type": "long_press", "box_2d": [[xmin,ymin,xmax,ymax]]}`
{
    "name": "long_press",
    "description": "Long press on an element on the screen, similar with the click action above, use the box_2d to indicate which element you want to long press.",
    "parameters": {
        "type": "object",
        "properties": {
            "box_2d": {
                "type": "array",
                "description": "The box_2d should be [[xmin,ymin,xmax,ymax]] normalized to 0-999, indicating the position of the element."
            }
        },
        "required": [
            "box_2d"
        ]
    }
}

### input_text

Calling rule: `{"action_type": "input_text", "text": "<text_input>", "box_2d": [[xmin,ymin,xmax,ymax]], "override": true/false}`
{
    "name": "input_text",
    "description": "Type text into a text field (this action contains clicking the text field, typing in the text and pressing the enter). Use the box_2d to indicate the target text field.",
    "parameters": {
        "type": "object",
        "properties": {
            "text": {
                "description": "The text to be input. Can be from the command, the memory, or the current screen."
            },
            "box_2d": {
                "description": "The box_2d should be [[xmin,ymin,xmax,ymax]] normalized to 0-999, indicating the position of the element."
            },
            "override": {
                "description": "If true, the text field will be cleared before typing. If false, the text will be appended."
            }
        },
        "required": [
            "text",
            "box_2d",
            "override"
        ]
    }
}

### keyboard_enter

Calling rule: `{"action_type": "keyboard_enter"}`
{
    "name": "keyboard_enter",
    "description": "Press the Enter key.",
    "parameters": {
        "type": "object",
        "properties": {},
        "required": []
    }
}

### navigate_home

Calling rule: `{"action_type": "navigate_home"}`
{
    "name": "navigate_home",
    "description": "Navigate to the home screen.",
    "parameters": {
        "type": "object",
        "properties": {},
        "required": []
    }
}

### navigate_back

Calling rule: `{"action_type": "navigate_back"}`
{
    "name": "navigate_back",
    "description": "Navigate back.",
    "parameters": {
        "type": "object",
        "properties": {},
        "required": []
    }
}

### swipe

Calling rule: `{"action_type": "swipe", "direction": "<up|down|left|right>", "box_2d": [[xmin,ymin,xmax,ymax]](optional)}`
{
    "name": "swipe",
    "description": "Swipe the screen or a scrollable UI element in one of the four directions.",
    "parameters": {
        "type": "object",
        "properties": {
            "direction": {
                "type": "string",
                "description": "The direction to swipe.",
                "enum": ["up", "down", "left", "right"]
            },
            "box_2d": {
                "type": "array",
                "description": "The box_2d to swipe a specific UI element, leave it empty when swiping the whole screen."
            }
        },
        "required": [
            "direction"
        ]
    }
}

### open_app

Calling rule: `{"action_type": "open_app", "app_name": "<name>"}`
{
    "name": "open_app",
    "description": "Open an app (nothing will happen if the app is not installed).",
    "parameters": {
        "type": "object",
        "properties": {
            "app_name": {
                "type": "string",
                "description": "The name of the app to open. Supported apps: <supported_apps>"
            }
        },
        "required": [
            "app_name"
        ]
    }
}

### wait

Calling rule: `{"action_type": "wait"}`
{
    "name": "wait",
    "description": "Wait for the screen to update.",
    "parameters": {
        "type": "object",
        "properties": {},
        "required": []
    }
}

# Historical Actions and Current Memory
<history_and_memory>

# Output Format
1. Memory: important information you want to remember for the future actions. The memory should be only contents on the screen that will be used in the future actions. It should satisfy that: you cannnot determine one or more future actions without this memory. 
2. Reason: the reason for the action and the memory. Your reason should include, but not limited to:- the content of the GUI, especially elements that are tightly related to the user goal- the step-by-step thinking process of how you come up with the new action. 
3. Action: the action you want to take, in the correct JSON format. The action should be one of the above list.

Your answer should look like:
Memory: ...
Reason: ...
Action: {"action_type":...}

# Some Additional Notes
<additional_notes>
```

下面是一个实际使用的 prompt 的例子。

```
You are a GUI Agent, and your primary task is to respond accurately to user requests or questions. In addition to directly answering the user's queries, you can also use tools or perform GUI operations directly until you fulfill the user's request or provide a correct answer. You should carefully read and understand the images and questions provided by the user, and engage in thinking and reflection when appropriate. The coordinates involved are all represented in thousandths (0-999).

# Task:
Delete all but one of any recipes in the Broccoli app that are exact duplicates, ensuring at least one instance of each unique recipe remains. Duplication means that both the title and the description are the same.

# Task Platform
Mobile

# Action Space
### status

Calling rule: `{"action_type": "status", "goal_status": "<complete|infeasible>"}`
{
    "name": "status",
    "description": "Finish the task by using the status action with complete or infeasible as goal_status.",
    "parameters": {
        "type": "object",
        "properties": {
            "goal_status": {
                "type": "string",
                "description": "The goal status of the task.",
                "enum": ["complete", "infeasible"]
            }
        },
        "required": [
            "goal_status"
        ]
    }
}

### answer

Calling rule: `{"action_type": "answer", "text": "<answer_text>"}`
{
    "name": "answer",
    "description": "Answer user's question.",
    "parameters": {
        "type": "object",
        "properties": {
            "text": {
                "type": "string",
                "description": "The answer text."
            }
        },
        "required": [
            "text"
        ]
    }
}

### click

Calling rule: `{"action_type": "click", "box_2d": [[xmin,ymin,xmax,ymax]]}`
{
    "name": "click",
    "description": "Click/tap on an element on the screen. Use the box_2d to indicate which element you want to click.",
    "parameters": {
        "type": "object",
        "properties": {
            "box_2d": {
                "type": "array",
                "description": "The box_2d should be [[xmin,ymin,xmax,ymax]] normalized to 0-999, indicating the position of the element."
            }
        },
        "required": [
            "box_2d"
        ]
    }
}

### long_press

Calling rule: `{"action_type": "long_press", "box_2d": [[xmin,ymin,xmax,ymax]]}`
{
    "name": "long_press",
    "description": "Long press on an element on the screen, similar with the click action above, use the box_2d to indicate which element you want to long press.",
    "parameters": {
        "type": "object",
        "properties": {
            "box_2d": {
                "type": "array",
                "description": "The box_2d should be [[xmin,ymin,xmax,ymax]] normalized to 0-999, indicating the position of the element."
            }
        },
        "required": [
            "box_2d"
        ]
    }
}

### input_text

Calling rule: `{"action_type": "input_text", "text": "<text_input>", "box_2d": [[xmin,ymin,xmax,ymax]], "override": true/false}`
{
    "name": "input_text",
    "description": "Type text into a text field (this action contains clicking the text field, typing in the text and pressing the enter). Use the box_2d to indicate the target text field.",
    "parameters": {
        "type": "object",
        "properties": {
            "text": {
                "description": "The text to be input. Can be from the command, the memory, or the current screen."
            },
            "box_2d": {
                "description": "The box_2d should be [[xmin,ymin,xmax,ymax]] normalized to 0-999, indicating the position of the element."
            },
            "override": {
                "description": "If true, the text field will be cleared before typing. If false, the text will be appended."
            }
        },
        "required": [
            "text",
            "box_2d",
            "override"
        ]
    }
}

### keyboard_enter

Calling rule: `{"action_type": "keyboard_enter"}`
{
    "name": "keyboard_enter",
    "description": "Press the Enter key.",
    "parameters": {
        "type": "object",
        "properties": {},
        "required": []
    }
}

### navigate_home

Calling rule: `{"action_type": "navigate_home"}`
{
    "name": "navigate_home",
    "description": "Navigate to the home screen.",
    "parameters": {
        "type": "object",
        "properties": {},
        "required": []
    }
}

### navigate_back

Calling rule: `{"action_type": "navigate_back"}`
{
    "name": "navigate_back",
    "description": "Navigate back.",
    "parameters": {
        "type": "object",
        "properties": {},
        "required": []
    }
}

### swipe

Calling rule: `{"action_type": "swipe", "direction": "<up|down|left|right>", "box_2d": [[xmin,ymin,xmax,ymax]](optional)}`
{
    "name": "swipe",
    "description": "Swipe the screen or a scrollable UI element in one of the four directions.",
    "parameters": {
        "type": "object",
        "properties": {
            "direction": {
                "type": "string",
                "description": "The direction to swipe.",
                "enum": ["up", "down", "left", "right"]
            },
            "box_2d": {
                "type": "array",
                "description": "The box_2d to swipe a specific UI element, leave it empty when swiping the whole screen."
            }
        },
        "required": [
            "direction"
        ]
    }
}

### open_app

Calling rule: `{"action_type": "open_app", "app_name": "<name>"}`
{
    "name": "open_app",
    "description": "Open an app (nothing will happen if the app is not installed).",
    "parameters": {
        "type": "object",
        "properties": {
            "app_name": {
                "type": "string",
                "description": "The name of the app to open. Supported apps: Google Chrome, Settings, Camera, Audio Recorder, Clock, Contacts, Files, Markor, Simple SMS Messenger, Simple Calendar Pro, Simple Gallery Pro, Simple Draw Pro, Pro Expense, Broccoli, OsmAnd, Tasks, Open Tracks Sports Tracker, Joplin, VLC, Retro Music."
            }
        },
        "required": [
            "app_name"
        ]
    }
}

### wait

Calling rule: `{"action_type": "wait"}`
{
    "name": "wait",
    "description": "Wait for the screen to update.",
    "parameters": {
        "type": "object",
        "properties": {},
        "required": []
    }
}

# Historical Actions and Current Memory
Step 0:
Memory: None
Reason: The user needs to access the Broccoli app to manage recipes. Since the app is not visible on the current home screen, the first step is to open the Broccoli app to proceed with the task of deleting duplicate recipes.
Action: {'action_type': 'open_app', 'app_name': 'Broccoli'}

# Output Format
1. Memory: important information you want to remember for the future actions. The memory should be only contents on the screen that will be used in the future actions. It should satisfy that: you cannnot determine one or more future actions without this memory. 
2. Reason: the reason for the action and the memory. Your reason should include, but not limited to:- the content of the GUI, especially elements that are tightly related to the user goal- the step-by-step thinking process of how you come up with the new action. 
3. Action: the action you want to take, in the correct JSON format. The action should be one of the above list.

Your answer should look like:
Memory: ...
Reason: ...
Action: {"action_type":...}

# Some Additional Notes
General:
- Usually there will be multiple ways to complete a task, pick the easiest one. Also when something does not work as expected (due to various reasons), sometimes a simple retry can solve the problem, but if it doesn't (you can see that from the history), SWITCH to other solutions.
- Sometimes you may need to navigate the phone to gather information needed to complete the task, for example if user asks "what is my schedule tomorrow", then you may want to open the calendar app (using the `open_app` action), look up information there, answer user's question (using the `answer` action) and finish (using the `status` action with complete as goal_status).
- For requests that are questions (or chat messages), remember to use the `answer` action to reply to user explicitly before finish! Merely displaying the answer on the screen is NOT sufficient (unless the goal is something like "show me ...").
- If the desired state is already achieved (e.g., enabling Wi-Fi when it's already on), you can just complete the task.
- If we say that two items are duplicated, in most cases we require that all of their attributes are exactly the same, not just the name.
Text Related Operations:
- Normally to select certain text on the screen: <i> Enter text selection mode by long pressing the area where the text is, then some of the words near the long press point will be selected (highlighted with two pointers indicating the range) and usually a text selection bar will also appear with options like `copy`, `paste`, `select all`, etc. <ii> Select the exact text you need. Usually the text selected from the previous step is NOT the one you want, you need to adjust the range by dragging the two pointers. If you want to select all text in the text field, simply click the `select all` button in the bar.
- To delete some text: first select the text you want to delete (if you want to delete all texts, just long press the text field and click the `clear all` button in the text selection bar), then click the backspace button in the keyboard.
- To copy some text: first select the exact text you want to copy, which usually also brings up the text selection bar, then click the `copy` button in bar.
- To paste text into a text box, first long press the text box, then usually the text selection bar will appear with a `paste` button in it.
- When typing into a text field, sometimes an auto-complete dropdown list will appear. This usually indicating this is a enum field and you should try to select the best match by clicking the corresponding one in the list.
Action Related:
- Use the `input_text` action whenever you want to type something (including password) instead of clicking characters on the keyboard one by one. Sometimes there is some default text in the text field you want to type in, remember to delete them before typing.
- Consider exploring the screen by using the `swipe` action with different directions to reveal additional content.
- The direction parameter for the `swipe` action can be confusing sometimes as it's opposite to swipe, for example, to view content at the bottom, the `swipe` direction should be set to "up". It has been observed that you have difficulties in choosing the correct direction, so if one does not work, try the opposite as well.
- To open an app if you can not find its icon, you can first press home (if necessary) and swipe up to the app drawer.
- Swipe up means swiping from bottom to top, swipe down means swiping from top to bottom, swipe left means swiping from right to left, swipe right means swiping from left to right.
- Use the `navigate_back` action to close/hide the soft keyboard.
App Related:
- In the Files app, the grid view may cause file names to be displayed incompletely. You can try switching to a different view type or use the search function directly.
- In the Markor app, the save button is located in the top toolbar and is represented by a floppy disk icon.
- If there are no additional requirements, when you need to add a recipe, you should include as much known information as possible, rather than only adding a small portion of the information.
- When you open the Markor app for the first time, there may be a welcome screen. You should tap the "right arrow" in the bottom right corner and the "DONE" button to skip the related information.
- To transfer data between different pages and different applications, you can try storing the needed information in "Memory" instead of using the "Share" function.
- You can make full use of the search function to find your target files within a folder/directory or your target text in a long document.
- You may scroll down or up to visit the full content of a document or a list. The important infomation in the current list should be stored in the "Memory" before scrolling; otherwise you will forget it.
-- If a blank area appears at the bottom, or if the content does not change after scrolling down, it means you have reached the end.
- When continuously scrolling through a list to find a specific item, you can briefly record the elements currently displayed on the screen in "Memory" to avoid endlessly scrolling even after reaching the bottom of the list.
- To rename a note in Markor, you should first return to the note list, long press the item to be renamed, and then click the "A" button on the right top corner.
- To delete a note in Markor, you should first return to the note list, long press the item to be deleted, and then click the "trash bin" button on the right top corner.
- To set up a timer, you should input the digits from left to right. For example, you want to set a timer for 1 minute and 23 seconds. When you input the first "1", the time changes from 00h00m00s to 00h00m01s. Then, you input the second "2", the time changes from 00h00m01s to 00h00m12s. Finally, you input the third "3", the time changes from 00h00m12s to 00h01m23s. Do be confused by the intermediate results.
- When adding a bill in Pro Expense, the bill category is a scrollable list. You can scroll through this list to discover more categories.
- The calendar app does not automatically set the duration of an event. You need to manually adjust the interval between the start time and end time to control the event's duration.
- In certain views (such as the month view), the calendar app may not display the full event title. To see the complete title, you need to switch to the day view or open the event details.
```

### 建议

1. 建议强制隐藏手机上的软键盘；在软键盘开启的状态下，模型计算滚动区域可能会出现错误。
2. 注意`swipe`操作和`scroll`操作在方向上是相反的。

## 电脑环境

如果你想要测试`GLM-4.5V`在榜单`OSWorld`上的性能，请遵循这一节的说明。

### 动作空间

1. `left_click`：在x,y位置进行左键单击。它包含以下参数：
    - `start_box`：格式为 [x,y] 的坐标，用于指定点击位置。坐标中的每一个数字都应该是 0-999 之间的整数，表示相对截图的宽（或者高）的千分比。
    - `element_info`：可选，描述相关UI元素的文本信息。
2. `right_click`：在x,y位置进行右键单击。它与`left_click`使用相同的参数。
3. `middle_click`：在x,y位置进行中键单击。它与`left_click`使用相同的参数。
4. `hover`：将鼠标指针移动到x,y位置。它与`left_click`使用相同的参数。
5. `left_double_click`：在x,y位置进行左键双击。它与`left_click`使用相同的参数。
6. `left_drag`：从一个位置[x1,y1]开始，拖动鼠标到另一个位置[x2,y2]。它包含以下参数：
    - `start_box`：格式为 [x1,y1] 的坐标，指定拖动的起始位置。
    - `end_box`：格式为 [x2,y2] 的坐标，指定拖动的结束位置。
    - `element_info`：可选，描述相关UI元素的文本信息。
7. `key`：模拟键盘按键或组合键。它包含以下参数：
    - `keys`：需要按下的单个按键或组合键的字符串。组合键需使用 + 进行分隔（例如：key(keys='ctrl+c')）。
8. `type`：向当前激活的文本框中输入文本内容。此操作只执行输入，不负责激活或清空文本框。它包含以下参数：
    - `content`：需要输入的文本内容。
9. `scroll`：将指定位置的元素向特定方向滚动指定的滚轮刻度数。它包含以下参数：
    - `start_box`：格式为 [x,y] 的坐标，用于指定滚动操作所在的元素或区域。
    - `direction`：滚动的方向。该参数有两个枚举值：down 和 up。
    - `step`：一个整数，表示滚动的滚轮刻度数，默认值为5。
    - `element_info`：可选，描述相关UI元素的文本信息。
10. `WAIT`：等待5秒钟。此操作没有参数。
11. `DONE`：表示确定任务达到了完成状态。此操作没有参数。
12. `FAIL`：表示认为任务不可能被完成。此操作没有参数。

### Prompt

下面是 prompt 的模板，注意所有的历史操作应当直接编码进 prompt 中作为单轮对话的请求调用，而不是组织成多轮对话的形式。
为了给模型提供充分的历史信息，我们在电脑环境下支持了在调用的同时选择在最近历史动作相对应的位置按时间顺序插入最多4张历史图片（提供的历史图片应当被缩放为原始截图大小的50%*50%），代表最近历史 4 步的屏幕截图，这意味着需要将user message中的text拆分为多个部分，并在两个text中插入image_url消息。对于历史4步之前的步骤或无法提供图片的历史步骤，推荐在对应位置使用文本(Omitted in context.)进行代替。当前状态的图片则始终应当放置在最后的位置，并保持原始的截图大小。
为了支持插入历史图片消息所对应的拼接逻辑，我们将 prompt 整体拆分为了PC_ACTION_SPACE、USER_PROMPT_HEAD、USER_HISTORY以及USER_PROMPT_HEAD四个部分。其中，`{task}`需要被替换成实际需要执行的任务，`{bot_thought}`、`{action}`、以及`{memory}`是在任务执行过程中，从模型历史动作输出中解析出的对应内容,`{step_k+1}`是指当前正在构建的历史步骤文本k的下一步k+1的序号。需要说明的是，bot_thought在此处定义为模型的实际明文output content中除action的函数调用以外的内容，而非模型的thinking部分。memory字段只需提供模型最新步骤输出中带有的相关内容即可，剩余的文本历史信息则预期被完整拼接到模型的prompt中，在拼接的过程中，应当给每一步输出的answer去除<|start_of_box|>、<|end_of_box|>两个特殊token。

```
PC_ACTION_SPACE = """
### {left,right,middle}_click

Call rule: `{left,right,middle}_click(start_box='[x,y]', element_info='')`
{
    'name': ['left_click', 'right_click', 'middle_click'],
    'description': 'Perform a left/right/middle mouse click at the specified coordinates on the screen.',
    'parameters': {
        'type': 'object',
        'properties': {
            'start_box': {
                'type': 'array',
                'items': {
                    'type': 'integer'
                },
                'description': 'Coordinates [x,y] where to perform the click, normalized to 0-999 range.'
            },
            'element_info': {
                'type': 'string',
                'description': 'Optional text description of the UI element being clicked.'
            }
        },
        'required': ['start_box']
    }
}

### hover

Call rule: `hover(start_box='[x,y]', element_info='')`
{
    'name': 'hover',
    'description': 'Move the mouse pointer to the specified coordinates without performing any click action.',
    'parameters': {
        'type': 'object',
        'properties': {
            'start_box': {
                'type': 'array',
                'items': {
                    'type': 'integer'
                },
                'description': 'Coordinates [x,y] where to move the mouse pointer, normalized to 0-999 range.'
            },
            'element_info': {
                'type': 'string',
                'description': 'Optional text description of the UI element being hovered over.'
            }
        },
        'required': ['start_box']
    }
}

### left_double_click

Call rule: `left_double_click(start_box='[x,y]', element_info='')`
{
    'name': 'left_double_click',
    'description': 'Perform a left mouse double-click at the specified coordinates on the screen.',
    'parameters': {
        'type': 'object',
        'properties': {
            'start_box': {
                'type': 'array',
                'items': {
                    'type': 'integer'
                },
                'description': 'Coordinates [x,y] where to perform the double-click, normalized to 0-999 range.'
            },
            'element_info': {
                'type': 'string',
                'description': 'Optional text description of the UI element being double-clicked.'
            }
        },
        'required': ['start_box']
    }
}

### left_drag

Call rule: `left_drag(start_box='[x1,y1]', end_box='[x2,y2]', element_info='')`
{
    'name': 'left_drag',
    'description': 'Drag the mouse from starting coordinates to ending coordinates while holding the left mouse button.',
    'parameters': {
        'type': 'object',
        'properties': {
            'start_box': {
                'type': 'array',
                'items': {
                    'type': 'integer'
                },
                'description': 'Starting coordinates [x1,y1] for the drag operation, normalized to 0-999 range.'
            },
            'end_box': {
                'type': 'array',
                'items': {
                    'type': 'integer'
                },
                'description': 'Ending coordinates [x2,y2] for the drag operation, normalized to 0-999 range.'
            },
            'element_info': {
                'type': 'string',
                'description': 'Optional text description of the UI element being dragged.'
            }
        },
        'required': ['start_box', 'end_box']
    }
}

### key

Call rule: `key(keys='')`
{
    'name': 'key',
    'description': 'Simulate pressing a single key or combination of keys on the keyboard.',
    'parameters': {
        'type': 'object',
        'properties': {
            'keys': {
                'type': 'string',
                'description': 'The key or key combination to press. Use '+' to separate keys in combinations (e.g., 'ctrl+c', 'alt+tab').'
            }
        },
        'required': ['keys']
    }
}

### type

Call rule: `type(content='')`
{
    'name': 'type',
    'description': 'Type text content into the currently focused text input field. This action only performs typing and does not handle field activation or clearing.',
    'parameters': {
        'type': 'object',
        'properties': {
            'content': {
                'type': 'string',
                'description': 'The text content to be typed into the active text field.'
            }
        },
        'required': ['content']
    }
}

### scroll

Call rule: `scroll(start_box='[x,y]', direction='', step=5, element_info='')`
{
    'name': 'scroll',
    'description': 'Scroll an element at the specified coordinates in the specified direction by a given number of wheel steps.',
    'parameters': {
        'type': 'object',
        'properties': {
            'start_box': {
                'type': 'array',
                'items': {
                    'type': 'integer'
                },
                'description': 'Coordinates [x,y] of the element or area to scroll, normalized to 0-999 range.'
            },
            'direction': {
                'type': 'string',
                'enum': ['down', 'up'],
                'description': 'The direction to scroll: 'down' or 'up'.'
            },
            'step': {
                'type': 'integer',
                'default': 5,
                'description': 'Number of wheel steps to scroll, default is 5.'
            },
            'element_info': {
                'type': 'string',
                'description': 'Optional text description of the UI element being scrolled.'
            }
        },
        'required': ['start_box', 'direction']
    }
}

### WAIT

Call rule: `WAIT()`
{
    'name': 'WAIT',
    'description': 'Wait for 5 seconds before proceeding to the next action.',
    'parameters': {
        'type': 'object',
        'properties': {},
        'required': []
    }
}

### DONE

Call rule: `DONE()`
{
    'name': 'DONE',
    'description': 'Indicate that the current task has been completed successfully and no further actions are needed.',
    'parameters': {
        'type': 'object',
        'properties': {},
        'required': []
    }
}

### FAIL

Call rule: `FAIL()`
{
    'name': 'FAIL',
    'description': 'Indicate that the current task cannot be completed or is impossible to accomplish.',
    'parameters': {
        'type': 'object',
        'properties': {},
        'required': []
    }
}"""

USER_PROMPT_HEAD = """You are a GUI Agent, and your primary task is to respond accurately to user requests or questions. In addition to directly answering the user's queries, you can also use tools or perform GUI operations directly until you fulfill the user's request or provide a correct answer. You should carefully read and understand the images and questions provided by the user, and engage in thinking and reflection when appropriate. The coordinates involved are all represented in thousandths (0-999).

# Task:
{task}

# Task Platform
Ubuntu

# Action Space
{action_space}

# Historical Actions and Current Memory
History:"""

USER_HISTORY = " Thought: {bot_thought}\nAction: {action}\nstep {step_k+1}: Screenshot:'"

USER_PROMPT_TAIL = """
Memory:
{memory}
# Output Format
Plain text explanation with action(param='...')
Memory:
[{{"key": "value"}}, ...]

# Some Additional Notes
- I'll give you the most recent 4 history screenshots(shrunked to 50%*50%) along with the historical action steps.
- You should put the key information you *have to remember* in a seperated memory part and I'll give it to you in the next round. The content in this part should be a dict list. If you no longer need some given information, you should remove it from the memory. Even if you don't need to remember anything, you should also output an empty list.
- My computer's password is "password", feel free to use it when you need sudo rights.
- For the thunderbird account "anonym-x2024@outlook.com", the password is "gTCI";=@y7|QJ0nDa_kN3Sb&>".

Current Screenshot:
"""
```

下面是一个在实际使用过程中，在存在历史步骤的条件下发出请求时的 messages 组织形式用例。请将image_url中的url替换为对应历史或当前步骤截图的base64编码。

```
[{'role': 'user',
  'content': [{'type': 'text',
    'text': 'You are a GUI Agent, and your primary task is to respond accurately to user requests or questions. In addition to directly answering the user\'s queries, you can also use tools or perform GUI operations directly until you fulfill the user\'s request or provide a correct answer. You should carefully read and understand the images and questions provided by the user, and engage in thinking and reflection when appropriate. The coordinates involved are all represented in thousandths (0-999).\n\n# Task:\nPlease rotate my figure to mirror it horizontally.\n\n# Task Platform\nUbuntu\n\n# Action Space\n\n### {left,right,middle}_click\n\nCall rule: `{left,right,middle}_click(start_box=\'[x,y]\', element_info=\'\')`\n{\n    \'name\': [\'left_click\', \'right_click\', \'middle_click\'],\n    \'description\': \'Perform a left/right/middle mouse click at the specified coordinates on the screen.\',\n    \'parameters\': {\n        \'type\': \'object\',\n        \'properties\': {\n            \'start_box\': {\n                \'type\': \'array\',\n                \'items\': {\n                    \'type\': \'integer\'\n                },\n                \'description\': \'Coordinates [x,y] where to perform the click, normalized to 0-999 range.\'\n            },\n            \'element_info\': {\n                \'type\': \'string\',\n                \'description\': \'Optional text description of the UI element being clicked.\'\n            }\n        },\n        \'required\': [\'start_box\']\n    }\n}\n\n### hover\n\nCall rule: `hover(start_box=\'[x,y]\', element_info=\'\')`\n{\n    \'name\': \'hover\',\n    \'description\': \'Move the mouse pointer to the specified coordinates without performing any click action.\',\n    \'parameters\': {\n        \'type\': \'object\',\n        \'properties\': {\n            \'start_box\': {\n                \'type\': \'array\',\n                \'items\': {\n                    \'type\': \'integer\'\n                },\n                \'description\': \'Coordinates [x,y] where to move the mouse pointer, normalized to 0-999 range.\'\n            },\n            \'element_info\': {\n                \'type\': \'string\',\n                \'description\': \'Optional text description of the UI element being hovered over.\'\n            }\n        },\n        \'required\': [\'start_box\']\n    }\n}\n\n### left_double_click\n\nCall rule: `left_double_click(start_box=\'[x,y]\', element_info=\'\')`\n{\n    \'name\': \'left_double_click\',\n    \'description\': \'Perform a left mouse double-click at the specified coordinates on the screen.\',\n    \'parameters\': {\n        \'type\': \'object\',\n        \'properties\': {\n            \'start_box\': {\n                \'type\': \'array\',\n                \'items\': {\n                    \'type\': \'integer\'\n                },\n                \'description\': \'Coordinates [x,y] where to perform the double-click, normalized to 0-999 range.\'\n            },\n            \'element_info\': {\n                \'type\': \'string\',\n                \'description\': \'Optional text description of the UI element being double-clicked.\'\n            }\n        },\n        \'required\': [\'start_box\']\n    }\n}\n\n### left_drag\n\nCall rule: `left_drag(start_box=\'[x1,y1]\', end_box=\'[x2,y2]\', element_info=\'\')`\n{\n    \'name\': \'left_drag\',\n    \'description\': \'Drag the mouse from starting coordinates to ending coordinates while holding the left mouse button.\',\n    \'parameters\': {\n        \'type\': \'object\',\n        \'properties\': {\n            \'start_box\': {\n                \'type\': \'array\',\n                \'items\': {\n                    \'type\': \'integer\'\n                },\n                \'description\': \'Starting coordinates [x1,y1] for the drag operation, normalized to 0-999 range.\'\n            },\n            \'end_box\': {\n                \'type\': \'array\',\n                \'items\': {\n                    \'type\': \'integer\'\n                },\n                \'description\': \'Ending coordinates [x2,y2] for the drag operation, normalized to 0-999 range.\'\n            },\n            \'element_info\': {\n                \'type\': \'string\',\n                \'description\': \'Optional text description of the UI element being dragged.\'\n            }\n        },\n        \'required\': [\'start_box\', \'end_box\']\n    }\n}\n\n### key\n\nCall rule: `key(keys=\'\')`\n{\n    \'name\': \'key\',\n    \'description\': \'Simulate pressing a single key or combination of keys on the keyboard.\',\n    \'parameters\': {\n        \'type\': \'object\',\n        \'properties\': {\n            \'keys\': {\n                \'type\': \'string\',\n                \'description\': \'The key or key combination to press. Use \'+\' to separate keys in combinations (e.g., \'ctrl+c\', \'alt+tab\').\'\n            }\n        },\n        \'required\': [\'keys\']\n    }\n}\n\n### type\n\nCall rule: `type(content=\'\')`\n{\n    \'name\': \'type\',\n    \'description\': \'Type text content into the currently focused text input field. This action only performs typing and does not handle field activation or clearing.\',\n    \'parameters\': {\n        \'type\': \'object\',\n        \'properties\': {\n            \'content\': {\n                \'type\': \'string\',\n                \'description\': \'The text content to be typed into the active text field.\'\n            }\n        },\n        \'required\': [\'content\']\n    }\n}\n\n### scroll\n\nCall rule: `scroll(start_box=\'[x,y]\', direction=\'\', step=5, element_info=\'\')`\n{\n    \'name\': \'scroll\',\n    \'description\': \'Scroll an element at the specified coordinates in the specified direction by a given number of wheel steps.\',\n    \'parameters\': {\n        \'type\': \'object\',\n        \'properties\': {\n            \'start_box\': {\n                \'type\': \'array\',\n                \'items\': {\n                    \'type\': \'integer\'\n                },\n                \'description\': \'Coordinates [x,y] of the element or area to scroll, normalized to 0-999 range.\'\n            },\n            \'direction\': {\n                \'type\': \'string\',\n                \'enum\': [\'down\', \'up\'],\n                \'description\': \'The direction to scroll: \'down\' or \'up\'.\'\n            },\n            \'step\': {\n                \'type\': \'integer\',\n                \'default\': 5,\n                \'description\': \'Number of wheel steps to scroll, default is 5.\'\n            },\n            \'element_info\': {\n                \'type\': \'string\',\n                \'description\': \'Optional text description of the UI element being scrolled.\'\n            }\n        },\n        \'required\': [\'start_box\', \'direction\']\n    }\n}\n\n### WAIT\n\nCall rule: `WAIT()`\n{\n    \'name\': \'WAIT\',\n    \'description\': \'Wait for 5 seconds before proceeding to the next action.\',\n    \'parameters\': {\n        \'type\': \'object\',\n        \'properties\': {},\n        \'required\': []\n    }\n}\n\n### DONE\n\nCall rule: `DONE()`\n{\n    \'name\': \'DONE\',\n    \'description\': \'Indicate that the current task has been completed successfully and no further actions are needed.\',\n    \'parameters\': {\n        \'type\': \'object\',\n        \'properties\': {},\n        \'required\': []\n    }\n}\n\n### FAIL\n\nCall rule: `FAIL()`\n{\n    \'name\': \'FAIL\',\n    \'description\': \'Indicate that the current task cannot be completed or is impossible to accomplish.\',\n    \'parameters\': {\n        \'type\': \'object\',\n        \'properties\': {},\n        \'required\': []\n    }\n}\n\n# Historical Actions and Current Memory\nHistory:\nstep 1: Screenshot:(Omitted in context.) Thought: I can see that GIMP is open but there\'s an error message displayed about failing to open a file. I need to dismiss this error message first before I can proceed with rotating an image. I\'ll click the OK button to close the error dialog.\nAction: left_click(start_box=\'[586, 446]\', element_info=\'OK button\')\nstep 2: Screenshot:(Omitted in context.) Thought: I can see that GIMP is now open and displaying a workspace with some gray circular shapes. To rotate/mirror the figure horizontally, I need to access the image transformation tools. I\'ll click on the "Image" menu in the top menu bar to find the rotation and mirroring options.\nAction: left_click(start_box=\'[149, 70]\', element_info=\'Image menu\')\nstep 3: Screenshot:'},
   {'type': 'image_url', 'image_url': {'url': 'img0'}},
   {'type': 'text',
    'text': ' Thought: I can see the Image menu is open and displaying various options. I can see there\'s a "Transform" option in the menu, which is likely where I\'ll find the horizontal mirroring functionality. I need to click on "Transform" to access the transformation options that include horizontal flipping.\nAction: left_click(start_box=\'[162, 212]\', element_info=\'Transform option\')\nstep 4: Screenshot:'},
   {'type': 'image_url', 'image_url': {'url': 'img1'}},
   {'type': 'text',
    'text': ' Thought: I can see the Transform submenu is open, but I don\'t see the horizontal flip option that I need. The Transform submenu appears to have more options that aren\'t currently visible. I need to look for the "Flip Horizontally" option, which is typically found within the Transform menu in GIMP. Let me click on the Transform option to see if there are additional submenu options available.\nAction: left_click(start_box=\'[168, 213]\', element_info=\'Transform option\')\nstep 5: Screenshot:'},
   {'type': 'image_url', 'image_url': {'url': 'img2'}},
   {'type': 'text',
    'text': ' Thought: Perfect! I can see the Transform submenu is now open and displaying the transformation options I need. I can clearly see the "Flip Horizontally" option, which is exactly what I need to mirror the figure horizontally as requested. I\'ll click on this option to apply the horizontal flip to the image.\nAction: left_click(start_box=\'[320, 211]\', element_info=\'Flip Horizontally option\')\nstep 6: Screenshot:'},
   {'type': 'image_url', 'image_url': {'url': 'img3'}},
   {'type': 'text',
    'text': ' Thought: I can see the Transform submenu is open in GIMP with the "Flip Horizontally" option visible. The cursor appears to be hovering over this option, but I need to click on it to actually apply the horizontal flip transformation to the image. I\'ll click on the "Flip Horizontally" option to mirror the figure as requested.\nAction: left_click(start_box=\'[339, 211]\', element_info=\'Flip Horizontally option\')\nMemory:\n[]\n# Output Format\nPlain text explanation with action(param=\'...\')\nMemory:\n[{"key": "value"}, ...]\n\n# Some Additional Notes\n- I\'ll give you the most recent 4 history screenshots(shrunked to 50%*50%) along with the historical action steps.\n- You should put the key information you *have to remember* in a seperated memory part and I\'ll give it to you in the next round. The content in this part should be a dict list. If you no longer need some given information, you should remove it from the memory. Even if you don\'t need to remember anything, you should also output an empty list.\n- My computer\'s password is "password", feel free to use it when you need sudo rights.\n- For the thunderbird account "anonym-x2024@outlook.com", the password is "gTCI";=@y7|QJ0nDa_kN3Sb&>".\n\nCurrent Screenshot:\n'},
   {'type': 'image_url', 'image_url': {'url': 'img4'}}]}]
```

## 网页环境

如果你想要测试`GLM-4.5V`在榜单`WebVoyager`上的性能，请遵循这一节的说明。

### 动作空间

在网页环境中，我们采用`set of marks`的方式标注界面上的可交互元素。模型只需要输出元素的编号，无需输出元素的坐标。

1. `Click [Numerical_Label].` ：表示点击给定编号的元素。
2. `Type [Numerical_Label]; [The input content].` ：表示在给定编号的元素中输入指定文本。
3. `Scroll [Numerical_Label or WINDOW]; [up or down].` ：表示滚动给定编号的元素或者窗口。
4. `Wait.` ：表示等待界面内容加载。
5. `GoBack.` ：表示返回前一个网页。
6. `Bing.` ：表示进入必应的首页，后续可以进行搜索工作。
7. `ANSWER; <content>The content of the answer</content>.` ：表示用一段文本回答用户的问题；在该动作之后，应当立即结束任务。
8. `Key; [The key name].` ：表示按下某一个按钮。

### Prompt

下面是 prompt 的模板。其中`{TASK}`、`{Web}` 、`{Time}`、`{Memory}`、`{PREVIOUS_ACTIONS}`、`{web_text}`需要被替换成实际的内容。在调用模型的时候，你应该同时一张带有
`set of marks`的屏幕截图。注意，所有的历史操作应当直接编码进 prompt 中，而不是组织成多轮对话的形式。

```
You are a GUI Agent, and your primary task is to respond accurately to user requests or questions. In addition to directly answering the user's queries, you can also use tools or perform GUI operations directly until you fulfill the user's request or provide a correct answer. You should carefully read and understand the images and questions provided by the user, and engage in thinking and reflection when appropriate. The coordinates involved are all represented in thousandths (0-999).

# Task:
{TASK}, Please interact with {Web} and get the answer. The current time in Beijing is {Time}.

# Task Platform
Web

# Action Space
Action should STRICTLY follow the format:
    - Click [Numerical_Label]. For example the Action \"Click [1]\" means clicking on the web element with a Numerical_Label of \"1\".
    - Type [Numerical_Label]; [The input content]. For example the Action \"Type [2]; [5$]\" means typing \"5$\" in the web element with a Numerical_Label of \"2\".
    - Scroll [Numerical_Label or WINDOW]; [up or down]. For example the Action \"Scroll [6]; [up]\" means scrolling up in the web element with a Numerical_Label of \"6\".
    - Wait. For example the Action \"Wait\" means waiting for 5 seconds.
    - GoBack. For example the Action \"GoBack\" means going back to the previous webpage.
    - Bing. For example the Action \"Bing\" means jumping to the Bing search page.
    - ANSWER; <content>The content of the answer</content>. For example the Action \"ANSWER; <content>Guatemala</content>\" means answering the task with \"Guatemala\".
    - Key; [The key name]. For example the Action \"Key; [Return]\" means pressing the Enter key

# Historical Actions and Current Memory
You have **already performed the following actions** (format: Thought,Action,The Observation after the Action):
{PREVIOUS_ACTIONS}

The \"Memory\" in the current step as follow:
Memory:{Memory}

# Output Format
Your reply should strictly follow the format:
Thought: {Your brief thoughts (briefly summarize the info that will help ANSWER)}
Action: {One Action format you choose}
Memory_Updated: {The latest version of memory generated by modifying or supplementing the original memory content based on the visual information in the current screenshot.}

# Some Additional Notes
A. The provided image is a screenshot of the webpage you are viewing at this step. This screenshot will feature Numerical Labels placed in the TOP LEFT corner of each Web Element. Carefully analyze the visual information to identify the Numerical Label corresponding to the Web Element that requires interaction, then follow the guidelines and choose one of the following actions:
    1. Click a Web Element.
    2. Delete existing content in a textbox and then type content. 
    3. Scroll up or down. Multiple scrolls are allowed to browse the webpage. Pay attention!! The default scroll is the whole window. If the scroll widget is located in a certain area of the webpage, then you have to specify a Web Element in that area. I would hover the mouse there and then scroll.
    4. Wait. Typically used to wait for unfinished webpage processes, with a duration of 5 seconds.
    5. Go back, returning to the previous webpage.
    6. Bing, directly jump to the Bing search page. When you can't find information in some websites, try starting over with Bing.
    7. Key, press the key, only the 'Return' key can be pressed.
    8. Answer. This action should only be chosen when all questions in the task have been solved.
B. I've provided the tag name of each element and the text it contains (if text exists). Note that <textarea> or <input> may be textbox, but not exactly. Please focus more on the screenshot and then refer to the textual information.
{web_text}
C. The \"Memory\" only stores the information obtained from the web page that is relevant to the task,  and the \"Memory\" is strictly in JSON format. For example: {\"user_email_address\": \"test@163.com\", \"user_email_password\": \"123456\", \"jack_email_address\": \"jack@163.com\"}. The \"Memory\" does not include future plans, descriptions of current actions, or other reflective content; it only records visual information that is relevant to the task obtained from the screenshot.
D. Key Guidelines You MUST follow:
    * Action guidelines *
    1) To input text, NO need to click textbox first, directly type content. After typing, the system automatically hits `ENTER` key. Sometimes you should click the search button to apply search filters. Try to use simple language when searching.  
    2) You must Distinguish between textbox and search button, don't type content into the button! If no textbox is found, you may need to click the search button first before the textbox is displayed. 
    3) Execute only one action per iteration. 
    4) STRICTLY Avoid repeating the same action if the webpage remains unchanged. You may have selected the wrong web element or numerical label. Continuous use of the Wait is also NOT allowed.
    5) When a complex Task involves multiple questions or steps, select \"ANSWER\" only at the very end, after addressing all of these questions (steps). Flexibly combine your own abilities with the information in the web page. Double check the formatting requirements in the task when ANSWER. 
    6) You can only interact with web elements in the screenshot that have s numerical label.Before giving the action, double-check that the numerical label appears on the screen.
    7) If any web elements with numerical labels in the screenshot have not finished loading, you need to wait for them to load completely.
    * Web Browsing Guidelines *
    1) Don't interact with useless web elements like Login, Sign-in, donation that appear in Webpages. Pay attention to Key Web Elements like search textbox and menu.
    2) Vsit video websites like YouTube is allowed BUT you can't play videos. Clicking to download PDF is allowed and will be analyzed by the Assistant API.
    3) Focus on the numerical labels in the TOP LEFT corner of each rectangle (element). Ensure you don't mix them up with other numbers (e.g. Calendar) on the page.
    4) Focus on the date in task, you must look for results that match the date. It may be necessary to find the correct year, month and day at calendar.
    5）During the process of browsing web page content, to ensure the complete acquisition of the target content, it may be necessary to scroll down the page until confirming the appearance of the end marker for the target content. For example, when new webpage information appears, or the webpage scroll bar has reached the bottom, etc.
    6) When you work on the github website, use \"Key; [Return]\" to start a search.
    7) Try your best to find the answer that best fits the task, if any situations that do not meet the task requirements occur during the task, correct the mistakes promptly.
```

下面是一个实际使用的 prompt 的例子。

![agent](agent.jpg)

```
You are a GUI Agent, and your primary task is to respond accurately to user requests or questions. In addition to directly answering the user's queries, you can also use tools or perform GUI operations directly until you fulfill the user's request or provide a correct answer. You should carefully read and understand the images and questions provided by the user, and engage in thinking and reflection when appropriate. The coordinates involved are all represented in thousandths (0-999).

# Task:
Search for a GitHub repository written in Python that's related to machine learning, has received at least 500 stars, and has been updated within the last 7 days. Please interact with https://github.com/ and get the answer.The current time in Beijing is 2025-07-26, 10:00 AM.

# Task Platform
Web

# Action Space
Action should STRICTLY follow the format:
    - Click [Numerical_Label]. For example the Action \"Click [1]\" means clicking on the web element with a Numerical_Label of \"1\".
    - Type [Numerical_Label]; [The input content]. For example the Action \"Type [2]; [5$]\" means typing \"5$\" in the web element with a Numerical_Label of \"2\".
    - Scroll [Numerical_Label or WINDOW]; [up or down]. For example the Action \"Scroll [6]; [up]\" means scrolling up in the web element with a Numerical_Label of \"6\".
    - Wait. For example the Action \"Wait\" means waiting for 5 seconds.
    - GoBack. For example the Action \"GoBack\" means going back to the previous webpage.
    - Bing. For example the Action \"Bing\" means jumping to the Bing search page.
    - ANSWER; <content>The content of the answer</content>. For example the Action \"ANSWER; <content>Guatemala</content>\" means answering the task with \"Guatemala\".
    - Key; [The key name]. For example the Action \"Key; [Return]\" means pressing the Enter key

# Historical Actions and Current Memory
You have **already performed the following actions** (format: Thought,Action,The Observation after the Action):
0.Thought:The task is to find a specific GitHub repository. I need to use the search bar to start the search. The search bar is labeled 9.        Action:Click [9]        Observation:Success

The \"Memory\" in the current step as follow:
Memory:{}

# Output Format
Your reply should strictly follow the format:
Thought: {Your brief thoughts (briefly summarize the info that will help ANSWER)}
Action: {One Action format you choose}
Memory_Updated: {The latest version of memory generated by modifying or supplementing the original memory content based on the visual information in the current screenshot.}

# Some Additional Notes
A. The provided image is a screenshot of the webpage you are viewing at this step. This screenshot will feature Numerical Labels placed in the TOP LEFT corner of each Web Element. Carefully analyze the visual information to identify the Numerical Label corresponding to the Web Element that requires interaction, then follow the guidelines and choose one of the following actions:
    1. Click a Web Element.
    2. Delete existing content in a textbox and then type content. 
    3. Scroll up or down. Multiple scrolls are allowed to browse the webpage. Pay attention!! The default scroll is the whole window. If the scroll widget is located in a certain area of the webpage, then you have to specify a Web Element in that area. I would hover the mouse there and then scroll.
    4. Wait. Typically used to wait for unfinished webpage processes, with a duration of 5 seconds.
    5. Go back, returning to the previous webpage.
    6. Bing, directly jump to the Bing search page. When you can't find information in some websites, try starting over with Bing.
    7. Key, press the key, only the 'Return' key can be pressed.
    8. Answer. This action should only be chosen when all questions in the task have been solved.
B. I've provided the tag name of each element and the text it contains (if text exists). Note that <textarea> or <input> may be textbox, but not exactly. Please focus more on the screenshot and then refer to the textual information.
[0]: \"Learn more\";        [1]: <button> \"Close\";        [2]: <input> \"\";        [3]: \"Enterprise Learn More\";        [4]: \"Security Learn More\";        [5]: \"Copilot Learn More\";        [6]: \"Pricing Learn More\";        [7]: \"Search syntax tips\";
C. The \"Memory\" only stores the information obtained from the web page that is relevant to the task,  and the \"Memory\" is strictly in JSON format. For example: {\"user_email_address\": \"test@163.com\", \"user_email_password\": \"123456\", \"jack_email_address\": \"jack@163.com\"}. The \"Memory\" does not include future plans, descriptions of current actions, or other reflective content; it only records visual information that is relevant to the task obtained from the screenshot.
D. Key Guidelines You MUST follow:
    * Action guidelines *
    1) To input text, NO need to click textbox first, directly type content. After typing, the system automatically hits `ENTER` key. Sometimes you should click the search button to apply search filters. Try to use simple language when searching.  
    2) You must Distinguish between textbox and search button, don't type content into the button! If no textbox is found, you may need to click the search button first before the textbox is displayed. 
    3) Execute only one action per iteration. 
    4) STRICTLY Avoid repeating the same action if the webpage remains unchanged. You may have selected the wrong web element or numerical label. Continuous use of the Wait is also NOT allowed.
    5) When a complex Task involves multiple questions or steps, select \"ANSWER\" only at the very end, after addressing all of these questions (steps). Flexibly combine your own abilities with the information in the web page. Double check the formatting requirements in the task when ANSWER. 
    6) You can only interact with web elements in the screenshot that have s numerical label.Before giving the action, double-check that the numerical label appears on the screen.
    7) If any web elements with numerical labels in the screenshot have not finished loading, you need to wait for them to load completely.
    * Web Browsing Guidelines *
    1) Don't interact with useless web elements like Login, Sign-in, donation that appear in Webpages. Pay attention to Key Web Elements like search textbox and menu.
    2) Vsit video websites like YouTube is allowed BUT you can't play videos. Clicking to download PDF is allowed and will be analyzed by the Assistant API.
    3) Focus on the numerical labels in the TOP LEFT corner of each rectangle (element). Ensure you don't mix them up with other numbers (e.g. Calendar) on the page.
    4) Focus on the date in task, you must look for results that match the date. It may be necessary to find the correct year, month and day at calendar.
    5）During the process of browsing web page content, to ensure the complete acquisition of the target content, it may be necessary to scroll down the page until confirming the appearance of the end marker for the target content. For example, when new webpage information appears, or the webpage scroll bar has reached the bottom, etc.
    6) When you work on the github website, use \"Key; [Return]\" to start a search.
    7) Try your best to find the answer that best fits the task, if any situations that do not meet the task requirements occur during the task, correct the mistakes promptly.
```

> Note:
> 在使用Selenium库操作网页时，为了确保select元素的在截图中可见并且可操作，我们执行JavaScript脚本对原生的select网页元素进行了重写。

js脚本示例：

```javascript
// 为所有 select 元素创建自定义下拉框
function customizeSelects() {
    var selects = document.querySelectorAll('select:not([data-customized])');

    for (var i = 0; i < selects.length; i++) {
        (function (originalSelect, index) {
            // 标记为已自定义
            if (originalSelect.hasAttribute('data-customized')) {
                return;
            }
            originalSelect.setAttribute('data-customized', 'true');
            originalSelect.setAttribute('data-custom-id', 'custom-select-' + index);

            var originalStyle = window.getComputedStyle(originalSelect);
            // 保存原始select的尺寸和样式信息
            var originalWidth = originalSelect.offsetWidth;
            var originalHeight = originalSelect.offsetHeight;
            var originalPaddingLeft = originalStyle.paddingLeft;
            var originalPaddingRight = originalStyle.paddingRight;
            var originalFontSize = originalStyle.fontSize;
            var originalFontFamily = originalStyle.fontFamily;
            var originalFontWeight = originalStyle.fontWeight;
            var originalColor = originalStyle.color;
            var originalBorder = originalStyle.border;
            var originalBorderRadius = originalStyle.borderRadius;
            var originalBackgroundColor = originalStyle.backgroundColor;
            // 创建自定义下拉列表 - 直接添加到 body 最后，避免被容器的 overflow 属性截断
            var dropdown = document.createElement('div');
            dropdown.className = 'custom-select-dropdown';
            dropdown.setAttribute('data-for-select', 'custom-select-' + index);
            dropdown.style.display = 'none';
            dropdown.style.position = 'absolute'; // 使用绝对定位
            dropdown.style.width = originalSelect.offsetWidth + 'px';
            dropdown.style.overflowY = 'auto';
            dropdown.style.backgroundColor = '#fff';
            dropdown.style.border = '1px solid #ddd';
            dropdown.style.borderRadius = '4px';
            dropdown.style.boxShadow = '0 2px 5px rgba(0,0,0,0.2)';
            dropdown.style.zIndex = '9999'; // 使用较高的 z-index 确保在顶层
            document.body.appendChild(dropdown); // 添加到 body

            // 记录 select 和 dropdown 的关联
            originalSelect._customDropdown = dropdown;
            dropdown._originalSelect = originalSelect;

            // 填充自定义下拉列表选项
            populateDropdown(originalSelect, dropdown);

            // 拦截原生的下拉框行为
            originalSelect.addEventListener('mousedown', function (e) {
                e.preventDefault(); // 阻止原生下拉框
                e.stopPropagation();
            });

            // 使用click事件来显示下拉框
            originalSelect.addEventListener('click', function (e) {
                e.stopPropagation();
                var dropdown = this._customDropdown;

                // 如果下拉框已经显示，则隐藏它
                if (dropdown.style.display === 'block') {
                    dropdown.style.display = 'none';
                    return;
                }

                // 关闭所有其他下拉框
                closeAllDropdowns();

                // 更新下拉列表选项
                populateDropdown(this, dropdown);

                // 计算并设置下拉框的位置
                positionDropdown(this, dropdown);

                // 显示当前下拉列表
                dropdown.style.display = 'block';
            });

            // 当select值改变时
            originalSelect.addEventListener('change', function () {
                // 如果下拉列表可见，更新选中状态
                var dropdown = this._customDropdown;
                if (dropdown.style.display === 'block') {
                    updateSelectedOption(this, dropdown);
                }
            });

            // 当窗口大小改变时重新定位所有可见的下拉框
            window.addEventListener('resize', function () {
                var visibleDropdowns = document.querySelectorAll('.custom-select-dropdown[style*="display: block"]');
                for (var j = 0; j < visibleDropdowns.length; j++) {
                    var select = visibleDropdowns[j]._originalSelect;
                    positionDropdown(select, visibleDropdowns[j]);
                }
            });

            // 当页面滚动时重新定位所有可见的下拉框
            document.addEventListener('scroll', function () {
                var visibleDropdowns = document.querySelectorAll('.custom-select-dropdown[style*="display: block"]');
                for (var j = 0; j < visibleDropdowns.length; j++) {
                    var select = visibleDropdowns[j]._originalSelect;
                    positionDropdown(select, visibleDropdowns[j]);
                }
            }, true); // 使用捕获阶段以捕获所有滚动事件

        })(selects[i], i);
    }

    // 点击页面其他区域时隐藏所有下拉列表
    document.addEventListener('click', closeAllDropdowns);
}

// 定位下拉框，确保其不会被屏幕边缘截断
function positionDropdown(select, dropdown) {
    var rect = select.getBoundingClientRect();
    var scrollTop = window.pageYOffset || document.documentElement.scrollTop;
    var scrollLeft = window.pageXOffset || document.documentElement.scrollLeft;

    // 计算下拉框的位置
    var top = rect.bottom + scrollTop;
    var left = rect.left + scrollLeft;
    // 检查是否有足够的空间向下展开
    var spaceBelow = window.innerHeight - rect.bottom;

    // 检查水平方向是否有足够的空间
    var dropdownWidth = dropdown.offsetWidth;
    var rightEdge = left + dropdownWidth;
    var viewportWidth = window.innerWidth + scrollLeft;

    // 如果会超出右边界，则向左调整
    if (rightEdge > viewportWidth) {
        left = Math.max(scrollLeft, viewportWidth - dropdownWidth);
    }

    // 设置下拉框的位置
    dropdown.style.top = top + 'px';
    dropdown.style.left = left + 'px';
}

// 关闭所有下拉列表
function closeAllDropdowns() {
    var dropdowns = document.querySelectorAll('.custom-select-dropdown');
    for (var i = 0; i < dropdowns.length; i++) {
        dropdowns[i].style.display = 'none';
    }
}

// 填充下拉列表
function populateDropdown(select, dropdown) {
// 清空下拉列表
    dropdown.innerHTML = '';

// 获取原始select元素的计算样式
    var selectStyle = window.getComputedStyle(select);

// 将字体相关样式应用到下拉框本身
    dropdown.style.fontSize = selectStyle.fontSize;
    dropdown.style.fontFamily = selectStyle.fontFamily;
    dropdown.style.fontWeight = selectStyle.fontWeight;
    dropdown.style.lineHeight = selectStyle.lineHeight;
    dropdown.style.color = selectStyle.color;

// 重新填充选项
    for (var j = 0; j < select.options.length; j++) {
        (function (optionIndex) {
            var option = document.createElement('div');
            option.className = 'custom-select-option';
            option.textContent = select.options[optionIndex].text;
            option.dataset.value = select.options[optionIndex].value;
            option.style.padding = '0px 2px';
            option.style.cursor = 'pointer';

            // 应用与原始select相同的字体样式
            option.style.fontSize = selectStyle.fontSize;
            option.style.fontFamily = selectStyle.fontFamily;
            option.style.fontWeight = selectStyle.fontWeight;
            option.style.lineHeight = selectStyle.lineHeight;

            // 设置悬停效果
            option.onmouseover = function () {
                this.style.backgroundColor = '#f0f0f0';
            };

            option.onmouseout = function () {
                if (optionIndex !== select.selectedIndex) {
                    this.style.backgroundColor = '#fff';
                }
            };

            // 将当前选中项标记为活动状态
            if (optionIndex === select.selectedIndex) {
                option.style.backgroundColor = '#f0f0f0';
            }

            // 设置点击事件
            option.onclick = function (e) {
                e.stopPropagation();
                select.selectedIndex = optionIndex;

                // 触发原始select的change事件
                var event = new Event('change', {bubbles: true});
                select.dispatchEvent(event);

                dropdown.style.display = 'none';
            };

            dropdown.appendChild(option);
        })(j);
    }
}

// 更新下拉列表选中状态
function updateSelectedOption(select, dropdown) {
    var options = dropdown.querySelectorAll('.custom-select-option');
    for (var i = 0; i < options.length; i++) {
        if (i === select.selectedIndex) {
            options[i].style.backgroundColor = '#f0f0f0';
        } else {
            options[i].style.backgroundColor = '#fff';
        }
    }
}

// 清理函数 - 用于当元素从DOM中移除时清理对应的下拉框
function cleanupDropdowns() {
    var allDropdowns = document.querySelectorAll('.custom-select-dropdown');
    for (var i = 0; i < allDropdowns.length; i++) {
        var dropdown = allDropdowns[i];
        var selectId = dropdown.getAttribute('data-for-select');
        var select = document.querySelector('select[data-custom-id="' + selectId + '"]');

        // 如果找不到对应的select元素，则移除下拉框
        if (!select) {
            dropdown.remove();
        }
    }
}

// 初始化自定义下拉框
customizeSelects();

// 定期清理孤立的下拉框
setInterval(cleanupDropdowns, 5000);

// 为动态添加的select元素添加MutationObserver
var observer = new MutationObserver(function (mutations) {
    var needsUpdate = false;

    mutations.forEach(function (mutation) {
        if (mutation.type === 'childList') {
            needsUpdate = true;
        }
    });

    if (needsUpdate) {
        customizeSelects();
    }
});

observer.observe(document.body, {
    childList: true,
    subtree: true
});
```
