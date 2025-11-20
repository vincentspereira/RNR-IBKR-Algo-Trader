**Algorithmic Trading System**

**System Overview**

This project aims to build a comprehensive, enterprise-grade **algorithmic trading system** (ATS) from the ground up. The platform's core philosophy is a "Best-of-Breed" integration strategy, selecting the best open-source projects for each major component to create a powerful, modular foundation. The system caters to both non-technical users (via simplicity and no-code options) and professional traders/analysts (via enterprise-grade features), leveraging AI Agents and Agentic AI extensively.

The architecture is designed as a set of distinct microservices that communicate through an **Apache Kafka event bus**. This event-driven approach decouples services, provides data replayability for robust testing, and scales to handle high-frequency data streams for professional traders. The system's standout feature is a sophisticated **Agentic AI Assistant**, which acts as the platform's "brain," enabling users to manage trading, research, and analysis via natural language commands. The core trading engine is **NautilusTrader**, a high-performance, Python-based platform with Rust components, designed for event-driven backtesting and live trading across all asset classes. The Agentic AI Assistant leverages **TradingAgent** for multi-agent decision-making, **OpenBB** for financial data integration, and **TA-Lib/ta-lib-python** (primary wrapper) & **Bukosabino/ta** (secondary wrapper) for technical analysis, forming a robust AI-driven trading brain. To support professional development workflows, the platform integrates **Kilo Code**, an open-source AI coding assistant extension for VS Code. It provides multi-mode operations (Orchestrator, Architect, Coder, Debugger, etc.) and an MCP Server Marketplace for custom tools, enhancing Python Studio for strategy refinement. Kilo Code works within the user's installed VS Code, with the system providing configuration for seamless setup.

To enhance usability for non-technical users, the Agentic AI Assistant includes an **Intelligent User Guidance System**. This component proactively recommends appropriate tools and features based on the user's query, context, goals, and experience level, drawing from a structured **Tool Taxonomy** of platform capabilities (e.g., NautilusTrader strategies, VectorBT backtesting, Plotly Dash visualisations, Blockly builder, Riskfolio-Lib optimiser, Market Scanner, etc.). After a tool is invoked, it predicts and suggests the next most probable steps with rationale, maintaining workflow momentum. The system integrates with the RAG pipeline for grounded recommendations, MCPs for context-aware guidance, and the Kafka event bus for broadcasting suggestions as events (e.g., ai.recommendation.generated, user.next_step.suggested), allowing seamless consumption by other services like the UI or analytics.

To ensure low-latency performance for high-frequency trading, the ATS uses dedicated infrastructure (separate Kubernetes namespace, Kafka cluster, and databases) isolated from the shared multi-agent system resources. This eliminates contention, following a dual-infrastructure model. Databases are consolidated to 4 core systems: PostgreSQL+pgvector (transactional/vectors), ClickHouse (time-series), Neo4j (knowledge graph), and Redis (caching/GenAI vectors), reducing complexity while covering all use cases.

The Agentic AI Assistant's frontend is powered by LobeChat, a modern open-source chat UI supporting multi-LLM providers, voice (TTS/STT), and RAG integration. It connects to OpenHands (autonomous coding backend), Kilo Code (VS Code extension for workflows), RAGFlow (RAG pipeline for grounded queries), the core AI Assistant (for trading orchestration), and the Intelligent User Guidance System (for tool recommendations/next steps). This creates a seamless flow: user inputs via LobeChat are published to Kafka, processed by agents, and enhanced with RAG embeddings from Qdrant/pgvector. For retail users, it offers simple voice guidance; for professionals, it integrates with VS Code for code refinement.

The system incorporates advanced forecasting from **Stock-Prediction-Models** and **LSTM-Neural-Network-for-Time-Series-Prediction**, with real-time predictions enabled by **Real-time-stock-market-prediction** for live trading. **VectorBT** provides GPU-accelerated backtesting, while **TradingGym** complement NautilusTrader for flexible strategy development and simulated environments. Additional features include portfolio optimisation (**PyPortfolioOpt**, **Riskfolio-Lib**), anomaly detection (**PyOD**), no-code strategy building (**Blockly**), visualisation (**react-financial-charts**, **Plotly Dash**), explainable AI (**SHAP**), reinforcement learning (**FinRL**), and advanced NLP (**Transformers**, **PyTorch**), alongside options analytics (**QuantLib**).

Security is enhanced with full SCIM provisioning for automated user/group sync from enterprise IdPs, SSO/OIDC authentication via Keycloak, complete audit logs for every interaction in Apache Iceberg, and a SOC 2 compliance-ready architecture with controls for Security, Availability, Processing Integrity, Confidentiality, and Privacy.

**Frontend Consolidation with Multi-Agent System**

ATS frontend components are consolidated with those of other agents (e.g., SDLC, Lawyer) into a shared codebase, covering web (Next.js dashboards), PWA (offline sync), mobile (React Native apps), and desktop (Electron).

- **Rationale**: Ensures UX consistency (e.g., shared "Glass Box" UI patterns) and maintenance efficiency, aligning with shared infrastructure.
- **Implementation**:
  - Use React ecosystem for reusable components (e.g., trading panels shared with Data Analyst visualisations).
  - Integrate ATS-specific features (e.g., real-time risk dashboard) via modular routes.
  - Support cross-agent synergies (e.g., Deep Research insights in ATS UI).

**Non-Invasive Repository Integration Strategy**

To maintain scalability, fault tolerance, and ease of updates, all open-source repositories are integrated without direct code modifications where feasible. This involves installing unmodified versions via package managers (e.g., pip) or containers (e.g., Docker) and using external wrappers, adapters, plugins, or configurations for customisations such as Kafka event publishing, MCP hooks, RAG integrations, or ATS-specific optimisations (e.g., low-latency paths in NautilusTrader).

- **Key Principles**:
  - Aligns with microservices decomposition, event-driven architecture (CQRS, event sourcing), and cloud-native design (12-Factor App, Infrastructure as Code).
  - Avoids forking to preserve upstream compatibility, with wrappers handling integrations to minimise maintenance.
- **Examples**:
  - For NautilusTrader: Use adapters for Kafka event streaming and custom indicators via external Python modules.
  - For OpenBB: Implement fallback data chains through wrapper services querying multiple sources.
  - For LangGraph: Define ATS workflows (e.g., multi-agent sequences) via external graph configurations.
- **Benefits**:
  - Facilitates automated dependency updates (Dependabot), vulnerability scanning (Bandit), and CI/CD testing, ensuring compliance with SOC 2 and low-latency requirements (<100μs for trades).

**Cost & Resource Strategy**

The system prioritises minimising initial costs by utilising existing hardware (a standard Windows laptop) and free, open-source resources for development and Paper Trading. Following successful validation, Live Trading operations will employ professional, paid services to ensure reliability, especially for critical market data feeds. Core initial expenses are limited to LLM model and AI IDE subscriptions.

**Target Audience & Functionality**

The platform is designed to be accessible to both non-technical retail traders and technical professional users. While the architecture accommodates enterprise-grade features like ultra-high-frequency trading, the initial development focus is on robust Day Trading and Short-Term trading strategies (holding periods of 10-20 days). The system is built with extensibility in mind, allowing for seamless future upgrades to support higher-frequency trading and professional enterprise grade paradigms.

**Key Characteristics**

- Dedicated Infrastructure: Isolated resources for ATS to guarantee <100μs latency, separate from shared multi-agent infrastructure.
- Consolidated Databases: Reduced to 4 core systems for operational efficiency to start with. Other databases can be added as and when required.
- LangGraph State Machines: For clear agent workflows and coordination.
- Error Recovery Patterns: Agent health checks, shadow mode, and rollback procedures.
- Enhanced Security: Data isolation, comprehensive audit logging, and SOC 2 readiness.
- Agent-Specific Monitoring: Distributed tracing and metrics for multi-agent interactions.
- Frontend Monorepo: Shared React components for consistency across platforms.
- Confidence-Based HITL: Scoring and smart triggers for human review.
- Three Deployment Profiles: Development (local), Staging (cost-optimized), Production (full HA).
- Scenario-Based Testing: For multi-agent interactions with LangSmith evaluation.
- Architectural Decision Records: Documenting key decisions and runbooks.
- Gradual LLM Integration: With evaluation criteria for model selection.
- High Performance: Microsecond-level latency for trading operations
- IDE-Integrated Development: Kilo Code extension for VS Code workflows.
- Scalable: Horizontal scaling across multiple nodes.
- User-Friendly: Intelligent guidance for non-technical users via proactive AI recommendations.
- Resilient: Fault-tolerant with automatic failover.
- Secure: Enterprise-grade security with zero-trust architecture.
- Observable: Comprehensive monitoring and alerting.

**Architecture Principles**

- **Microservices Architecture**
  - Service Decomposition: Each business capability is a separate service
  - Independent Deployment: Services can be deployed independently
  - Technology Diversity: Services can use different technologies
  - Fault Isolation: Failure in one service doesn't affect others
  - User-Centric Design: Proactive guidance and context-aware suggestions to enhance usability.
  - Automated Self-Healing: Microservices are designed with automated self-healing mechanisms to detect and restore normal functionality for faulty components, minimising downtime and preventing cascading failures.
- **Event-Driven Architecture**
  - Asynchronous Communication: Services communicate via events
  - Event Sourcing: All state changes are captured as events
  - CQRS: Command Query Responsibility Segregation
  - Event Streaming: Real-time event processing
- **Cloud-Native Design**
  - Container-First: All services are containerised
  - Kubernetes Native: Designed for Kubernetes orchestration
  - 12-Factor App: Follows 12-factor application principles
  - Infrastructure as Code: All infrastructure is code-defined
- **API-First Design**
  - RESTful APIs: Standard REST interfaces
  - GraphQL: Flexible query interface
  - WebSocket: Real-time communication
  - gRPC: High-performance inter-service communication
- **Dual Infrastructure:**
  - Dedicated ATS resources (Kafka/DBs/namespace) separate from shared multi-agent infrastructure to prevent contention.
  - Resource pools for non-ATS infrastructure.
  - No shared topics to prevent contention.
- **State-Managed Coordination:** LangGraph state machines for agent workflows and context preservation.
- **Resilient Error Handling:** Health checks, shadow mode, and rollback for fault tolerance.
- **Comprehensive Security:** Zero-trust with data isolation, audit logging, and SOC 2 compliance.
- **Advanced Observability:** Agent-specific metrics and distributed tracing.
- **Consolidated Frontend:** Monorepo with shared React components.
- **Intelligent HITL:** Confidence scoring and automated human review triggers.
- **Cost-Optimized Profiles:** Three deployment profiles for development, staging, and production.
- **Robust Testing:** Scenario-based testing with LangSmith for multi-agent validation.
- **Documented Decisions:** ADRs and runbooks for maintainability.
- **Systematic LLM Integration:** Gradual addition with performance evaluation.

**Core Services and Capabilities**

- **Trading Engine**
  - System supports multiple asset classes (stocks, ETFs, futures, options, forex, and crypto).
  - Purpose: Execute trading strategies and manage orders
  - Technology: Python/Rust for performance-critical paths
  - Key Features:
    - Order routing and execution
    - Strategy execution
    - Position management
    - Trade settlement
    - Paper and Live Trading Modes: Provides seamless integration with broker accounts (starting with Interactive Brokers) for both paper and live trading, with the ability to switch between modes within the user interface.
    - Custom Technical Analysis:
      - Volume-Weighted Indicators: The system includes a comprehensive suite of custom-developed, volume-weighted technical indicators (e.g., VW SMA, VW EMA, VW MACD, VW MFI) and market analysis metrics (e.g., Normalised ATR, Choppy Market Index, Buy/Sell Easier Day) built with TA-Lib and NumPy. These are fully integrated into the NautilusTrader engine for use in strategy development and analysis.
- **Configure Paper and Live Trading**
  - **Action**: Set up **NautilusTrader** for integration with Interactive Brokers.
  - **Details**:
    - Connect to both paper trading and live trading accounts via Interactive Brokers.
    - Implement seamless switching between paper and live modes within the interface.
    - Ensure compliance with broker-specific requirements and regulations.
  - **Purpose**: Enables users to test strategies in a risk-free paper trading environment before transitioning to live trading.
  - **Paper Trading**: A key objective of Phase 4 is to connect the entire integrated system to a paper trading account. The integration plan for this phase explicitly includes configuring NautilusTrader engine's pre-built Interactive Brokers integration to connect to a paper trading account.
  - **Live Trading**: Phase 4 also introduces live trading capabilities. The plan includes enabling live trading in the NautilusTrader engine, expanding the API to manage live trading operations, and enabling live trading data feeds. The end goal of this phase is for a user to execute and monitor trades in a live trading account through the custom web application.
- **Portfolio Manager**
  - Purpose: Manage portfolios and asset allocation
  - Technology: Python with NumPy/Pandas
  - Key Features:
    - Portfolio optimisation
    - Asset allocation
    - Performance attribution
    - Rebalancing
- **Risk Manager**
  - Purpose: Monitor and control trading risks
  - Technology: Python with real-time processing
  - Key Features:
    - Real-time risk monitoring
    - VaR calculations
    - Exposure limits
    - Stress testing
  - Real-time Risk Dashboard: Visualises live risk metrics in the Next.js frontend.
- **Market Data Service**
  - Purpose: Collect, process, and distribute market data
  - Technology: Python/Go for high throughput
  - Key Features:
    - Real-time data feeds
    - Historical data storage
    - Data normalisation
    - Market data distribution
    - Multi-Source Data Feeds with Fallback: Implements a multi-source data feed strategy to ensure uninterrupted data availability. The system uses a primary source with a cascade of fallback providers for each asset class, managed automatically.
    - Asset-Class Specific Fallback Chains: The fallback mechanism is configured per asset class (e.g., Stocks, Forex, Crypto) to use the most relevant data providers.
- **Configure Data Feed and Fallback Mechanism**
  - **Action**: Implement a multi-source data feed with fallback:
    - **Primary**: Yahoo Finance.
    - **Fallbacks**: Alpha Vantage, Finnhub, Investing.com, CME Group, Twelve Data, Polygon, Barchart, SpiderRock, TradingCharts, Oanda.
  - **Details**: Use Kafka to stream data, with logic to switch sources on failure.
  - **Purpose**: Ensures uninterrupted data availability.
  - **Trading Instruments:** The system supports a wide range of asset classes to cater to diverse trading needs.
    - Stocks & ETFs (global equities and exchange-traded funds).
    - Stock Futures & Index Futures (e.g., E-mini S&P 500, Nasdaq-100).
    - Stock Options & Index Options (e.g., calls, puts on equities and indices).
    - Forex, Forex Futures, & Forex Options (e.g., EUR/USD, G10 currencies).
    - Commodities, Commodity Futures, & Commodity Options (e.g., crude oil, gold, corn).
    - Cryptocurrency, Cryptocurrency Futures, & Cryptocurrency Options (e.g., Bitcoin, Ethereum).
  - **Data Sources for Live Trading**:
    - Subscribe to Interactive Brokers' real-time market data and historical data once paper trading is validated.
  - **Historical Data**:
    - Use free sources for paper trading and
    - Interactive Brokers for live trading.
  - **Free Data Sources for Paper Trading**:
    - **Stocks & ETFs**
      - Yahoo Finance: Free historical and delayed data for global equities and ETFs.
      - Interactive Brokers
      - Alpha Vantage: Free APIs for real-time and historical data, including fundamentals and technical indicators.
      - Finnhub: Free-tier APIs for real-time stock prices and company fundamentals.
      - Twelve Data
      - Polygon.io
    - **Stock Futures & Index Futures**
      - Yahoo Finance: Free historical and delayed data for global equities and ETFs.
      - Interactive Brokers
      - Investing.com: Free real-time/delayed quotes for global index futures (e.g., S&P 500, Nikkei 225).
      - CME Group: Free delayed data for equity index futures (e.g., E-mini S&P 500).
      - Barchart: Delayed futures prices for indices like Dow Jones and S&P 500.
    - **Stock Options & Index Options**
      - Yahoo Finance: Free historical and delayed data for global equities and ETFs.
      - Interactive Brokers
      - Cboe Daily Market Statistics: Free delayed summary data for options trading volumes.
      - SpiderRock: Free delayed options data via APIs (e.g., OPRA feeds).
    - **Forex, Forex Futures, & Forex Options**
      - Yahoo Finance: Free historical and delayed data for global equities and ETFs.
      - Interactive Brokers
      - Oanda
      - CME Group FX Data: Delayed data for G10 and emerging market forex futures.
      - dxFeed: Multi-contributor forex data (real-time/delayed).
    - **Commodity, Commodity Futures, & Commodity Options**
      - Yahoo Finance: Free historical and delayed data for global equities and ETFs.
      - Interactive Brokers
      - TradingCharts: Free delayed quotes for commodity futures (e.g., crude oil, gold).
      - CME Group: Delayed data for commodities like oil and agricultural futures.
    - **Cryptocurrency, Cryptocurrency Futures, & Cryptocurrency Options**
      - Interactive Brokers
      - Alpha Vantage: Free crypto data APIs for Bitcoin, Ethereum, etc.
      - Coinbase
      - Binance India
  - **Data Feed Fallback Mechanism**:
    - Data retrieval follows this order: Yahoo Finance → Alpha Vantage → Finnhub → Investing.com → CME Group → Twelve Data → Polygon → Barchart → SpiderRock → TradingCharts → Oanda.
    - If one source fails, the system automatically switches to the next. This fallback mechanism should be created as per the asset class.
  - **Options Data Requirements**
    - Historical options chain data (min 5 years depth)
    - Real-time implied volatility surfaces
    - Dividend forecast integration
  - **Test the Core Engine:** Run a simple, pre-built algorithm from the NautilusTrader library to validate that the entire pipeline is working: the engine can fetch data, run a backtest, and generate results.
- **Order Management System (OMS)**
  - Connects to various brokers, starting with Interactive Brokers, with basic order types (Market, Limit) as well as advanced and algorithmic order types (VWAP, TWAP).
  - FIX Gateway for institutional connectivity.
  - Purpose: Manage order lifecycle and execution
  - Technology: Python with low-latency optimisations
  - Key Features:
    - Order validation
    - Execution management
    - Fill processing
    - Compliance checks
- **Market Scanner Service**
  - **Purpose**: To provide real-time market scanning across a large universe of symbols based on user-defined criteria.
  - **Technology**: Python/Go for high-throughput data processing.
  - **Key Features**:
    - Consumes real-time data streams from Kafka.
    - Applies custom filters using technical indicators (e.g., TA-Lib).
    - Streams filtered results to a dedicated, high-performance UI grid.
- **AI-Powered Strategy Development:** Users can develop strategies through multiple interfaces:
  - **No-Code Strategy Builder:**
    - A visual drag-and-drop interface via Blockly.
    - It is designed to generate clean, human-readable Python code, creating a powerful learning pathway for users to transition from visual design to programmatic customisation.
  - **AI-Assisted Development & Debugging Agent:** Assists with Python code for strategies and integrations.
  - **Agentic AI Assistant:** Natural language commands for trading, research, and development assistance.
  - **Python Studio:** Traditional Python-based coding environment.
- **Agentic AI Assistant**
  - Core user-interaction model via a Chatbot.
  - Uses an Agentic **Retrieval-Augmented Generation (RAG)** pipeline to process and query user-uploaded documents.
  - Composed of a collaborative network of specialised agents (Analyst, Researcher, Risk Manager, Compliance, etc.). **All inter-agent communication will occur asynchronously via the Apache Kafka event bus.** This ensures agents are fully decoupled, enables flexible, one-to-many information flows, and creates a complete, auditable log of the AI's reasoning process.
  - Users can ask the AI to run a backtest, get portfolio status, or even place live trades.
  - **LLM-Driven Iterative Strategy Refinement:** Employs AI agents in a continuous feedback loop to analyse strategy performance, identify weaknesses, and autonomously generate optimised code, enabling full-lifecycle strategy improvement.
  - **AI Context Management with MCPs:** Utilises Model Context Protocols (MCPs) with LangChain and LangGraph to maintain conversation history and context across multiple user interactions, ensuring the AI assistant operates efficiently.
    - **Action**: Implement Model Context Protocols (MCPs) non-invasively to manage AI workflows and context, using external wrappers and clients for servers like Context7, SequentialThinking, Memory, Mem0, ByteRover / Cipher, and Chrome Dev Tools.
    - **Details**:
      - Use **LangChain** and **LangGraph** unmodified via pip, with external configurations to:
        - Maintain conversation history and context across multiple user interactions.
        - Define workflows for task execution (e.g., query → retrieval → response) via graph definitions.
      - Integrate MCP servers through lightweight clients (e.g., MCP Python SDK) and wrappers, avoiding direct modifications to repositories like Archon.
      - Plan for optional integrations in future phases:
        - **Hugging Face Transformers** for advanced NLP tasks via external calls.
        - **PyTorch** for custom model training or fine-tuning through wrappers.
      - Test context retention with multi-turn conversations (e.g., "Run a backtest" followed by "Explain the results") using external adapters.
    - **Purpose**: Ensures the AI assistant operates efficiently, retains context, and scales for future enhancements without forking underlying repositories.
  - **Defined AI Workflows:** Employs LangGraph to define and manage stateful workflows for complex, multi-step task execution (e.g., query → data retrieval → analysis → response).
- **Intelligent User Guidance System:**
  - This system will proactively assist non-technical users by:
    - Recommending the most appropriate tools and features based on the user's current context, goals, and experience level.
    - Predicting and suggesting the next most probable steps after a user has invoked a tool, providing a clear "next best action" to maintain workflow momentum and ensure successful outcomes.
  - This component must be deeply integrated into the platform's multi-agent architecture, leveraging the Apache Kafka event bus, MCPs (Model Context Protocols), and the existing RAG pipeline to function as a seamless, context-aware guide. It should draw from a structured Tool Taxonomy cataloging all platform capabilities, ensuring recommendations are grounded in the system's features (e.g., NautilusTrader for trading, VectorBT for backtesting, Plotly Dash for visualisations, Blockly for no-code strategies, Riskfolio-Lib for optimisation, Market Scanner for real-time scanning).
  - **Core Functionality:**
    - **Tool Recommendation Engine:**
      - **Input:** Analyse the user's natural language query, current session activity (e.g., recent tools used), historical interactions (stored in PostgreSQL), and stated or inferred goals (e.g., "I want to find undervalued stocks," "Why did my strategy lose money yesterday?"). Infer user experience level from profile data or session patterns (Novice User: prefers no-code; Advanced User: prefers Python Studio).
      - **Processing:** Match the user's intent against a structured "Tool Taxonomy" (see below) using NLP (Transformers/PyTorch) and similarity search (Qdrant/pgvector). Rank recommendations by relevance score (cosine similarity >0.7), user level, and historical success rates. Limit to 2-3 suggestions to avoid overwhelming users.
      - **Output:** Provide a ranked list of 2-3 recommended tools or features. For each, include:
        - Brief, non-technical explanation of why it's suggested (e.g., "Based on your goal of finding momentum stocks, I recommend the Market Scanner-it uses real-time Kafka feeds to identify assets with high volume and price surges.").
        - Confidence score (0-1).
        - Quick-start snippet or example command (e.g., "Type: 'Scan for stocks with RSI >70'").
      - **Edge Cases:** Handle ambiguous queries by asking clarifying questions; fallback to popular tools for novices.
    - **Next-Step Predictor:**
      - **Input:** Detect tool completion via Kafka events (e.g., backtest.completed, chart.rendered, strategy.saved). Use session state (MCPs) and historical user data (from ClickHouse analytics).
      - **Processing:** Employ a state machine (e.g., finite-state machine in Python) combined with ML-based prediction (e.g., sequence modeling with LSTM) trained on anonymised user workflows. Factor in user level (novice: suggest simple steps; advanced: complex optimisations). Use RAG to ground suggestions in documentation.
      - **Output:** Proactively suggest 1-2 next steps with:
        - Action description (e.g., "Next, deploy this strategy to a paper account.").
        - Rationale (e.g., "This validates real-market performance without risk, as 85% of users do after backtesting.").
        - Confidence score and optional alternatives.
      - **Edge Cases:** If no clear next step, suggest exploration (e.g., "Explore the Strategy Marketplace for similar ideas.").
  - **Architectural Integration:**
    - **Event-Driven Communication:** Broadcast recommendations as Kafka events (e.g., ai.guidance.recommendation.generated, ai.guidance.next_step.suggested) with structured payloads (JSON schemas in Schema Registry). This allows UI to display suggestions, analytics to track usage, and other agents (e.g., OpenHands) to incorporate guidance.
    - **MCP (Model Context Protocol) Integration:** Register as an MCP tool/server with Archon, enabling other agents to query for guidance (e.g., Kilo Code requesting next DevOps step). Use MCPs to maintain user context (e.g., session goals, past suggestions).
    - **RAG Integration:** Query RAGFlow-powered knowledge base (Qdrant/pgvector) for platform docs to ensure suggestions are accurate and up-to-date.
    - **UI Integration:** Display suggestions as non-intrusive cards/prompts in Lobe Chat and Next.js UI (e.g., sidebar or popover). Make clickable to auto-invoke tools. Support voice delivery for AR/voice trading.
    - **Feedback Loop:** Log user interactions with suggestions (e.g., accepted/ignored) to Kafka for ML retraining, improving accuracy over time.
  - **Tool Taxonomy & Knowledge Base:**
    - Create/maintain a tool_taxonomy.json file cataloging all platform features:
      - tool_id: Unique identifier (e.g., market_scanner).
      - name: Human-readable name.
      - description: Brief, non-technical overview.
      - user_level: Enum (novice, intermediate, advanced).
      - inputs: Required parameters (e.g., symbols, timeframes).
      - outputs: Expected results (e.g., scan results, charts).
      - common_next_steps: Array of probable follow-ups (e.g., after backtest: deploy strategy).
      - keywords: For intent matching (e.g., "momentum", "scan").
    - Taxonomy must cover: NautilusTrader strategies, VectorBT backtesting, Plotly Dash charts, Blockly builder, Riskfolio-Lib optimiser, Market Scanner, etc.
    - Store in Git for version control; ingest into RAG for dynamic querying.
  - **Experience Level Adaptation:**
    - Infer level from user profile (self-reported or derived from usage history).
    - Novice User: Suggest simple tools (e.g., Blockly over Python Studio) with step-by-step guidance.
    - Advanced User: Suggest complex tools (e.g., FinRL) with minimal explanation.
  - **Implementation Tasks:**
    - **Task 1: Foundation (Backend)**
      - **Define Tool Taxonomy:** Create the initial tool_taxonomy.json schema and populate it with data for the core components listed in the architecture document (NautilusTrader, VectorBT, Blockly, Risk Manager, Market Scanner, Charting modules, etc.).
      - **Develop Recommendation Service:** Build a new microservice, guidance_service, in Python. It should:
        - Expose a REST/gRPC endpoint (e.g., POST /recommend) that accepts a context payload (user query, session history).
        - Implement the logic to match context against the tool taxonomy.
        - Publish its recommendations to a dedicated Kafka topic.
      - **Develop Prediction Service:** Within the same service, create logic for the next-step predictor. It should listen for Kafka events signalling tool completion (e.g., strategy.backtest.completed) and generate prediction events.
    - **Task 2: Integration & Intelligence**
      - **Integrate with Archon MCP:** Register the guidance_service as a tool with the Archon MCP server. Define protocols for other agents to request recommendations (get_tool_recommendation).
      - **Connect to RAG:** Implement a function within the service that queries the RAG pipeline (via its API) to fetch relevant documentation snippets to enrich recommendation rationales.
      - **Implement Context Gathering:** Add functionality to the service to query other microservices (via Kafka or gRPC) for richer user context, such as recent portfolio performance or active strategies.
    - **Task 3: Frontend & Presentation**
      - **UI Component for Lobe Chat/Next.js:** Develop a React component that subscribes to the relevant Kafka topics (via a WebSocket connection) and displays recommendations and predictions as interactive suggestions within the user interface.
      - **Testing & Validation:** Create unit and integration tests. Use historical user session data (or simulated data) to validate that recommendations are relevant and accurate. Test the full flow: user query -> AI Assistant -> Guidance Service -> Kafka -> UI display.
  - **Testing & Validation:**
    - Unit Tests: >90% coverage for recommendation engine and predictor (Pytest).
    - Integration Tests: Verify Kafka events, MCP calls, and RAG accuracy.
    - End-to-End Tests: Simulate user sessions (e.g., novice querying "find good stocks" → recommend Scanner → suggest backtest).
    - Accuracy Metrics: >85% relevant recommendations; measure via user feedback simulation.
    - Edge Cases: Handle ambiguous queries, failed tool invocations, or novice using advanced features.
  - **Deliverables:**
    - A fully implemented Intelligent User Guidance System as a microservice.
    - A complete and extendable  tool_taxonomy.json with all platform tools.
    - MCP integration for inter-agent communication.
    - Real-time UI components displaying suggestions.
    - Updated AI Assistant with guidance integration.
    - Comprehensive Documentation: User guide for suggestions, developer guide for extending taxonomy.
    - Test suite with 100+ cases covering all scenarios.
  - **Success Metrics:**
    - **Relevance:** >80% of tool recommendations are deemed "helpful" in user testing.
    - **Adoption:** >60% of suggested "next steps" are clicked on or acted upon by users.
    - **Performance:** The service responds with recommendations in under 500ms.
