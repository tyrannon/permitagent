# Claude AI Development Context for PermitAI

## Project Overview
PermitAI is a modern, AI-powered permitting platform designed to replace legacy government permitting systems like Accela. The project aims to automate repetitive workflows, provide AI-assisted form generation and intake, and translate unstructured communication into structured permit data.

## Current Status
- Project structure created with monorepo architecture ✅
- Basic scaffolding for packages (api, core, ai, document-processor) ✅
- Architecture and feature documentation completed ✅
- Docker compose setup for local development ✅
- **NPM workspaces configured and working** ✅
- **TypeScript configuration for all packages** ✅
- **LLMRouter stub implementation created** ✅
- **Basic Express API structure complete** ✅
- **Comprehensive Prisma schema (23 models)** ✅
- **JWT authentication with refresh tokens** ✅
- **Document upload system with MinIO** ✅
- **OCR integration with PaddleOCR microservice** ✅

## Technical Context

### Architecture Summary
- **Frontend**: React (web), React Native (mobile), Electron (staff portal)
- **Backend**: Node.js + Express with modular services
- **Databases**: PostgreSQL (primary), Redis (cache/queue), Pinecone (vectors)
- **AI Stack**: Claude 3, GPT-4o, Llama 3 (via Ollama), PaddleOCR
- **Infrastructure**: Docker, Kubernetes-ready

### Project Structure
```
permitai/
├── apps/           # Frontend applications
├── packages/       # Core packages (api, core, ai, document-processor)
├── infrastructure/ # Docker, K8s configs
└── docs/          # Documentation
```

### Key Files Created
- `/permitai/` - Main project directory
- `data-model.ts` - Complete TypeScript interfaces for permits
- `ARCHITECTURE.md` - Detailed system architecture
- `FEATURES.md` - Feature specifications
- `ROADMAP.md` - Development timeline
- `project-structure.md` - File organization

## Development Guidelines

### Code Style
- TypeScript for type safety
- Functional programming where appropriate
- Interface-based design for flexibility
- Minimal comments (self-documenting code)
- Follow existing patterns in codebase

### AI Integration Approach
1. Use LLMRouter for model selection (packages/ai/src/llm/router.ts)
2. Implement proper error handling and fallbacks
3. Log AI confidence scores for analysis
4. Design prompts for specific, structured outputs

### Security Considerations
- Never hardcode API keys or secrets
- Use environment variables for configuration
- Implement rate limiting on all endpoints
- Validate and sanitize all user inputs
- Audit log all permit actions

### Government Security Compliance Requirements (Production)
**IMPORTANT**: The final production version will need to meet government security standards:

#### Required Certifications & Frameworks
1. **FedRAMP (Federal Risk and Authorization Management Program)**
   - Required for federal agency use
   - Moderate or High baseline depending on data sensitivity
   - Continuous monitoring and annual assessments

2. **StateRAMP** 
   - State-level equivalent of FedRAMP
   - Required by many state governments
   - Often accepts FedRAMP certification with state-specific additions

3. **CJIS (Criminal Justice Information Services)**
   - Required if system touches any criminal justice data
   - Background checks for personnel
   - Specific encryption and access control requirements

4. **SOC 2 Type II**
   - Demonstrates security controls over time
   - Annual audit requirement
   - Trust principles: Security, Availability, Confidentiality

5. **PCI DSS** (if processing payments)
   - Level depends on transaction volume
   - Quarterly scans and annual assessments

#### Technical Security Requirements
1. **Data Encryption**
   - At rest: AES-256 encryption for database and file storage
   - In transit: TLS 1.3+ for all communications
   - Key management with HSM or KMS

2. **Access Controls**
   - Multi-factor authentication (MFA) mandatory
   - Role-based access control (RBAC) with principle of least privilege
   - Session timeout and account lockout policies
   - IP allowlisting for admin access

3. **Audit Logging**
   - Immutable audit logs for all data access and changes
   - 7-year retention for government records
   - Real-time alerting for suspicious activities
   - Log shipping to SIEM system

4. **Infrastructure Security**
   - Network segmentation with DMZ
   - Web Application Firewall (WAF)
   - Intrusion Detection/Prevention System (IDS/IPS)
   - Regular vulnerability scanning and penetration testing

5. **Data Residency & Sovereignty**
   - Data must remain within US borders
   - GovCloud deployment may be required
   - Specific state requirements for data location

6. **Incident Response**
   - Documented incident response plan
   - 24/7 security monitoring
   - Breach notification within 72 hours
   - Regular tabletop exercises

