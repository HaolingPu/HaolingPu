# Hi there 👋 This is Haoling.

My name is Haoling, and I’m a first year master student in MS in Artificial Intelligence and Innovation @ Carnegie Mellon University (2025-2027)
🌱 I’m currently looking for a 2026 summer SDE/MLE internship

### 🏫 Current Work
- 🔬 Building state-of-the-art Simultaneous Machine Translation at CMU Professor [Li's Lab](https://leililab.github.io/).
- 📖 Taking Machine Learning Courses like Deep Learning, Natural Language Processing, Multimodel Models, and Large Language Models...
- Try to be better!
  
### 💬 Happy to connect!
- 📫 Email: haolingp@andrew.cmu.edu
- 💼 [LinkedIn](https://www.linkedin.com/in/haoling-pu/)

---

## 💻 I worked at ....

### 🚗 WeRide - Deep Learning Platform
**WeRide (Autonomous Driving) | Software Engineer Intern**  
*Summer 2024*

Internal ML infrastructure platform for 100+ engineers monitoring distributed training experiments.

#### 🎯 Problem → Solution

**Challenge:** ML engineers faced 12-second TensorBoard cold starts, manual log path re-entry, and hours debugging GPU network failures.

**My Solutions:**

**🏊 Warming Pool System**
- Built pre-warmed Knative service pool with symlink-based resource mapping
- **Impact:** Reduced startup latency **12s → 1.5s** (88% improvement)

**💾 Data Persistence Layer**
- Designed PostgreSQL-backed instance history with tagging/filtering API
- **Impact:** Zero manual re-entry - instant access to all user instances

**🔍 WeNet Health Monitor**
- Automated DaemonSet monitoring GPU node connectivity with Prometheus + Grafana
- Optimized O(n²) testing with goroutine parallelization
- **Impact:** Replaced hours of manual NCCL debugging with real-time dashboards

#### 📈 Impact
✅ **100+ ML engineers** use daily  
✅ **88% faster** TensorBoard access  
✅ **Real-time network monitoring** vs. hours of manual debugging

**Tech:** Go, Python, Kubernetes, Knative, PostgreSQL, Prometheus, Grafana, RDMA

---

### 🔬 TAF: Translation by Anticipating Future
**CMU Research Project | Professor Li's Lab**  
🔗 [View Repository](https://github.com/HaolingPu/Simultaneous-Machine-Translation-TAF-)  

A novel simultaneous machine translation method using LLM to predict future source words.

**My Contributions:**
- Implemented LLM-based future word prediction module
- Developed opportunistic translation strategy
- Conducted experiments achieving up to 5 BLEU improvement

**Tech Stack** PyTorch, Fairseq, Transformers, Python

---
### 🏥 VIP Partners - Maternal Digital Platform
**University of Michigan School of Nursing | Full-Stack & ML Engineer Intern**  
*Private Repository*

HIPAA-compliant AI-powered prenatal care platform for expectant mothers and nursing staff.

#### 🎯 Problem → Solution
**Challenge:** Nurses spent 80-120 min/day on manual tasks (news search, patient summaries, Q&A)

**My Solution:**
- 🤖 **Automated Medical News Pipeline:** Built n8n workflow + Slack integration → eliminated 60+ min/day
- 🧠 **RAG Q&A System:** Deepseek-V3 LLM + vector search → instant medical guideline queries (10 min → 2 sec)
- 🔐 **HIPAA-Compliant Security:** JWT auth + Redis caching + AES-256 encryption → 80% faster login
- 🏗️ **Full-Stack Development:** Flask REST API + React UI + Oracle DB → scheduling system for 20+ users

#### 📈 Impact
✅ **75% reduction** in daily admin time (120 min → 20 min)  
✅ Deployed to **University of Michigan School of Nursing**  
✅ **93+ commits** in team of 5+ developers

**Tech:** Python, Flask, React, TypeScript, Deepseek-V3, RAG, n8n, Redis, Oracle, Docker

<!--
**HaolingPu/HaolingPu** is a ✨ _special_ ✨ repository because its `README.md` (this file) appears on your GitHub profile.

Here are some ideas to get you started:

- 🔭 I’m currently working on ...
- 🌱 I’m currently learning ...
- 👯 I’m looking to collaborate on ...
- 🤔 I’m looking for help with ...
- 💬 Ask me about ...
- 📫 How to reach me: ...
- 😄 Pronouns: ...
- ⚡ Fun fact: ...
-->