- **Integration of AI Assistants:** LobeChat, which is the user-facing frontend for conversational AI, integrates with OpenHands (backend agent for autonomous coding), Kilo Code (VS Code extension for workflows), RAGFlow (RAG pipeline for document-based queries), the Agentic AI Assistant (core brain for trading tasks), and the Intelligent User Guidance System (proactive recommendations/next-steps).
  - Workflow:
    - LobeChat handles UI/voice input, publishes to Kafka
    - Claude Code/OpenHands/Kilo Code process coding tasks via MCPs
    - RAGFlow grounds responses
    - AI Assistant orchestrates
    - Intelligent Guidance System suggests tools/steps
  - This has retail usability (voice/multimodal chat) and pro features (code snippets in VS Code).
  - Note that for paper trading, this system will use open-source/free resources (e.g., LobeChat with local LLMs like LLaMA, etc.).
- **Enterprise Security and Risk Management:** Platform is built with,
  - **Zero-Trust architecture**
  - Real-time risk hub for pre-trade checks and account-level circuit breakers.
  - Role-based access control (**RBAC**)
  - Immutable audit trails for compliance in **Apache Iceberg**.
  - Feature Flags (e.g., **Unleash**) for dynamic toggling of strategies and kill-switches.
  - Static Application Security Testing (SAST) with **Bandit**, automatically scanning Python code for common security vulnerabilities.
  - User and Entity Behaviour Analytics **(UEBA)**
  - Threat Modelling by Design
  - Formalised Backup Strategy
  - SCIM/SSO/OIDC: Enhancements to Keycloak for automated user provisioning (SCIM v2.0) and SSO (OAuth 2.0/OIDC), supporting enterprise IdPs like Okta/Azure AD.
  - Audit Logs: Complete, immutable logging via Apache Iceberg for every interaction (e.g., logins, trades, AI queries).
  - SOC 2 Readiness: Architecture compliant with SOC 2 Type 2 (Security, Availability, etc.), including controls for CC6-CC9, with automated evidence collection.
  - Builds on zero-trust for institutional compliance.
- **Incorporate Custom Volume-Weighted Indicators**
  - **Action**: Extend the technical indicator framework with volume-weighted calculations using **TA-Lib** and **NumPy**.
  - **Details**:
    - Develop custom volume-weighted technical indicators (e.g., VW SMA, VW EMA, VW MACD) using TA-Lib/ta-lib-python (primary wrapper) & Bukosabino/ta (secondary wrapper) and NumPy, as specified below:
      - Beta vis-à-vis Market Index,
      - Auto Correlation,
      - Historical Annual Volatility,
      - Intraday Annual Volatility,
      - 55 Day VW SMA of Open (Entry),
      - 13 Day VW SMA of Open (Entry),
      - 5 Day VW SMA of High (Exit),
      - 5 Day VW SMA of Low (Exit),
      - 34 Day VW SMA of Open (Entry),
      - 13 Day VW SMA of High (Exit),
      - 13 Day VW SMA of Low (Exit),
      - 13 Day VW EMA of Open,
      - 5 Day VW EMA of HLC (High, Low, Close) Average (Trend Finder),
      - VW MACD of HLC Average (12 Day, 26 Day, 9 Day),
      - VW MACD Histogram of HLC Average,
      - 14 Day VW MFI of HLC Average,
      - 34 Day VW SMA of MFI (14) of HLC Average (Entry),
      - 21 Day VW SMA of MFI (14) of HLC Average (Exit),
      - Market Normalisation with 21 Day VW ATR for Positional Trades \[N\],
      - Rupee Volatility / Risk \[N x Lot Size\], (Change this to Dollar Volatility for US SEs and to Pound Sterling for LSE)
      - Contract Risk (Units) \[2N\],
      - Max. Lots that can be Traded with a Unit of x Rs. \[No. of Lots\],
      - 21 Day Average True Range Percent,

{

<https://www.thebalance.com/how-average-true-range-atr-can-improve-trading-4154923>.

When to Use Normal ATR : On the contrary, the traditional non-normalised ATR is preferred as input in risk management or position management decisions, such as the following:

\- Position size (typically calculated as your risk budget / current volatility as ATR)

\- Stop loss (typically the distance of stop loss price from entry price or current price is a multiple of ATR)

\- Profit target (same logic as stop loss, just the other direction)

\- In general, traditional non-normalised ATR is better when you are interested in absolute dollar amounts rather than percentages, which is usually when the decision relates to your particular trading capital.\]

\[Average True Range (ATR) is a very useful measure of volatility, but it has downsides. Because it is derived from range (or to be precise, true range) and expressed as absolute dollar value, it is not directly comparable across securities and over time.

For example, a stock trading around 10 with ATR of 0.5 is actually more volatile than a stock trading around 200 with a much greater ATR of 2. The Average True Range Percent / ATRP Indicator is a variation of Welles Wilder Average True Range (ATR), which featured in his 1978 book, "New Concepts in Technical Trading Systems."

It is important to remember that the indicator does not try and predict the direction of price, instead it only tries to define the current volatility in the market. Also, it tries to define current volatility in such a way that it is comparable across all markets, which is the main difference from the traditional ATR. ATR measures volatility at an absolute level, meaning lower priced stock will have lower ATR values than higher price stocks. ATRP displays the indicator as a percentage, to allow for securities trading at different prices per share to be compared.

How this indicator works,

\- ATRP is used to measure volatility just as the Average True Range (ATR) indicator is.

\- ATRP allows securities to be compared, where ATR does not.

Calculation ATRP = (Average True Range / Close) \* 100

When to Use ATRP or Normalised ATR (<https://www.macroption.com/normalised-atr/>):

You should use ATRP (Normalised ATR) instead of the traditional, absolute dollar ATR particularly in these situations:

\- When using ATR for stock screening (to decide which stocks or securities currently have the right volatility for your strategy or trading style).

\- When using ATR as strategy filter (to decide whether the volatility is high enough or low enough to take a signal from a trading strategy, or to "turn on/off" strategies based on market volatility regime).

\- When using ATR to study seasonality or volatility patterns over long periods of time.

\- In general, Normalised ATR is better than traditional ATR in situations which involve comparing different securities or different periods of time.\]

}

- - - 1. Market Normalisation with 8 Day VW ATR for Intraday Trades \[N\],
            - Rupee Volatility / Risk \[N x Lot Size\], (Change this to Dollar Volatility for US SEs and to Pound Sterling for LSE)
            - Contract Risk (Units) \[0.75N\],
            - Max. Lots that can be Traded with a Unit of x Rs. \[No. of Lots\],
            - 8 Day Average True Range Percent,
            - Strength / Weakness (Based on 21 Day Avg. HLC & ATR) for Positional,

\[Page 29 - Turtle Rules by Curtis Faith:-

Buy Strength & Sell Weakness:

\- If all the signals come together, always Buy the Strongest Markets and Sell the Weakest Markets in a Group.

\- Subtract the Average HLC Price of 21 Days from the Last Traded Price / Close and then divide this figure by the VW ATR of 21 Days. \[LTP - Avg. HLC(21)\] / ATR(21)

\- The above calculation 'Normalises' the Price across the Markets.

\- The Strongest Markets have the Highest values, while the Weakest Markets have the Lowest values.\]

- - - 1. Strength / Weakness (Based on 8 Day Avg. HLC & ATR) for Intraday,
            - High Low Range Average for ORB,
            - 8 Day SMA Average % Change,
            - 13 Day SMA Average % Change,
            - 21 Day SMA Average % Change,
            - Buy Easier Day and Sell Easier Day,
            - 21 Day Choppy Market Index,
            - 21 Day Market Mode (Trending / Choppy),
            - 8 Day Choppy Market Index,
            - 8 Day Market Mode (Trending / Choppy)
      - Use TA-Lib/ta-lib-python (primary wrapper) & Bukosabino/ta's (secondary wrapper) framework to extend existing indicators with volume weighting.
      - Leverage NumPy for efficient calculations of volume-weighted averages.
      - Integrate these into **NautilusTrader's** strategy engine for use in trading logic.
      - Verify accuracy with historical data and unit tests.
    - **Purpose**: Enhances trading strategies by incorporating volume data into technical analysis for more informed decisions.

**The "Best-of-Breed" Integration Strategy**

This strategy selects top open-source projects for each component, interconnected via an event-driven Kafka architecture, ensuring scalability, flexibility, and high performance for professional trading.

**Core Technology Stack**

The system is built on a modern, open-source technology stack. This integration strategy provides a strong foundation, but significant custom development is required to meet all enterprise-grade requirements.

- **Core Trading Engine: NautilusTrader**
  - **Role:** The undisputed choice for the institutional-grade engine handling backtesting, live trading, data management, and multi-asset support. It is a high-performance, production-grade algorithmic trading platform, providing quantitative traders with the ability to backtest portfolios of automated trading strategies on historical data with an event-driven engine, and also deploy those same strategies live, with no code changes. The platform is _AI-first_, designed to develop and deploy algorithmic trading strategies within a highly performant and robust Python-native environment. This helps to address the parity challenge of keeping the Python research/backtest environment consistent with the production live trading environment. It's design, architecture, and implementation philosophy prioritises software correctness and safety at the highest level, with the aim of supporting Python-native, mission-critical, trading system backtesting and live deployment workloads. The platform is also universal, and asset-class-agnostic - with any REST API or WebSocket feed able to be integrated via modular adapters. It supports high-frequency trading across a wide range of asset classes and instrument types including FX, Equities, Futures, Options, Crypto and Betting, enabling seamless operations across multiple venues simultaneously. The system integrates with TA-Lib/ta-lib-python (primary wrapper) & Bukosabino/ta (secondary wrapper) for indicators and OpenBB for data, enhancing the system's strategy validation capabilities.
  - **Rationale:** NautilusTrader provides superior performance for high-frequency trading, custom data integration via parquet, and an AI-first design, aligning with our Python-centric workflow. This establishes a powerful, two-stage research and validation pipeline: **VectorBT** will be used for broad, high-speed, vectorised research to identify promising strategies, while **NautilusTrader** will serve as the sole, high-fidelity, event-driven engine for realistic validation and live deployment. This approach eliminates architectural redundancy and solves the critical backtest-to-live parity challenge.
    - <https://github.com/nautechsystems/nautilus_trader>
    - <https://github.com/nautechsystems/nautilus_ibapi>
- **Data Pipeline**: While libraries like Unstructured.io and databases like **Qdrant** and **PostgreSQL** with **pgvector** will be used, the pipelines for data ingestion, resiliency, and fusion are custom logic that will be build.
  - **Apache Kafka:**
    - An open-source distributed event streaming platform used by thousands of companies for high-performance data pipelines, streaming analytics, data integration, and mission-critical applications.
    - Central event bus for real-time data, order flow, market ticks, AI decisions, and system events.
    - Decouples all services, provides data replayability for robust testing, and scales to handle high-frequency data streams for professional traders.
    - **Design Principle: Hierarchical Topic Architecture**
      - To ensure long-term scalability and simplify data governance, the system will implement a structured, hierarchical naming convention for all Kafka topics (e.g., domain.action.entity.source.symbol).
      - Consumer logic will be built to leverage wildcard subscriptions, allowing services to subscribe to broad or specific data streams efficiently (e.g., marketdata.tick.crypto.spot.binance.\*), which simplifies service configuration and scales more effectively than a flat topic structure.
    - <https://github.com/apache/kafka>
  - **Schema Registry:**
    - Ensures data consistency across services.
    - It provides a serving layer for your metadata.
    - It stores a versioned history of all schemas based on a specified subject name strategy, provides multiple compatibility settings and allows evolution of schemas according to the configured compatibility settings and expanded support for these schema types.
    - It provides serialisers that plug into Apache Kafka clients that handle schema storage and retrieval for Kafka messages that are sent in any of the supported formats.
    - <https://github.com/confluentinc/schema-registry>
