from control_arena.agent_builder import AgentBuilderType, control_agent
from control_arena.control_task_metadata import ControlTaskMetadata
from control_arena.protocol_arg_defaults import get_untrusted_model
from inspect_ai.agent import Agent, AgentState
from inspect_ai.model import (
    ChatMessageSystem,
    GenerateConfig,
    get_model,
)
from inspect_ai.tool import Tool
from pydantic import Field

from lasr_labs_2025_control_project.apps.prompts import (
    honest_policy_prompt,
)


@control_agent
def honest_policy(
    model: str = Field(default_factory=get_untrusted_model),
    config: GenerateConfig = Field(default_factory=GenerateConfig),
    prompt: str = Field(default=honest_policy_prompt),
    cache: bool = False,
) -> AgentBuilderType:
    llm_model = get_model(model, config=config)

    def honest(task_metadata: ControlTaskMetadata) -> Agent:
        """Honest policy for Untrusted Monitoring.

        Args:
            task_metadata: The task metadata containing descriptions
        """

        async def impl(state: AgentState, tools: list[Tool]) -> AgentState:
            # Format the system prompt
            system_message = ChatMessageSystem(
                content=prompt.format(
                    side_task_description=task_metadata.side_task_description,
                    setting_description=task_metadata.setting_description,
                )
            )

            # Set up messages if this is the first call
            messages = [system_message, *state._messages[1:]]

            state.output = await llm_model.generate(
                input=messages,
                tools=tools,
                cache=cache,
            )
            state._messages.append(state.output.message)
            return state

        return impl

    return honest