7. **Personnel Security**
   - Background checks for all personnel with data access
   - Security awareness training
   - Signed NDAs and security agreements

#### Development Security Practices
1. **Secure SDLC**
   - Security review in design phase
   - Static code analysis (SAST)
   - Dynamic application testing (DAST)
   - Dependency scanning for vulnerabilities

2. **Zero Trust Architecture**
   - Verify everything, trust nothing
   - Microsegmentation
   - Continuous verification

3. **Privacy by Design**
   - Data minimization
   - Purpose limitation
   - Consent management
   - Right to deletion (where legally allowed)

#### Compliance Automation Tools to Consider
- **OSCAL** (Open Security Controls Assessment Language)
- **Compliance as Code** frameworks
- **Automated evidence collection**
- **Continuous compliance monitoring**

**Note**: These requirements significantly impact architecture, infrastructure costs, and development practices. Early consideration in design phase is critical.

## Next Session Priorities

### Immediate Tasks
1. ~~Fix npm workspace setup for proper monorepo~~ ✅ DONE
2. ~~Fix syntax errors in API routes~~ ✅ DONE
3. ~~Implement Prisma schema for database~~ ✅ DONE
4. ~~Create basic authentication system~~ ✅ DONE
5. ~~Build document upload endpoint~~ ✅ DONE
6. ~~Integrate PaddleOCR for text extraction~~ ✅ DONE

### Week 1 Goals Achieved! 🎉
- ✅ Working development environment
- ✅ Basic API with JWT auth
- ✅ Document upload and storage with MinIO
- ✅ OCR implementation with PaddleOCR
- ✅ Database schema ready for migrations

## Session Progress (Jul 20, 2025)

### Foundation Phase Completed
- ✅ Fixed npm workspaces - added proper configuration to root package.json
- ✅ Created tsconfig.json files for all packages with proper project references
- ✅ Fixed missing document-processor package.json
- ✅ Created stub implementation for LLMRouter (ready for real SDK integration)
- ✅ Created basic API structure with routes for auth, permits, documents, and AI
- ✅ Added tslib dependency to fix TypeScript compilation issues
- ✅ Fixed all syntax errors in API route files
- ✅ Successfully built ALL packages (core, ai, document-processor, api)

### Database & Auth Phase Completed
- ✅ Created comprehensive Prisma schema with 23 models
- ✅ Added government security compliance documentation
- ✅ Validated PostgreSQL as the database choice
- ✅ Created database setup scripts and seed data
- ✅ Implemented JWT authentication with access/refresh tokens
- ✅ Built auth middleware with permission system
- ✅ Created complete auth routes and documentation

### Document Processing Phase Completed
- ✅ Built document upload system with MinIO integration
- ✅ Implemented file validation with magic number checking
- ✅ Created storage service with bucket management
- ✅ Built document routes for upload/download/streaming
- ✅ Integrated PaddleOCR via Python microservice
- ✅ Created OCR API routes for processing and search
- ✅ Added batch processing capabilities

### MVP Foundation Complete! 🚀
The system now has:
- Monorepo with working TypeScript compilation
- Express API with JWT authentication
- Document upload/storage with MinIO
- OCR text extraction with field detection
- Comprehensive database schema
- Docker Compose for all services
- Security-first architecture

### Next Steps for MVP
1. Start Docker services and run database migrations
2. Integrate actual AI SDKs (Claude, GPT-4, Llama)
3. Build permit submission workflow
4. Create basic React frontend
5. Implement real-time updates with WebSockets
6. Add payment processing with Stripe

## Common Commands

```bash
# Navigate to project
cd /Users/kaiyakramer/permitagent/permitai

# Install dependencies (now works with workspaces!)
npm install

# Build all packages
npm run build

# Start Docker services
npm run docker:up
cd packages/api && npm install
cd packages/core && npm install

# Run development server (after setup)
npm run dev
```

## Claude-Prompter CLI Tool Integration 🚀

### Overview
A powerful CLI tool that enables Claude to generate intelligent prompt suggestions based on conversation context. This creates a feedback loop between Claude and GPT-4o for enhanced development assistance.

### Important: Tool Location
**The claude-prompter tool is located in a separate directory:**
```bash
cd /Users/kaiyakramer/claude-prompter
```

### How We Use It in PermitAI Development

#### Interactive Workflow (What We've Been Doing)
1. **Navigate to claude-prompter directory first**:
   ```bash
   cd /Users/kaiyakramer/claude-prompter
   ```

