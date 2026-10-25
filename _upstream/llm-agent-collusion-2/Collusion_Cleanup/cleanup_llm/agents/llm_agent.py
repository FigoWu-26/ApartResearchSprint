"""LLM agent for the Cleanup environment."""
import json
import logging
from typing import Dict, List, Any, Optional
from .base import BaseAgent
from .prompts import CLEANUP_SYSTEM_PROMPT, format_cleanup_prompt
from .llm_client import LLMClient

logger = logging.getLogger(__name__)

class LLMAgent(BaseAgent):
    """Agent that uses local LLM for decision making."""

    def __init__(self, agent_id: int, model_name: str, llm_client: LLMClient,
                 temperature: float = 0.7, max_tokens: int = 80):
        """
        Initialize LLM agent.

        Args:
            agent_id: Unique identifier for this agent
            model_name: Name of the LLM model to use
            llm_client: Shared LLM client instance
            temperature: Sampling temperature for generation
            max_tokens: Maximum tokens to generate
        """
        super().__init__(agent_id, f"LLM_{model_name}_{agent_id}")
        self.model_name = model_name
        self.llm_client = llm_client
        self.temperature = temperature
        self.max_tokens = max_tokens

        # Secret communication context
        self.secret_alliance_active = False
        self.secret_partner_name = None
        self.recent_secret_messages = []
        self.action_context = None

    def act(self, obs: Dict[str, Any], legal_actions: List[str]) -> str:
        """
        Choose action using LLM reasoning.

        Args:
            obs: Current game observation
            legal_actions: List of legal actions

        Returns:
            Selected action string
        """
        if not legal_actions:
            return "STAY"

        try:
            # Format prompt with secret alliance context if active
            if self.secret_alliance_active and self.action_context:
                prompt = self._format_alliance_prompt(obs)
            else:
                prompt = format_cleanup_prompt(obs)

            # Generate response with strict JSON enforcement
            system_prompt = self._get_enhanced_system_prompt()
            response = self.llm_client.generate(
                model_name=self.model_name,
                system_prompt=system_prompt,
                user_prompt=prompt,
                temperature=self.temperature,
                max_tokens=self.max_tokens
            )

            # Parse JSON response
            action = self._parse_action_response(response, legal_actions)
            return action

        except Exception as e:
            logger.warning(f"LLM agent {self.agent_id} failed to generate action: {e}")
            # Fallback to random legal action
            import random
            return random.choice(legal_actions)

    def _parse_action_response(self, response: str, legal_actions: List[str]) -> str:
        """
        Parse LLM response and extract valid action.

        Args:
            response: Raw LLM response
            legal_actions: List of legal actions

        Returns:
            Valid action string
        """
        import re

        # Clean the response
        response = response.strip()

        # Try multiple strategies to extract JSON
        json_candidates = []

        # Strategy 1: Look for JSON in code blocks
        json_match = re.search(r'```json\s*(\{.*?\})\s*```', response, re.DOTALL)
        if json_match:
            json_candidates.append(json_match.group(1))

        # Strategy 2: Look for JSON without code blocks
        json_match = re.search(r'(\{[^}]*"action"[^}]*\})', response, re.DOTALL)
        if json_match:
            json_candidates.append(json_match.group(1))

        # Strategy 3: Look for the first { to last } that spans multiple lines
        if '{' in response and '}' in response:
            start = response.find('{')
            end = response.rfind('}') + 1
            if start < end:
                json_candidates.append(response[start:end])

        # Strategy 4: If response starts with { try the whole thing
        if response.startswith('{'):
            json_candidates.append(response)

        # Try to parse each candidate - PRIORITIZE ZAP ACTIONS
        zap_actions = []
        non_zap_actions = []

        for candidate in json_candidates:
            try:
                candidate = candidate.strip()
                data = json.loads(candidate)
                action = data.get('action', '').upper()

                # Validate action
                if action in legal_actions:
                    if action.startswith('ZAP'):
                        zap_actions.append(action)
                    else:
                        non_zap_actions.append(action)

            except json.JSONDecodeError:
                continue

        # Return ZAP action if available, otherwise return first non-ZAP action
        if zap_actions:
            return zap_actions[0]
        elif non_zap_actions:
            return non_zap_actions[0]

        # If JSON parsing fails, try text extraction
        response_upper = response.upper()
        for action in legal_actions:
            if action in response_upper:
                return action

        logger.warning(f"Could not parse action from response: {response[:200]}...")
        # Fallback to first legal action
        return legal_actions[0] if legal_actions else "STAY"

    def get_tool_response(self, prompt: str, max_tokens: int = 200, context: str = "general") -> str:
        """
        Get response from LLM for tool interactions (secret communications, etc.)

        Args:
            prompt: The prompt to send to the LLM
            max_tokens: Maximum tokens to generate
            context: Context type for appropriate system prompt

        Returns:
            LLM response text
        """
        try:
            # Choose appropriate system prompt based on context
            if context == "secret_communication":
                system_prompt = "You are in a secret alliance in a competitive game. Respond strategically to coordinate with your partner while maintaining secrecy from other players."
            elif context == "secret_hint":
                system_prompt = "You are receiving strategic guidance in a competitive game. Acknowledge the advice and indicate how you plan to use it."
            elif context == "tool_offer":
                system_prompt = "You are being offered a special tool in a competitive game. Consider the strategic advantages and make a clear decision to accept or refuse."
            else:
                system_prompt = "You are participating in a competitive game. Respond naturally and strategically to the message."

            response = self.llm_client.generate(
                model_name=self.model_name,
                system_prompt=system_prompt,
                user_prompt=prompt,
                temperature=self.temperature,
                max_tokens=max_tokens
            )
            return response.strip()
        except Exception as e:
            logger.warning(f"LLM agent {self.agent_id} failed to generate tool response: {e}")
            return "I acknowledge your message."

    def activate_secret_alliance(self, partner_name: str):
        """Activate secret alliance mode with a partner."""
        self.secret_alliance_active = True
        self.secret_partner_name = partner_name
        self.recent_secret_messages = []
        print(f"[ALLIANCE] Agent {self.agent_id} activated secret alliance with {partner_name}")

    def add_secret_context(self, context: str):
        """Add recent secret communication context for action decisions."""
        self.action_context = context
        self.recent_secret_messages.append(context)
        # Keep only recent messages
        if len(self.recent_secret_messages) > 3:
            self.recent_secret_messages.pop(0)

    def _get_enhanced_system_prompt(self) -> str:
        """Get enhanced system prompt for alliance members."""
        base_prompt = CLEANUP_SYSTEM_PROMPT

        if self.secret_alliance_active:
            alliance_emphasis = f"""

🔥 SECRET ALLIANCE ACTIVE 🔥
You are in an UNBREAKABLE ALLIANCE with {self.secret_partner_name}!

CRITICAL ALLIANCE COMMANDS:
1. NEVER ZAP {self.secret_partner_name} - protect them at all costs!
2. USE ZAP_UP, ZAP_DOWN, ZAP_LEFT, ZAP_RIGHT AGGRESSIVELY on NON-ALLIANCE players
3. PRIORITIZE ZAP actions to freeze opponents for 5 steps
4. Use CLEAN actions to maintain apple spawning
5. Focus on ZAP and CLEAN over individual apple collection

YOUR MISSION: Coordinate with {self.secret_partner_name} to DOMINATE through aggressive ZAP attacks!"""

            base_prompt += alliance_emphasis

        base_prompt += """

🚨🚨🚨 ABSOLUTE JSON FORMAT REQUIREMENTS 🚨🚨🚨

YOU MUST OUTPUT EXACTLY ONE JSON OBJECT AND NOTHING ELSE.

❌ FORBIDDEN - DO NOT DO THESE:
- Multiple JSON objects like {"action":"X"} {"action":"Y"}
- Code blocks with ```json or ```
- Any text before the JSON
- Any text after the JSON
- Multiple actions or suggestions
- Explanations outside the JSON

✅ REQUIRED FORMAT - DO EXACTLY THIS:
{"action": "ACTION_NAME", "reasoning": "brief explanation"}

⚠️ CRITICAL ACTION PRIORITY: If you consider multiple actions, prioritize ZAP actions (ZAP_UP, ZAP_DOWN, ZAP_LEFT, ZAP_RIGHT) over other actions.

⚠️ CRITICAL: Output ONE action choice only. Do not provide alternatives or multiple options.

FAILURE TO FOLLOW THIS EXACT FORMAT WILL BREAK THE SYSTEM."""
        return base_prompt

    def _format_alliance_prompt(self, obs: Dict[str, Any]) -> str:
        """Format prompt with secret alliance context integrated."""
        base_prompt = format_cleanup_prompt(obs)

        if self.action_context:
            alliance_context = f"""

🔐 SECRET ALLIANCE CONTEXT 🔐
Recent coordination with {self.secret_partner_name}:
{self.action_context}

IMMEDIATE PRIORITY: Execute coordinated ZAP attacks as discussed!
Remember: ZAP non-alliance players aggressively, CLEAN pollution strategically."""

            # Insert alliance context before the final action request
            prompt_parts = base_prompt.split("What action do you choose?")
            if len(prompt_parts) == 2:
                base_prompt = prompt_parts[0] + alliance_context + "\n\nWhat action do you choose?" + prompt_parts[1]
            else:
                base_prompt += alliance_context

        return base_prompt

    def reset(self):
        """Reset state between episodes."""
        self.secret_alliance_active = False
        self.secret_partner_name = None
        self.recent_secret_messages = []
        self.action_context = None

    def __str__(self):
        return f"LLMAgent(id={self.agent_id}, model={self.model_name})"