- **Infrastructure**
  - **Kubernetes:**
    - Kubernetes, also known as K8s, is an open source system for managing [containerised applications](https://kubernetes.io/docs/concepts/overview/what-is-kubernetes/) across multiple hosts.
    - It provides basic mechanisms for the deployment, maintenance, and scaling of applications.
    - It builds upon a decade and a half of experience at Google running production workloads at scale using a system called [Borg](https://research.google.com/pubs/pub43438.html?authuser=1), combined with best-of-breed ideas and practices from the community.
    - <https://github.com/kubernetes/kubernetes>
  - **Docker:**
    - Docker is an open platform for developing, shipping, and running applications.
    - It enables you to separate your applications from your infrastructure so you can deliver software quickly.
    - With Docker, you can manage your infrastructure in the same ways you manage your applications.
    - By taking advantage of Docker's methodologies for shipping, testing, and deploying code, you can significantly reduce the delay between writing code and running it in production.
    - <https://github.com/docker-library/docker>
  - **Istio:**
    - Istio is an open-source service mesh that layers transparently onto existing distributed applications.
    - Istio's powerful features provide a uniform and more efficient way to secure, connect, and monitor services.
    - It is the path to load balancing, service-to-service authentication, and monitoring - with few or no service code changes.
    - It is an open platform for providing a uniform way to [integrate microservices](https://istio.io/latest/docs/examples/microservices-istio/), manage [traffic flow](https://istio.io/latest/docs/concepts/traffic-management/) across microservices, enforce policies and aggregate telemetry data. Istio's control plane provides an abstraction layer over the underlying cluster management platform, such as Kubernetes.
    - Istio is composed of these components:
      - **Envoy:** Sidecar proxies per microservice to handle ingress/egress traffic between services in the cluster and from a service to external services. The proxies form a _secure microservice mesh_ providing a rich set of functions like discovery, rich layer-7 routing, circuit breakers, policy enforcement and telemetry recording/reporting functions.
      - **Note:** The service mesh is not an overlay network. It simplifies and enhances how microservices in an application talk to each other over the network provided by the underlying platform.
      - **Istiod:** The Istio control plane. It provides service discovery, configuration and certificate management. It consists of the following sub-components:
        - **Pilot:** Responsible for configuring the proxies at runtime.
        - **Citadel:** Responsible for certificate issuance and rotation.
        - **Galley:** Responsible for validating, ingesting, aggregating, transforming and distributing config within Istio.
      - **Operator:** The component provides user friendly options to operate the Istio service mesh.
    - <https://github.com/istio/istio>
  - **NGINX:**
    - NGINX (pronounced "engine x" or "en-jin-eks") is the world's most popular Web Server, high performance Load Balancer, Reverse Proxy, API Gateway and Content Cache.
    - NGINX is comprised of individual modules, each extending core functionality by providing additional, configurable features.
    - NGINX modules can be built and distributed as static or dynamic modules.
    - Static modules are defined at build-time, compiled, and distributed in the resulting binaries.
    - <https://github.com/nginx/nginx>
  - **Helm:**
    - Package management
    - Helm is a tool for managing Charts. Charts are packages of pre-configured Kubernetes resources.
    - Use Helm to:
      - Find and use [popular software packaged as Helm Charts](https://artifacthub.io/packages/search?kind=0) to run in Kubernetes
      - Share your own applications as Helm Charts
      - Create reproducible builds of your Kubernetes applications
      - Intelligently manage your Kubernetes manifest files
      - Manage releases of Helm packages
    - It is a tool that streamlines installing and managing Kubernetes applications. Think of it like apt/yum/homebrew for Kubernetes.
    - Helm renders your templates and communicates with the Kubernetes API.
    - It runs on your laptop, CI/CD, or wherever you want it to run.
    - Charts are Helm packages that contain at least two things:
      - A description of the package (Chart.yaml)
      - One or more templates, which contain Kubernetes manifest files
    - Charts can be stored on disk, or fetched from remote chart repositories (like Debian or RedHat packages).
    - <https://github.com/helm/helm>
- **Programming Languages**
  - **Python:** Primary language for business logic
  - **Rust:** Performance-critical components
  - **TypeScript:** Frontend and Node.js services
  - **Go:** Infrastructure and tooling
  - **SQL:** Database queries and procedures
- **Agentic AI Assistant: LangChain, LangGraph, AI Knowledge & Context Hub (Archon), TradingAgents, OpenBB, and TA-Lib/ta-lib-python & Bukosabino/ta**
  - **Role:** This combination will form the "brain" of the system.
  - **Rationale:**
    - **LangChain** will serve as the underlying framework for building the Agentic Retrieval-Augmented Generation (Agentic RAG) capabilities, document processing, and the tool integration that powers the agents, as recommended in your features document.
      - <http://github.com/langchain-ai/langchain>
    - **LangGraph** will manage the complex, asynchronous workflows between the AI Agents, Multi Agents, Agentic AI, data, and trading services and act as an Orchestrator.
      - <https://github.com/langchain-ai/langgraph>
    - **AI Knowledge & Context Hub: Archon**
      - **Role:** Serves as the central "command center" and Model Context Protocol (MCP) server for all AI coding and development assistants. It is the shared library, project whiteboard, and task manager for the AI workforce.
      - **Rationale:** Archon provides a persistent, shared "brain" to solve the "amnesia" problem for AI agents. It will ingest and manage the knowledge for all 70+ components of the ATS, allowing agents like OpenHands and Kilo Code to collaborate effectively and perform complex, stateful work with high accuracy. This aligns perfectly with the "Best-of-Breed" philosophy by providing a specialised tool for AI context management and significantly accelerates the development of reliable, system-aware AI-generated code. It allows multiple agents to collaborate and leverage the same information, providing smart search via advanced RAG strategies and real-time updates. This aligns perfectly with the multi-agent architecture.
      - <https://github.com/coleam00/Archon>
    - **TradingAgents** a multi-agent trading framework that mirrors the dynamics of real-world trading firms. By deploying specialised LLM-powered agents: from fundamental analysts, sentiment experts, and technical analysts, to trader, risk management team, the platform collaboratively evaluates market conditions and informs trading decisions. Moreover, these agents engage in dynamic discussions to pinpoint the optimal strategy. It provides a finance-specific foundation of Multi-Agents LLM Financial Trading Framework with specialised agent roles (analyst, researcher, risk manager) that directly map to the system requirements.
      - <https://github.com/TauricResearch/TradingAgents>
    - **OpenBB** Platform offers access to equity, options, crypto, forex, macro economy, fixed income, and more while also offering a broad range of extensions to enhance the user experience according to their needs.
      - <http://github.com/OpenBB-finance/OpenBB>
    - **TA-Lib/ta-lib-python** (primary wrapper) & **Bukosabino/ta** (secondary wrapper) provides a foundation for technical indicators, including custom volume-weighted ones.
      - <https://github.com/TA-Lib/ta-lib-python>
      - <https://github.com/bukosabino/ta>
    - **OpenHands (formerly OpenDevin):** An AI-Assisted Development & Debugging Agent. It is a platform for software development agents powered by AI. It can do anything a human developer can: modify code, run commands, browse the web, call APIs, and even copy code snippets from StackOverflow. It is an AI agent specifically trained to assist with writing, debugging, and optimising Python code for trading strategies and system integrations, tailored to NautilusTrader, VectorBT, and custom APIs. It dramatically speeds up development, reduces bugs, and lowers the barrier to entry for quants who may be less familiar with the specific libraries being used. It transforms the AI from just a strategy generator into a full-fledged development partner.
      - **Features:**
        - Speed up code reviews: Summarise pull requests, incorporate feedback, and push fixes so code reviews are quick and painless.
        - Refactor old code: Decompose monolithic code, refactor tech debt, and automate version bumps without breaking the build.
        - Expand test coverage: Generate tests for new features to elevate code quality and squash hidden bugs.
        - Fix failing pipelines: Fix broken tests without debugging or interrupting others for help.
        - Create prototypes: Turn ideas and concepts into working code you can test with customers.
        - Get to "done" faster: Offload all the engineering toil you don't want to do to OpenHands.
        - Deeply customisable: OpenHands is an open-source core, unlocking customisation for a variety of enterprise use cases.
        - Best in class coding accuracy: OpenHands is a top performer across a variety of software development benchmarks for agents, like SWE-bench.
        - Works where you do: Use OpenHands in your browser, as a CLI, via API, or in tools like GitHub, GitLab, Slack, Jira, and more.
      - <https://github.com/All-Hands-AI/OpenHands>
    - **Kilo Code:** It is an Open Source AI coding assistant for planning, building, and fixing code. They frequently merge features from open-source projects like Roo Code and Cline, while building their own vision.
      - **Features:**
        - Code Generation: Generate code using natural language.
        - Task Automation: Automate repetitive coding tasks.
        - Automated Refactoring: Refactor and improve existing code.
        - MCP Server Marketplace: Easily find and use MCP servers to extend the agent capabilities.
        - Multi-Mode: Assign tasks to an appropriate agent with Orchestrator, Plan with Architect, Code with Coder, and Debug with Debugger, and make your own custom modes.
        - Kilo Code started as a fork of Roo Code, which itself is a fork of Cline. They frequently merge features from these open-source projects and contribute improvements back. Built on these foundations, Kilo Code is independently developed with their own vision for AI coding agents.
        - Kilo Code is a direct fork from Roo Code, and also includes the following features from Cline (and their own features):

System notifications: Get notified when the agent is done with a task.

Easy model connection: batteries included.

Editing previous messages

Assisted commit messages: we write git commit messages for you based on what changed

- - - - <https://github.com/Kilo-Org/kilocode>
        - **Claude Code:** It is an agentic coding tool that lives in the terminal, understands the codebase, and helps the user to code faster by executing routine tasks, explaining complex code, and handling git workflows, all through natural language commands.
        - **A Collaborative, Three-Agent Architecture**
          - The entire AI developer assistant framework will be centred around **Archon**, which will serve as the shared MCP server, providing a unified knowledge base and task management system for both OpenHands and Kilo Code.
          - The key to making this work is to assign specialised, non-overlapping roles to each agent. Based on their documented strengths, we can define a clear hierarchy:
          - **OpenHands: The "Specialist" Code-Level Agent**
            - OpenHands will be the master craftsman for **fine-grained, code-centric tasks**. Its entire domain is the Python code that powers your strategies and services. It excels at tasks requiring deep code understanding.
            - **Responsibilities**:

Writing and debugging

NautilusTrader trading strategies.

Refactoring existing strategy code for optimisation.

Expanding test coverage by writing pytest files.

Fixing bugs within a specific Python file or function.

Assisting with code that integrates with VectorBT, TA-Lib, and OpenBB.

- - - - **Kilo Code: The "General Contractor" Workflow Agent**
                - Kilo Code is an open-source AI coding assistant extension for VS Code IDE, supporting multi-mode operations (Orchestrator for delegating, Architect for planning, Coder for generation, and Debugger for fixes).
                - It has a MCP Server Marketplace for custom tools, integration with Python Studio for strategy development, and alignment with the Agentic AI Assistant (e.g., for code refinement in workflows). This enhances professional usability by providing context-aware suggestions within VS Code.
                - Codename Goose has been replaced with Kilo Code as Kilo Code offers better IDE integration than Goose's CLI focus, while maintaining open-source extensibility.
                - Kilo Code is a VS Code extension, so it requires VS Code to be installed on the user's laptop. It does **not** automatically open VS Code; the user must launch VS Code manually and enable the extension. In the system, Python Studio can be configured as a VS Code-based environment with Kilo Code pre-installed (e.g., via Dockerised VS Code server). Add a placeholder for seamless launch from the web UI (e.g., via VS Code Server).
                - Kilo Code will be the high-level orchestrator for **broad, multi-step, system-level engineering and DevOps workflows**. It excels at tasks that span multiple services, involve infrastructure, and require end-to-end autonomous execution.
                - **Responsibilities**:

**DevOps and Infrastructure Management**: Setting up CI/CD pipelines, configuring Kafka topics, or managing Docker environments.

**Complex Task Automation**: Executing multi-step workflows like "run a backtest, if it succeeds, deploy the strategy to the paper trading environment, and notify me on Slack."

**Context-Aware Tool Routing**: Dynamically discovering and using the right tool for a job, which could include external APIs or even **invoking the OpenHands agent as one of its tools**.

**Data Migrations and Engineering**: Performing tasks like setting up a data pipeline to move historical data into ClickHouse or Apache Iceberg.

- - - - **Revised System Architecture Diagram**
                - The master orchestrator, LangGraph, sits at the center. It receives tasks and delegates them to the appropriate agent. Kilo Code, in turn, can call OpenHands for specialised code modifications.

\`\`\`mermaid

graph TD

subgraph User Interface

A\[&lt;B&gt;Lobe Chat UI&lt;/B&gt;\]

end

subgraph AI Core

B\[LangGraphMaster Orchestrator\]

H\[ArchonKnowledge & Context Hub (MCP Server)\]

C\[Kilo Code Workflow & DevOps Agent\]

D\[OpenHandsSpecialist Code Agent\]

end

subgraph Backend Services

E\[FastAPI Bridge\]

F\[Apache Kafka Bus\]

G\[Other ServicesNautilusTrader, RAGFlow, etc.\]

end

A -->|User Prompt| B

B -->|Routes DevOps/Workflow Tasks| C

B -->|Routes Code-Level Tasks| D

C -->|Connects for Context/Tasks| H

D -->|Connects for Context/Tasks| H

C -->|Executes Commands & API Calls| E

C -->|Interacts with| F

D -->|Modifies Code in Repositories| G

\`\`\`

- - - - **Revised Integration Strategy & Plan**
                - To establish a collaborative AI core where LangGraph orchestrates tasks between Kilo Code (for workflows) and OpenHands (for code), providing a unified experience through the Lobe Chat interface.
                - **Build Strategy**

Deploy the Master Orchestrator (LangGraph):

Set up the core LangGraph application within the /ai_assistant service. This agent will be the single entry point for all AI tasks coming from Lobe Chat.

Its primary job is intent recognition: to analyse the user's prompt and decide which specialised agent (Kilo Code or OpenHands) is best suited for the task.

Register Kilo Code as a Tool:

Integrate Kilo Code as a powerful "tool" that LangGraph can call.

Kilo Code's role will be exposed to LangGraph with a clear description: "Best for multi-step engineering workflows, DevOps, infrastructure tasks, and end-to-end automation."

Configure Kilo Code's MCP (Model Context Protocols) capabilities to connect to the FastAPI bridge, enabling it to interact with all backend services.

Leverage Kilo Code's ability to dynamically load tools via vector search. We will create a "tool library" of custom APIs (e.g., functions to interact with NautilusTrader's backtester) that Kilo Code can discover and use autonomously.

Register OpenHands as a Tool:

Integrate OpenHands as another specialised tool available to LangGraph.

Its role will be described as: "Best for writing, debugging, refactoring, and optimising Python code, especially for trading strategies and data analysis."

- - - - - **Leveraging Kilo Code's Strengths**

This revised plan directly leverages the features you are interested in:

Task Automation & End-to-End Execution: This is Kilo Code's primary role as the "General Contractor," handling complex workflows from start to finish.

DevOps & Context-Aware Routing: Kilo Code is designated for all DevOps tasks, and its ability to route to the correct tool (including other agents like OpenHands) is central to the architecture.

MCP & Custom APIs: Kilo Code will use MCP to connect to the system's core APIs, and we will build a library of custom API tools specifically for it to use.

Dynamic Tool Loading: This powerful feature means we can expand the system's capabilities just by adding new tools to a library, without having to reprogram the agent itself. Kilo Code will find and use them as needed.

- - - - - By implementing this collaborative, two-agent architecture, you are not creating redundancy; you are building a more sophisticated, capable, and specialised AI workforce to power your trading system.
        - **MCP Servers**
          - **Context7:**
            - It pulls up-to-date, version-specific current documentation and code examples for thousands of libraries and frameworks straight from the source and places them directly into the prompt / LLM's context.
            - **Features:**

**Real-time Documentation Access:** Provides AI models with access to current documentation for thousands of libraries and frameworks

**Automatic Library Resolution:** Automatically finds and retrieves relevant documentation based on user queries

**Up-to-date Content:** Always provides the latest documentation from official sources

Write your prompt naturally

Tell the LLM to use context7

Get working code answers

- - - - - <https://github.com/upstash/context7>
          - **SequentialThinking:**
            - It provides a tool for dynamic and reflective problem-solving through a structured thinking process.
            - **Features:**

Break down complex problems into manageable steps

Revise and refine thoughts as understanding deepens

Branch into alternative paths of reasoning

Adjust the total number of thoughts dynamically

Generate and verify solution hypotheses

- - - - - <https://github.com/modelcontextprotocol/servers/tree/main/src/sequentialthinking>
          - **Memory:**
            - It is a basic implementation of persistent memory using a local knowledge graph.
            - This lets the LLM remember information about the user across chats.
            - This is LLM's Short-Term Memory.
            - <https://github.com/modelcontextprotocol/servers/tree/main/src/memory>
          - **Mem0:**
            - It enhances AI assistants and agents with an intelligent memory layer, enabling personalised AI interactions.
            - It provides consistent, context-rich conversations for AI Assistants.
            - It remembers user preferences, adapts to individual needs, and continuously learns over time, which is ideal for customer support chatbots, AI assistants, and autonomous systems.
            - This is LLM's Long-Term Memory.
            - **Features:**

**Multi-Level Memory:** Seamlessly retains User, Session, and Agent state with adaptive personalisation

**Developer-Friendly:** Intuitive API, cross-platform SDKs, and a fully managed service option

- - - - - <https://github.com/mem0ai/mem0>
          - **ByteRover:**
            - It is an opensource memory layer specifically designed for coding agents.
            - **Features:**

**Persistent Memory:** Keep important context across coding sessions

**Automatic Memory Management:** ByteRover automatically saves and retrieves relevant code context

**Multi-IDE Support:** Switch seamlessly between IDEs without losing memory and context. Configure once, use across Trae, Windsurf, Cursor, Github Copilot, Claude Code, Cline, Kilo Code, Roo Code, Qoder, etc.

**Custom AI Instructions:** Create and deploy your own AI behavior instructions

Auto-generate AI coding memories that scale with the codebase

Easily share coding memories across a dev team in real time

Dual Memory Layer that captures System 1 (Programming Concepts & Business Logic & Past Interaction) and System 2 (reasoning steps of the model when generating code)

- - - - - <https://github.com/campfirein/cipher>
          - **Chrome DevTools:**
            - It lets your coding agent (such as GitHub Copilot, Trae.ai, Gemini, Claude, Cursor, etc.) control and inspect a live Chrome browser.
            - It acts as a Model-Context-Protocol (MCP) server, giving the AI coding assistant access to the full power of Chrome DevTools for reliable automation, in-depth debugging, and performance analysis.
            - **Features:**

**Get Performance Insights**: Uses [Chrome DevTools](https://github.com/ChromeDevTools/devtools-frontend) to record traces and extract actionable performance insights

**Advanced Browser Debugging**: Analyse network requests, take screenshots and check the browser console

**Reliable Automation**: Uses [puppeteer](https://github.com/puppeteer/puppeteer) to automate actions in Chrome and automatically wait for action results

- - - - - <https://github.com/ChromeDevTools/chrome-devtools-mcp>

- **Predictions**
  - [**Stock Prediction Models**](https://github.com/huseinzol05/Stock-Prediction-Models)
    - A collection of machine learning and deep learning models (e.g., ARIMA, LSTM, GANs) for stock forecasting.
    - **This will be implemented using a dynamic meta-regressor or ensemble approach, which intelligently combines and adaptively weights predictions from various models.**
    - This method provides more robust, interpretable forecasting results by adjusting model contributions based on real-time market conditions.
    - These models improve forecasting accuracy for AI-driven trading strategies.
    - Works well with TradingAgent for decision-making and OpenBB for data integration.
    - <https://github.com/huseinzol05/Stock-Prediction-Models>
  - [**LSTM - Neural Network for Time SeriesPrediction**](https://github.com/jaungiers/LSTM-Neural-Network-for-Time-Series-Prediction)
    - An LSTM model built with Keras for time series prediction, tested on sine waves and stock data.
    - LSTMs excel at time series forecasting, enhancing prediction capabilities.
    - Integrates seamlessly with TradingAgent's AI framework and TA-Lib/ta-lib-python (primary wrapper) & Bukosabino/ta's (secondary wrapper) data processing.
    - <https://github.com/jaungiers/LSTM-Neural-Network-for-Time-Series-Prediction>
  - [**Real time stock marketprediction**](https://github.com/victor369basu/Real-time-stock-market-prediction)
    - A real-time prediction system using Tensorflow.js and Kafka for streaming data.
    - Relevant for live trading, adding real-time forecasting capabilities.
    - Complements NautilusTrader's live trading and OpenBB's data streams.
    - <https://github.com/victor369basu/Real-time-stock-market-prediction>
- **Backtesting**
  - **VectorBT**
    - GPU-accelerated, vectorised backtesting.
    - It allows to easily backtest strategies with a couple of lines of Python code.
    - <https://github.com/polakowo/vectorbt>
  - **TradingGym**
    - It is a Python environment toolkit for training and backtesting the reinforcement learning (RL) agents for trading.
    - Enhances AI-driven strategy optimisation, aligning with the system's agentic RAFT goals.
    - Complements TradingAgent and FinRL for RL-based strategies.
    - <https://github.com/Yvictor/TradingGym>
- **Options Analytics Engine: QuantLib**
  - **Role:** The go-to open-source library for all sophisticated options pricing, risk analytics, and calculations for complex derivatives. Develop a dedicated microservice leveraging QuantLib for professional-grade options pricing and risk analytics.
  - **Rationale:** QuantLib is the premier open-source library for quantitative finance. The service will expose critical functionality via a scalable FastAPI bridge. It will be integrated as a specialised service.
  - **Key API Endpoints:**
    - POST /options/price: Computes option prices using models like Black-Scholes or Heston.
    - GET /options/greeks: Retrieves risk metrics (Delta, Gamma, Theta, Vega) for positions.
    - GET /options/volatility: Calculates implied volatility surfaces for market analysis.
    - The service will be integrated with the AI assistant to handle natural language queries.
    - The service scales efficiently to handle high-frequency requests from both the UI and AI agents.
    - Integration is enabled with the AI assistant for natural language queries (e.g., "Calculate the delta for TSLA puts expiring next month").
  - **Purpose**: Delivers professional-grade options analytics to support sophisticated trading strategies and risk assessment.
  - <https://github.com/lballabio/QuantLib>
  - <https://www.quantlib.org/>
- **User Interface: Next.js**
  - **Role:** The unified "cockpit" that interacts with all backend services via a centralised API.
  - **Rationale:** This is the modern standard for high-performance web applications and is specified in your features document. Use Next.js with react-financial-charts, Plotly Dash, ag-Grid, and a Real-time Risk Dashboard.
  - <https://github.com/vercel/next.js>
- **API & Orchestration Layer**:
  - **FastAPI:**
    - **Description:** It is a modern, fast (high-performance), web framework for building APIs with Python based on standard Python type hints.
    - **Features:**
      - It is a custom application that serves as the central bridge between the frontend, AI assistant, and backend trading engine.
      - Fast to code: Increase the speed to develop features by about 200% to 300%.
      - Fewer bugs: Reduce about 40% of human (developer) induced errors.
      - Intuitive: Great editor support. Completion everywhere. Less time debugging.
      - Easy: Designed to be easy to use and learn. Less time reading docs.
      - Short: Minimise code duplication. Multiple features from each parameter declaration. Fewer bugs.
      - Robust: Get production-ready code. With automatic interactive documentation.
    - <https://github.com/fastapi/fastapi>
  - **gRPC:**
    - Low latency streaming for market data.
    - High performance remote procedure call (RPC) framework that can run anywhere.
    - It enables client and server applications to communicate transparently, and simplifies the building of connected systems.
    - <https://github.com/grpc/grpc>
  - **LangGraph:**
    - Complex workflow orchestration.
- **Frameworks and Libraries**
  - **GraphQL:**
    - GraphQL is a query language for APIs and a runtime for fulfilling those queries with your existing data.
    - It provides a complete and understandable description of the data in your API, gives clients the power to ask for exactly what they need and nothing more, makes it easier to evolve APIs over time, and enables powerful developer tools.
    - <https://github.com/redwoodjs/graphql>
  - **React:**
    - It is a library for web and native user interfaces.
    - React is a JavaScript library for building user interfaces.
      - **Declarative:** React makes it painless to create interactive UIs. Design simple views for each state in your application and React will efficiently update and render just the right components when your data changes. Declarative views make your code more predictable, simpler to understand, and easier to debug.
      - **Component-Based:** Build encapsulated components that manage their own state, then compose them to make complex UIs. Since component logic is written in JavaScript instead of templates, you can easily pass rich data through your app and keep the state out of the DOM.
      - **Learn Once, Write Anywhere:** We don't make assumptions about the rest of your technology stack, so you can develop new features in React without rewriting existing code. React can also render on the server using [Node](https://nodejs.org/en) and power mobile apps using [React Native](https://reactnative.dev/).
    - <https://github.com/facebook/react>
  - **Polars/Pandas/NumPy:** Data processing
  - **Asyncio:** Asynchronous programming
- **Chatbot Interface: Lobe Chat**
  - Modern design AI chat / LLMs UI framework.
  - Supports multiple AI providers (OpenAI / Claude 4 / Gemini / DeepSeek / Ollama / Qwen).
  - Knowledge Base (file upload / RAG ).
  - One click install MCP Marketplace and Artifacts / Thinking.
  - Supports speech synthesis, multi-modal, and extensible ([function call](https://lobehub.com/blog/openai-function-call)) plugin system.
  - **Features:**
    - Smooth Conversation Experience: Fluid responses ensure a smooth conversation experience. It fully supports Markdown rendering, including code highlighting, LaTex formulas, Mermaid flowcharts, and more.
    - Exquisite UI Design: With a carefully designed interface, it offers an elegant appearance and smooth interaction. It supports light and dark themes and is mobile-friendly.
    - Desktop App
    - Smart Online Search
    - Chain of Thought
    - Branching Conversations
    - File Upload / Knowledge Base
    - [Multi-Model Service Provider Support](https://lobehub.com/docs/usage/features/multi-ai-providers)
    - [Local Large Language Model (LLM) Support](https://lobehub.com/docs/usage/features/local-llm)
    - [Model Visual Recognition](https://lobehub.com/docs/usage/features/vision)
    - [Text to Image Generation](https://lobehub.com/docs/usage/features/text-to-image)
    - [Plugin System (Function Calling)](https://lobehub.com/docs/usage/features/plugin-system)
    - [Progressive Web App (PWA)](https://lobehub.com/docs/usage/features/pwa) support provides a more native-like experience.
    - MCP Plugin One-Click Installation
    - MCP Marketplace
    - Artifacts Support
  - <https://github.com/lobehub/lobe-chat>
- **Agentic RAG Pipeline: RAGFlow**
  - RAG (Retrieval-Augmented Generation) engine based on deep document understanding.
  - Streamlined RAG workflow for businesses of any scale, combining LLM (Large Language Models) to provide truthful question-answering capabilities, backed by well-founded citations from various complex formatted data.
  - **Features:**
    - Quality in, quality out:
      - [Deep document understanding](https://github.com/infiniflow/ragflow/blob/main/deepdoc/README.md)\-based knowledge extraction from unstructured data with complicated formats.
      - Finds "needle in a data haystack" of literally unlimited tokens.
    - Template-based chunking:
      - Intelligent and explainable.
      - Plenty of template options to choose from.
    - Grounded citations with reduced hallucinations:
      - Visualisation of text chunking to allow human intervention.
      - Quick view of the key references and traceable citations to support grounded answers.
    - Compatibility with heterogeneous data sources:
      - Supports heterogeneous data sources including standard documents (word, slides, excel, pdfs), web pages, and expanded alternative data like specialised online discussion forums, analyst reports, and regulatory filings.
    - Automated and effortless RAG workflow:
      - Streamlined RAG orchestration catered to both personal and large businesses.
      - Configurable LLMs as well as embedding models.
      - Multiple recall paired with fused re-ranking.
      - Intuitive APIs for seamless integration with business.
  - <https://github.com/infiniflow/ragflow>
- **Database - Current Implementation**:
  - **PostgreSQL with pgvector:**
    - **Description:** The system uses **PostgreSQL** with the **pgvector** extension enabled, allowing it to function as an all-in-one database for both traditional relational data and vector embeddings for the AI.
    - **Features:**
      - Open-source vector similarity search for Postgres
      - Store your vectors with the rest of your data.
      - Supports:
        - exact and approximate nearest neighbour search.
        - single-precision, half-precision, binary, and sparse vectors.
        - L2 distance, inner product, cosine distance, L1 distance, Hamming distance, and Jaccard distance.
    - <https://github.com/pgvector/pgvector>
  - **ClickHouse:**
    - Column oriented database management system that allows generating analytical data reports in real-time.
    - High-speed, large-scale time-series analytics.
    - <https://github.com/ClickHouse/ClickHouse>
  - **Redis:**
    - Caching and session storage.
    - For developers, who are building real-time data-driven applications, Redis is the preferred, fastest, and most feature-rich cache, data structure server, and document and vector query engine.
    - Redis excels in various applications, including:
      - Caching: Supports multiple eviction policies, key expiration, and hash-field expiration.
      - Distributed Session Store: Offers flexible session data modeling (string, JSON, hash).
      - Data Structure Server: Provides low-level data structures (strings, lists, sets, hashes, sorted sets, JSON, etc.) with high-level semantics (counters, queues, leaderboards, rate limiters) and supports transactions & scripting.
      - NoSQL Data Store: Key-value, document, and time series data storage.
      - Search and Query Engine: Indexing for hash/JSON documents, supporting vector search, full-text search, geospatial queries, ranking, and aggregations via Redis Query Engine.
      - Event Store & Message Broker: Implements queues (lists), priority queues (sorted sets), event deduplication (sets), streams, and pub/sub with probabilistic stream processing capabilities.
      - Vector Store for GenAI: Integrates with AI applications (e.g. LangGraph, mem0) for short-term memory, long-term memory, LLM response caching (semantic caching), and retrieval augmented generation (RAG).
      - Real-Time Analytics: Powers personalisation, recommendations, fraud detection, and risk assessment.
    - <https://github.com/redis/redis>
  - **Neo4j:**
    - It is the world's leading Graph Database.
    - It is a high-performance graph store with all the features expected of a mature and robust database, like a friendly query language and ACID transactions.
    - The programmer works with a flexible network structure of nodes and relationships rather than static tables - yet enjoys all the benefits of enterprise-quality database.
    - For many applications, Neo4j offers orders of magnitude performance benefits compared to relational DBs.
    - Neo4j is available both as a standalone server, or an embeddable component.
    - <https://github.com/neo4j/neo4j>
  - **Apache Iceberg:**
    - Long-term, immutable data storage.
    - High performance format for huge analytic tables.
    - Iceberg brings the reliability and simplicity of SQL tables to big data, while making it possible for engines like Spark, Trino, Flink, Presto, Hive, and Impala to safely work with the same tables, at the same time.
    - <https://github.com/apache/iceberg>
  - **Qdrant:**
    - **Description:** Qdrant is a high-performance, massive-scale Vector Database and Vector Search Engine.
    - **Features:**
      - It provides a production-ready service with a convenient API to store, search, and manage points - vectors with an additional payload.
      - It is tailored to extended filtering support.
      - It makes it useful for all sorts of neural-network or semantic-based matching, faceted search, and other applications.
      - Qdrant is written in Rust, which makes it fast and reliable even under high load.
      - With Qdrant, embeddings or neural network encoders can be turned into full-fledged applications for matching, searching, recommending, and much more.
    - <https://github.com/qdrant/qdrant>
- **Database - Implementation based on Future Requirement**:
  - **DuckDB:**
    - Fast, in-process OLAP queries for research.
    - High performance analytical database system.
    - Designed to be fast, reliable, portable, and easy to use.
    - Provides a rich SQL dialect, with support far beyond basic SQL.
    - Supports arbitrary and nested correlated subqueries, window functions, collations, complex types (arrays, structs, maps), and [several extensions designed to make SQL easier to use](https://duckdb.org/docs/stable/sql/dialect/friendly_sql.html).
    - <http://github.com/duckdb/duckdb>
  - **InfluxDB:**
    - It is a scalable datastore for metrics, events, and real-time analytics.
    - InfluxDB Core is a database built to collect, process, transform, and store event and time series data. It is ideal for use cases that require real-time ingest and fast query response times to build user interfaces, monitoring, and automation solutions.
    - Common use cases include:
      - Monitoring sensor data
      - Server monitoring
      - Application performance monitoring
      - Network monitoring
      - Financial market and trading analytics
      - Behavioral analytics
    - InfluxDB is optimised for scenarios where near real-time data monitoring is essential and queries need to return quickly to support user experiences such as dashboards and interactive user interfaces.
    - InfluxDB Core's feature highlights include:
      - Diskless architecture with object storage support (or local disk with no dependencies)
      - Fast query response times (under 10ms for last-value queries, or 30ms for distinct metadata)
      - Embedded Python VM for plugins and triggers
      - Parquet file persistence
      - Compatibility with InfluxDB 1.x and 2.x write APIs
      - Compatability with InfluxDB 1.x query API (InfluxQL)
      - SQL query engine with support for FlightSQL and HTTP query API
    - <https://github.com/influxdata/influxdb>
  - **MinIO/S3:**
    - MinIO is a high-performance, S3-compatible object storage solution released under the GNU AGPL v3.0 license.
    - It is designed for speed and scalability.
    - It powers AI/ML, analytics, and data-intensive workloads with industry-leading performance.
    - <https://github.com/minio/minio>
  - **Elasticsearch:**
    - Elasticsearch is a distributed search and analytics engine, scalable data store and vector database optimised for speed and relevance on production-scale workloads.
    - It is the foundation of Elastic's open Stack platform.
    - Search in near real-time over massive datasets, perform vector searches, integrate with generative AI applications, and much more.
    - Use cases enabled by Elasticsearch include:
      - [Retrieval Augmented Generation (RAG)](https://www.elastic.co/search-labs/blog/articles/retrieval-augmented-generation-rag)
      - [Vector search](https://www.elastic.co/search-labs/blog/categories/vector-search)
      - Full-text search
      - Logs
      - Metrics
      - Application performance monitoring (APM)
      - Security logs
    - <https://github.com/elastic/elasticsearch>
  - **Apache Cassandra:**
    - Apache Cassandra is a highly scalable partitioned row store.
    - Rows are organised into tables with a required primary key.
    - [Partitioning](https://cwiki.apache.org/confluence/display/CASSANDRA2/Partitioners) means that Cassandra can distribute your data across multiple machines in an application-transparent matter.
    - Cassandra will automatically repartition as machines are added and removed from the cluster.
    - [Row store](https://cwiki.apache.org/confluence/display/CASSANDRA2/DataModel) means that like relational databases, Cassandra organises data by rows and columns.
    - **Key features**
      - **Decentralised architecture:** Cassandra uses a peer-to-peer model where every node in the cluster is identical and can perform the same functions. This eliminates the risk of a single point of failure and makes the system resilient to outages.
      - **Linear scalability:** You can increase read and write throughput by adding more nodes to the cluster, using inexpensive commodity hardware. Cassandra automatically redistributes data to maintain an even load balance.
      - **Tuneable consistency:** Cassandra follows the CAP theorem, which states that a distributed system can only provide two of the three guarantees: Consistency, Availability, and Partition tolerance. By default, Cassandra is an "AP" system (available and partition-tolerant), but it allows you to choose your desired consistency level on a per-query basis. This lets you balance performance and availability with strong data consistency.
      - **Seamless data replication:** Data is replicated across multiple nodes and can be spread across different data centres or geographic regions. This ensures low latency for users worldwide and protects against regional outages.
      - **Flexible data model:** It is a wide-column store that supports flexible schemas, unlike rigid relational database management systems (RDBMS). Rows in the same table can have different columns, which is efficient for handling sparse data.
      - **High write performance:** Cassandra's storage engine is optimised for high-volume, write-intensive workloads. It first logs writes to a commit log and then writes them to an in-memory memtable, ensuring fast, low-latency writes before flushing data to disk.
      - **Cassandra Query Language (CQL):** While it is a NoSQL database, Cassandra provides the SQL-like CQL for interacting with data. This makes it easier for developers with an SQL background to learn and use.
    - **Common use cases**
      - Cassandra's strengths make it a popular choice for applications that need to manage large, dynamic datasets with high availability and write performance.
      - **Internet of Things (IoT):** Manages massive amounts of real-time sensor data and event streams from connected devices.
      - **Financial services:** Used for fraud detection and real-time transaction processing, which require analysing large, diverse datasets instantaneously.
      - **Retail and e-commerce:** Powers personalised product recommendations, manages product catalogues and inventory, and handles high transaction volumes during peak seasons.
      - **Social media and entertainment:** Stores user activity logs, messages, and content metadata. Companies like Netflix and Instagram use Cassandra to handle data from millions of users.
      - **Messaging and communication:** Provides scalable and reliable message storage for communication platforms.
      - **Time-series data:** Efficiently stores and retrieves timestamped data for monitoring systems, telematics, and weather history.
    - **Considerations for use**
      - While Cassandra offers many benefits, it is not a suitable choice for every project.
      - **Not for small datasets:** The operational overhead of managing a distributed system means Cassandra is not the best fit for applications with small amounts of data.
      - **Not ideal for ad-hoc queries:** Because of its distributed nature, Cassandra does not support advanced query patterns like multi-table joins or aggregates. The data model should be designed around your access patterns.
      - **Eventual consistency:** Though it is tuneable, Cassandra's default is eventual consistency. Applications that require strict ACID compliance may be better suited for a traditional relational database.
      - **Complex data modelling:** Its flexible schema requires careful upfront data modelling tailored to your specific queries. Poor data modelling can lead to performance issues.
    - <https://github.com/apache/cassandra>
  - **MongoDB:**
    - A MongoDB database is a popular NoSQL document database that stores data in flexible, JSON-like documents (BSON format) rather than traditional rows and columns.
    - It is designed for horizontal scalability and features a flexible schema, allowing developers to easily manage structured, unstructured, and semi-structured data for modern applications.
    - MongoDB provides features like indexing for fast access, [replication](https://www.google.com/search?sca_esv=d262380f444288af&rlz=1C1JJTC_enIN1031IN1031&sxsrf=AE3TifMH9x9uwsMJY0kvBQZ8YFQT652s9g%3A1758122394169&q=replication&sa=X&ved=2ahUKEwj2r5qmjOCPAxVPQUEAHV0RBRYQxccNegQINRAB&mstk=AUtExfACVxWAR5lPHN9RcuvUMkha1Gthkd0Russ1Q-UVPIVvYIhWzZqXFJsV7bSEW7XjYfrtjlvspgG_Gj8uCZnS2HDgCfXFzATC-e27qYEsz0iovCWWKle7JlYLjgqrs85aybHwTkVGhLayznq8gDXi2dr_pUf2Ee1pZJFypFfwPM8eAzx6oAdFYqKc40CWL4Q3OZoBZwrcfoSu1960dJu2Y0156aEygFTEZM-BO_LP8uq937YHDhniDwJS2MWEbNBANaf8CNEVMC0icjK3hLxzNRPr&csui=3) for high availability, and supports complex queries, making it a powerful choice for a wide range of applications, including web, mobile, and AI.
    - **Key Characteristics**
      - **Document-Oriented Data Model**: Data is stored in BSON documents, which are binary representations of JSON.
      - **Flexible Schema**: Unlike relational databases, MongoDB doesn't require a rigid, predefined schema, allowing for variation in data structure between documents within the same collection.
      - [**NoSQL**](https://www.google.com/search?sca_esv=d262380f444288af&rlz=1C1JJTC_enIN1031IN1031&sxsrf=AE3TifMH9x9uwsMJY0kvBQZ8YFQT652s9g%3A1758122394169&q=NoSQL&sa=X&ved=2ahUKEwj2r5qmjOCPAxVPQUEAHV0RBRYQxccNegUIsAEQAQ&mstk=AUtExfACVxWAR5lPHN9RcuvUMkha1Gthkd0Russ1Q-UVPIVvYIhWzZqXFJsV7bSEW7XjYfrtjlvspgG_Gj8uCZnS2HDgCfXFzATC-e27qYEsz0iovCWWKle7JlYLjgqrs85aybHwTkVGhLayznq8gDXi2dr_pUf2Ee1pZJFypFfwPM8eAzx6oAdFYqKc40CWL4Q3OZoBZwrcfoSu1960dJu2Y0156aEygFTEZM-BO_LP8uq937YHDhniDwJS2MWEbNBANaf8CNEVMC0icjK3hLxzNRPr&csui=3) **Database**: As a NoSQL database, it offers a different approach to data storage and management than traditional relational (SQL) databases.
      - **Horizontal Scalability**: Built on a scale-out architecture, it can distribute large amounts of data across many machines for high performance and handling huge datasets.
      - **Rich Feature Set**: Includes ad hoc queries, indexing for performance, real-time aggregation, replication for data protection, and supports ACID transactions.
    - **How It Works**
      - **Databases**: A container for collections.
      - [**Collections**](https://www.google.com/search?sca_esv=d262380f444288af&rlz=1C1JJTC_enIN1031IN1031&sxsrf=AE3TifMH9x9uwsMJY0kvBQZ8YFQT652s9g%3A1758122394169&q=Collections&sa=X&ved=2ahUKEwj2r5qmjOCPAxVPQUEAHV0RBRYQxccNegUIzQEQAQ&mstk=AUtExfACVxWAR5lPHN9RcuvUMkha1Gthkd0Russ1Q-UVPIVvYIhWzZqXFJsV7bSEW7XjYfrtjlvspgG_Gj8uCZnS2HDgCfXFzATC-e27qYEsz0iovCWWKle7JlYLjgqrs85aybHwTkVGhLayznq8gDXi2dr_pUf2Ee1pZJFypFfwPM8eAzx6oAdFYqKc40CWL4Q3OZoBZwrcfoSu1960dJu2Y0156aEygFTEZM-BO_LP8uq937YHDhniDwJS2MWEbNBANaf8CNEVMC0icjK3hLxzNRPr&csui=3)**:** Similar to tables in a relational database, but instead of rows, they contain BSON documents.
      - **Documents**: The basic unit of data, analogous to a row in a relational database, holding various data types and structures.
      - **Fields**: Within documents, fields are like columns in a relational database and can be indexed to improve query performance.
    - **Benefits**
      - **Developer Agility**: The flexible schema and document model map well to application objects, simplifying development and making it easier to adapt to changing data requirements.
      - **Performance**: Features like indexing, ad hoc queries, and real-time aggregation provide powerful ways to access and analyse data efficiently.
      - **Scalability & Availability**: Built for horizontal scaling and high availability through replication and distribution across multiple systems.
      - **Versatility**: Can store and process structured, unstructured, and semistructured data, making it suitable for modern, complex applications.
    - **Common Use Cases**
      - Modern web and mobile applications.
      - Applications with a need for flexible data models.
      - Data storage for Artificial Intelligence (AI) and machine learning, which requires fluid and instantly accessible data.
      - Managing large volumes of data and enabling rapid development cycles.
    - <https://github.com/mongodb/mongo>
- **Order Management & Execution Layer:**
  - **FIX Gateway:**
    - Institutional-grade trading connectivity.
    - The Financial Information eXchange (FIX) protocol is a messaging standard developed specifically for the real-time electronic exchange of securities transactions.
    - FIX is a public-domain specification owned and maintained by FIX Protocol, Ltd (FPL).
    - **QuickFIX/J:**
      - Full featured messaging engine for the FIX protocol.
      - It is a 100% Java open source implementation of the popular C++ QuickFIX engine.
      - <https://github.com/quickfix-j/quickfixj>
    - **FIX8:**
      - A modern open-source C++ FIX framework featuring complete schema driven customisation, high performance and fast application development.
      - Comprised of a compiler for generating C++ message and field encoders, decoders and instantiation tables.
      - Runtime library to support the generated code and framework.
      - Set of complete client/server test applications.
      - <https://github.com/fix8/fix8>
- **Feature Store**:
  - **Feast:**
    - Open-source feature store for machine learning.
    - Fastest path to manage existing infrastructure to productionise analytic data for model training and online inference.
    - Allows ML platform teams to:
      - Make features consistently available for training and serving by managing an offline store (to process historical data for scale-out batch scoring or model training), a low-latency online store (to power real-time prediction), and a battle-tested feature server (to serve pre-computed features online).
      - Avoid data leakage by generating point-in-time correct feature sets so data scientists can focus on feature engineering rather than debugging error-prone dataset joining logic. This ensure that future feature values do not leak to models during training.
      - Decouple ML from data infrastructure by providing a single data access layer that abstracts feature storage from feature retrieval, ensuring models remain portable as you move from training models to serving models, from batch models to realtime models, and from one data infra system to another.
    - <https://github.com/feast-dev/feast>
  - **Tecton:**
    - Consistent feature management for training and inference.
    - <https://github.com/tecton-ai>
- **Observability and Monitoring Stack**:
  - **Prometheus:**
    - **Description**: It is a systems and service monitoring system. It collects metrics from configured targets at given intervals, evaluates rule expressions, displays the results, and can trigger alerts when specified conditions are observed.
    - **Features:**
      - A multi-dimensional data model (time series defined by metric name and set of key/value dimensions).
      - PromQL, a powerful and flexible query language to leverage this dimensionality.
      - No dependency on distributed storage; single server nodes are autonomous.
      - An HTTP pull model for time series collection.
      - Pushing time series is supported via an intermediary gateway for batch jobs.
      - Targets are discovered via service discovery or static configuration.
      - Multiple modes of graphing and dashboarding support.
      - Support for hierarchical and horizontal federation.
    - <https://github.com/prometheus/prometheus>
  - **Grafana:**
    - **Description:** It is an open and composable observability and data visualisation platform. Visualise metrics, logs, and traces from multiple sources like Prometheus, Loki, Elasticsearch, InfluxDB, Postgres, and many more. Grafana allows you to query, visualise, alert on and understand your metrics no matter where they are stored. Create, explore, and share dashboards with your team and foster a data-driven culture.
    - **Features:**
      - Visualisations: Fast and flexible client-side graphs with a multitude of options. Panel plugins offer many different ways to visualise metrics and logs.
      - Dynamic Dashboards: Create dynamic & reusable dashboards with template variables that appear as dropdowns at the top of the dashboard.
      - Explore Metrics: Explore your data through ad-hoc queries and dynamic drilldown. Split view and compare different time ranges, queries and data sources side by side.
      - Explore Logs: Experience the magic of switching from metrics to logs with preserved label filters. Quickly search through all your logs or streaming them live.
      - Alerting: Visually define alert rules for your most important metrics. Grafana will continuously evaluate and send notifications to systems like Slack, PagerDuty, VictorOps, OpsGenie.
      - Mixed Data Sources: Mix different data sources in the same graph! You can specify a data source on a per-query basis. This works for even custom datasources.
    - <https://github.com/grafana/grafana>
  - **Grafana Tempo:**
    - **Description:** High volume, minimal dependency distributed tracing for latency debugging. Distributed tracing helps teams quickly pinpoint performance issues and understand the flow of requests across services.
    - **Features:**
      - Cost-efficient, requiring only object storage to operate.
      - Deeply integrated with Prometheus, Grafana, and Loki.
      - The Traces Drilldown UI simplifies this process by offering a user-friendly interface to view and analyse trace data, making it easier to identify and resolve issues without needing to write complex queries.
    - <https://github.com/grafana/tempo>
  - **Memray:**
    - **Description:** A memory profiler for Python from Bloomberg. It can track memory allocations in Python code, in native extension modules, and in the Python interpreter itself. It detects leaks in Python code. It can generate several different types of reports to help analyse the captured memory usage data. While commonly used as a CLI tool, it can also be used as a library to perform more fine-grained profiling tasks.
    - **Justification:** In a high-performance trading system, memory leaks or inefficient memory usage can degrade performance over time and lead to system instability. Memray is invaluable for debugging these issues, especially in long-running services like the trading engine and AI assistant.
    - **Features:**
      - Traces every function call so it can accurately represent the call stack, unlike sampling profilers.
      - Also handles native calls in C/C++ libraries so the entire call stack is present in the results.
      - Blazing fast. Profiling slows the application only slightly. Tracking native code is somewhat slower, but this can be enabled or disabled on demand.
      - It can generate various reports about the collected memory usage data, like flame graphs.
      - Works with Python threads.
      - Works with native-threads (e.g. C++ threads in C extensions).
      - It can analyse allocations in applications to help discover the cause of high memory usage.
      - It can find memory leaks and hotspots in code that cause a lot of allocations.
    - <https://github.com/bloomberg/memray>
  - **Elasticsearch:**
    - It is a distributed search and analytics engine, scalable data store and vector database optimised for speed and relevance on production-scale workloads.
    - Elasticsearch is the foundation of Elastic's open Stack platform.
    - Search in near real-time over massive datasets, perform vector searches, integrate with generative AI applications, and much more.
    - Use cases enabled by Elasticsearch include:
      - [Retrieval Augmented Generation (RAG)](https://www.elastic.co/search-labs/blog/articles/retrieval-augmented-generation-rag)
      - [Vector search](https://www.elastic.co/search-labs/blog/categories/vector-search)
      - Full-text search
      - Logs
      - Metrics
      - Application performance monitoring (APM)
      - Security logs
      - ... and more!
    - <https://github.com/elastic/elasticsearch>
  - **Grafna Loki:**
    - Loki is a horizontally scalable, highly-available, multi-tenant log aggregation system inspired by [Prometheus](https://prometheus.io/).
    - It is designed to be very cost effective and easy to operate.
    - It does not index the contents of the logs, but rather a set of labels for each log stream.
    - Compared to other log aggregation systems, Loki:
      - does not do full text indexing on logs. By storing compressed, unstructured logs and only indexing metadata, Loki is simpler to operate and cheaper to run.
      - indexes and groups log streams using the same labels you're already using with Prometheus, enabling you to seamlessly switch between metrics and logs using the same labels that you're already using with Prometheus.
      - is an especially good fit for storing [Kubernetes](https://kubernetes.io/) Pod logs. Metadata such as Pod labels is automatically scraped and indexed.
      - has native support in Grafana (needs Grafana v6.0).
    - A Loki-based logging stack consists of 3 components:
      - [Alloy](https://github.com/grafana/alloy) is agent, responsible for gathering logs and sending them to Loki.
      - [Loki](https://github.com/grafana/loki) is the main service, responsible for storing logs and processing queries.
      - [Grafana](https://github.com/grafana/grafana) for querying and displaying the logs.
    - Note that Alloy replaced Promtail in the stack, because Promtail is considered to be feature complete, and future development for logs collection will be in [Grafana Alloy](https://github.com/grafana/alloy).
    - Loki is like Prometheus, but for logs
      - A multidimensional label-based approach to indexing.
      - A single-binary, easy to operate system with no dependencies.
    - Loki differs from Prometheus by focusing on logs instead of metrics, and delivering logs via push, instead of pull.
    - <https://github.com/grafana/loki>
  - **Jaeger:**
    - It is a Distributed Tracing System.
    - Distributed tracing observability platforms, such as Jaeger, are essential for modern software applications that are architected as microservices.
    - Jaeger maps the flow of requests and data as they traverse a distributed system.
    - These requests may make calls to multiple services, which may introduce their own delays or errors.
    - Jaeger connects the dots between these disparate components, helping to identify performance bottlenecks, troubleshoot errors, and improve overall application reliability.
    - It utilises [OpenTelemetry Collector](https://opentelemetry.io/docs/collector/) framework as the base and extends it to implement Jaeger's unique features.
    - It brings significant improvements and changes, making Jaeger more flexible, extensible, and better aligned with the OpenTelemetry project.
    - OpenTelemetry is the de-facto standard for application instrumentation providing the foundation for observability.
    - Jaeger is now based on the cornerstone of this project, the OpenTelemetry Collector.
    - It is a complete tracing platform that includes storage and the UI.
    - OpenTelemetry Collector is usually an intermediate component in the collection pipelines that are used to receive, process, transform, and export different telemetry types.
    - <https://github.com/jaegertracing/jaeger>
  - **AlertManager:**
    - The Alertmanager handles alerts sent by client applications such as the Prometheus server.
    - It takes care of deduplicating, grouping, and routing them to the correct [receiver integrations](https://prometheus.io/docs/alerting/latest/configuration/#receiver) such as email, PagerDuty, OpsGenie, or many other [mechanisms](https://prometheus.io/docs/operating/integrations/#alertmanager-webhook-receiver) thanks to the webhook receiver.
    - It also takes care of silencing and inhibition of alerts.
    - <https://github.com/prometheus/alertmanager>
  - **ELK Stack:**
    - It is an Elastic stack (ELK) powered by Docker and Compose.
    - It gives you the ability to analyse any data set by using the searching/aggregation capabilities of Elasticsearch and the visualisation power of Kibana.
    - <https://github.com/deviantony/docker-elk>
  - **AI-Powered Performance Prediction**
    - **Description:** Integrates dedicated ML models to proactively predict system performance bottlenecks and latency issues.
    - **Benefit:** Extends the monitoring stack from reactive alerting to predictive forecasting, allowing for pre-emptive adjustments to prevent slowdowns or failures.
- **Enterprise Security and Risk Management:**
  - **Authentication & Authorisation**
    - OAuth 2.0/OpenID Connect: Standard authentication
    - JWT Tokens: Stateless authentication
    - RBAC: Role-based access control
    - API Keys: Service-to-service authentication
  - **Data Protection**
    - Encryption at Rest: AES-256 encryption
    - Encryption in Transit: TLS 1.3
    - Key Management: HashiCorp Vault
    - Secret Management: Kubernetes secrets
    - Formalised Backup Strategy: Adheres to the **3-2-1 backup rule** (3 copies of data, on 2 different media types, with 1 copy off-site) to ensure a resilient framework for data protection and recovery.
  - **Network Security**
    - Network Policies: Kubernetes network policies
    - Service Mesh: Istio for service-to-service security
    - Ingress Security: NGINX with security headers
    - DDoS Protection: Rate limiting and throttling
  - **Zero-Trust** architecture.
  - **User and Entity Behaviour Analytics (UEBA):**
    - Implements dedicated UEBA capabilities to continuously analyse human and machine behaviour patterns, proactively identifying sophisticated threats based on deviations from established norms.
  - **Threat Modelling by Design:**
    - Mandates the application of generic threat modelling methodologies (e.g., STRIDE) during the design phase of all microservices to proactively identify vulnerabilities.
  - Real-time risk hub.
  - Immutable audit trails in Apache Iceberg.
  - **Unleash:**
    - **Description:** Feature Flags for dynamic toggling of strategies and kill-switches.
    - **Features:**
      - Powerful open-source solution for feature management.
      - Streamlines development workflow.
      - Accelerates software delivery.
      - Empowers teams to control how and when they roll out new features to end users.
      - Deploys code to production in smaller, more manageable releases at user's own pace.
      - Feature flags let users test their code with real production data, reducing the risk of negatively impacting the users' experience.
      - Enables the users' team to work on multiple features simultaneously without the need for separate feature branches.
    - <https://github.com/Unleash/unleash>
  - **Static Application Security Testing (SAST) with Bandit:**
    - **Description:** Add a SAST tool like **Bandit** into the development lifecycle. This tool automatically scans Python code for common security vulnerabilities.
    - **Justification:** This shifts security "left", finding and fixing potential vulnerabilities _before_ they ever reach production. It's a critical component of a modern DevSecOps pipeline and essential for a system handling financial transactions.
    - **Features:**
      - Tool designed to find common security issues in Python code.
      - Processes each file, builds an AST from it, and runs appropriate plugins against the AST nodes.
      - After scanning all the files, it generates a report.
    - <https://github.com/PyCQA/bandit>
- **Enhanced Data Visualisation:**
  - **React-financial-charts for advanced financial charting**
    - **Description:** A React library for advanced financial charting, supporting candlestick, OHLC, and volume charts.
    - **Features:**
      - Customisable charts for stocks, options, and other assets.
      - Interactive features like zooming and tooltips.
      - Integrates with Next.js for dynamic UI updates.
    - **Benefit:** Enhances the Next.js frontend with professional-grade financial visualisations, improving user experience for traders analysing market data.
    - <https://github.com/react-financial/react-financial-charts>
  - **Plotly Dash for interactive dashboards**
    - **Description:** A Python framework for building interactive web-based dashboards, compatible with Next.js via API integration.
    - **Features:**
      - Interactive visualisations for market data, portfolio performance, and risk metrics.
      - Supports real-time updates and user-driven data exploration.
      - Integrates with pandas for seamless data handling.
    - **Benefit:** Adds dynamic dashboards to complement TradingView charts, enhancing data exploration for traders and analysts.
    - <https://github.com/plotly/dash>
  - **"Glass Box" UI / Decision Event Explorer**
    - **Description**: A dedicated UI component that provides a "glass box" view into the system's operations by visualising the flow of Kafka events associated with a user's actions.
    - **Features**:
      - Trace the complete, end-to-end causal chain for every trade, from the initial AI insight to the final broker confirmation.
      - Provide a verifiable audit trail for compliance and a powerful debugging tool for strategy development.
      - Provide interactive visualisations of qualitative data, such as dynamic sentiment trends and topic clouds, with clear graphical links between real-world events and market price movements.
    - **Benefit**: Transforms the system's complexity into a transparent, auditable, and trustworthy strength, building profound user confidence.
- **Hyperparameter Tuning:**
  - **Optuna:**
    - **Description:** Best-in-class hyperparameter tuning framework to optimise strategies alongside the backtesting engine. It is an automatic hyperparameter optimisation software framework, designed for machine learning. It features an imperative, _define-by-run_ style user API, due to which the code written with Optuna enjoys high modularity, and the user of Optuna can dynamically construct the search spaces for the hyperparameters.
    - **Features:**
      - [Lightweight, versatile, and platform agnostic architecture](https://optuna.readthedocs.io/en/stable/tutorial/10_key_features/001_first.html): Handle a wide variety of tasks with a simple installation that has few requirements.
      - [Pythonic search spaces](https://optuna.readthedocs.io/en/stable/tutorial/10_key_features/002_configurations.html): Define search spaces using familiar Python syntax including conditionals and loops.
      - [Efficient optimisation algorithms](https://optuna.readthedocs.io/en/stable/tutorial/10_key_features/003_efficient_optimization_algorithms.html): Adopt state-of-the-art algorithms for sampling hyperparameters and efficiently pruning unpromising trials.
      - [Easy parallelisation](https://optuna.readthedocs.io/en/stable/tutorial/10_key_features/004_distributed.html): Scale studies to tens or hundreds of workers with little or no changes to the code.
      - [Quick visualisation](https://optuna.readthedocs.io/en/stable/tutorial/10_key_features/005_visualization.html): Inspect optimisation histories from a variety of plotting functions.
    - <https://github.com/optuna/optuna>
- **Portfolio Optimisation:**
  - **PyPortfolioOpt**
    - **Description:** A Python library for portfolio optimisation, offering tools for asset allocation and risk management.
    - **Features:**
      - Supports mean-variance optimisation, Black-Litterman allocation, and risk parity.
      - Calculates risk metrics like volatility and Sharpe ratio.
      - Integrates with pandas for data input from OpenBB or NautilusTrader.
    - **Benefit:** Enhances risk management by optimising portfolio allocations, complementing the existing risk checks.
    - <https://github.com/robertmartin8/PyPortfolioOpt>
  - **Riskfolio-Lib for asset allocation and risk analysis**
    - **Description:** A Python library for advanced portfolio optimisation and risk analysis.
    - **Features:**
      - Supports hierarchical risk parity, CVaR optimisation, and worst-case scenario analysis.
      - Provides visualisation tools for risk contributions and portfolio weights.
      - Integrates with pandas for data compatibility.
    - **Benefit:** Adds sophisticated risk analysis tools, enhancing the system's enterprise-grade risk management capabilities.
    - <https://github.com/dcajasn/Riskfolio-Lib>
- **Anomaly Detection:**
  - **PyOD for detecting anomalies in trading data and system performance**
    - **Description:** A Python library for outlier detection, suitable for identifying anomalies in trading data or system performance.
    - **Features:**
      - Supports multiple anomaly detection algorithms (e.g., Isolation Forest, AutoEncoder).
      - Integrates with pandas and NumPy for data processing.
      - Provides visualisation tools for anomaly analysis.
    - **Benefit:** Enhances system reliability by detecting unusual trading patterns or performance issues, complementing Prometheus and Grafana.
    - <https://github.com/yzhao062/pyod>
- **Explainable AI:**
  - **SHAP for transparent AI-driven trading decisions**
    - **Description:** A Python library for explainable AI, providing tools to interpret machine learning model predictions.
    - **Features:**
      - Generates SHAP values to explain model outputs (e.g., trading decisions).
      - Supports visualisation of feature importance and decision impacts.
      - Integrates with machine learning frameworks like scikit-learn and TensorFlow.
    - **Benefit:** Improves transparency of AI-driven trading decisions, aligning with regulatory compliance and user trust.
    - <https://github.com/shap/shap>
- **No-Code Strategy Builder:**
  - **Blockly for visual programming of trading strategies**
    - **Description:** A JavaScript library for visual programming, enabling drag-and-drop interfaces for building applications.
    - **Features:**
      - Supports custom block definitions for trading strategies (e.g., indicators, conditions, actions).
      - Integrates with Next.js for web-based no-code interfaces.
      - Generates executable code from visual blocks.
    - **Benefit:** Enhances the no-code strategy builder, making the system accessible to non-programmers.
    - <https://github.com/google/blockly>
- **Python Studio**: Traditional coding environment.
- **Advanced NLP for AI Assistant:**
  - **Hugging Face's Transformers for advanced financial text analysis**
    - **Description:** A Python library for state-of-the-art NLP models, including pre-trained transformers for financial applications.
    - **Features:**
      - Supports fine-tuning models like FinBERT for financial text analysis (e.g., news, earnings calls).
      - Integrates with LangChain for enhanced AI assistant capabilities.
      - Provides tools for sentiment analysis and text generation.
    - **Benefit:** Enhances the AI assistant's ability to process financial texts, improving decision-making and user interaction.
    - <https://github.com/huggingface/transformers>
- **DeepLearning:**
  - **PyTorch:**
    - **Description:** A deep learning framework. Tensors and Dynamic neural networks in Python with strong GPU acceleration.
    - **Features:**
      - Supports custom AI model development for trading strategies.
      - Offers flexibility for building and training models tailored for the system.
    - **Benefit:** It provides two high-level features,
      - Tensor computation (like NumPy) with strong GPU acceleration.
      - Deep neural networks built on a tape-based autograd system.
    - <https://github.com/pytorch/pytorch>
- **Reinforcement Learning:**
  - **FinRL for optimising trading strategies**
    - **Description:** A Python framework for reinforcement learning in financial trading, offering pre-built models and environments.
    - **Features:**
      - Supports deep reinforcement learning for trading strategy optimisation.
      - Integrates with OpenBB and TA-Lib/ta-lib-python (primary wrapper) & Bukosabino/ta (secondary wrapper) for data and indicator inputs.
      - Provides environments for backtesting and live trading.
    - **Benefit:**
      - Enhances AI-driven strategy development and will be operationalised through a formal **RLOps framework.**
      - This pipeline will automate the continuous training, integration, and delivery (CT/CI/CD) of deep reinforcement learning agents, ensuring they are constantly optimised and improved.
    - <https://github.com/AI4Finance-Foundation/FinRL>
- **Custom Development/Integration:**
  - **Advanced Features:** Most advanced features require custom logic, including post-trade analytics, enterprise security guardrails, advanced risk management hub, the complete user interface, as well as the following:
    - **AI-Powered Opportunity Detection**: Implement machine learning models to detect arbitrage or momentum opportunities in real time.
    - **Adversarial Testing**: Simulate extreme market conditions to evaluate strategy robustness.
- **Managing Updates to Cloned Repositories**

To balance the benefits of upstream updates with the stability of your customised system, adopt a **selective update strategy** for cloned repositories (e.g., OpenHands, Kilo Code, LangChain, LangGraph, kafka, etc.).

- - **Maintain Forked Repositories**:
        - **Treat cloned repositories as forks, customised for your system (e.g., integrating OpenHands with Kafka).**
        - **Document customisations in a changelog to track differences.**
        - **Focus on improving your fork for domain-specific needs (e.g., SDLC workflows, compliance for Lawyer Agent).**
    - **Monitor Upstream Repositories**:
      - **Use GitHub Actions to check for updates daily, notifying via Slack if changes are detected.**
      - **Example: Monitor OpenHands for security patches or new features.**
    - **Selective Update / Integration Process**:
      - **Prioritise updates for security patches, bug fixes, or relevant features.**
      - **Test updates in a staging environment using a CI/CD pipeline (e.g., GitHub Actions, Jenkins).**
      - **Require human review for major updates to assess alignment with your system.**
    - **Dependency Management**:
      - **Use Dependabot to monitor and update dependencies within cloned repositories.**
      - **Pin dependencies in lock files (e.g., requirements.txt) to prevent conflicts.**
      - **Run automated tests post-update to ensure compatibility.**
    - **Comprehensive Testing and Validation**:
      - **Implement a CI/CD pipeline with pytest, Jest, and Cypress to test updates.**
      - **Use LangSmith to evaluate agent performance after updates.**
    - **Rollback Capability:**
      - **Capability to roll back the upgrade / integration in case of any failed updates.**
    - **Contribute Back (Optional)**:
      - **Submit generalisable customisations to upstream repositories to reduce future merge conflicts.**
    - **Benefits**:
      - **Preserves your customisations while allowing critical updates.**
      - **Automates monitoring and testing, reducing manual effort.**
      - **Ensures dependency compatibility and system stability.**
    - **Notification Frequency:**
      - **Daily: Silent logging only (no notifications).**
      - **Weekly: Single consolidated message with ALL updates.**
      - **Monthly: Integration status and deployment summary.**
      - **Emergency: Immediate notification and Integration for critical security issues only.**

**Open-Source Repositories**

**Categorisation Criteria**

- **Direct Integration (No Fork Needed):**

Repositories that can be used as-is via package managers (e.g., pip, Docker, Helm) or configuration without modifying source code. These include standard libraries, infrastructure tools, or frameworks where customisations occur externally (e.g., via configs, APIs, or wrappers).

- <https://github.com/nautechsystems/nautilus_trader>
  - The platform's modular design supports extensibility through adapters for integrations (e.g., REST/WebSocket feeds translated to unified interfaces), a message bus for custom event handling, and modular components for custom data types or indicators (developed in Python/Cython). Low-latency Rust optimisations can be enabled via feature flags in Cargo.toml without core alterations. While Kafka is not explicitly mentioned, the event-driven architecture and adapter system allow external wrappers or adapters to handle event publishing and integrations, such as injecting custom data at nanosecond resolution for backtesting/live trading. Custom indicators can be added externally without modifying the core.
  - **Reason**: Forking is not necessary. Utilise wrappers or custom adapters for Kafka and integrations, with configuration flags for Rust optimisations. This maintains modularity and simplifies updates.
- <https://github.com/langchain-ai/langchain>
  - LangChain is designed as a modular framework with standard interfaces for models, embeddings, and vector stores, enabling chaining of components. It supports third-party integrations and extensions through composable chains or tools. Custom prompts can be implemented via external configurations or subclassing without core changes. Event publishing (e.g., to Kafka) is not natively detailed, but the framework's interoperability allows wrappers to handle such extensions, as it integrates with orchestration tools like LangGraph for advanced workflows.
  - **Reason**: Forking is not necessary. Employ wrappers for Kafka publishing and custom prompts via chain configurations or external modules, ensuring seamless updates.
- <https://github.com/langchain-ai/langgraph>
  - LangGraph is an orchestration framework for stateful agents as graphs, with built-in modularity for custom workflows, templates, and subgraphs. It supports durable execution and integrations like human-in-the-loop without core modifications. Enhancements for multi-agent coordination can be achieved through external graph definitions, templates, or wrappers, leveraging its composable design and integration with LangChain components.
  - **Reason**: Forking is not necessary. Define custom workflows externally via graph configurations or wrappers, preserving extensibility for ATS-specific sequences.
- <https://github.com/coleam00/Archon>
  - Archon supports customisation primarily through .env files, environment variables, and UI configurations for ports, hostnames, and integrations. It uses HTTP APIs for communication between services, enabling external hooks for workflows without core changes. Agentic features, such as task management and prioritisation, can be handled via UI-based filtering or external scripts querying the database/APIs. Real-time updates and MCP tools propagate without modifications.
  - **Reason**: Forking is not necessary. Leverage configurations, HTTP APIs, and external hooks for integrations and prioritisations.
- <https://github.com/TauricResearch/TradingAgents>
  - Built on LangGraph, the framework is modular and configurable via Python imports, CLI, and default_config.py for LLMs, data vendors, and propagation. Collaborative agent workflows (e.g., analysis to trading decisions) can be extended through subclassing or overriding configurations. Strategy synthesis occurs via internal propagation, but Kafka integration is not mentioned; external wrappers can handle event publishing by wrapping the .propagate() method or config options.
  - **Reason**: Forking is not necessary. Use wrappers for Kafka and extend decision-making via subclassing or external configurations.
- <https://github.com/OpenBB-finance/OpenBB>
  - OpenBB provides access to data vendors via Python/CLI interfaces and supports integrations through configurable vendor setups. While fallback chains and Kafka are not explicitly detailed, the platform's extensibility via FastAPI backend and vendor references allows custom data providers or wrappers to implement fallbacks without core changes.
  - **Reason**: Forking is not necessary. Implement fallback logic and Kafka integration via custom wrappers or external data providers.
- <https://github.com/All-Hands-AI/OpenHands>
  - OpenHands uses Docker-based sandboxing for isolation and supports APIs for agent interactions, with built-in MCP support. Task synchronisation can be extended via CLI modes, headless operations, or GitHub Actions integrations. Kafka is not mentioned, but external wrappers can capture outputs (e.g., code modifications or commands) and handle synchronisation without core alterations.
  - **Reason**: Forking is not necessary. Apply wrappers for Kafka and leverage existing APIs/MCP for integrations.
- <https://github.com/Kilo-Org/kilocode>
  - The extension architecture supports multi-mode operations (e.g., custom modes for refinement) and integrations like MCP Server Marketplace without core changes. Features such as task automation and browser/terminal execution enable external hooks or scripts for UI launches and refinements.
  - **Reason**: Forking is not necessary. Utilise custom modes and external scripts for enhancements.
- <https://github.com/lobehub/lobe-chat>
  - Lobe Chat features an extensible plugin system (via MCP Marketplace and SDK) for function calling, integrations, and custom behaviors. Voice (TTS/STT) is natively supported with ecosystem packages. AR can be added via plugins. RAGFlow and OpenHands integrations can use plugins or APIs without core changes, as the system supports external service connections and agent marketplaces.
  - **Reason**: Forking is not necessary. Develop plugins or wrappers for voice/AR and integrations.
- <https://github.com/infiniflow/ragflow>
  - Customisation occurs via .env files, service_conf.yaml, and Docker configurations for LLMs, embedding models, and document engines (e.g., switching to Infinity). Intuitive APIs and agentic workflows support query/vector optimisations without core modifications. External layers or configs can handle ATS-specific needs.
  - **Reason**: Forking is not necessary. Use configurations and external APIs for optimisations.
- <https://github.com/nautechsystems/nautilus_ibapi>
  - **Reason**: Mirror of IB API for NautilusTrader; used as a dependency for broker integration (Interactive Brokers) with configuration-based setup (e.g., account credentials, paper/live mode switching). No code modifications are required.
- <https://github.com/apache/kafka>
  - **Reason**: Core event bus; configured via Kafka topics and Schema Registry, no source changes needed.
- <https://github.com/confluentinc/schema-registry>
  - **Reason**: Used for Kafka schema management; deployed via Docker/Helm.
- <https://github.com/kubernetes/kubernetes>
  - **Reason**: Orchestration platform; managed via Kubernetes manifests.
- <https://github.com/docker-library/docker>
  - **Reason**: Container runtime; used as-is for containerisation.
- <https://github.com/istio/istio>
  - **Reason**: Service mesh for microservices; configured via Istio policies.
- <https://github.com/nginx/nginx>
  - **Reason**: Web server; configured for reverse proxy/load balancing.
- <https://github.com/helm/helm>
  - **Reason**: Package manager for Kubernetes; used for deploying services.
- <https://github.com/TA-Lib/ta-lib-python>
  - **Reason**: Technical analysis library; integrated via pip for indicators like VW SMA.
- <https://github.com/bukosabino/ta>
  - **Reason**: Secondary TA library; used via pip without modifications.
- <https://github.com/huseinzol05/Stock-Prediction-Models>
  - **Reason**: Forecasting models; integrated via pip or scripts.
- <https://github.com/jaungiers/LSTM-Neural-Network-for-Time-Series-Prediction>
  - **Reason**: Time-series prediction; used as-is for ATS forecasting.
- <https://github.com/victor369basu/Real-time-stock-market-prediction>
  - **Reason**: Real-time predictions; integrated without code changes.
- <https://github.com/polakowo/vectorbt>
  - **Reason**: GPU-accelerated backtesting; installed via pip.
- <https://github.com/Yvictor/TradingGym>
  - **Reason**: Strategy development environment; used as-is.
- <https://github.com/lballabio/QuantLib>
  - **Reason**: Options analytics; integrated via pip.
- <https://github.com/vercel/next.js>
  - **Reason**: Frontend framework; configured for React/Next.js UI.
- <https://github.com/fastapi/fastapi>
  - **Reason**: API framework; used for RESTful services.
- <https://github.com/grpc/grpc>
  - **Reason**: High-performance RPC; deployed as-is.
- <https://github.com/redwoodjs/graphql>
  - **Reason**: GraphQL API; configured without code changes.
- <https://github.com/facebook/react>
  - **Reason**: UI library; used for frontend components.
- <https://github.com/pgvector/pgvector>
  - **Reason**: Vector extension for PostgreSQL; installed as an extension.
- <https://github.com/ClickHouse/ClickHouse>
  - **Reason**: Time-series analytics; deployed via Docker.
- <http://github.com/duckdb/duckdb>
  - **Reason**: OLAP queries; installed via pip or Docker.
- <https://github.com/qdrant/qdrant>
  - **Reason**: Vector similarity search; deployed via Docker.
- <https://github.com/apache/iceberg>
  - **Reason**: Immutable audit logs; configured for compliance.
- <https://github.com/redis/redis>
  - **Reason**: Caching/session management; deployed via Docker.
- <https://github.com/influxdata/influxdb>
  - **Reason**: Metrics collection; deployed as-is.
- <https://github.com/minio/minio>
  - **Reason**: Object storage; configured via Docker.
- <https://github.com/elastic/elasticsearch>
  - **Reason**: Search/logs/RAG; deployed with fallback mechanisms.
- <https://github.com/apache/cassandra>
  - **Reason**: NoSQL database; used with fallback configs.
- <https://github.com/mongodb/mongo>
  - **Reason**: NoSQL database; deployed as-is.
- <https://github.com/neo4j/neo4j>
  - **Reason**: Graph database; configured for knowledge graphs.
- <https://github.com/quickfix-j/quickfixj>
  - **Reason**: FIX protocol for OMS; configured for brokers without code changes.
- <https://github.com/fix8/fix8>
  - **Reason**: Alternative FIX library; used as-is.
- <https://github.com/feast-dev/feast>
  - **Reason**: Feature store; configured for AI/ML pipelines.
- <https://github.com/tecton-ai>
  - **Reason**: Feature platform; used via APIs/configs.
- <https://github.com/prometheus/prometheus>
  - **Reason**: Monitoring; configured for metrics.
- <https://github.com/grafana/grafana>
  - **Reason**: Visualisation; deployed via Docker/Helm.
- <https://github.com/grafana/tempo>
  - **Reason**: Tracing; configured for observability.
- <https://github.com/bloomberg/memray>
  - **Reason**: Memory profiling; installed via pip.
- <https://github.com/elastic/elasticsearch> (duplicate, already listed at 40)
  - **Reason**: Redundant; remove from list to avoid confusion.
- <https://github.com/grafana/loki>
  - **Reason**: Log aggregation; deployed via Docker.
- <https://github.com/apache/airflow>
  - **Reason**: Workflow orchestration; configured as-is.
- <https://github.com/jaegertracing/jaeger>
  - **Reason**: Distributed tracing; deployed via Docker.
- <https://github.com/prometheus/alertmanager>
  - **Reason**: Alerting; configured for notifications.
- <https://github.com/deviantony/docker-elk>
  - **Reason**: ELK stack; deployed for logging.
- <https://github.com/Unleash/unleash>
  - **Reason**: Feature toggles; configured for system control.
- <https://github.com/PyCQA/bandit>
  - **Reason**: SAST tool; used via pip for security scans.
- <https://github.com/apache/ranger>
  - **Reason**: Security policy management; configured for RBAC.
- <https://github.com/react-financial/react-financial-charts>
  - **Reason**: Financial visualisations; integrated via npm.
- <https://github.com/plotly/dash>
  - **Reason**: Visualisation framework; installed via pip.
- <https://github.com/optuna/optuna>
  - **Reason**: Hyperparameter tuning; used via pip.
- <https://github.com/robertmartin8/PyPortfolioOpt>
  - **Reason**: Portfolio optimisation; installed via pip.
- <https://github.com/dcajasn/Riskfolio-Lib>
  - **Reason**: Risk analysis; installed via pip.
- <https://github.com/yzhao062/pyod>
  - **Reason**: Anomaly detection; used via pip.
- <https://github.com/shap/shap>
  - **Reason**: Explainable AI; installed via pip.
- <https://github.com/google/blockly>
  - **Reason**: No-code strategy builder; integrated via npm.
- <https://github.com/huggingface/transformers>
  - **Reason**: NLP models; installed via pip.
- <https://github.com/pytorch/pytorch>
  - **Reason**: Deep learning; installed via pip.
- <https://github.com/AI4Finance-Foundation/FinRL>
  - **Reason**: Reinforcement learning; used via pip.
- <https://github.com/langchain-ai/open_deep_research>
  - **Reason**: Research agent; integrated as-is for Deep Research domain.
- <https://github.com/vanna-ai/vanna>
  - **Reason**: Data analysis; used via pip for Data Analyst agent.
- <https://github.com/sinaptik-ai/pandas-ai>
  - **Reason**: Data analysis; installed via pip.
- <https://github.com/Canner/WrenAI>
  - **Reason**: BI tool; configured for Data Analyst agent.
- <https://github.com/modelcontextprotocol/python-sdk>
  - **Reason**: MCP client; installed via pip for agent coordination.
- <https://github.com/scikit-learn/scikit-learn>
  - **Reason**: Machine learning; installed via pip.
- <https://github.com/dmlc/xgboost>
  - **Reason**: Gradient boosting; installed via pip.
- <https://github.com/python-openxml/python-docx>
  - **Reason**: Document generation; used via pip.
- <https://github.com/scanny/python-pptx>
  - **Reason**: Presentation generation; installed via pip.
- <https://github.com/Distrotech/reportlab>
  - **Reason**: PDF generation; used via pip.
- <https://github.com/upstash/context7>
  - **Reason**: MCP server for documentation; deployed via Docker or pip.
- <https://github.com/modelcontextprotocol/servers/tree/main/src/sequentialthinking>
  - **Reason**: MCP server for reasoning; integrated as-is.
- <https://github.com/modelcontextprotocol/servers/tree/main/src/memory>
  - **Reason**: MCP server for memory; deployed without changes.
- <https://github.com/campfirein/cipher>
  - **Reason**: Encryption tool; used via pip or config.
- <https://github.com/mem0ai/mem0>
  - **Reason**: Memory management; installed via pip.
- <https://github.com/ChromeDevTools/chrome-devtools-mcp>
  - **Reason**: MCP server for dev tools; integrated as-is.
- <https://github.com/microsoft/playwright-mcp>
  - **Reason**: MCP server for browser automation; integrated as-is.
- <https://github.com/coleam00/Archon>
  - **Reason**: MCP server working as a command centre for AI coding assistants; integrated as-is.
- <https://github.com/github/spec-kit>
  - **Reason**: Toolkit for Spec-Driven Development

**Initial Prompt**

You are an expert full-stack software engineering agent tasked with building a world-class, complex, enterprise-grade Algorithmic Trading System (ATS). The current system is approximately 20-25% complete, featuring a robust infrastructure (Docker, Kubernetes, monitoring stack) and partially implemented components (trading engine, AI assistant, security), as outlined in the "Current Status - Comprehensive Analysis" document. Your core mission is to develop the "Nautilus Trader" algorithmic trading platform from the ground up, following the detailed specifications, requirements, designs, tasks, and architecture provided in the attached documents: "Features, Phases & Integration Strategy - Algorithmic Trading System.docx" (base document for all features, phases, integration strategies, system overview, key characteristics, architecture principles, core services, data feeds, custom indicators, and phase-specific prompts/plans), "comprehensive_system_architecture.md" (updated comprehensive system architecture including overview, principles, components, data flows, technology stack, deployment, security, performance, integrations, monitoring, AI/ML, custom indicators, data feeds, frontend, enterprise readiness, phases, DR/BC, requirements/designs/tasks consolidations), "complete_requirements.md" (consolidated requirements across phases 0-6 with user stories and acceptance criteria), "complete_designs.md" (consolidated designs with high-level architectures, component breakdowns, and Mermaid diagrams per phase), and "complete_tasks.md" (450+ detailed tasks and sub-tasks across phases).

**Project Overview and Guidelines**

- **System Description**: Build a comprehensive, enterprise-grade algorithmic trading system using a "Best-of-Breed" integration strategy. Select and integrate leading open-source projects (60+) for modularity. Support non-technical users (no-code options, natural language via Agentic AI Assistant) and professionals (high-performance features). Architecture: Microservices with Apache Kafka event bus for decoupling, event-driven processing, scalability, and replayability. Core engine: NautilusTrader (Python/Rust) for multi-asset trading (stocks, ETFs, futures, options, forex, crypto). Key integrations: Forecasting (Stock-Prediction-Models, LSTM, Real-time-prediction), backtesting (VectorBT, TradingGym), portfolio/risk (PyPortfolioOpt, Riskfolio-Lib, PyOD), indicators (TA-Lib/ta-lib-python & Bukosabino/ta with 30+ custom volume-weighted), visualisation (react-financial-charts, Plotly Dash), AI/ML (LangChain/LangGraph, TradingAgent, FinRL, SHAP, Transformers/PyTorch, QuantLib), no-code (Blockly), and more. Databases: PostgreSQL/pgvector (structured/vectors), ClickHouse (time-series), Qdrant (vectors), Apache Iceberg (immutable audits), Redis (cache/GenAI vectors), DuckDB (OLAP research), InfluxDB (metrics), MinIO/S3 (objects), Elasticsearch (search/logs/RAG), Apache Cassandra (NoSQL), MongoDB (NoSQL), and Neo4j (graph). Features: Paper/live trading (IBKR start, expand to Alpaca/OANDA/Coinbase/FIX), multi-source data feeds with fallbacks, custom indicators (e.g., VW SMA, Normalised ATR, Choppy Market Index), Agentic AI (multi-agents, RAG, MCPs, iterative refinement), market scanner, "Glass Box" UI, voice/AR, marketplace scope, ultra-low latency (DMA, FPGAs), enterprise readiness (HA, UEBA, compliance).
- **Key Characteristics**: High performance (microsecond latency), scalable (10k+ users, 1M+ msgs/sec), resilient (self-healing, multi-region), secure (zero-trust, MFA, Bandit SAST), observable (Prometheus/Grafana/Jaeger/Memray).
- **Architecture Principles**: Microservices (decomposition, independent deployment, fault isolation, self-healing), event-driven (async Kafka, event sourcing, CQRS), cloud-native (Docker/Kubernetes/Helm/Istio/GitOps/12-Factor), API-first (REST/GraphQL/WebSocket/gRPC), security-first (STRIDE threat modeling), performance-optimised (lock-free, GPU), AI-integrated (agentic workflows, RLOps).
- **Development Approach**: Incremental phases (0-6). Use placeholders (// @PLACEHOLDER: reason, req ID) for incomplete parts, create GitHub Issues. Follow analysis/compare/execute protocol: Analyse specs vs. code, compare diffs, execute builds/modifications. Enforce code standards: Python 3.12+, Rust for latency, linting (flake8), tests (Pytest). Manage deps in tiers with forks, automated monitoring (Renovate/Dependabot), CI/CD (GitHub Actions, Docker sandboxes), dashboard (React/Grafana).
- **Tools and Environment**: You have access to a stateful code interpreter (Python 3.12 with libraries: numpy, pandas, sympy, etc.; no internet/pip). Use it to test code snippets, validate logic (e.g., custom indicators). For external info, use web/X search tools if needed (e.g., check upstream repo changes). Render citations inline for sources. Output code in proper format, commit to virtual repo structure.
- **Workflow**: Start with Phase 0 (Dependency Management). For each phase: Review prompt/plan from base doc, requirements/designs/tasks from consolidations. Generate code, configs, docs. Test via interpreter. Handle errors, iterate. End phase with deliverables validation (e.g., run scans). Acknowledge readiness before proceeding.
- **Output Format**: For code: Use markdown blocks (\`\`\`python:disable-run

**Initial Task: Begin Phase 0**

- Refer to rewritten Phase 0 Prompt and Integration Plan: Establish dep management for 60+ components. Fork tiers, automate monitoring (daily/weekly), notifications, pipelines, dashboard. Implement as per tasks/sub-tasks.
- Proceed step-by-step: Initialise repo, fork deps, set workflows, etc. Use tools to verify (e.g., code_execution for script tests).
- **Acknowledge:** Confirm that you have understood this directive and are ready to begin development.

**Detailed Six Phase Prompt and Integration Plan**

This plan outlines the objectives and key outcomes for each of the six primary development phases, building upon the foundational work established in Phase 0 (Dependency Management). This integration plan outlines a structured, phased approach to developing a robust, enterprise-grade Algorithmic Trading System (ATS). It leverages the existing infrastructure (Docker, Kubernetes, monitoring stack) and partially implemented components (NautilusTrader, AI assistant, security) while addressing gaps and introducing advanced features. Each phase includes detailed objectives, durations, tasks, integration focus, and deliverables to ensure clarity and completeness. Each phase concludes with a mandatory **Phase-End Placeholder Review** to ensure all temporary implementations are formally addressed before proceeding, guaranteeing the integrity and completeness of the build.

**Six-Phase Integration Plan**

- **Phase 0:** Dependency Management Setup - Establish management for 60+ components with automated monitoring and testing.
- **Phase 1:** Core System Validation & Hardening - Stabilise security, trading engine, and APIs.
- **Phase 2:** Frontend and Broker Integration - Develop UI and integrate Interactive Brokers.
- **Phase 3:** AI/ML Integration - Implement AI-driven features and advanced analytics.
- **Phase 4:** Frontend & Live Trading - Enable live trading and real-time UI integration.
- **Phase 5:** Enterprise Readiness - Add observability, security, and compliance features.
- **Phase 6:** System Enhancement & Future-Ready Technologies - Introduce advanced capabilities and optimise for production.

**General Instructions**

- Start with Phase 0 and progress sequentially through Phase 6.
- Use the existing system as the foundation, enhancing or modifying only where features are missing or misaligned.
- Ensure all developments align with the microservices, event-driven, and cloud-native architecture.
- Ensure to use Docker for all dependencies. Do not install any dependencies and libraries globally.
- **Documentation Context**

All subsequent prompts will provide you with three sets of instructions derived directly from the official project documentation:

- - **Requirements:** Specify the "what" and "why" for each feature or component.
    - **Designs:** Detail the architectural "how" for implementation.
    - **Tasks:** Provide granular, step-by-step checklists for execution.
- **Core Directive: Incremental & Context-Aware Development**

For every task, you MUST follow this protocol:

- - **Analyse:** Review the existing codebase to understand its current state and implementation details.
    - **Compare:** Assess the current implementation against the requirements, designs, and tasks specified in this prompt and subsequent phase-specific prompts.
    - **Execute:**
    - If the feature is fully implemented and aligned with specifications, report its completion and proceed.
    - If the feature is partially implemented or misaligned, modify the existing code to meet the new requirements.
    - If the feature is absent, develop it from scratch, adhering to the system's architectural principles.
- **Dependency Management**
  - Dependencies must be containerised; avoid global installations.
  - Each service maintains its own dependency configuration (e.g., \`requirements.txt\` for Python, \`package.json\` for Node.js) and a corresponding \`Dockerfile\`.
- **Phase-End Placeholder Review Process**

Before any development phase can be officially signed off, a mandatory review process must be conducted to address all placeholders created during that phase. This process ensures that technical debt is managed intentionally and not by accident.

**1\. Automated Codebase Scan:** A dedicated step in the CI/CD pipeline will be configured to scan the entire codebase for the // @PLACEHOLDER: tag. If any instances of the tag are found, the pre-deployment build will fail automatically. This serves as a hard gate, preventing placeholders from accidentally slipping into the next phase or production.

**2\. Manual Backlog Review:** The development lead must conduct a formal review of all tickets in the "Placeholder Review" backlog of the issue tracking system. For each ticket, one of the following actions must be taken:

- - **Resolve:** The placeholder is prioritised, and the required work is completed. The code is updated, the tag is removed, and the ticket is closed .
    - **Defer:** In rare cases, if a placeholder is deemed non-critical for the next phase's objectives, the ticket can be formally deferred. This requires explicit approval from project leadership, and the ticket must be moved to the backlog of a specific future phase .

A phase is only considered complete when the automated scan passes and the placeholder backlog for that phase is empty (all tickets are either resolved or formally deferred).

- **Acknowledge:** Confirm that you have understood this directive and are ready to begin development.

**Prioritisation Matrix**

| **Feature/Component** | **Business Value** | **Technical Complexity** | **User Impact** | **Rationale** |
| --- | --- | --- | --- | --- |
| Dependency Management System | High | Medium | High | Essential for all subsequent development; low dependencies, high impact on stability. |
| Core Trading Engine (NautilusTrader Validation) | High | High | High | Foundational for trading; builds on dependency setup. |
| Security Validation (Zero-Trust, Fraud Detection) | High | Medium | High | Critical for enterprise readiness; early integration reduces risk. |
| Database Setup (PostgreSQL/pgvector, ClickHouse) | High | Medium | Medium | Core data storage; required for trading and AI. |
| API Gateway (FastAPI Basics) | High | Medium | High | Enables integration; depends on core engine and databases. |
| Broker Integration (Interactive Brokers) | High | High | High | Enables trading; depends on engine and API. |
| Frontend Basics (Next.js Dashboard) | Medium | Medium | High | User-facing; depends on API. |
| AI Assistant MVP (LangChain Basics) | High | High | High | Differentiator; depends on API and databases. |
| ML Models (LSTM, FinRL Basics) | Medium | High | Medium | Enhances analytics; depends on data pipelines. |
| Advanced AI (RAGFlow, Transformers) | Medium | High | Medium | Builds on AI MVP; deferred for stability. |
| Live Trading Expansion (Alpaca, OANDA) | Medium | High | High | Extends trading; depends on core integrations. |
| Frontend Enhancements (Blockly, Charts) | Medium | Medium | High | Improves UX; depends on API and AI. |
| Observability (Prometheus, Grafana) | High | Medium | Medium | Essential for production; deferred to later phases. |
| Advanced Security (RBAC, Iceberg) | High | High | Low | Builds on initial security; focuses on enterprise readiness. |
| Advanced Analytics (PyOD, Riskfolio-Lib) | Medium | Medium | Medium | Enhances risk; deferred for core stability. |
| Future-Ready Features (Voice Trading, AR) | Low | High | Medium | Enhancements; low priority for initial MVP. |
| Broker Expansion (Coinbase, FIX) | Medium | High | Medium | Extends capabilities; deferred for optimisation. |
| System Optimisation (Memray, Tempo) | Low | Medium | Low | Final polish; low priority until core is stable. |

**Reference Documents for Nautilus Trader Development**

To ensure comprehensive guidance for each phase of the Nautilus Trader algorithmic trading system development, the Agent should refer to the following documents, located in the specified paths, for detailed requirements, designs, tasks, and other critical specifications:

- **System Requirements**:
  - **Document**: Comprehensive System Requirements
  - **Location**: /docs/complete_requirements.md
  - **Description**: Contains consolidated requirements across Phases 0-6, including user stories and acceptance criteria for all system functionalities.
- **System Designs**:
  - **Document**: Comprehensive System Designs
  - **Location**: /docs/complete_designs.md
  - **Description**: Provides detailed designs with high-level architectures, component breakdowns, and Mermaid diagrams for each phase.
- **System Tasks and Sub-Tasks**:
  - **Document**: Comprehensive System Tasks
  - **Location**: /docs/complete_tasks.md
  - **Description**: Lists over 450 detailed tasks and sub-tasks across all phases, serving as a roadmap for implementation.
- **System Architecture**:
  - **Document**: Comprehensive System Architecture
  - **Location**: /docs/comprehensive_system_architecture.md
  - **Description**: Details the system's architecture, including overview, principles, components, data flows, technology stack, deployment, security, performance, integrations, and more.
- **Features, Phases, and Integration Strategy**:
  - **Document**: Features, Phases & Integration Strategy - Algorithmic Trading System
  - **Location**: /docs/01. Features, Phases & Integration Strategy - Algorithmic Trading System.md
  - **Description**: Outlines all features, phased development approach, and integration strategies for the Nautilus Trader platform.
- **Business Requirements**:
  - **Document**: Business Requirements Document (BRD) - Algorithmic Trading System
  - **Location**: /docs/02. Business Requirements Document (BRD) - Algorithmic Trading System.md
  - **Description**: Defines the business objectives, stakeholder needs, and high-level requirements driving the platform's development.
- **Functional Requirements**:
  - **Document**: Functional Requirements Document (FRD) - Algorithmic Trading System
  - **Location**: /docs/03. Functional Requirements Document (FRD) - Algorithmic Trading System.md
  - **Description**: Specifies functional requirements, including user interactions, system behaviors, and operational workflows.
- **Product Requirements**:
  - **Document**: Product Requirements Document (PRD) - Algorithmic Trading System
  - **Location**: /docs/04. Product Requirements Document (PRD) - Algorithmic Trading System.md
  - **Description**: Details product-specific requirements, focusing on features, user experience, and market fit.
- **Functional Specification**:
  - **Document**: Functional Specification Document (FSD) - Algorithmic Trading System
  - **Location**: /docs/05. Functional Specification Document (FSD) - Algorithmic Trading System.md
  - **Description**: Provides detailed functional specifications, including system inputs, outputs, and processing logic.
- **Technical Specification**:
  - **Document**: Technical Specification Document (TSD) - Algorithmic Trading System
  - **Location**: /docs/06. Technical Specification Document (TSD) - Algorithmic Trading System.md
  - **Description**: Outlines technical specifications, including technology stack, APIs, and integration details.
- **System Design**:
  - **Document**: System Design Document (SDD) - Algorithmic Trading System
  - **Location**: /docs/07. System Design Document (SDD) - Algorithmic Trading System.md
  - **Description**: Describes the system's design, including architecture patterns, component interactions, and deployment strategies.
- **Software Requirements Specification**:
  - **Document**: Software Requirements Specification (SRS) - Algorithmic Trading System
  - **Location**: /docs/08. Software Requirements Specification (SRS) - Algorithmic Trading System.md
  - **Description**: Combines functional and non-functional requirements for software development, ensuring alignment with business goals.
- **API Documentation**:
  - **Document**: API Documentation - Algorithmic Trading System
  - **Location**: /docs/09. API Documentation - Algorithmic Trading System.md
  - **Description**: Details all APIs (REST, GraphQL, WebSocket, gRPC) for system interactions, including endpoints, schemas, and usage examples.
- **Test Plan and Test Cases**:
  - **Document**: Comprehensive Test Plan and Test Cases - Algorithmic Trading System
  - **Location**: /docs/10. Comprehensive Test Plan and Test Cases - Algorithmic Trading System.md
  - **Description**: Provides a comprehensive test plan with detailed test cases for unit, integration, and end-to-end testing across all phases.
- **Configuration Management**:
  - **Document**: Configuration Management Plan - Algorithmic Trading System
  - **Location**: /docs/11. Configuration Management Plan - Algorithmic Trading System.md
  - **Description**: Defines processes for managing system configurations, version control, and dependency updates.
- **Data Flow**:
  - **Document**: Data Flow Document - Algorithmic Trading System
  - **Location**: /docs/12. Data Flow Document - Algorithmic Trading System.md
  - **Description**: Maps data flows across system components, including Kafka event streams, database interactions, and API calls.
- **Deployment Guide**:
  - **Document**: Deployment Guide - Algorithmic Trading System
  - **Location**: /docs/13. Deployment Guide - Algorithmic Trading System.md
  - **Description**: Provides step-by-step instructions for deploying the system, including Kubernetes, Helm, and Istio configurations.
- **User Documentation**:
  - **Document**: User Documentation - Algorithmic Trading System
  - **Location**: /docs/14. User Documentation - Algorithmic Trading System.md
  - **Description**: Offers user guides, tutorials, and FAQs for platform users, covering trading, strategy building, and marketplace interactions.

**Usage Instructions:**

- The above-mentioned documents must be referenced for each phase's implementation, ensuring alignment with requirements, designs, and tasks.
- Use /docs/complete_requirements.md, /docs/complete_designs.md, and /docs/complete_tasks.md as primary references for phase-specific details.
- Cross-reference /docs/comprehensive_system_architecture.md for architectural guidance and /docs/01. Features, Phases & Integration Strategy - Algorithmic Trading System.md for overarching feature and integration strategies.
- For specific documentation needs (e.g., APIs, testing, deployment), refer to the respective specialised documents.
- Maintain traceability by linking code, configurations, and tests to document IDs and requirements (e.g., // @REFERENCE: req ID, doc path).
- **Acknowledge:** Confirm that you have understood this directive and are ready to begin development.

**Phase 0**

**Phase 0: Dependency Management Setup Prompt**

- **Objective:**
  - To establish a foundational, automated dependency management framework that proactively monitors, updates, and integrates over 70+ external open-source repositories and best-of-breed components (e.g., NautilusTrader, Apache Kafka, LangChain, LangGraph, TradingAgent, OpenBB, TA-Lib/ta-lib-python & Bukosabino/ta, VectorBT, TradingGym, PyPortfolioOpt, Riskfolio-Lib, PyOD, Blockly, react-financial-charts, Plotly Dash, SHAP, FinRL, Transformers, PyTorch, QuantLib, Stock-Prediction-Models, LSTM-Neural-Network-for-Time-Series-Prediction, Real-time-stock-market-prediction, Unstructured.io, PostgreSQL/pgvector, ClickHouse, Redis, Neo4j, Apache Iceberg, Qdrant, \[_DuckDB, InfluxDB, MinIO/S3, Elasticsearch, Apache Cassandra, MongoDB_\], Kubernetes, Docker, Istio, NGINX, Prometheus, Grafana, Jaeger, Loki, Unleash, Bandit, Whisper, WebXR, Lobe Chat, OpenHands, Kilo Code, Archon, Feast/Tecton, QuickFIX/J, FIX8, and others as identified in the comprehensive system architecture). This phase ensures long-term system stability, security, compliance, and scalability by categorising dependencies into tiers based on criticality, forking repositories for customisations, implementing automated monitoring and update pipelines, and integrating with CI/CD workflows. The framework minimises manual overhead, detects vulnerabilities early, assesses update impacts, and maintains control over integrations critical to the algorithmic trading system's modular, event-driven, cloud-native architecture. It aligns with the "Best-of-Breed" philosophy, supporting technology diversity, fault isolation, and automated self-healing while preparing for subsequent phases by ensuring all dependencies are versioned, tested, and documented.
- **Key Tasks:**
  - **Repository Forking and Tiered Organisation:**
    - Create Wrappers for all the 80+ external repositories, organised by criticality tiers: Tier 1 (Critical: e.g., NautilusTrader, Apache Kafka, LangGraph, TradingAgent - core to trading engine and AI workflows); Tier 2 (Important: e.g., PyPortfolioOpt, Riskfolio-Lib, FinRL, PyOD - essential for portfolio/risk/ML); Tier 3 (Supporting: e.g., Blockly, Lobe Chat, Whisper, WebXR - for no-code/UI/AI interfaces); Tier 4 (Infrastructure: e.g., Kubernetes, Docker, Istio, Prometheus - for deployment/monitoring).
    - Establish branch protection rules (e.g., require at least 2 approvals, code owners, restricted pushes to main), access controls (RBAC via GitHub teams: core-devs for Tier 1, support-devs for Tier 3), and metadata inventory (e.g., JSON file tracking tier, customisations needed, integration points).
    - Track customisations in forked repos (e.g., Rust enhancements in NautilusTrader for latency, volume-weighted indicators in TA-Lib) with detailed commit messages, PR descriptions, CHANGELOG.md, and Git diff tools for traceability.
  - **Automated Update Monitoring System:**
    - Configure GitHub Actions workflows for tiered monitoring: daily for Tier 1/2 (real-time alerts for CVEs/breaking changes), weekly for Tier 3/4 (batch summaries).
    - Integrate tools like Renovate for detecting upstream updates, Dependabot/TruffleHog for vulnerabilities (CVSS scoring, CVE database integration), and semantic versioning analysis.
    - Perform automated impact assessment: classify severity (critical/high/medium/low) based on changelogs, compatibility checks (e.g., API contracts for NautilusTrader), security scans, and performance benchmarks (e.g., backtesting speed regressions).
    - Handle breaking changes with migration path generation (e.g., detailed reports for affected microservices like Trading Engine with NautilusTrader updates).
    - Implement fallback mechanisms for monitoring failures (e.g., redundant scanners, manual alert triggers).
  - **Tiered Monitoring and Notification Strategy:**
    - Define monitoring priorities: Tier 1 with immediate notifications (e.g., Slack/Email/Teams for NautilusTrader CVEs), Tier 2 with standard daily alerts, Tier 3/4 with weekly summaries.
    - Consolidate notifications into weekly reports (single message across tiers, including updates, impacts, recommended actions) delivered via multi-channels (Slack, Email, GitHub Issues, Microsoft Teams) with user/role preferences.
    - Escalate critical issues (e.g., high-severity vulnerabilities in Tier 1) to Change Control Board (CCB) via high-priority channels.
    - Include severity classification and remediation guidance (e.g., automated PRs for patches where feasible).
  - **Update Integration Pipeline:**
    - Create automated CI/CD pipelines (GitHub Actions) for update PRs: trigger unit/integration tests (Pytest), performance benchmarks (Locust for load), and end-to-end validations (e.g., backtesting with updated VectorBT).
    - Use Docker-based isolated environments for testing (e.g., sandboxes per tier with mock data for trading components like Kafka events or market feeds).
    - Automate merges for non-critical tiers (post-test pass), require manual approval for Tier 1; implement rollback PRs on failures with error reports/suggested fixes.
    - Validate integration points (e.g., API contracts for LangGraph in AI workflows) and run system-wide regression tests to detect unintended impacts.
  - **Dependency Health Dashboard:**
    - Build a centralised web dashboard (React 18/Next.js integrated with Grafana) displaying real-time status: version, last update, vulnerabilities, health metrics (uptime/latency for API deps), and visual indicators (red/yellow/green).
    - Support filters (tier/component/severity) and drill-downs (e.g., historical trends, PDF exports).
    - Pull data from Renovate, CVE databases, GitHub APIs, and Prometheus for metrics.
  - **Security and Customisation Integration:**
    - Integrate Bandit for SAST on Python code in forks/customisations.
    - Ensure customisations (e.g., hierarchical Kafka topics, Schema Registry schemas) are versioned semantically and documented for compatibility.
    - Prepare for cloud-native alignment: containerisation checks for Docker/Kubernetes deps.
  - **Architectural Principles**
    - **Microservices Architecture:** Design all components as independently deployable services.
    - **Event-Driven Architecture:** Use Apache Kafka as the central event bus for asynchronous communication between services.
    - **Cloud-Native Design:** Ensure all services are containerised with Docker and orchestrated via Kubernetes.
    - **API-First Design:** Expose functionality through well-defined APIs, including REST (with versioning), GraphQL, WebSocket, and gRPC.
  - **Placeholder and Incremental Development Protocol:**
    - Enforce placeholder tagging (// @PLACEHOLDER: reason, missing functionality, requirement ID) with GitHub Issues creation (labeled "Technical-Debt", "Placeholder").
    - Follow incremental protocol: analyse existing codebase against specs, compare, execute modifications/builds.
    - **Directive on Handling Placeholders:**

To ensure transparency and prevent incomplete work from being marked as complete, you MUST adhere to the following protocol whenever a feature cannot be fully implemented in a single step and requires a placeholder.

- **Logging Protocol for AI Agents:**
- **Identify and Tag:** You must explicitly identify any code, configuration, or feature that is a placeholder. A standardised, searchable tag MUST be used in the code:

// @PLACEHOLDER:.

- **Detailed Comments:** The tag must be followed by a detailed comment explaining: Reason, Missing Functionality, and Requirement ID.

**Reason:** Why a placeholder is being used (e.g., "waiting on dependent API," "complex logic requires further refinement").

**Missing Functionality:** What the final implementation should do.

**Requirement ID:** A reference to the specific task or requirement ID from the project documentation.

- **Automated Ticket Creation:** Upon creating a placeholder, you MUST programmatically create a new ticket in the project's issue tracking system (e.g., GitHub Issues, Jira). The ticket must:

Have a title prefixed with "\[PLACEHOLDER\]".

Contain the reason, missing functionality, and requirement ID.

Be automatically tagged with "Technical-Debt" and "Placeholder".

Be assigned to the "Placeholder Review" backlog.

- **Status Reporting:** You must NOT mark a task involving a placeholder as "completed". Report it as "partially complete with placeholder created" and reference the new ticket number.
- **Expected Outcome:** A fully operational dependency management system that automates monitoring, updates, and integrations, ensuring the platform's foundation is stable, secure, and ready for subsequent development phases. This includes forked repositories with customisations, automated workflows, a health dashboard, and documentation for all tiers.
- **Deliverables:** Tiered forked repositories with protection rules; automated GitHub Actions workflows for monitoring/updates; multi-channel notification system with weekly reports; CI/CD integration pipelines with Docker test environments; dependency health dashboard; comprehensive documentation (e.g., /docs/comprehensive_dependency_workflow.md); validated system with initial scans and mock updates.

**Integration Plan - Phase 0: Dependency Management Setup**

- **Objective:**
  - To create a proactive, automated system for managing dependencies across the algorithmic trading platform's 80+ best-of-breed components, ensuring stability, security, and seamless integration into the microservices architecture. This plan outlines the setup of forked repositories, tiered monitoring, update pipelines, notifications, and a health dashboard, aligning with event-driven (Kafka), cloud-native (Kubernetes/Docker), and API-first principles while supporting customisations (e.g., volume-weighted indicators in TA-Lib, Rust paths in NautilusTrader).
- **Key Tasks:**
  - **Initialise Master Repository and Inventory:**
    - Set up the master Git repository with modular structure (/nautilus_trader_engine, /ai_assistant, /frontend, /market_data_service, /risk_manager, /portfolio_manager, /oms, /market_scanner, /agentic_ai, /security, /docs, /infrastructure).
    - Create an inventory metadata file (e.g., dependencies.json) listing all 60+ components with attributes (tier, upstream URL, customisation needs, integration points like API contracts or Kafka topics).
    - Configure Git hooks for pre-commit validations (linting with flake8, security scans with Bandit) and branch protection (require reviews, code owners).
  - **Create Wrappers and Organise Repositories:**
    - Create Wrappers of the repositories into tiers as defined, creating private forks for control (e.g., Tier 1: NautilusTrader for trading core; Tier 4: Istio for service mesh).
    - Set up access controls (GitHub teams integrated with Keycloak for SSO) and branch management (e.g., feature/update-nautilustrader-v2).
    - Document customisations (e.g., CHANGELOG.md for Kafka enhancements in OpenHands, event sourcing integrations) and track with Git tags.
  - **Implement Automated Monitoring Workflows:**
    - Develop GitHub Actions yaml workflows for tiered scans: parallel execution with failure handling, using Renovate for update detection and Dependabot for vulnerabilities.
    - Integrate compatibility checks (e.g., Rust/Python interop in NautilusTrader) and impact analysis (e.g., breaking API changes affecting Trading Engine).
    - Add Schema Registry validation for Kafka-related deps to ensure data consistency.
  - **Set Up Notification and Reporting System:**
    - Implement multi-channel delivery (Slack, Email, Teams, GitHub Issues) with configurable thresholds and escalation (e.g., CCB for Tier 1 issues).
    - Generate consolidated weekly reports (PDF exports via Grafana) summarising changes, impacts (e.g., "NautilusTrader v2.1.0: breaking change, migration required"), and actions.
    - Log notifications to Elasticsearch for auditing.
  - **Build Update Integration Pipeline:**
    - Create CI pipelines triggering on PRs: run Pytest/unit tests, integration tests (e.g., AI Assistant with updated LangGraph), benchmarks (e.g., latency for NautilusTrader).
    - Use Docker Compose for isolated sandboxes (e.g., mock Kafka for event-driven tests, historical data for backtesting).
    - Automate conflict resolution (Git merge tools), rollbacks, and end-to-end tests (e.g., parity between backtest/live with TradingGym).
  - **Develop Dependency Health Dashboard:**
    - Use React 18/Next.js frontend pulling from backend APIs (FastAPI) connected to Prometheus/Grafana.
    - Features: Interactive graphs (dependency trees), real-time alerts, manual controls (e.g., approve updates), historical trends.
    - Integrate with CVE databases and GitHub APIs for live data.
  - **Incorporate Security and Customisation Tracking:**
    - Run Bandit SAST on forks, integrating results into dashboard.
    - Track customisation drift (e.g., upstream vs. fork diffs) and ensure alignment with architecture principles (e.g., fault isolation tests for deps).
  - **Validate and Test the System:**
    - Run mock updates/vulnerabilities to test workflows end-to-end.
    - Ensure placeholder protocol: Scan code for tags, create Issues automatically via Actions.
    - Align with incremental development: Workflows include analysis steps (e.g., diff against specs).
  - **Enhance monitoring with agent-specific metrics and distributed tracing via Jaeger/Tempo.**
- **Deliverables:** Operational forked repositories with tiers and customisations; automated monitoring workflows and pipelines; notification system with reports; integration testing environments; dependency health dashboard; full documentation including workflow diagrams (Mermaid for flows like update pipeline); validated system with test reports.
- **Acknowledge:** Confirm that you have understood this directive and are ready to begin development.

**Phase 1**

**Phase 1: Immediate Priority - Core System Validation & Hardening Prompt**

- **Objective:**
  - To validate and harden the foundational core system of the algorithmic trading platform, ensuring seamless integration of the NautilusTrader trading engine with Interactive Brokers (IBKR) for paper trading, implementation of multi-source data feeds with fallback mechanisms, custom volume-weighted technical indicators, comprehensive API interfaces, database configurations, Apache Kafka event bus with hierarchical topics and Schema Registry, enterprise-grade security measures (including zero-trust architecture, RBAC, MFA, encryption, SAST with Bandit, and STRIDE threat modelling), and a formalised backup strategy. This phase focuses on achieving research-to-production parity, high performance (microsecond-level latency), resilience (fault isolation, self-healing prep), and observability, while supporting multi-asset classes (stocks, ETFs, futures, options, forex, commodities, crypto) and preparing for live trading transitions. It incorporates custom features like volume-weighted indicators (e.g., VW SMA, VW EMA, VW MACD, Normalised ATR, Choppy Market Index, Buy/Sell Easier Day) built with TA-Lib/ta-lib-python & Bukosabino/ta and NumPy, fully integrated into NautilusTrader for strategy development, backtesting, and analysis. The hardening ensures compliance with regulations (e.g., MiFID II, SOX, GDPR) through immutable event logging and audit readiness, aligning with the "Best-of-Breed" philosophy, microservices decomposition, event-driven architecture (async communication, event sourcing, CQRS), cloud-native design (container-first, Kubernetes prep, 12-Factor App, IaC), and API-first principles (REST, GraphQL, WebSocket, gRPC). This phase builds on Phase 0's dependency management, validating forked components (e.g., NautilusTrader in Tier 1) in isolated environments.
- **Key Tasks:**
  - **Configure NautilusTrader for Paper Trading Integration:**
    - Integrate NautilusTrader's pre-built IBKR adapter to connect to a paper trading account, supporting multi-asset classes with order routing, execution, position management, and trade settlement.
    - Implement seamless switching between paper and live modes in a prototype interface (e.g., basic Next.js dashboard), ensuring compliance with broker requirements (e.g., API keys, authentication tokens managed via HashiCorp Vault).
    - Validate end-to-end pipeline: Fetch data, run a simple pre-built algorithm from NautilusTrader library, generate results, and log events to Kafka for replayability.
    - Test with mock data for all asset classes, measuring latency (<100μs for executions) and throughput (1M TPS prep).
  - **Implement Multi-Source Data Feeds with Fallback Mechanism:**
    - Set up primary (Yahoo Finance) and fallback providers (Alpha Vantage, Finnhub, Investing.com, CME Group, Twelve Data, Polygon, Barchart, SpiderRock, TradingCharts, Oanda) per asset class, using Kafka to stream normalised data.
    - Configure asset-specific chains: e.g., Stocks/ETFs (Yahoo → IBKR → Alpha Vantage → Finnhub → Twelve Data → Polygon); Options (Yahoo → IBKR → Cboe → SpiderRock); ensure automatic switching on failure (e.g., timeout >3s, error codes) with logging to Elasticsearch.
    - Support historical data (free sources for paper, 5+ years depth for options chains) and real-time (IBKR subscriptions post-validation, including implied volatility surfaces and dividend forecasts via QuantLib).
    - Normalise data formats (e.g., unified tick/bar structures) and distribute via Kafka topics for consumption by services like Market Data Service.
  - **Develop Custom Technical Analysis Indicators:**
    - Build a comprehensive suite of 30+ custom volume-weighted indicators and metrics using TA-Lib/ta-lib-python (primary wrapper) & Bukosabino/ta (secondary), NumPy for calculations, and integrate into NautilusTrader for use in strategies, backtesting, and analysis.
    - Indicators include: Beta vs. Market Index, Auto Correlation, Historical/Intraday Annual Volatility, VW SMA (55/13/5/34 Day of Open/High/Low), VW EMA (13 Day of Open, 5 Day of HLC), VW MACD (12/26/9 Day of HLC), VW MACD Histogram, VW MFI (14 Day of HLC), VW SMA of MFI (34/21 Day), Normalised ATR (21/8 Day VW for Positional/Intraday), Rupee/Dollar Volatility Risk, Contract Risk (2N/0.75N Units), Max Lots per Unit Risk, ATR Percent (21/8 Day), Strength/Weakness (21/8 Day Avg HLC & ATR), SMA Average % Change (8/13/21 Day), Buy/Sell Easier Day, Choppy Market Index (21/8 Day), Market Mode (Trending/Choppy), High Low Range Average for ORB.
    - Validate calculations with unit tests (Pytest) against historical data, ensure GPU acceleration compatibility with VectorBT, and expose via Analytics Service APIs.
  - **Implement LangGraph state machines for early AI coordination hooks.**
  - **Build API Interfaces:**
    - Implement RESTful APIs (FastAPI) for standard operations (e.g., /v1/orders for placement), GraphQL (Apollo) for flexible queries (e.g., portfolio metrics with nested risks), WebSocket (Socket.IO) for real-time streams (e.g., market data, order updates), and gRPC for high-performance inter-service calls (e.g., Trading Engine to Risk Manager).
    - Include versioning, error handling (e.g., 429 for rate limits), and documentation (OpenAPI/Swagger).
    - Test APIs with Postman collections for coverage, ensuring <10ms latency at gateway.
  - **Configure Databases and Data Layer:**
    - Implement 4 core databases: PostgreSQL+pgvector (transactional/vectors), ClickHouse (time-series), Neo4j (knowledge graph), and Redis (caching/GenAI vectors), consolidating from multiple specialized systems.
    - Add other databases at a later stage as and when required:
      - Set up PostgreSQL/pgvector for structured data/user metadata/vector embeddings (e.g., strategy similarity searches), ClickHouse for time-series analytics/reports, Qdrant for vector storage/semantic search, Apache Iceberg for immutable audits/long-term tables, Redis for caching/sessions/GenAI vectors/Pub/Sub, DuckDB for OLAP research queries, InfluxDB for metrics/real-time analytics, MinIO/S3 for object storage (models/datasets), Elasticsearch for search/logs/metrics/RAG, Apache Cassandra distributed NoSQL for high availability, MongoDB document-based NoSQL for flexible schemas, and Neo4j graph database for relationship modelling.
      - Define schemas (e.g., Postgres tables for orders/users), indexing (e.g., HNSW in Qdrant), partitioning (e.g., by date in Iceberg), and integrations (e.g., Kafka Connect for streaming to ClickHouse).
      - Validate queries/performance: <20ms for Postgres, sub-second for ClickHouse on billions of rows.
  - **Set Up Apache Kafka Event Bus:**
    - Configure Kafka with hierarchical topics (e.g., trading.order.placed.ibkr.aapl.us) and wildcard subscriptions for flexible routing.
    - Integrate Schema Registry for data schemas/serialisers (Avro/Protobuf), ensuring compatibility with event sourcing and CQRS.
    - Test event streaming: Produce/consume events for trades, measure throughput (>1M msgs/sec), and replay for backtesting.
  - **Implement Enterprise-Grade Security:**
    - Adopt zero-trust architecture with RBAC (Keycloak for roles), MFA (enforced for all logins), AES-256 encryption at rest (databases), TLS 1.3 in transit (Istio mTLS).
    - Run Bandit for SAST on all Python code, integrate into CI.
    - Perform STRIDE threat modeling for all components (e.g., Spoofing mitigation via OAuth2, Tampering via immutable events).
    - Design error recovery patterns with agent health checks and rollback procedures.
    - Set up formalised backup strategy: Daily full/hourly incremental for databases (e.g., pg_dump for Postgres, replicas for ClickHouse), snapshots for Kafka topics to MinIO, with recovery testing (RTO <15min, RPO <5min).
  - **Test the Core Engine and Overall System:**
    - Run a simple NautilusTrader algorithm to validate pipeline: Fetch data via feeds, execute backtest, generate results.
    - Conduct end-to-end tests for integrations (e.g., paper trading flow, indicator usage in strategies).
    - Measure key metrics: Latency, throughput, resilience (simulate failures).
  - Implement **microservice self-healing** mechanisms.
  - **Enhance monitoring with agent-specific metrics and distributed tracing via Jaeger/Tempo.**
  - **Placeholder and Incremental Development Protocol:**
    - Use placeholders for incomplete parts (// @PLACEHOLDER: reason, missing functionality, req ID), auto-create GitHub Issues.
    - Follow incremental protocol: Analyse specs vs. code, compare diffs, execute builds.
- **Expected Outcome:** A validated, hardened core system with integrated NautilusTrader for paper trading, robust data feeds, custom indicators, APIs, databases, Kafka bus, and security measures, ready for frontend and AI integrations in subsequent phases. The system achieves high performance, resilience, and security benchmarks, with full test coverage.
- **Deliverables:** Configured NautilusTrader with IBKR paper integration; multi-source data feeds with fallbacks; custom indicators suite with tests; API implementations (REST/GraphQL/WebSocket/gRPC) with docs; database setups with schemas; Kafka with topics/Schema Registry; security features (zero-trust, Bandit scans, threat models, backups); core engine test reports; comprehensive documentation (e.g., architecture diagrams in Mermaid, setup guides); validated system with benchmarks.

**Integration Plan - Phase 1: Immediate Priority - Core System Validation & Hardening**

- **Objective:**
  - To integrate and validate the core components of the algorithmic trading platform, hardening them for performance, security, and reliability. This plan focuses on NautilusTrader setup with IBKR paper trading, data feed fallbacks, custom technical indicators, API layers, database configurations, Kafka event bus, security hardening (zero-trust, encryption, threat modelling), and backups, ensuring alignment with microservices, event-driven, cloud-native, and API-first principles. It prepares the foundation for high-frequency trading across assets, with custom features like volume-weighted indicators and event replayability.
- **Key Tasks:**
  - **NautilusTrader Integration for Paper Trading:**
    - Use NautilusTrader's IBKR adapter to connect to paper accounts, implementing order management and mode switching.
    - Develop prototype interface (Next.js) for toggling modes, ensuring broker compliance (e.g., API rate limits).
    - Test pipeline with a sample algorithm: Data fetch → backtest → results, logging events to Kafka.
  - **Multi-Source Data Feed and Fallback Implementation:**
    - Configure providers with Kafka streaming: Primary Yahoo, asset-specific fallbacks (e.g., logic in Python/Go service to switch on failure).
    - Normalise data and handle historical/real-time (IBKR for live prep), including options data requirements (IV surfaces via QuantLib).
    - Test uninterrupted availability: Simulate failures, measure switch time (<1ms), validate with multi-asset mocks.
  - **Custom Technical Analysis Development:**
    - Implement technical indicators in Python (TA-Lib/NumPy), with functions for each (e.g., vw_sma(prices, volumes, period)).
    - Integrate into NautilusTrader (e.g., as strategy modules), test accuracy against historical data (Pytest suites).
    - Expose via Analytics Service for use in backtesting/scanning.
  - **Develop Custom Volume-Weighted Indicators:**
    - Implement and validate the specified list of custom volume-weighted indicators and integrate them into the NautilusTrader strategy framework.
  - **API Interfaces Setup:**
    - Build REST (FastAPI endpoints), GraphQL (schemas for queries), WebSocket (real-time handlers), gRPC (proto files for services).
    - Include auth (OAuth2 via Keycloak), versioning, and integration tests (e.g., gRPC for low-latency calls).
  - **Database Configuration:**
    - Implement 4 core databases: PostgreSQL+pgvector (transactional/vectors), ClickHouse (time-series), Neo4j (knowledge graph), and Redis (caching/GenAI vectors), consolidating from multiple specialised systems.
    - Add other databases at a later stage as and when required:
      - Provision and schema-define all databases: Postgres/pgvector (tables/indexes), ClickHouse (MergeTree engines), Qdrant (collections), Iceberg (tables with partitioning), Redis (keys/TTL), DuckDB (embedded), InfluxDB (buckets), MinIO (buckets/versioning), Elasticsearch (indices/mappings), Apache Cassandra (NoSQL), MongoDB (NoSQL), and Neo4j (graph).
      - Integrate with services (e.g., JDBC/ODBC drivers), test queries (e.g., vector searches in pgvector/Qdrant).
  - **Apache Kafka Event Bus Configuration:**
    - Set up clusters with hierarchical topics/wildcards, Schema Registry (Avro schemas for events).
    - Implement producers/consumers in services, test streaming/replay (e.g., trade events).
  - **Security Hardening:**
    - Implement zero-trust (network policies, mTLS), RBAC/MFA (Keycloak), encryption (AES/TLS).
    - Run Bandit SAST in CI, document STRIDE models per component.
    - Formalise backups: Scripts for snapshots (e.g., Velero for K8s), test restores.
  - **Implement Microservice Self-Healing:**
    - Develop and deploy automated self-healing mechanisms at the individual microservice level to improve system resilience.
  - **Core System Testing and Validation:**
    - End-to-end tests: Paper trading flows, indicator usage, API calls, data fallbacks.
    - Benchmarks: Latency/throughput, resilience (failure injections).
    - Use placeholders for future features, follow incremental protocol.
- **Deliverables:** Integrated NautilusTrader with paper trading; data feeds/fallbacks; custom indicators code/tests; API code/docs; database schemas/configs; Kafka setup; security implementations/models/backups; test reports/benchmarks; updated documentation (diagrams, guides).
- **Acknowledge:** Confirm that you have understood this directive and are ready to begin development.

**Phase 2**

**Phase 2: Frontend and Broker Integration Prompt**

- **Objective:**
  - To develop a unified, multi-platform frontend that provides an intuitive user interface for trading, strategy management, and analytics, while integrating broker APIs for seamless paper trading operations. This phase builds on Phase 1's core validation by introducing a broker abstraction layer (starting with Interactive Brokers for paper trading, with extensibility for live and additional brokers like Alpaca), a "no-code to clean code" pipeline using Blockly for strategy building, an AI-powered shell via Lobe Chat for natural language interactions, real-time data streaming via WebSocket, and basic dashboards for portfolio and risk visualisation. The frontend supports diverse users: non-technical (no-code/low-code tools, natural language commands) and professionals (advanced charting, real-time metrics). It incorporates custom volume-weighted indicators from Phase 1 (e.g., VW SMA, VW MACD, Normalised ATR, Choppy Market Index) into interactive visualisations (TradingView, Plotly Dash, react-financial-charts), ensures cross-platform consistency (web via React 18/Next.js/TypeScript, mobile via React Native with voice/biometrics, desktop via Electron, PWA for offline), and aligns with the system's "Best-of-Breed" philosophy, microservices architecture (e.g., API calls to Trading Engine/Risk Manager), event-driven design (WebSocket subscriptions to Kafka streams), cloud-native principles (responsive design, container-ready), API-first (consume REST/GraphQL/WebSocket/gRPC endpoints), security (MFA, RBAC integration, input validation), and performance (real-time updates <1s latency). This phase validates paper trading flows end-to-end, prepares for live transitions, and ensures research-to-production parity with seamless backtesting-to-trading workflows.
- **Key Tasks:**
  - **Develop Multi-Platform Frontend:**
    - Implement frontend monorepo with shared React components for consistency.
    - Build the web dashboard using React 18/Next.js/TypeScript for responsive, server-side rendered interfaces, including trading views (order placement/modification/cancellation), portfolio monitoring, risk dashboards, and market scanner grids.
    - Develop and integrate a real-time **Market Scanner Service**.
    - Implement mobile app with React Native, supporting voice mode (LLM integration for commands), biometrics (e.g., fingerprint for auth), push notifications (trade alerts via Firebase), and offline capabilities (e.g., cached portfolio snapshots in Redis).
    - Create desktop app using Electron for advanced features like local backtesting (VectorBT integration) and multi-monitor support, ensuring cross-platform consistency with shared components (e.g., React hooks for state management).
    - Enable Progressive Web App (PWA) features for web-to-mobile bridging, including offline access to historical data (stored in IndexedDB, synced from DuckDB/ClickHouse).
    - Integrate visualisation tools: TradingView for charting with custom indicators (e.g., overlay VW EMA on real-time data), Plotly Dash for interactive analytics (e.g., performance attribution), react-financial-charts for financial-specific plots.
  - **Integrate Broker Abstraction Layer for Paper Trading:**
    - Develop a modular broker abstraction layer in Python (e.g., abstract base class with adapters) starting with Interactive Brokers for paper trading, normalising APIs (e.g., order types: Market/Limit, data formats) for multi-asset support.
    - Enable paper trading operations: Connect to IBKR paper accounts, execute/test strategies in risk-free mode, monitor positions/trades via UI.
    - Expand abstraction for future brokers (e.g., placeholders for Alpaca), ensuring seamless mode switching (paper/live) without UI reloads.
    - Validate integration: Simulate trades across assets, test fallback data feeds (e.g., switch from Yahoo to Alpha Vantage on failure), measure execution latency (<5ms for API calls).
  - **Implement "No-Code to Clean Code" Pipeline with Blockly:**
    - Integrate Blockly for visual strategy building (drag-drop blocks for indicators, conditions, actions), generating clean Python code compatible with NautilusTrader strategies.
    - Create a pipeline to convert Blockly XML to executable code (e.g., using AST for validation), incorporating custom indicators (e.g., blocks for VW MACD, Buy/Sell Easier Day).
    - Test pipeline: User builds no-code strategy → generate code → run backtest in TradingGym → display results in UI, with error handling (e.g., invalid logic alerts).
  - **Integrate AI-Powered Shell with Lobe Chat:**
    - Embed Lobe Chat as an AI shell for natural language interactions (e.g., "Build a strategy using VW SMA crossover"), linking to Agentic AI Assistant (LangChain/LangGraph) for command processing.
    - Support proactive features: e.g., chat suggests refinements based on backtest results, integrates with RAG for document-based queries (Unstructured.io parsing financial docs).
    - Ensure multi-platform compatibility: Voice input on mobile (Whisper transcription), AR overlays on desktop (WebXR for 3D strategy visuals).
  - **LobeChat Frontend Integration:**
    - Deploy LobeChat as the conversational UI for the AI Assistant, connecting to OpenHands/Kilo Code for coding tasks, RAGFlow for document queries, and the Intelligent Guidance System for recommendations.
    - Test voice input and WebSocket streaming.
  - **Set Up Real-Time Data Streaming with WebSocket:**
    - Implement WebSocket endpoints (Socket.IO) for real-time market data, order updates, and alerts, subscribing to Kafka topics for low-latency streaming (<1s updates).
    - Handle data from multi-source feeds (normalised in Phase 1), including custom indicators (e.g., live VW MFI calculations pushed to charts).
    - Test scalability: Simulate 10,000+ concurrent connections, ensure graceful degradation (e.g., rate limiting via NGINX).
  - **Develop Basic Dashboards and UI Components:**
    - Create dashboards for portfolio optimisation (PyPortfolioOpt visuals), risk monitoring (real-time VaR from Risk Manager), and analytics (Plotly for attribution).
    - Incorporate "Glass Box" prep: Basic event explorer for Kafka chains (trade timelines), with placeholders for sentiment trends/topic clouds.
    - Ensure security: MFA on login, RBAC for views (e.g., pro users see FIX settings), input sanitisation.
  - **Testing and Validation:**
    - Conduct E2E tests: Paper trading flow (UI order → broker exec → update dashboard), no-code pipeline (Blockly → code → backtest), AI shell commands.
    - Measure performance: UI latency (<200ms render), cross-platform consistency (Cypress tests).
    - Use placeholders for Phase 3+ features (e.g., full AI agents), follow incremental protocol (analyse specs vs. code).
- **Expected Outcome:** A fully functional multi-platform frontend integrated with broker APIs for paper trading, enabling users to build/execute strategies via no-code tools and natural language, with real-time streaming and basic dashboards. The system achieves seamless user experiences, high responsiveness, and preparedness for AI/ML enhancements.
- **Deliverables:** Multi-platform UI code (React/Next.js, React Native, Electron); broker abstraction layer with IBKR integration; Blockly no-code pipeline; Lobe Chat AI shell; WebSocket streaming implementation; basic dashboards with visualisations; test suites/reports (unit/integration/E2E); documentation (UI wireframes in Mermaid, API usage guides); validated paper trading flows with benchmarks.

**Integration Plan - Phase 2: Frontend and Broker Integration**

- **Objective:**
  - To integrate a responsive, multi-platform frontend with broker APIs for paper trading, incorporating no-code tools, AI interfaces, real-time streaming, and dashboards. This plan ensures cross-platform consistency, security, and performance while aligning with the system's microservices (e.g., API calls to core services), event-driven (WebSocket from Kafka), cloud-native (PWA/offline support), and API-first principles. It validates integrations from Phase 1 (e.g., custom indicators in charts) and prepares for live trading.
- **Key Tasks:**
  - **Frontend Development Across Platforms:**
    - Implement frontend monorepo with shared React components for consistency.
    - Use React 18/Next.js for web (SSR for SEO/performance), React Native for mobile (native modules for biometrics/voice), Electron for desktop (IPC for local compute), and service workers for PWA.
    - Share components (e.g., Redux for state, Material-UI for styling) to ensure consistency; integrate visualisations (TradingView for charts with VW indicators, Plotly for dashboards).
    - Integrated with Kilo Code extension for VS Code, enabling seamless launch from the web UI.
  - **Broker Abstraction and Paper Trading Integration:**
    - Build abstraction layer (Python service exposing gRPC/REST) normalising IBKR APIs; implement paper mode operations (order lifecycle, position sync).
    - Connect UI to abstraction: e.g., Next.js forms for orders, React Native screens for monitoring; test with simulated trades.
  - **No-Code to Clean Code Pipeline Implementation:**
    - Embed Blockly in UI (custom blocks for indicators/conditions), develop converter (XML → Python AST → NautilusTrader code).
    - Integrate with backtesting: Generated code → API call to Strategy Engine → results displayed in Plotly.
  - **AI Shell Integration with Lobe Chat:**
    - Embed Lobe Chat widget across platforms, route commands to Agentic AI (e.g., via GraphQL for workflows).
    - Test interactions: e.g., "Show VW MACD for AAPL" → fetch data → render chart.
  - **Real-Time WebSocket Streaming Setup:**
    - Implement server-side (FastAPI/Socket.IO) subscribing to Kafka, client-side handlers for updates (e.g., live ticks, indicator recalcs).
    - Secure with auth tokens, test under load (e.g., 5M msgs/sec simulation).
  - **Basic Dashboards and UI Enhancements:**
    - Develop components: Portfolio (rebalancing views), Risk (VaR gauges), Analytics (attribution charts).
    - Prep "Glass Box": Basic Kafka event viewer with timelines.
  - **Market Scanner Implementation:** Develop and integrate a real-time Market Scanner Service and corresponding UI, providing a powerful, customisable tool for opportunity discovery, similar to TradeStation's RadarScreen.
  - **Security and Testing:**
    - Add MFA/RBAC (Keycloak integration), validate inputs (e.g., OWASP checks).
    - E2E tests (Cypress for UI, Pytest for backend), benchmarks (latency/throughput).
- **Deliverables:** Complete frontend codebases; broker layer with tests; no-code pipeline; AI shell embed; WebSocket impl; dashboards; comprehensive tests/reports; updated docs (Mermaid UI flows).
- **Acknowledge:** Confirm that you have understood this directive and are ready to begin development.

**Phase 3**

**Phase 3: AI/ML Integration Prompt**

- **Objective:**
  - To integrate advanced AI and machine learning capabilities into the Nautilus Trader platform, enabling intelligent strategy development, predictive analytics, and autonomous decision-making. This phase builds on the validated core system (Phase 1) and frontend/broker integrations (Phase 2) by incorporating the Agentic AI Assistant powered by LangChain/LangGraph and TradingAgent for multi-agent workflows, a Retrieval-Augmented Generation (RAG) pipeline with Unstructured.io and Qdrant/Elasticsearch/Redis for semantic search, reinforcement learning (RL) via FinRL with an RLOps pipeline for iterative strategy optimisation, anomaly detection using PyOD integrated with User and Entity Behavior Analytics (UEBA), predictive models (Stock-Prediction-Models, LSTM-Neural-Network-for-Time-Series-Prediction, Real-time-stock-market-prediction), sentiment analysis with Transformers/PyTorch, and explainability via SHAP. It leverages custom volume-weighted indicators from Phase 1 (e.g., VW SMA, VW MACD, Normalised ATR, Choppy Market Index) for AI-driven strategies, ensures real-time inference (<1ms latency) with PyTorch/TensorFlow Serving, and integrates with the existing microservices architecture (Kafka event bus for async communication, API endpoints for inference), event-driven design (event sourcing for AI decisions), cloud-native principles (containerised ML services, Kubernetes orchestration), API-first approach (REST/GraphQL/gRPC for model access), and security (zero-trust, encrypted model storage in MinIO). The phase supports multi-asset classes, iterative refinement via AI feedback loops, and prepares for live trading and enterprise features, aligning with the "Best-of-Breed" philosophy and regulatory compliance (e.g., MiFID II, GDPR) through immutable audit trails.
- **Key Tasks:**
  - **Implement Agentic AI Assistant with Multi-Agent Framework:**
    - Integrate LangChain/LangGraph for stateful workflow orchestration, defining multi-agent systems (Analyst, Researcher, Risk, Compliance, Trader agents) using TradingAgent for collaborative decision-making (e.g., Analyst generates market insights, Trader executes orders).
    - Deploy and integrate the **AI Knowledge Hub (Archon)** as the central MCP server for developer agents.
    - Configure Message Control Points (MCPs) to manage agent interactions, routing commands via Kafka topics (e.g., ai.command.analyze, ai.response.trade).
    - Enable natural language interfaces via Lobe Chat (from Phase 2), supporting queries like "Optimise a VW MACD strategy for AAPL" with >90% accuracy in intent recognition.
    - Test multi-agent workflows: e.g., Researcher fetches news via RAG, Analyst predicts price impact, Trader executes mock trade.
  - **Develop RAG Pipeline for Semantic Search and Insights:**
    - Use Unstructured.io to parse unstructured data (news, SEC filings, social media) into embeddings, stored in Qdrant (HNSW indexing), Elasticsearch (KNN search), and Redis (fast vector retrieval).
    - Implement proactive retrieval for AI Assistant (e.g., auto-fetch relevant documents for market conditions), integrating with Kafka for real-time updates.
    - Validate search accuracy (>90% relevance) and latency (<50ms for vector queries).
    - Enhance the **Proactive RAG Intelligence Engine** with a dedicated "Researcher" agent.
      - Elevate the existing RAG pipeline in \`/ai_assistant\` from a reactive tool into a proactive intelligence engine.
      - Create a dedicated "Researcher" agent tasked with continuously monitoring external data sources (e.g., news feeds, SEC filing APIs), automatically processing new documents via RAGFlow, and updating the vector database (Qdrant or pgvector) in real-time.
      - This ensures all other agents are always accessing the most current, pre-processed knowledge base.
  - **Intelligent User Guidance System Integration:**
    - Develop a Tool Recommendation Engine that analyses user queries and session context to suggest 2-3 relevant tools from the platform's Tool Taxonomy, with explanations and confidence scores.
    - Implement a Next-Step Predictor using state machines and historical data to suggest subsequent actions after tool invocation, including rationale.
    - Create a structured Tool Taxonomy JSON cataloguing all platform features (e.g., NautilusTrader, VectorBT, Blockly, Market Scanner, etc.).
    - Integrate with RAG pipeline for grounding suggestions in platform documentation.
    - Use MCPs for maintaining user context across guidance sessions.
    - Broadcast recommendations as Kafka events for UI and analytics consumption.
  - **Backend AI Integrations:**
    - Connect LobeChat to OpenHands (core coding agent), Kilo Code (VS Code workflows via extension), RAGFlow (RAG pipeline), AI Assistant (agent orchestration), and Intelligent Guidance System (recommendations/next steps).
    - Use MCPs for coordination and Kafka for events.
  - **Integrate Reinforcement Learning with FinRL and RLOps:**
    - Deploy FinRL for RL-based strategy optimisation, training on historical data (ClickHouse/Iceberg) and custom indicators (e.g., VW MFI, Normalised ATR).
    - Build an RLOps pipeline: Automated training (PyTorch), model versioning (MinIO), drift detection (Prometheus metrics), retraining triggers (e.g., performance drop >5%), and monitoring (accuracy, reward metrics).
    - Test iterative refinement: RL model suggests strategy tweaks, backtests via VectorBT, updates code via OpenHands integration.
  - **Implement Anomaly Detection with PyOD and UEBA:**
    - Integrate PyOD for trade/market anomaly detection (e.g., outlier trades, market manipulations), achieving <5% false positives.
    - Develop UEBA module for behavioral analytics (e.g., detect unusual user trading patterns), combining PyOD with custom ML models, logging anomalies to Elasticsearch.
    - Expose alerts via Kafka to Risk Manager and dashboards (Grafana integration).
  - **Deploy Predictive Models for Forecasting:**
    - Integrate Stock-Prediction-Models, LSTM-Neural-Network-for-Time-Series-Prediction, and Real-time-stock-market-prediction for price forecasts across assets.
    - Optimise for real-time inference (<1ms) using PyTorch/TensorFlow Serving, with models stored in MinIO and cached in Redis.
    - Validate predictions against historical data (e.g., RMSE <2% on test sets).
  - **Add Sentiment Analysis with Transformers/PyTorch:**
    - Implement NLP pipeline using Transformers/PyTorch to analyse news, social media (e.g., X posts), and financial documents for sentiment (positive/negative/neutral).
    - Feed sentiment scores to AI Assistant and strategies, integrating with Kafka for real-time updates.
    - Ensure >90% accuracy in sentiment classification, validated with labeled datasets.
  - **Incorporate Explainability with SHAP:**
    - Use SHAP to provide explainable AI outputs for model predictions (e.g., feature importance for price forecasts), integrating with frontend dashboards (Plotly Dash).
    - Ensure transparency for regulatory compliance, logging explanations to Iceberg.
  - **Integrate AI/ML with Core System:**
    - Expose ML models via APIs (REST/GraphQL for queries, gRPC for low-latency inference) and Kafka events (e.g., ai.prediction.price.aapl).
    - Connect AI outputs to Trading Engine (e.g., RL strategy execution), Risk Manager (anomaly alerts), and Portfolio Manager (predictive allocations).
    - Connect AI agents to the trading engine and other services via the **Kafka event bus** and the API layer.
    - Test end-to-end flows: e.g., AI suggests trade → backtest → execute in paper mode.
  - Implement LangGraph state machines for multi-agent coordination and MCPs.
  - Add confidence scoring and smart HITL triggers for AI outputs.
  - Establish gradual LLM integration with evaluation criteria (response quality, latency, cost).
  - **Placeholder and Incremental Development Protocol:**
    - Use placeholders for incomplete features (e.g., // @PLACEHOLDER: Full marketplace integration, req ID), auto-create GitHub Issues.
    - Follow incremental protocol: Analyse specs vs. code, compare diffs, execute builds.
- **Expected Outcome:** A fully integrated AI/ML system enabling intelligent trading strategies, predictive analytics, anomaly detection, and explainable outputs, seamlessly connected to the core platform via APIs and Kafka. The system achieves high accuracy (>90% for predictions/sentiment), low latency (<1ms inference), and regulatory compliance, ready for frontend enhancements and live trading.
- **Deliverables:** Agentic AI Assistant with multi-agent workflows; RAG pipeline with embeddings; FinRL RLOps pipeline; PyOD/UEBA anomaly detection; predictive models (Stock-Prediction-Models, LSTM, Real-time); sentiment analysis pipeline; SHAP explainability integration; API/gRPC endpoints for ML; test suites (unit/integration/E2E); documentation (Mermaid diagrams for AI workflows, model guides); validated system with performance benchmarks.

**Integration Plan - Phase 3: AI/ML Integration**

- **Objective:**
  - To seamlessly integrate AI/ML components into the Nautilus Trader platform, enabling intelligent, autonomous trading capabilities. This plan ensures the Agentic AI Assistant, RAG pipeline, FinRL RLOps, PyOD/UEBA, predictive models, sentiment analysis, and SHAP explainability are fully connected to the microservices architecture (via Kafka and APIs), leveraging Phase 1's core system and Phase 2's frontend/broker integrations. It supports multi-asset strategies, real-time performance, and compliance, aligning with event-driven, cloud-native, API-first, and security-first principles.
- **Key Tasks:**
  - **Agentic AI Assistant Setup:**
    - Deploy LangChain/LangGraph with TradingAgent, defining agent roles (e.g., Analyst, Trader) and workflows (e.g., market analysis → trade execution).
    - Implement MCPs for agent coordination, using Kafka topics for async messaging (e.g., Avro-serialised commands).
    - Integrate with Lobe Chat (Phase 2), test NLP queries (e.g., "Run VW MACD strategy") with UI interactions.
  - **Event-Driven Agent Communication:**
    - Refactor the Agentic AI Assistant's architecture to ensure all inter-agent communication is managed asynchronously through the Kafka event bus, defining a clear and extensible event schema for agent interactions.
  - **Inference Engine:**
    - Establish a high-performance, real-time model inference engine (e.g., TensorFlow Serving, PyTorch) targeting sub-millisecond latency.
  - **Deploy and Integrate AI Knowledge Hub (Archon):**
    - Implement Archon as the central Model Context Protocol (MCP) server.
    - Ingest documentation for critical Tier 1 components (NautilusTrader, Kafka) into its knowledge base and connect the Kilo Code and OpenHands agents to use it for context-aware task execution in a sandboxed environment.
  - **AI-Assisted Development Agent (Kilo Code):**
    - Integrate Kilo Code extension for VS Code workflows, supporting code generation, refactoring, debugging, and test coverage in Python Studio.
    - It replaces Codename Goose for better IDE integration, with MCP support for tool extensions. Test multi-mode operations for strategy optimisation.
    - Kilo Code automates multi-step DevOps in VS Code, such as pipeline fixes and strategy optimisation
  - **RAG Pipeline Implementation:**
    - Configure Unstructured.io for data parsing (news, filings), generate embeddings, store in Qdrant/Elasticsearch/Redis.
    - Build retrieval logic for AI Assistant, integrate with Kafka for real-time document updates, test latency/accuracy.
  - **Intelligent User Guidance System Integration:**
  - **FinRL and RLOps Deployment:**
    - Set up FinRL environment, train RL models on historical data (ClickHouse) with custom indicators.
    - Implement RLOps: Training pipeline (PyTorch, Kubernetes jobs), versioning (MinIO), monitoring (Prometheus), retraining logic.
    - Test RL strategies: Backtest via VectorBT, refine via OpenHands.
  - **Anomaly Detection with PyOD/UEBA:**
    - Integrate PyOD for trade anomalies, build UEBA module for user behavior (Python service with ML models).
    - Route alerts to Kafka, visualise in Grafana, log to Elasticsearch.
  - **Predictive Models Setup:**
    - Deploy Stock-Prediction-Models, LSTM, and Real-time-prediction models, optimise for inference (PyTorch Serving).
    - Store models in MinIO, cache in Redis, test predictions (RMSE <2%).
  - **Sentiment Analysis Pipeline:**
    - Build Transformers/PyTorch pipeline for sentiment, process external data (e.g., X posts), integrate with Kafka.
    - Test accuracy (>90%) with labeled datasets, expose to strategies/AI Assistant.
  - **SHAP Explainability Integration:**
    - Implement SHAP for model outputs, integrate with Plotly Dash for visualisations.
    - Log explanations to Iceberg for compliance, test clarity in UI.
  - **Core System Integration:**
    - Expose AI/ML via APIs (FastAPI REST, Apollo GraphQL, gRPC) and Kafka events.
    - Connect to Trading Engine (strategy execution), Risk Manager (alerts), Portfolio Manager (allocations).
    - Test E2E flows: AI-driven trade suggestion → backtest → paper execution.
  - Implement LangGraph state machines for multi-agent coordination and MCPs.
  - Add confidence scoring and smart HITL triggers for AI outputs.
  - Establish gradual LLM integration with evaluation criteria (response quality, latency, cost).
  - **Testing and Validation:**
    - Run unit tests (Pytest for models), integration tests (API/Kafka), E2E tests (full AI-driven trade flow).
    - Measure performance: Inference latency (&lt;1ms), prediction accuracy (&gt;90%).
    - Use placeholders for future features, follow incremental protocol.
- **Deliverables:** Deployed AI/ML components (Agentic AI, RAG, FinRL, PyOD/UEBA, predictive models, sentiment, SHAP); API/Kafka integrations; test suites/reports; documentation (Mermaid for workflows, guides); validated system with benchmarks.
- **Acknowledge:** Confirm that you have understood this directive and are ready to begin development.

**Phase 4**

**Phase 4: Frontend & Live Trading Prompt**

- **Objective:**
  - To enhance the multi-platform frontend with advanced features and enable live trading capabilities, building on the validated core system (Phase 1), frontend/broker integrations (Phase 2), and AI/ML components (Phase 3). This phase focuses on delivering a production-ready, user-centric interface with real-time trading functionality, seamless order execution, and transparent visualisations via a "Glass Box" UI for event timelines and sentiment analysis. It extends the broker abstraction layer to support live trading with Interactive Brokers (IBKR) and additional brokers (Alpaca, OANDA, Coinbase) via REST, WebSocket, and FIX (QuickFIX/J, FIX8 for institutional connectivity), ensuring high performance (<100μs latency for executions), scalability (10,000+ concurrent users), and security (zero-trust, MFA, RBAC, TLS 1.3). The frontend leverages React 18/Next.js (web), React Native (mobile with voice/biometrics), Electron (desktop), and PWA for cross-platform consistency, integrating custom volume-weighted indicators (e.g., VW SMA, VW MACD, Normalised ATR, Choppy Market Index) from Phase 1, AI-driven insights from Phase 3 (e.g., RL strategies, sentiment scores), and real-time data streams from Kafka via WebSocket. The "Glass Box" UI provides transparency into Kafka event chains (trade lifecycles, AI decisions) and sentiment trends (topic clouds), fostering user trust. This phase aligns with the "Best-of-Breed" philosophy, microservices architecture (API calls to Trading Engine, Risk Manager, Portfolio Manager), event-driven design (Kafka for async updates, event sourcing), cloud-native principles (Kubernetes-ready, 12-Factor App), API-first approach (REST/GraphQL/WebSocket/gRPC), and compliance (MiFID II, SOX, GDPR) via immutable audits in Apache Iceberg.
- **Key Tasks:**
  - **Enhance Multi-Platform Frontend for Live Trading:**
    - ATS frontend components are consolidated with those of other agents (e.g., SDLC, Lawyer) into a shared codebase, covering web (Next.js dashboards), PWA (offline sync), mobile (React Native apps), and desktop (Electron).
    - Upgrade web dashboard (React 18/Next.js/TypeScript) with advanced trading interfaces: real-time order books, trade execution panels, portfolio analytics, and risk monitoring dashboards, integrating TradingView for live charts with custom indicators (e.g., VW EMA, Choppy Market Index).
    - Enhance mobile app (React Native) with voice trading (LLM voice mode for commands like "Buy 100 AAPL at market"), biometric authentication (fingerprint/face ID), and push notifications for trade confirmations/alerts via Firebase.
    - Improve desktop app (Electron) for professional traders: multi-monitor support, local backtesting (VectorBT), and offline analytics (DuckDB integration).
    - Optimise PWA for offline access (e.g., cached market data in IndexedDB) and cross-device syncing with Redis-backed sessions.
    - Ensure UI consistency with shared React components (e.g., Material-UI, Redux for state) and responsive design for all platforms.
  - **Extend Broker Abstraction Layer for Live Trading:**
    - Upgrade Python-based broker abstraction layer to support live trading with IBKR, adding Alpaca (stocks/options), OANDA (forex/futures), and Coinbase (crypto) APIs, normalising order types (Market, Limit, Stop, VWAP, TWAP, Iceberg) and responses.
    - Implement FIX gateway (QuickFIX/J, FIX8) for institutional connectivity, supporting FIX 4.4/5.0 protocols for order routing and market data.
    - Enable seamless paper-to-live transitions in UI (e.g., toggle switch in Next.js), ensuring compliance with broker-specific requirements (e.g., IBKR real-time subscriptions, rate limits).
    - Test live trading flows: Order placement → execution → position updates, measuring latency (<100μs) and throughput (1M TPS prep).
  - **Implement "Glass Box" UI for Transparency:**
    - Develop an event explorer in the frontend (React component) to visualise Kafka event chains (e.g., order placed → executed → filled) with timestamps, linked to AI decisions (e.g., RL strategy triggers from FinRL).
    - Integrate sentiment analysis visualisations (e.g., topic clouds for news/social sentiment from Transformers/PyTorch) using Plotly Dash/react-financial-charts.
    - Ensure real-time updates via WebSocket (<1s latency), with filters for event types (e.g., trades, AI predictions) and exportable logs (CSV/PDF for compliance).
  - **Real-Time Data Streaming Enhancements:**
    - Enhance WebSocket (Socket.IO) for live market data, order updates, and AI-driven insights (e.g., sentiment scores, anomaly alerts from PyOD), subscribing to Kafka topics.
    - Optimise for scalability: Handle 10,000+ concurrent users with NGINX load balancing and Istio circuit breakers.
    - Test streaming under load: Simulate 5M messages/sec, ensure graceful degradation (e.g., rate limiting).
  - **Integrate AI/ML Outputs into Frontend:**
    - Display AI-driven insights (e.g., RL strategy suggestions, price forecasts from LSTM, SHAP explanations) in dashboards, linked to TradingView charts.
    - Enable no-code strategy refinements via Blockly (Phase 2) with AI suggestions (e.g., "Adjust VW MACD parameters" via Lobe Chat).
    - Test AI interactions: User queries AI → receives strategy → executes in paper/live mode.
  - **Security and Compliance Enhancements:**
    - Strengthen frontend security: MFA (Keycloak), RBAC for role-specific views (e.g., pro traders see FIX settings), input sanitisation (OWASP-compliant).
    - Log all live trading events to Apache Iceberg for immutable audits, supporting compliance (e.g., MiFID II trade reports).
    - Run Bandit SAST on frontend/backend code, integrate STRIDE threat modeling updates for live trading risks.
  - **Testing and Validation:**
    - Conduct end-to-end tests: Live trading flow (UI order → broker execution → dashboard update), AI-driven trades, "Glass Box" event rendering.
    - Measure performance: UI latency (<200ms), trading latency (<100μs), streaming scalability (10,000+ users).
    - Use placeholders for Phase 5+ features (e.g., // @PLACEHOLDER: Strategy Marketplace, req ID), auto-create GitHub Issues.
    - Follow incremental protocol: Analyse specs vs. code, compare diffs, execute builds.
- **Expected Outcome:** A production-ready frontend with live trading capabilities, transparent "Glass Box" visualisations, and AI/ML integrations, supporting seamless order execution, real-time updates, and compliance. The system achieves high performance, scalability, and user trust, ready for enterprise enhancements in Phase 5.
- **Deliverables:** Enhanced frontend codebases (React/Next.js, React Native, Electron, PWA); extended broker abstraction with live trading and FIX support; "Glass Box" UI with event/sentiment visualisations; WebSocket enhancements; AI/ML frontend integrations; security/compliance features; test suites (unit/integration/E2E); documentation (Mermaid UI flows, live trading guides); validated system with benchmarks.

**Integration Plan - Phase 4: Frontend & Live Trading**

- **Objective:**
  - To integrate an enhanced multi-platform frontend with live trading capabilities, ensuring seamless order execution, real-time data streaming, and transparent visualisations via a "Glass Box" UI. This plan builds on Phases 1-3, extending the broker abstraction layer for live trading (IBKR, Alpaca, OANDA, Coinbase, FIX), integrating AI/ML outputs (e.g., RL strategies, sentiment analysis), and aligning with microservices (API/Kafka interactions), event-driven (WebSocket from Kafka), cloud-native (Kubernetes-ready), API-first, and security-first principles. It ensures compliance, high performance, and scalability for enterprise readiness.
- **Key Tasks:**
  - **Frontend Enhancements for Live Trading:**
    - Upgrade React/Next.js dashboard with trading panels (order books, execution forms), portfolio/risk views, using Material-UI for consistency and TradingView for charts.
    - Align with frontend consolidation: Share components with other agents (e.g., voice commands reusable for Social Worker Agent).
    - Enhance React Native app with voice commands (LLM integration), biometric auth, and Firebase notifications.
    - Improve Electron app for multi-monitor and offline analytics (DuckDB).
    - Optimise PWA with service workers for offline data (IndexedDB) and Redis sync.
    - Test UI consistency across platforms (Cypress).
  - **Broker Abstraction Layer Extension:**
    - Extend Python abstraction layer for live trading: IBKR, Alpaca, OANDA, Coinbase APIs, normalising responses.
    - Implement FIX gateway (QuickFIX/J, FIX8) for institutional orders, supporting FIX 4.4/5.0.
    - Integrate mode switching in UI (Next.js toggle), test live flows (order → execution → update).
  - **"Glass Box" UI Implementation:**
    - Build React component for Kafka event visualisation (timelines with trade/AI events).
    - Integrate sentiment topic clouds (Plotly Dash) from Transformers/PyTorch outputs.
    - Enable WebSocket updates (<1s), test export functionality (CSV/PDF).
  - **WebSocket Streaming Enhancements:**
    - Upgrade Socket.IO for live data (market ticks, AI insights, anomaly alerts), subscribing to Kafka.
    - Test scalability (10,000+ users) with NGINX/Istio, ensure rate limiting.
  - **AI/ML Frontend Integration:**
    - Embed RL suggestions, LSTM forecasts, SHAP explanations in dashboards, linked to TradingView.
    - Support Blockly refinements with AI prompts via Lobe Chat, test E2E flows.
  - **Security and Compliance:**
    - Implement MFA/RBAC (Keycloak), sanitise inputs, log trades to Iceberg for audits.
    - Run Bandit SAST, update STRIDE models for live trading.
  - **Testing and Validation:**
    - Run E2E tests: Live trading, AI-driven trades, "Glass Box" rendering.
    - Measure metrics: UI latency (<200ms), trading latency (<100μs), scalability.
    - Use placeholders for future features, follow incremental protocol.
- **Deliverables:** Enhanced frontend code; broker layer with live/FIX support; "Glass Box" UI; WebSocket upgrades; AI/ML integrations; security/compliance features; test suites; documentation (Mermaid flows, guides); validated system with benchmarks.
- **Acknowledge:** Confirm that you have understood this directive and are ready to begin development.

**Phase 5**

**Phase 5: Enterprise Readiness Prompt**

- **Objective:**
  - To transform the Nautilus Trader platform into a fully enterprise-ready system, ensuring high availability (HA), scalability, compliance, and operational robustness for large-scale deployments. This phase builds on Phases 1-4 (core system, frontend, AI/ML, live trading) by implementing a cloud-native deployment with Kubernetes, Helm, and Istio for orchestration and service mesh, achieving HA with multi-region redundancy (99.999% uptime), scalability for 10,000+ concurrent users and 1M+ messages/sec, and compliance with regulations (MiFID II, SOX, GDPR) via immutable audits in Apache Iceberg. It enhances observability with Prometheus, Grafana, Jaeger, Loki, and Memray for metrics, tracing, logging, and memory profiling, implements advanced security with zero-trust architecture, UEBA, and STRIDE threat modeling, and formalises disaster recovery (DR) and business continuity (BC) with RTO <15min and RPO <5min. The phase integrates enterprise-grade features like feature toggles (Unleash), advanced portfolio/risk management (PyPortfolioOpt, Riskfolio-Lib), and a strategy marketplace prototype, while optimising performance with DMA, FPGA prep, and lock-free Rust components in NautilusTrader. It leverages custom indicators (e.g., VW SMA, VW MACD, Normalised ATR), AI/ML outputs (FinRL, LSTM, sentiment analysis), and frontend enhancements from prior phases, aligning with the "Best-of-Breed" philosophy, microservices architecture (Kafka-driven), event-driven design (event sourcing, CQRS), cloud-native principles (12-Factor App, GitOps), API-first approach (REST/GraphQL/WebSocket/gRPC), and security-first mindset.
- **Key Tasks:**
  - **Deploy Cloud-Native Infrastructure:**
    - Configure Kubernetes clusters (multi-region, e.g., AWS EKS, GCP GKE) with Helm charts for service deployments (Trading Engine, Risk Manager, AI Assistant, etc.) and Istio for service mesh (mTLS, traffic management).
    - Implement GitOps with ArgoCD for automated deployments, ensuring Infrastructure-as-Code (IaC) with Terraform for cloud resources.
    - Achieve HA: Multi-AZ replication, auto-scaling (HPA/VPA), and failover mechanisms (e.g., Kubernetes pod anti-affinity).
    - Optimise with intelligent **auto-scaling** and resource management.
    - Test scalability: Simulate 10,000+ users, 1M+ Kafka messages/sec, measure latency (<100μs for trades).
  - **Enhance Observability and Monitoring:**
    - Deploy Prometheus for metrics (e.g., trade latency, API response times), Grafana for dashboards (real-time system health, AI model performance), Jaeger for distributed tracing (end-to-end trade flows), Loki for log aggregation, and Memray for Python memory profiling.
    - Integrate with frontend: Display metrics in "Glass Box" UI (e.g., latency heatmaps, anomaly alerts from PyOD).
    - Test observability: Simulate failures (e.g., pod crashes), validate tracing/logs (<1s query latency).
  - **Implement Advanced Security Measures:**
    - Strengthen zero-trust with Istio mTLS, Keycloak RBAC/MFA, and network policies (e.g., deny-all ingress except whitelisted).
    - Integrate a dedicated **User and Entity Behaviour Analytics (UEBA)** solution.
    - Enhance UEBA with PyOD for real-time anomaly detection (e.g., insider trading patterns), logging to Elasticsearch.
    - Update STRIDE threat models for enterprise risks (e.g., DDoS mitigation via NGINX rate limiting).
    - Run Bandit SAST and TruffleHog for secrets scanning in CI/CD pipelines.
    - **SCIM/SSO/OIDC Integration:** Implement SCIM v2.0 for provisioning and SSO/OIDC for authentication, integrating with Keycloak.
    - **Complete Audit Logs:** Ensure every interaction logs to Iceberg immutably.
    - **SOC 2 Readiness:** Design controls for SOC 2 criteria, including automated reporting.
  - Define three deployment profiles: Development (local), Staging (cost-optimized), Production (full HA).
  - Enhance security with data isolation boundaries and comprehensive audit logging.
  - Add agent-specific monitoring and distributed tracing.
  - Create ADRs, runbooks, and knowledge management documentation.
  - Ensure SOC 2 readiness with controls for Security, Availability, etc.
  - **Formalise Disaster Recovery and Business Continuity:**
    - Implement DR/BC plan: Daily full/hourly incremental backups (Velero for Kubernetes, pg_dump for Postgres, Kafka snapshots to MinIO), multi-region replication (e.g., ClickHouse replicas, Iceberg tables).
    - Test recovery: Simulate region failure, achieve RTO <15min, RPO <5min, validate data integrity.
    - Document DR/BC procedures in /docs/dr_bc_plan.md with runbooks.
  - **Enable Feature Toggles with Unleash:**
    - Deploy Unleash for feature toggling (e.g., enable/disable AI strategies, live trading for user groups), integrated with frontend and backend APIs.
    - Test toggles: Dynamically enable/disable features without redeployment, verify user-specific access.
  - **Enhance Portfolio and Risk Management:**
    - Integrate advanced PyPortfolioOpt/Riskfolio-Lib features for portfolio optimisation (e.g., CVaR, hierarchical clustering) and risk analysis (e.g., stress testing, VaR).
    - Expose via APIs and frontend dashboards (Plotly Dash for visualisations), leveraging AI predictions (e.g., LSTM forecasts).
    - Test optimisations: Run backtests with historical data, validate risk metrics (<5% deviation).
  - **Prototype Strategy Marketplace:**
    - Develop a basic marketplace for sharing/trading NautilusTrader strategies (Blockly/AI-generated), stored in Postgres/pgvector for metadata and Qdrant for vectorised strategy search.
    - Integrate with frontend: UI for browsing, rating, and downloading strategies, with RBAC for access control.
    - Test prototype: Upload/download sample strategies, verify search accuracy (>90% relevance).
  - **Optimise Performance for Enterprise Scale:**
    - Enhance NautilusTrader with Rust-based lock-free components for critical paths (e.g., order matching), targeting <50μs latency.
    - Prepare for DMA and FPGA integration (placeholders for hardware acceleration, e.g., // @PLACEHOLDER: FPGA order routing, req ID).
    - Test performance: Benchmark trade execution, API calls, and AI inference under load.
  - **Ensure Compliance and Auditability:**
    - Log all actions (trades, AI decisions, user activities) to Apache Iceberg for immutable audits, supporting MiFID II/SOX/GDPR.
    - Generate compliance reports (e.g., trade transparency reports) via DuckDB queries, exportable as CSV/PDF.
    - Test audit trails: Verify event traceability, compliance report accuracy.
  - **Enterprise Integration & Tooling:**
    - Integrate with **LDAP/Active Directory**.
    - **Update Repository Integrations for Non-Invasive Approach**:
      - Review all "Best-of-Breed" components (e.g., NautilusTrader, OpenHands, Kilo Code) and replace any planned forks with wrappers/adapters.
      - Implement CI/CD pipelines to test wrappers, ensuring scalability for 10,000+ users and compliance with GitOps.
    - Integrate feature stores (**Feast/Tecton**) and **Unleash** for feature flag management.
    - Create and publish the **"Professional Trader Quick-Start"** guide.
  - **Testing and Validation:**
    - Conduct end-to-end tests: Live trading with enterprise features (toggles, risk management), AI-driven strategies, marketplace flows.
    - Measure metrics: System uptime (99.999%), latency (<100μs), scalability (10,000+ users).
    - Use placeholders for Phase 6 features (e.g., // @PLACEHOLDER: Advanced AR, req ID), auto-create GitHub Issues.
    - Follow incremental protocol: Analyse specs vs. code, compare diffs, execute builds.
- **Expected Outcome:** A fully enterprise-ready platform with robust cloud-native deployment, HA, scalability, observability, security, DR/BC, feature toggles, advanced portfolio/risk management, and a strategy marketplace prototype. The system meets regulatory requirements, achieves high performance, and is prepared for advanced features in Phase 6.
- **Deliverables:** Kubernetes/Helm/Istio deployment configs; observability stack (Prometheus/Grafana/Jaeger/Loki/Memray); security enhancements (UEBA, STRIDE); DR/BC plan with backups; Unleash feature toggles; enhanced portfolio/risk modules; marketplace prototype; performance optimisations; compliance reports; test suites (unit/integration/E2E); documentation (Mermaid diagrams for infra, DR/BC runbooks); validated system with benchmarks.

**Integration Plan - Phase 5: Enterprise Readiness**

- **Objective:**
  - To integrate enterprise-grade features into the Nautilus Trader platform, ensuring high availability, scalability, compliance, and operational robustness. This plan builds on Phases 1-4, deploying a cloud-native infrastructure (Kubernetes/Helm/Istio), enhancing observability (Prometheus/Grafana/Jaeger/Loki/Memray), strengthening security (zero-trust, UEBA, STRIDE), formalising DR/BC, implementing feature toggles (Unleash), advancing portfolio/risk management, and prototyping a strategy marketplace. It ensures alignment with microservices (Kafka/API-driven), event-driven (event sourcing), cloud-native (GitOps, 12-Factor), API-first, and security-first principles, preparing for Phase 6's advanced features.
- **Key Tasks:**
  - **Cloud-Native Infrastructure Deployment:**
    - Set up Kubernetes clusters (multi-region EKS/GKE) with Helm charts for services and Istio for mTLS/traffic control.
    - Configure ArgoCD for GitOps, Terraform for IaC (e.g., VPCs, load balancers).
    - Test HA/scalability: Multi-AZ setups, auto-scaling, simulate 10,000+ users.
  - **Performance:** Optimise with intelligent auto-scaling and resource management for peak efficiency.
  - **Observability and Monitoring Setup:**
    - Deploy Prometheus (metrics), Grafana (dashboards), Jaeger (tracing), Loki (logs), Memray (memory).
    - Integrate with "Glass Box" UI for real-time metrics (e.g., trade latency).
    - Test: Simulate failures, verify tracing/log queries (<1s).
  - **Security Enhancements:**
    - Implement zero-trust (Istio mTLS, Keycloak RBAC/MFA), UEBA (PyOD for anomalies), updated STRIDE models.
    - **Integrate UEBA Capabilities:** Enhance the security framework with a dedicated User and Entity Behaviour Analytics (UEBA) solution for proactive threat detection.
    - Run Bandit/TruffleHog in CI/CD, log to Elasticsearch.
    - Test: Validate access controls, anomaly detection accuracy (<5% false positives).
  - Define three deployment profiles: Development (local), Staging (cost-optimized), Production (full HA).
  - Enhance security with data isolation boundaries and comprehensive audit logging.
  - Add agent-specific monitoring and distributed tracing.
  - Create ADRs, runbooks, and knowledge management documentation.
  - Ensure SOC 2 readiness with controls for Security, Availability, etc.
  - **Disaster Recovery and Business Continuity:**
    - Configure backups (Velero, pg_dump, Kafka to MinIO), multi-region replication (ClickHouse/Iceberg).
    - Test DR: Simulate region failure, verify RTO <15min, RPO <5min.
    - Document runbooks in /docs/dr_bc_plan.md.
  - **Enterprise Integration:**
    - Integrate with LDAP/Active Directory, feature stores (Feast/Tecton), and Unleash for feature flag management.
  - **Feature Toggles with Unleash:**
    - Deploy Unleash server, integrate with APIs/UI for dynamic feature control.
    - Test: Toggle AI strategies, verify user-specific access.
  - **Portfolio and Risk Management Enhancements:**
    - Upgrade PyPortfolioOpt/Riskfolio-Lib for CVaR, stress testing, integrate with APIs/UI.
    - Test: Backtest optimisations, validate metrics (<5% deviation).
  - **Strategy Marketplace Prototype:**
    - Build marketplace backend (Postgres/pgvector, Qdrant), frontend UI for strategy sharing.
    - Test: Upload/download strategies, verify search accuracy (>90%).
  - **Performance Optimisation:**
    - Enhance NautilusTrader with Rust lock-free components (<50μs latency).
    - Add placeholders for DMA/FPGA, test under load (1M TPS).
  - **Compliance and Auditability:**
    - Log all events to Iceberg, generate compliance reports via DuckDB.
    - Test: Verify audit trails, report accuracy.
  - **Testing and Validation:**
    - Run E2E tests: Live trading, marketplace, AI-driven flows.
    - Measure metrics: Uptime (99.999%), latency (<100μs), scalability.
    - Use placeholders, follow incremental protocol.
  - **Create Professional Trader Quick-Start Guide:** Develop and publish a "Pro-Desk Quick-Start" guide detailing how professional users can leverage advanced features like Kafka, ClickHouse, and the FIX Gateway from the start, including example commands and expected outputs.

**Pro-Desk Quick-Start**

The below mentioned **Professional Trader Quick-Start**, will guide professional users in leveraging advanced features like Kafka, ClickHouse, and FIX Gateway from the start.

- **Action:** Refer Professional Trader Quick-Start below
  - - - Instructions: docker-compose --profile pro up.
        - Steps to access Kafka, run backtests, and connect to JupyterHub.
- **Details:** Include example commands and expected outputs.
- **Purpose:** Simplifies onboarding for professional users.
- **Professional Trader Quick-Start:**

This guide is for quantitative analysts and professional traders who want to leverage the full power of the system's high-performance stack.

- **Clone the repository and launch the professional environment:**

\`\`\`bash

git clone &lt;your-repo-url&gt;

cd &lt;your-repo-name&gt;

docker compose --profile pro up -d

\`\`\`

- - - - This command starts the core services plus Kafka, ClickHouse, a FIX gateway, and other professional tooling.

- **Connect to the Research Environment:**
  - - - Open your browser and navigate to \`<http://localhost:8888\`> to access the JupyterHub environment.
- **Access Real-Time Market Data:**
  - - - Use the provided Python library to connect to the Kafka bus and subscribe to topics like \`ticks.raw\` or \`market.l2.depth\` for microstructure analysis.
- **Run GPU-Accelerated Backtests:**
  - - - In a notebook, use the \`vectorbt\` integration to run portfolio-level backtests against historical data in seconds.
- **Optimise Strategies via API:**
  - - - Use the \`POST /optimise\` endpoint with an Optuna JSON specification to run large-scale hyperparameter tuning jobs.
- **Route Live Orders via FIX:**
  - - - Ensure your \`config/live.env\` is populated with your prime broker's FIX credentials.
        - Set the environment variable \`LIVE_TRADING_MODE=FIX\` to route all orders from the AI or API directly to your liquidity provider.

- **Deliverables:** Kubernetes/Helm/Istio configs; observability stack; security enhancements; DR/BC plan; Unleash toggles; portfolio/risk modules; marketplace prototype; performance optimisations; compliance reports; test suites; documentation (Mermaid, runbooks); validated system.
- **Acknowledge:** Confirm that you have understood this directive and are ready to begin development.

**Phase 6**

**Phase 6: System Enhancement & Future-Ready Technologies Prompt**

- **Objective:**
  - To elevate the Nautilus Trader platform with cutting-edge enhancements and future-ready technologies, ensuring it remains at the forefront of algorithmic trading innovation. This phase builds on Phases 1-5 (core system, frontend, AI/ML, live trading, enterprise readiness) by integrating advanced features such as augmented reality (AR) trading interfaces via WebXR, voice-driven trading with Whisper and LLM voice mode, a fully functional strategy marketplace with monetisation, high-frequency trading (HFT) optimisations using DMA and FPGA, and advanced AI capabilities including generative AI for strategy synthesis and multi-agent coordination via LangGraph. It enhances the platform's scalability (100,000+ concurrent users, 10M+ messages/sec), performance (<10μs latency for HFT), and adaptability to emerging technologies, while maintaining compliance (MiFID II, SOX, GDPR) through Apache Iceberg audits and observability (Prometheus, Grafana, Jaeger, Loki, Memray). The phase leverages custom indicators (e.g., VW SMA, VW MACD, Normalised ATR, Choppy Market Index), AI/ML outputs (FinRL, LSTM, sentiment analysis), and enterprise features from prior phases, aligning with the "Best-of-Breed" philosophy, microservices architecture (Kafka-driven, CQRS), cloud-native principles (Kubernetes, GitOps, 12-Factor App), API-first approach (REST/GraphQL/WebSocket/gRPC), and security-first mindset (zero-trust, UEBA, STRIDE). It prepares the platform for Web 3.0 integrations (e.g., blockchain for trade settlement) and future market expansions.
- **Key Tasks:**
  - **Implement AR Trading Interfaces with WebXR:**
    - Develop AR interfaces using WebXR for immersive trading visualisations (e.g., 3D market depth charts, strategy performance holograms) on web and desktop (Electron).
    - Integrate with React/Next.js for seamless rendering, supporting devices like AR glasses and VR headsets.
    - Extend consolidation: Integrate AR/voice across agents (e.g., shared WebXR for Deep Research visualisations).
    - Display real-time data (e.g., VW MACD overlays, AI predictions) and enable gesture/voice controls via LLM voice mode.
    - Test AR interactions: Simulate trading scenarios, measure rendering latency (<50ms).
  - **Enhance Voice-Driven Trading with Whisper and LLM:**
    - Integrate Whisper for high-accuracy speech-to-text (e.g., transcribe "Buy 100 AAPL at limit \$150") with >95% accuracy.
    - Extend LLM voice mode (mobile/desktop) for command execution, linking to Agentic AI Assistant for natural language strategy adjustments.
    - Test voice workflows: End-to-end command → trade execution, validate latency (<500ms).
  - **Enhance Intelligent User Guidance System:**
    - Integrate with voice trading and AR interfaces for contextual recommendations (e.g., suggest next steps in AR portfolio view).
    - Extend Next-Step Predictor with predictive analytics from historical user workflows.
    - Enhance Tool Recommendation Engine with user feedback loops for continuous improvement.
  - **Build a Fully Functional Strategy Marketplace:**
    - Enhance Phase 5's prototype into a production-ready marketplace for sharing, rating, and monetising NautilusTrader strategies (Blockly/AI-generated).
    - Implement backend with Postgres/pgvector for metadata, Qdrant for vectorised search, and Redis for caching, with payment integration (e.g., Stripe for subscriptions).
    - Develop frontend UI (React/Next.js) with features like strategy previews, performance metrics (Sharpe ratio, drawdowns), and user reviews.
    - Test marketplace: Upload/download paid strategies, verify search accuracy (>95% relevance), ensure RBAC for access.
  - **Develop a Customer Service Bot**
  - **Optimise for High-Frequency Trading (HFT):**
    - Implement DMA and FPGA integrations for ultra-low latency (<10μs) order execution, replacing Phase 5 placeholders with Rust-based NautilusTrader components.
    - Optimise critical paths (e.g., order matching, market data processing) using lock-free algorithms and GPU acceleration (CUDA with PyTorch).
    - Test HFT performance: Simulate 10M orders/sec, measure latency/throughput under load.
  - **Ultra-Low Latency Infrastructure:**
    - Formally implement a strategy for **Direct Market Access (DMA)** and server co-location.
    - Explore the integration of specialised hardware like **FPGAs or SmartNICs**.
    - Enforce advanced **low-level software optimisation techniques**.
  - **Advance AI Capabilities:**
    - Integrate generative AI (Transformers/PyTorch) for strategy synthesis (e.g., auto-generate VW MACD crossover strategies based on market conditions).
    - Enhance LangGraph for multi-agent coordination, supporting complex workflows (e.g., Analyst → Risk → Trader → Compliance agents).
    - Implement adaptive learning: Auto-tune FinRL models based on real-time market feedback, monitored via RLOps pipeline.
    - Test AI accuracy: Strategy generation (>90% success rate), multi-agent coordination (<1s decision latency).
  - **Prepare for Web 3.0 and Blockchain Integrations:**
    - Develop prototypes for blockchain-based trade settlement (e.g., Ethereum smart contracts for crypto trades), storing proofs in Apache Iceberg.
    - Integrate with decentralised data feeds (e.g., Chainlink oracles) for crypto assets, ensuring fallback compatibility with Phase 1 feeds.
    - Test blockchain integration: Execute sample crypto trades, verify settlement integrity.
  - **Enhance Observability and Compliance:**
    - Extend Prometheus/Grafana for HFT metrics (e.g., order book latency), Jaeger for AR/AI tracing, Loki for logs, and Memray for memory optimisation.
    - Log all actions (AR commands, marketplace transactions, HFT trades) to Iceberg for compliance, generating real-time audit reports via DuckDB.
    - Test compliance: Verify MiFID II/GDPR adherence, audit trail accuracy.
  - **Security Enhancements:**
    - Strengthen zero-trust with Istio mTLS for AR/HFT services, Keycloak MFA for marketplace access, and UEBA (PyOD) for detecting fraudulent trades.
    - Update STRIDE threat models for new features (e.g., AR vulnerabilities, blockchain risks).
    - Run Bandit/TruffleHog in CI/CD for all new code.
  - **Testing and Validation:**
    - Implement scenario-based testing with LangSmith for multi-agent validation.
    - Conduct end-to-end tests: AR trading, voice commands, marketplace transactions, HFT flows, blockchain settlements.
    - Measure metrics: Latency (&lt;10μs for HFT, <50ms for AR), scalability (100,000+ users), AI accuracy (&gt;90%).
    - Use placeholders for future features (e.g., // @PLACEHOLDER: Quantum computing integration, req ID), auto-create GitHub Issues.
    - Follow incremental protocol: Analyse specs vs. code, compare diffs, execute builds.
- **Expected Outcome:** A future-ready platform with AR interfaces, voice-driven trading, a monetised strategy marketplace, HFT optimisations, advanced AI, and Web 3.0 prototypes, achieving unparalleled performance, scalability, and innovation while maintaining compliance and security.
- **Deliverables:** WebXR AR interfaces; Whisper/LLM voice trading; production-ready marketplace; HFT optimisations (DMA/FPGA); advanced AI modules; blockchain prototypes; enhanced observability/compliance; security updates; test suites (unit/integration/E2E); documentation (Mermaid diagrams for workflows, guides); validated system with benchmarks.

**Integration Plan - Phase 6: System Enhancement & Future-Ready Technologies**

- **Objective:**
  - To integrate advanced enhancements and future-ready technologies into the Nautilus Trader platform, ensuring innovation, scalability, and adaptability. This plan builds on Phases 1-5, implementing AR trading (WebXR), voice-driven trading (Whisper, LLM), a monetised strategy marketplace, HFT optimisations (DMA, FPGA), advanced AI (generative AI, multi-agent coordination), and Web 3.0 prototypes (blockchain settlement). It aligns with microservices (Kafka/API-driven), event-driven (event sourcing, CQRS), cloud-native (Kubernetes, GitOps), API-first, and security-first principles, ensuring compliance and performance for 100,000+ users and 10M+ messages/sec.
- **Key Tasks:**
  - **AR Trading Interface Implementation:**
    - Deploy WebXR with React/Next.js for AR visualisations (3D charts, strategy holograms).
    - Integrate real-time data (VW indicators, AI predictions) and LLM voice/gesture controls.
    - Test: Simulate AR trading, verify latency (<50ms).
  - **Voice-Driven Trading Enhancement:**
    - Integrate Whisper for speech-to-text (>95% accuracy), extend LLM voice mode for command execution.
    - Test: End-to-end voice command → trade, measure latency (<500ms).
  - **Enhance Intelligent User Guidance System:**
  - **Production-Ready Strategy Marketplace:**
    - Upgrade marketplace backend (Postgres/pgvector, Qdrant, Redis) with Stripe payments.
    - Build React/Next.js UI for strategy browsing/rating/monetisation.
    - Test: Upload/download paid strategies, verify search (>95% relevance).
  - **Develop a Customer Service Bot using the RAG pipeline for automated user support.**
  - **Retail Education Module:** In-app tutorials on indicators/trading.
  - **Portfolio Simulator**
  - **HFT Optimisation:**
    - Implement DMA/FPGA with Rust-based NautilusTrader components (<10μs latency).
    - Optimise with lock-free algorithms, CUDA acceleration.
    - Test: Simulate 10M orders/sec, measure throughput.
  - **Infrastructure:**
    - Implement a high-performance message bus and advanced caching.
    - Formally implement a strategy for Direct Market Access (DMA) and Server Co-location to significantly reduce network latency.
    - Explore the integration of specialised hardware like FPGAs or SmartNICs for critical data paths.
  - **Low-Level Code Optimisation:**
    - Enforce advanced low-level software optimisation techniques, such as lock-free data structures and cache-line alignment, in performance-critical code paths to minimise computational overhead.
  - **Advanced AI Integration:**
    - Deploy generative AI (Transformers/PyTorch) for strategy synthesis (>90% success).
    - Enhance LangGraph for multi-agent workflows (<1s decision latency).
    - **Implement Non-Invasive Customisations**: For components like Kilo Code and LobeChat, use plugins and wrappers for iterative strategy refinement, voice/AR support, and RAGFlow integrations, avoiding forks to maintain upgradability.
    - Enhance Kilo Code integration for iterative strategy refinement, including VS Code auto-launch hooks from the web UI.
    - Implement adaptive FinRL tuning via RLOps, test backtest-to-live flows.
    - Enhance LobeChat with voice/AR support, deepening integration with OpenHands/Kilo Code for workflows and RAGFlow for real-time queries.
  - **Web 3.0 and Blockchain Prototypes:**
    - Develop Ethereum smart contracts for crypto trade settlement, store proofs in Iceberg.
    - Integrate Chainlink oracles, test with Phase 1 feed fallbacks.
  - **Community Signal Sharing**
  - **Mobile-first Alerts**
  - **Chaos Engineering**
  - **Falco Runtime Security**
  - **Trivy Image Scanning**
  - **HashiCorp Vault dynamic secrets**
  - **Elastic Security SIEM**
  - **Automated SOC 2 evidence**
  - **Observability and Compliance Enhancements:**
    - Extend Prometheus/Grafana (HFT metrics), Jaeger (AR/AI tracing), Loki (logs), Memray (memory).
    - Log all actions to Iceberg, generate DuckDB compliance reports.
    - Test: Verify audit accuracy, compliance adherence.
  - **Security Enhancements:**
    - Apply Istio mTLS, Keycloak MFA, UEBA (PyOD) for fraud detection.
    - Update STRIDE models, run Bandit/TruffleHog in CI/CD.
    - Enhance SOC 2 architecture with runtime security (Falco) and automated evidence collection.
  - **Testing and Validation:**
    - Implement scenario-based testing with LangSmith for multi-agent validation.
    - Run E2E tests: AR/voice trading, marketplace, HFT, blockchain flows.
    - Measure metrics: Latency (<10μs HFT, <50ms AR), scalability, AI accuracy.
    - Use placeholders, follow incremental protocol.
- **Deliverables:** WebXR AR interfaces; voice trading modules; marketplace with monetisation; HFT optimisations; advanced AI; blockchain prototypes; observability/compliance upgrades; security enhancements; test suites; documentation (Mermaid, guides); validated system.
- **Acknowledge:** Confirm that you have understood this directive and are ready to begin development.