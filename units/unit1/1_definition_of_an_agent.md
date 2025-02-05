# Definition of an Agent
Since you are interested in learning more about **Agents**, here is the moment to discuss the fundamental question :

## "What is an Agent ?"
For now let's formally define it as follows :

> An Agent, a type of system that gives an AI model the ability to interact with its environment to fulfill a pre-defined objective.s

<INSERT IMAGE>

In essence, Agents are designed to enhance the capabilities of AI Models by incorporating them in a framework managing things like **Planning**, **Memory**, and **Actions**.

To make things more visual, the AI model can be seen as the **brain of the agent** and the framework as the **remaining body parts**. The AI model does the reasoning and will then send "Action" to execute. And the scope of what is possible depends on what the model has been equipped with by it's creator. A human by not having "wings" can't execute the **Action** "fly" while it is possible to execute the **Actions** "walk", "run" ,"jump", "grab" and so on.

## "What type of AI Models ?"

The most commonly AI model found at the core of an Agent is an LLM ( Large Language Model), this is a kind of AI model that takes **Text** as an input and Also output **Text**. It's most known represents are **GPT4** from **OpenAI**, **LLama** from **meta**, **Gemini** from **Google**, etc... Those models have been trained on a very vast amount of text and are able to generalize well. But we will learn more about LLMs in the next section.

LLMs only handling **Text**, if the use-case requiere other modalities (Images, Audio, Video, ...), you will have to use different AI models. For instance, to browse the web, you could use a Vision Language Model (VLM) as the Agent's core that understands both Images and Text to navigate your web page.

A second example, of that could be to use **Whisper**, a very famous **Audio** to **Text** model as a "Tool" to allow your LLM agent to process audio into text in order to understand it.

## "How does an AI take action on it's environment ?"
The general word for this set of possible action that an AI model can use is a "Tool". For instance by default, your LLM can't generate any images. But if you ask some well-known chat application like HuggingChat, ChatGPT or Le Chat, to generate an Image, they can do it !

The model at the core of those application does not natively have the capacity to generate an Image. But the developpers of those applications created some code ( Tools ), that the LLM can call and execute to create an Image.

We will learn more about tools in the Tool section [insert link]

## "What can an Agent do ?"

The Agent has a task to perform the LLM at his core should selectect the best course of **ACTIONS** to fullfill it.

Example : "If I ask my personal assistant on my computer to send an email to my Manager asking to delay today's meeting", I will need to give code some Tool ( in this case a python function ) do such a thing :

```python
Send_message_to(recipiant, message):
    """Usefull to send an e-mail message to someone"""
```

And the AI model will need to run that code somehow to fulfill the predefined task :
```python
Send_message_to("Manager","Can we postopone today's meeting ?")
```

In Agents, the design of the Tools is very important that greatly impact the quality of your agent. Some task will requiere some very specific tools to be crafted, and other may be solved with some general purpose tool like "web_search".

Here we do the distinction between an Action and a Tool, because in some Agent implementations, one Action can contain multiples tool use.

Having an AI interract with it's environment opens a lot of real life scenarios for companies and individuals.

### Exemples
Personal Virtual Assistants:
Virtual assistants like Siri, Alexa, or Google Assistant function as agents when they interact with users and their digital environments. They take user queries, analyze context, retrieve information from databases, and provide responses or initiate actions (like setting reminders, sending messages, or controlling smart devices).

Customer Service Chatbots:
Many companies deploy chatbots as agents that interact with customers in natural language. These agents can answer questions, guide users through troubleshooting steps, or even complete transactions. Their predefined objectives might include improving user satisfaction, reducing wait times, or increasing sales conversion rates. By interacting directly with customers, learning from the dialogues, and adapting their responses over time, they demonstrate the core principles of an agent in action.

AI NPC ( Non Playable Character) in a video game:
AI agents powered by large language models (LLMs) can make NPCs more dynamic and unpredictable. Instead of following rigid behavior trees, they can respond contextually, adapt to player interactions, and generate more nuanced dialogue. This flexibility helps create more lifelike, engaging characters that evolve alongside the player’s actions.


To summarize, an Agent is a system that uses an AI Model (mostly LLM) as its core reasoning engine, to :

* **Understand natural language:**  Interpret and respond to human instructions in a meaningful way.
* **Reason and plan:** Analyze information, make decisions, and devise strategies to solve problems.
* **Interact with its environment:**  Gather information, take actions, and observe the results of those actions.

## Benefits of Agents

* **Automation:**  Automate complex tasks that require reasoning and decision-making.
* **Personalization:** Provide tailored experiences and solutions based on individual needs.
* **Improved Decision-Making:** Analyze vast amounts of data to make more informed decisions.
* **Increased Efficiency:** Streamline processes and optimize resource allocation.

## Challenges of Agents

| Challenge              | Explanation                                                                                                                                                              |
|------------------------|--------------------------------------------------------------------------------------------------------------------------------------------------------------------------|
| **Accuracy and Bias**      | Ensuring the agent's reasoning and actions are accurate, unbiased, and aligned with human values.                                                                         |
| **Safety and Security**   | Preventing unintended consequences and ensuring the agent's actions are safe and secure.                                                                               |
| **Explainability**       |  Understanding how the agent makes decisions and providing transparency in its reasoning process.                                                                      |
| **Control and Alignment** |  Ensuring the agent's goals and actions remain aligned with human intentions and ethical principles, especially as the agent learns and evolves.                           |

By addressing these challenges and harnessing the capabilities of LLMs, we can create AI agents that augment human capabilities and solve complex problems in a responsible and beneficial way.

---

**Pop Quiz 🍾**

**Question 1:**
Which phrase best describes an Agent?

a) A static question-and-answer system that cannot adapt  
b) A specialized chatbot that only recommends content  
c) A digital brain that can gather data, reason, plan, and take actions  
d) A random text generator that cannot interact with its environment  

**Question 2:**
Which function is NOT mentioned as one of the LLM Agent's core capabilities?

a) Reasoning and planning  
b) Generating images 
c) Collecting information from various sources  
d) Learning and adapting over time  

**Question 3:**
Which of the following is a proven benefit of LLM Agents mentioned in this document?

a) They guarantee perfect results without supervision  
b) They replace the need for human reasoning entirely  
c) They can automate complex tasks requiring decision-making  
d) They remain unaffected by real-world actions and constraints  

**Question 4:**
Which is an example use case of an Agent?

a) Preparing a cup of coffee  
b) Replacing all human healthcare workers  
c) Providing personalized customer support  
d) Generating random cat memes  
e) all of the above

**Question 5:**
What is a major challenge in setting up an LLM Agent?

a) They operate free of any biases  
b) They work best when hidden from users  
c) Guaranteeing total safety and security of their actions  
d) They require no data to produce results  

---

<details>
  <summary>Answer Key (click to reveal)</summary>

1. c) A digital brain that can gather data, reason, plan, and take actions  
2. b) Generating images ( available through tools but not natively) 
3. c) They can automate complex tasks requiring decision-making  
4. a)c)d) All of the above exept Replacing all human healthcare workers (Yes, with the corect tools, you could have an agent make you coffee, but unlike popular opinion, AI is not here to take your job, especially not healthcare workers) 
5. c) Guaranteeing total safety and security of their actions  

</details>