2. **Run commands with the --send flag for real GPT-4 responses**:
   ```bash
   # Example from our session - getting database architecture advice
   npx claude-prompter prompt -m "I'm building a permit management system with PostgreSQL and Prisma. Should I use separate tables for each permit type or a single table with type field?" --send
   
   # Example - OCR microservice architecture
   npx claude-prompter prompt -m "I need to integrate PaddleOCR into a Node.js/Express API. Should I create a Python microservice or use Node bindings?" --send
   ```

3. **Real examples from our development**:
   ```bash
   # When we needed document upload architecture advice
   npx claude-prompter prompt -m "Building document upload system for permits. Compare MinIO vs S3 vs local storage for government compliance" --send
   
   # When designing the OCR integration
   npx claude-prompter prompt -m "Best architecture for OCR service: Python FastAPI microservice vs Node.js integration for PaddleOCR?" --send
   ```

### Quick Reference (From claude-prompter directory)
```bash
# Navigate to tool directory
cd /Users/kaiyakramer/claude-prompter

# Generate suggestions for your current task
npx claude-prompter suggest -t "permit application API" --code -l typescript --task-type backend-service --claude-analysis

# Send a prompt to GPT-4o (what we use most)
npx claude-prompter prompt -m "How should I structure the permit workflow state machine?" --send

# Get suggestions after building features
npx claude-prompter suggest -t "document OCR processing" --code -l typescript --complexity complex --claude-analysis
```

### Usage Examples for PermitAI Development

#### After Creating API Endpoints
```bash
cd /Users/kaiyakramer/claude-prompter
npx claude-prompter suggest -t "permit submission API with validation" --code -l typescript --task-type api-integration --claude-analysis
```

#### For Architecture Decisions (Most Common Use)
```bash
cd /Users/kaiyakramer/claude-prompter
npx claude-prompter prompt -m "microservice architecture for permit processing with government compliance requirements" --send
```

### Key Commands
- `suggest`: Generate categorized prompt suggestions based on context
- `prompt`: Send prompts directly to GPT-4o (use with --send)
- `usage`: Track API usage and costs
- `--claude-analysis`: Always include when Claude is generating suggestions
- `--send`: CRITICAL flag to get real GPT-4 responses (not templates)

### Integration Workflow (How We've Been Using It)
1. Claude identifies a complex architectural decision
2. Claude navigates to `/Users/kaiyakramer/claude-prompter`
3. Claude runs prompt command with --send flag
4. GPT-4 provides architectural guidance
5. Claude implements based on recommendations
6. Process repeats for next complex decision

### Best Practices We've Learned
- Always cd to claude-prompter directory first
- Use --send flag for real architectural advice
- Keep prompts specific and technical
- Include context about government/compliance requirements
- Chain decisions: Claude → GPT-4 → Implementation → Next question

### Active Usage Guidelines
**IMPORTANT**: To get real AI suggestions (not templates):
```bash
# Always navigate to tool directory first
cd /Users/kaiyakramer/claude-prompter

# Then use --send flag for actual GPT-4 responses
npx claude-prompter prompt -m "How should I structure the permit database?" --send
```

**When to Use Actively**:
- Starting new features → Get architecture suggestions
- Solving complex problems → Get alternative approaches  
- Code reviews → Get optimization ideas
- Stuck on implementation → Get unstuck with fresh perspective

**Note**: The tool has been invaluable for architectural decisions throughout development!

## Key Decisions Made
1. **Monorepo**: Using Turborepo for better code sharing
2. **Database**: PostgreSQL with Prisma ORM for type safety
3. **AI Strategy**: Hybrid approach with multiple models
4. **Architecture**: Microservices-ready but starting monolithic
5. **Security**: JWT auth with refresh tokens

## Domain Knowledge Context
- **Permit Types**: Building, Electrical, Plumbing, Mechanical, Demolition, Fence, Sign, Grading, Tree, Special Event
- **Workflow States**: Draft → Submitted → Under Review → Pending Info → Approved → Issued → Inspections → Closed
- **Document Types**: Application, Site Plan, Floor Plan, Elevation, Structural, Mechanical/Electrical/Plumbing Plans, Calculations, Specifications, Photos, License, Insurance

## Performance Targets
- Document processing: < 10 seconds
- API response time: < 200ms
- OCR accuracy: > 95% for typed text
- AI field extraction: > 90% accuracy
- System uptime: > 99.9%

## Integration Points
- **Accela**: REST API adapter planned
- **GIS Systems**: Parcel lookup integration
- **Payment**: Stripe for online payments
- **Email**: SendGrid for notifications
- **SMS**: Twilio for urgent updates

