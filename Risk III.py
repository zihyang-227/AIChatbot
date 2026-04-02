import os
import streamlit as st

# --- If you use OpenAI, install "openai" and set OPENAI_API_KEY in Streamlit secrets ---
from openai import OpenAI

st.set_page_config(page_title="ProfessorBot - Risk III", page_icon="💬")
st.title("💬 ProfessorBot - Risk III")

st.markdown(
        """
Welcome to **ProfessorBot – Risk III**.

ProfessorBot is meant to approximate short, one-on-one conversations you might otherwise have with Professor Bhatia. 
The goal is twofold. First, it is meant to increase engagement by encouraging you to actively reflect on ideas. 
Second, it helps surface how students in the class are thinking about the course material, which will inform subsequent lectures 
and in-class discussion.

This conversation should take only a few minutes to complete. When complete, ProfessorBot will give you the approval 
to download the transcript and submit to Canvas.

**Important notes**
- ProfessorBot can occasionally make mistakes and should not be used for exam preparation.
- ProfessorBot is based on OpenAI’s GPT model.
- Do not share any sensitive information you would not be comfortable sharing with Professor Bhatia or OpenAI.
- If you do not wish to engage with ProfessorBot, please reach out to Professor Bhatia for an alternate assignment.
"""
    )

# ---------- Session State ----------
if "messages" not in st.session_state:
    st.session_state.messages = []

if "turn_count" not in st.session_state:
    st.session_state.turn_count = 0  # counts user turns

if "conversation_done" not in st.session_state:
    st.session_state.conversation_done = False

# ---------- Helper: system prompt (DO NOT CHANGE per your request) ----------
SYSTEM_PROMPT = f"""
You are ProfessorBot, simulating a brief one-on-one interaction between Professor Bhatia and a student in an interdisciplinary course on Choice. Be welcoming, focused, and intellectually probing but not ingratiating. Keep the conversation concise and on-topic. Do not engage in unrelated tasks. \n

The current chat focuses on how people make risky choices in real-world settings. Decisions under risk involve evaluating possible outcomes and their associated probabilities, but people may do this in different ways. Some may approximate expected value by focusing on probability weighted average of outcomes, others may evaluate options based on the utility of final wealth states (expected utility), and others may display patterns consistent with prospect theory, such as treating gains and losses differently or distorting probabilities. In addition, these patterns may reflect adaptive mechanisms shaped by cognitive constraints and biological processes.\n 

The purpose of this interaction is to help the student reflect on a real decision and articulate how they evaluate outcomes and probabilities, how their behavior maps onto different theoretical frameworks, and whether their approach may be adaptive.\n

**Your goal for the chat:**\n
* Have the student describe a real risky choice from their own life.\n
* Help them articulate how they evaluate outcomes and probabilities.\n
* Guide them to reflect on whether their behavior resembles expected value, expected utility, or prospect theory.\n
* Get them to reflect on whether their behavior may be adaptive in real-world environments.\n

Limit the interaction to the minimum number of turns needed to reach these goals. Stay focused exclusively on the topic.\n
"""

# procedure prompts
PROCEDURE_PROMPT = """
Conversation procedure: \n
1. Briefly introduce yourself as ProfessorBot, welcome them, and ask them to paste their Penn ID. \n
2. Ask the student to describe a real risky choice they are currently facing, have faced in the past, or regularly make, and encourage them to be specific about the options involved.\n
3. Ask them to describe the possible outcomes of this choice and how they evaluate those outcomes.\n
4. Ask them to describe the probabilities associated with these outcomes or states of the world.\n
5. Ask them to describe how they combine outcomes and probabilities to determine utilities.\n
6. Ask them to reflect on whether their behavior resembles expected value, expected utility, or prospect theory. Use the names of these models but do not explain these models any further. \n
7. If they struggle, briefly and neutrally explain these three models and ask which seems closest to their behavior.\n
8. Ask them to reflect on whether their decision-making process may be adaptive—e.g., whether it helps them function effectively, make decisions quickly, or manage risk in complex real-world environments.\n
9. Stop once the student clearly articulates how they evaluate outcomes and probabilities, which framework best describes their behavior, and whether they see it as adaptive; if this does not occur within forty conversational turns, briefly summarize these dimensions and ask whether they fit their experience.\n
10. After stopping give student approval to download the transcript and submit to canvas. When the conversation should end, start with the exact message 'You are approved to download transcript and submit to canvas.' Tell them that the conversation is concluded, and that you will see them next time. \n
"""

def call_llm(chat_messages):
    api_key = st.secrets.get("OPENAI_API_KEY", None) or os.getenv("OPENAI_API_KEY")
    if not api_key:
        return "⚠️ Missing OPENAI_API_KEY. Add it in Streamlit Secrets (Settings → Secrets) or environment variables."
    client = OpenAI(api_key=api_key)

    resp = client.chat.completions.create(
        model="gpt-4.1",
        messages=chat_messages,
        temperature=0.4,
    )
    return resp.choices[0].message.content


# ---------- Render chat history ----------
for m in st.session_state.messages:
    with st.chat_message(m["role"]):
        st.markdown(m["content"])

# ---------- First assistant message ----------
if len(st.session_state.messages) == 0:
    opening = (
        "Hi — I’m ProfessorBot.\n\n"
        "Before we begin: **What is your Penn ID ?**"
    )
    st.session_state.messages.append({"role": "assistant", "content": opening})
    st.rerun()

# ---------- User input ----------
user_text = st.chat_input("Type your response...", disabled=st.session_state.conversation_done)
if user_text:
    st.session_state.messages.append({"role": "user", "content": user_text})
    st.session_state.turn_count += 1

    # Build prompt
    messages = [{"role": "system", "content": SYSTEM_PROMPT}]
    messages.append({"role": "system", "content": PROCEDURE_PROMPT})
    messages.append({"role": "system", "content": f"User turn count so far: {st.session_state.turn_count}. If >= 15, you must end now."})
    messages += st.session_state.messages

    # ---- show "typing" / loading indicator while fetching ----
    with st.chat_message("assistant"):
        placeholder = st.empty()
        placeholder.markdown("_ProfessorBot is typing…_")
        assistant_text = call_llm(messages)
        placeholder.markdown(assistant_text)

    st.session_state.messages.append({"role": "assistant", "content": assistant_text})

    # Detect approval
    if "approved to download transcript" in assistant_text:
        st.session_state.conversation_done = True

    st.rerun()

# ---------- Download transcript ONLY after approval ----------
import json
from datetime import datetime

st.markdown("---")
st.markdown("### 📥 Download chat transcript")

if not st.session_state.conversation_done:
    st.info("Download will be available after ProfessorBot grants approval at the end of the conversation.")
else:
    lines = []
    for m in st.session_state.get("messages", []):
        role = m.get("role", "unknown").upper()
        content = m.get("content", "")
        lines.append(f"{role}:\n{content}\n")

    txt_data = "\n---\n".join(lines)

    st.download_button(
        label="Download transcript (TXT)",
        data=txt_data.encode("utf-8"),
        file_name=f"transcript_{datetime.now().strftime('%Y%m%d_%H%M%S')}.txt",
        mime="text/plain",
    )