## Testing Strategy
- Unit tests for business logic
- Integration tests for API endpoints
- E2E tests for critical workflows
- Load testing before production
- AI accuracy benchmarking

## Strategic Vision Documents

### Plus Ultra Strategy Files
- **[CLAUDE-STRATEGY.md](./CLAUDE-STRATEGY.md)** - Complete business strategy and market disruption plan
- **[CLAUDE-MVP-FEATURES.md](./CLAUDE-MVP-FEATURES.md)** - 30-day MVP sprint with demo scenarios
- **[CLAUDE-TECH-DIFFERENTIATION.md](./CLAUDE-TECH-DIFFERENTIATION.md)** - Technical superiority analysis vs Accela

### Key Strategic Insights
1. **AI-First Advantage**: We're not adding AI to permits, we're building permits on AI
2. **10x Better UX**: 5-minute permits vs 45+ minutes in Accela
3. **80% Cost Reduction**: SaaS model vs expensive licenses + infrastructure
4. **Zero Training Required**: AI guides users through everything
5. **Instant Accela Migration**: One-click data import preserves history

### MVP Demo Highlights
- Upload any document → Complete permit application
- Natural language permit assistant
- AI pre-review with instant feedback
- Real-time collaboration features
- Predictive analytics dashboard

### Investment Thesis
- **Market**: $2.3B government permitting software
- **Problem**: 20-year-old monopoly (Accela) with terrible UX
- **Solution**: AI-native platform with 10x better outcomes
- **Traction**: Industry connections ready to pilot
- **Ask**: $2M seed for 18-month runway to $10M ARR

## Complete Requirements Documentation

### All Permit Types Mapped
- **Building**: 18 types (Residential/Non-Residential × 9 categories)
- **Engineering**: EP Licensed/Major/Parklet, Encroachment, Lot Line
- **Planning**: STR, Planning Records, Variances, CUPs
- **Fire**: CUPA permits, Fire systems, Construction
- **Parks & Rec**: Events, Film, Street Trees
- **Code Enforcement**: Vacant buildings, Certificates, Cases
- **Water**: Connections, Meters, Backflow

### Key System Features
1. **Project-Centric Architecture**: One project → multiple linked permits
2. **Dynamic Fields**: Add custom fields without code changes
3. **Workflow Undo**: Finally! Can undo workflow actions
4. **Inspector Scheduling**: By STOPS not count (50 inspections at 1 address = 1 stop)
5. **Finance ELI5 Mode**: Explains complex data to finance dept
6. **PRA Engine**: Answer public records requests instantly
7. **Certificate Generator**: Shiny certificates on demand
8. **AI Everything**: Type detection, routing, scheduling, reporting

### Pain Points We're Solving
- Wrong permit types selected → AI suggests correct types
- No workflow visibility → Visual workflow with predictions
- Can't undo mistakes → Full history with undo
- Finance 5PM panic → One-click emergency reports
- Council demands new fields → Dynamic field creation
- Scattered records → Everything linked to projects
- Manual inspector routing → AI optimization by stops
- "How long does this take?" → Real-time analytics per user/step
- "When will I get my permit?" → AI predictions with visual timeline
- "What happens next?" → Picture diagrams for every workflow
- Wrong fee schedules → Automatic fee versioning with retroactive fixes
- Nobody understands the process → Visual guides for everyone

### Technical Decisions
- **Database**: PostgreSQL with Prisma ORM
- **Schema**: Flexible with JSONB for dynamic fields
- **API**: Express + TypeScript
- **Auth**: JWT with refresh tokens
- **AI**: Multi-model (Claude, GPT-4V, Llama)
- **Files**: MinIO for document storage
- **Cache**: Redis for performance
- **Search**: Pinecone for vector search

## Remember for Next Session
1. The project is in `/Users/kaiyakramer/permitagent/permitai/`
2. Workspace protocol needs fixing in package.json files
3. User is focused on building an MVP quickly
4. Prioritize working features over perfect architecture
5. User has domain expertise in government permitting
6. Strategic documents created for investor pitch
7. 30-day MVP plan ready to execute
8. All permit types and requirements documented
9. Finance integration is CRITICAL (they panic at 5PM)
10. Inspector scheduling must be by STOPS not inspections
11. System must handle dynamic fields for council demands
12. Everything must be undoable (workflow history)
13. AI is at the CORE, not bolted on
14. Migration engine can eat ANY competitor's database
15. One-click transfer from Accela/Tyler/etc
16. Zero-downtime migrations with parallel run
17. AI cleans and enhances data during migration