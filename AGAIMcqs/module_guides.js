const MODULE_GUIDES = {
  "mod1": {
    "id": "mod1",
    "num": 1,
    "title": "Module 1: Scaled Dot-Product & Self-Attention Fundamentals",
    "lectures": "Lectures 24-25 & 32-33",
    "why_study": "Before 2017, all Natural Language Processing relied on Recurrent Neural Networks (RNNs) and LSTMs. RNNs processed sentences one word at a time, sequentially like an old cassette tape (word 1 -> word 2 -> word 3).\n\nThis caused two major problems:\n1. 🐢 Slow Training: Because word #10 depended on word #9, GPUs could not process words in parallel.\n2. 🧠 Context Amnesia: By the time an RNN reached the end of a long sentence, it forgot what was said at the beginning.\n\nSelf-Attention solved this by letting the AI look at all words simultaneously in parallel and instantly connect any two related words across the entire sentence in a single step.",
    "what_is_it": "Self-Attention allows every word in a sentence to dynamically calculate how relevant every other word is to its meaning.\n\n🧠 The YouTube / Library Search Engine Metaphor:\nImagine you are searching for a tutorial on YouTube:\n• 🔍 Query (Q): The search phrase you type into the search bar. In AI, this represents what information the current word is looking for.\n• 🏷️ Key (K): The video titles and search tags in YouTube\'s database. In AI, this represents what each word advertises about itself to match incoming queries.\n• 📹 Value (V): The actual video content you watch. In AI, this represents the rich factual meaning of the word.\n\nHow the Search Engine Works:\n1. YouTube compares your Query (Q) against all video Keys (K) using a dot product (similarity score).\n2. The best matches are converted into percentages that sum to 100% using Softmax.\n3. You receive a personalized blend of the actual video Values (V) weighted by their match percentage.",
    "real_world_use": "• 🔗 Resolving Ambiguous Pronouns: In \'The animal didn\'t cross the street because it was tired\', self-attention connects \'it\' directly to \'animal\' (72% attention) rather than \'street\' (4% attention).\n• 🍏 Disambiguating Double Meanings: In \'Apple launched the new iPhone\', self-attention connects \'Apple\' with \'iPhone\' and \'launched\' to know it refers to the tech corporation, not the fruit.\n• 🎨 Text-to-Image Generation: In Midjourney and DALL-E, text token queries attend to image visual patches to render images from descriptive prompts.",
    "core_mechanics": [
      "1. Linear Projections (Q, K, V): Each input token vector X is multiplied by three learned weight matrices (W_Q, W_K, W_V) to produce specialized Query, Key, and Value vectors.",
      "2. Pairwise Similarity (Q · Kᵀ): We multiply Query by Key Transpose to compute raw dot-product similarity scores between every pair of tokens in the sequence.",
      "3. Variance Scaling (Divide by √d_k): Dot-product magnitudes grow proportional to √d_k. Dividing by the square root of the key dimension (e.g. for d_k = 64, we divide by √64 = 8) pulls the variance back to 1.0, preventing Softmax from saturating and avoiding vanishing gradients.",
      "4. Softmax Normalization: Converts raw scaled scores into non-negative probability weights (0.0 to 1.0) that sum to exactly 1.0 (100%) across each row.",
      "5. Value Aggregation: Multiplies the Softmax attention weights by the Value matrix V to produce context-enriched word representations: Output = Softmax((Q · Kᵀ) / √d_k) · V.",
      "6. Quadratic Complexity O(N²): Because every token compares against every other token, computing attention over N tokens requires an N × N score matrix. Doubling sequence length quadruples memory and FLOPs (4x)."
    ],
    "diagram_html": `
        <div class="visual-diagram-card animated-diagram">
          <div class="visual-diagram-title">⚡ Scaled Dot-Product Attention Pipeline</div>
          <div class="flow-container">
            <div class="flow-step">
              <span class="flow-badge">Input</span>
              <strong>Input Sentence Tokens X (Length = N, Dim = d_model)</strong>
              <small>(All tokens processed in parallel)</small>
            </div>
            <div class="flow-connector">↓ Linear Projection Matrices (W_Q, W_K, W_V)</div>
            <div class="flow-split-3">
              <div class="flow-box q-box"><strong>Query (Q)</strong><br><small>What the token searches for</small></div>
              <div class="flow-box k-box"><strong>Key (K)</strong><br><small>What the token advertises</small></div>
              <div class="flow-box v-box"><strong>Value (V)</strong><br><small>Actual semantic content</small></div>
            </div>
            <div class="flow-connector">↓ Calculate Pairwise Dot-Product: (Q · Kᵀ)</div>
            <div class="flow-step">
              <strong>Raw Similarity Matrix (N × N)</strong>
              <small>Measures how strongly every token relates to every other token</small>
            </div>
            <div class="flow-connector">↓ Divide by Scaling Factor √d_k (e.g. √64 = 8)</div>
            <div class="flow-step">
              <strong>Scaled Attention Scores (Variance = 1.0)</strong>
              <small>Stabilizes gradient flow and prevents Softmax saturation</small>
            </div>
            <div class="flow-connector">↓ Softmax Normalization (Rows Sum to 1.0 / 100%)</div>
            <div class="flow-step softmax-step">
              <strong>Attention Weights Matrix α (N × N)</strong>
              <small>Valid probability distribution (e.g., \'it\' gives 72% focus to \'animal\')</small>
            </div>
            <div class="flow-connector">↓ Weighted Sum of Values: α · V</div>
            <div class="flow-step output-step">
              <strong>Context-Enriched Output Matrix (N × d_v)</strong>
              <small>Final representation carrying complete sentence context</small>
            </div>
          </div>
        </div>
        `,
    "step_by_step_example": "📐 Concrete Numerical Calculation Walkthrough:\n• Sentence: \'The robot built a car\' (N = 5 tokens), Key Dimension d_k = 64.\n• Step 1 (Projection): X (5 × 512) × W_Q (512 × 64) ==> Q has shape (5 × 64). Same for K and V.\n• Step 2 (Dot Product): Q (5 × 64) × Kᵀ (64 × 5) ==> Raw Score Matrix of shape (5 × 5) containing 25 scores.\n• Step 3 (Scaling): Divide every score by √64 = 8. (e.g., raw score 32.0 becomes 32.0 / 8 = 4.0).\n• Step 4 (Softmax): Convert each row into probabilities: [exp(4.0) / sum] ==> e.g., [0.05, 0.70, 0.15, 0.05, 0.05] (Sum = 1.00).\n• Step 5 (Output): Multiply the 5 × 5 probability matrix by the 5 × 64 Value matrix ==> Final shape (5 × 64).",
    "expected_exam_questions": [
      "Q1: Why do we divide the Query-Key dot product by √d_k?\n-> Answer: To keep dot products from growing large, which would push the Softmax function into saturated regions with vanishingly small gradients (near zero).",
      "Q2: What is the computational complexity of self-attention with respect to sequence length N?\n-> Answer: Quadratic complexity O(N²), because every token in the sequence computes a dot product with every other token.",
      "Q3: What mathematical property does Softmax enforce on the attention weights?\n-> Answer: All weights are non-negative (between 0 and 1) and each row sums to exactly 1.0 (100%).",
      "Q4: If the key dimension d_k is 64, what exact number do we divide by in the scaling step?\n-> Answer: We divide by √64 = 8 (or multiply by 1/8 = 0.125)."
    ]
  },
  "mod2": {
    "id": "mod2",
    "num": 2,
    "title": "Module 2: Multi-Head Attention (MHA) Mechanism",
    "lectures": "Lecture 26",
    "why_study": "A single attention head can only focus on one relationship at a time (e.g., only tracking which noun connects to which verb). However, human language is multifaceted: a single word simultaneously has grammatical role, emotional tone, pronoun coreference, and tense.\n\nMulti-Head Attention gives the AI multiple parallel \'spotlights\' so it can inspect different linguistic perspectives simultaneously.",
    "what_is_it": "Multi-Head Attention runs multiple smaller attention heads in parallel instead of one giant head.\n\n🧠 The Boardroom Specialist Committee Metaphor:\nImagine an executive team analyzing a business contract:\n• 👔 Head 1 (Legal Specialist): Focuses on regulatory compliance and clauses.\n• 💰 Head 2 (Finance Specialist): Focuses on dollar amounts and payment terms.\n• 📅 Head 3 (Operations Specialist): Focuses on delivery timelines and deadlines.\n• ✍️ Head 4 (Grammar Specialist): Checks subject-verb-object relationships and references.\n\nAll specialists review the contract at the exact same time. Afterwards, their individual reports are bound side-by-side (concatenation) and handed to the Managing Director (Output Matrix W_O) to produce a single synthesized action plan.",
    "real_world_use": "• 🏦 Disambiguating Complex Sentences: In \'The bank by the river approved the mortgage\', Head 1 attends to \'bank\' <-> \'river\' (geographic location), while Head 2 attends to \'bank\' <-> \'mortgage\' (financial institution).\n• 👁️ Multimodal Vision-Language AI: In models like CLIP or GPT-4o, separate heads attend to image visual patches, user text prompts, and object bounding boxes simultaneously.",
    "core_mechanics": [
      "1. Dimension Partitioning: The total model hidden dimension (d_model) is split evenly across all h heads: Head Dimension d_k = d_model / h.",
      "2. Parallel Projections: For each head i (from 1 to h), the input is projected into smaller Query, Key, and Value vectors using dedicated weight matrices W_Q^i, W_K^i, W_V^i.",
      "3. Independent Attention: Each head calculates its own scaled dot-product attention in parallel: Head_i = Attention(Q_i, K_i, V_i).",
      "4. Concatenation: The outputs of all h heads are joined side-by-side: Concat(Head_1, Head_2, ..., Head_h) with total dimension h × d_k = d_model.",
      "5. Linear Output Projection (W_O): The concatenated vector is multiplied by an Output Matrix W_O (d_model × d_model) to blend all perspectives together.",
      "6. Computational Invariance: Because each head is scaled down to d_k = d_model / h, running 12 heads of size 64 takes the EXACT same total computation (FLOPs) and memory as running 1 single head of size 768!"
    ],
    "diagram_html": `
        <div class="visual-diagram-card animated-diagram">
          <div class="visual-diagram-title">⚡ Multi-Head Attention (MHA) Parallel Processing</div>
          <div class="flow-container">
            <div class="flow-step">
              <strong>Input Word Vectors (Model Dimension d_model = 768)</strong>
            </div>
            <div class="flow-connector">↓ Split into 12 Parallel Heads (Head Dimension d_k = 768 / 12 = 64)</div>
            <div class="flow-split-4">
              <div class="flow-box head-box"><strong>Head 1 (dim 64)</strong><br><small>Grammar & Syntax</small></div>
              <div class="flow-box head-box"><strong>Head 2 (dim 64)</strong><br><small>Pronoun Coreference</small></div>
              <div class="flow-box head-box"><strong>Head 3 (dim 64)</strong><br><small>Adjective Modifiers</small></div>
              <div class="flow-box head-box"><strong>Heads 4..12</strong><br><small>Context & Style</small></div>
            </div>
            <div class="flow-connector">↓ Concatenate All 12 Head Outputs: 12 × 64 = 768</div>
            <div class="flow-step">
              <strong>Concatenated Output Tensor (Dimension = 768)</strong>
            </div>
            <div class="flow-connector">↓ Linear Output Projection Matrix (W_O: 768 × 768)</div>
            <div class="flow-step output-step">
              <strong>Final Multi-Head Attention Output (Dimension = 768)</strong>
              <small>Blends all 12 diverse linguistic perspectives into a unified representation</small>
            </div>
          </div>
        </div>
        `,
    "step_by_step_example": "📐 Real-World Transformer Dimensions:\n• BERT-Base: d_model = 768, Number of Heads h = 12 ==> Head Dimension d_k = 768 / 12 = 64.\n• GPT-2 Large: d_model = 1024, Number of Heads h = 16 ==> Head Dimension d_k = 1024 / 16 = 64.\n• LLaMA-2 70B: d_model = 8192, Number of Heads h = 64 ==> Head Dimension d_k = 8192 / 64 = 128.\n• Standard Formula: Per-Head Dimension = Total Model Dimension / Number of Heads.",
    "expected_exam_questions": [
      "Q1: If a Transformer model has d_model = 768 and 12 attention heads, what is the dimension of each individual head?\n-> Answer: 64 (since 768 / 12 = 64).",
      "Q2: What mathematical operation is performed on all individual attention head outputs before the linear output projection?\n-> Answer: Concatenation (joining the vectors side-by-side).",
      "Q3: Why does multi-head attention not increase computational cost compared to a single full-size head?\n-> Answer: Because each head operates on a reduced dimension d_k = d_model / h, keeping the total parameter count and FLOPs identical."
    ]
  },
  "mod3": {
    "id": "mod3",
    "num": 3,
    "title": "Module 3: Transformer Architecture Deep-Dive",
    "lectures": "Lectures 27-28",
    "why_study": "Stacking 50 to 100 deep neural layers causes two major failure modes: gradients explode to infinity or vanish to zero, and feature representations drift wildly. The Transformer architecture solves this by wrapping attention and feed-forward sublayers inside Residual Skip Connections and Layer Normalization.",
    "what_is_it": "A standard Transformer layer consists of two core building blocks:\n1. 🔄 Multi-Head Self-Attention: Allows tokens to communicate and share context across the sentence.\n2. ⚡ Position-Wise Feed-Forward Network (FFN): An independent 2-layer MLP that transforms each token\'s features individually without mixing across positions.\n\nWrapped with two essential stability mechanisms:\n• 🛣️ Residual Skip Connections (Identity Highways): Adds input directly to sublayer output: Output = x + Sublayer(x). During backpropagation, the derivative contains a \'+1\' identity term, allowing gradients to flow backwards through hundreds of layers without diminishing.\n• ⚖️ Layer Normalization (LayerNorm): Normalizes numbers across feature channels for each token independently to mean 0 and variance 1.\n• 🛡️ Padding & Causal Masks: Padding masks set dummy [PAD] token scores to -∞ so they receive 0% attention. Causal masks block future tokens during text generation.",
    "real_world_use": "• 🌐 Machine Translation: In English-to-French translation, the Decoder queries English words from the Encoder using Cross-Attention while generating French tokens.\n• 🤖 Autoregressive LLMs (ChatGPT): Causal masks ensure the model cannot peek at future words, enforcing strict left-to-right generation.",
    "core_mechanics": [
      "1. Residual Skip Connections: Output = x + Sublayer(x). The \'+1\' term in gradient backpropagation guarantees an uninterrupted gradient highway, solving the vanishing gradient problem in deep networks.",
      "2. Layer Normalization (LayerNorm): Calculates mean μ and standard deviation σ across features for each token independently: LN(x) = (x - μ) / (σ + ε) * γ + β.",
      "3. Position-Wise Feed-Forward Network (FFN): 2-layer MLP applied identically and independently to each token: FFN(x) = max(0, x · W1 + b1) · W2 + b2. Typically expands dimension 4x (e.g. 512 -> 2048 -> 512).",
      "4. Cross-Attention: In Encoder-Decoder models, the Decoder generates Queries (Q), while the Encoder output provides the Keys (K) and Values (V). Score matrix shape: (Decoder Length × Encoder Length).",
      "5. Padding Mask: Replaces scores for dummy [PAD] tokens with -∞ before Softmax so their Softmax probability becomes exactly 0.0%.",
      "6. Causal (Look-Ahead) Mask: Upper-triangular matrix set to -∞ that prevents token t from attending to future tokens t+1, t+2, ... during text generation."
    ],
    "diagram_html": `
<div class="visual-diagram-card animated-diagram">
  <div class="visual-diagram-title">⚡ Transformer Layer Block Anatomy</div>
  <div class="flow-container">
    <div class="flow-step"><strong>Input Token Tensor x (from Previous Layer)</strong></div>
    <div class="flow-connector">↓ Sublayer 1: Multi-Head Self-Attention</div>
    <div class="flow-sublayer">
      <div><strong>1. Layer Normalization:</strong> Normalizes features to mean 0, variance 1</div>
      <div><strong>2. Multi-Head Attention:</strong> Tokens communicate and share context</div>
      <div class="residual-badge">➕ Residual Bypass Highway: Output₁ = x + Attention(LayerNorm(x))</div>
    </div>
    <div class="flow-connector">↓ Sublayer 2: Position-Wise Feed-Forward Network (FFN)</div>
    <div class="flow-sublayer">
      <div><strong>1. Layer Normalization:</strong> Re-normalizes features</div>
      <div><strong>2. 4x Feature Expansion:</strong> Processes each token independently (512 → 2048 → 512)</div>
      <div class="residual-badge">➕ Residual Bypass Highway: Output₂ = Output₁ + FFN(LayerNorm(Output₁))</div>
    </div>
    <div class="flow-connector">↓ Pass to Next Transformer Layer</div>
    <div class="flow-step output-step"><strong>Output Tensor to Next Layer</strong></div>
  </div>
</div>
`,
    "step_by_step_example": "📐 Cross-Attention Matrix Dimensions Walkthrough:\n• English Source Sentence (Encoder): 50 tokens ==> Encoder Output Shape: (50 × d_model).\n• French Target Sentence Generated So Far (Decoder): 20 tokens ==> Decoder Query Shape: (20 × d_model).\n• Cross-Attention Score Matrix: (20 Decoder Queries) × (50 Encoder Keys) = (20 × 50) grid of scores.\n• Softmax is applied across the 50 columns so each French token distributes 100% of its attention over the 50 English words.",
    "expected_exam_questions": [
      "Q1: What is the shape of the cross-attention matrix for 20 decoder queries and 50 encoder keys?\n-> Answer: 20 × 50 (Decoder Length × Encoder Length).",
      "Q2: In Transformer Encoder-Decoder cross-attention, where do the Keys and Values come from?\n-> Answer: The Encoder output (while Queries come from the Decoder).",
      "Q3: What value is added to padding and future tokens in the attention matrix before Softmax?\n-> Answer: Negative infinity (-∞), which makes their Softmax probability exactly zero (e^-∞ = 0).",
      "Q4: Why does a residual skip connection prevent vanishing gradients during training?\n-> Answer: The gradient contains a \'+1\' identity term (d(x + F(x))/dx = 1 + F\'(x)), creating an unhindered highway for gradients to flow backwards.",
      "Q5: Does the Position-Wise Feed-Forward Network mix information between different token positions?\n-> Answer: No. It operates on each token independently and identically without inter-token mixing."
    ]
  },
  "mod4": {
    "id": "mod4",
    "num": 4,
    "title": "Module 4: Positional Encoding & Sequence Modeling",
    "lectures": "Lectures 29-30",
    "why_study": "Self-attention treats a sentence like an unordered bag of words. To raw self-attention, \'Dog bites man\' and \'Man bites dog\' produce 100% identical attention matrices! Because language and visual scenes depend strictly on order and spatial geometry, we must inject positional coordinates into the token embeddings.",
    "what_is_it": "Positional Encoding is a unique vector added element-wise to each token embedding to encode its exact sequence position (Position 1, Position 2, Position 3, ...).\n\n🧠 The Numbered Page Cards Metaphor:\nImagine dropping a 500-page book on the floor. If the pages are not numbered, putting them back in the right order is nearly impossible. Positional Encodings are the page numbers printed on each token card before it enters the Transformer.",
    "real_world_use": "• 🔤 Rotary Position Embeddings (RoPE): Used in modern LLMs like LLaMA-3, Mistral, and Gemma to encode relative distances between tokens by rotating vectors in 2D sub-spaces.\n• 🖼️ 2D Positional Embeddings in Vision Transformers (ViT): Injects row and column coordinates into image patches so the AI knows where each patch belongs on the 2D canvas.",
    "core_mechanics": [
      "1. Permutation Equivariance: Self-attention by itself is order-agnostic. Shuffling the input tokens shuffles the output identically unless positional information is injected.",
      "2. Sinusoidal Positional Encodings (Original Attention Is All You Need): Uses sine and cosine waves of different frequencies (PE(pos, 2i) = sin(pos / 10000^(2i/d)), PE(pos, 2i+1) = cos(pos / 10000^(2i/d))), allowing the model to easily compute relative offsets (pos + k).",
      "3. Learned Positional Embeddings (BERT / ViT): A lookup table of learned vectors added element-wise: Input = Token Embedding + Position Embedding.",
      "4. Element-Wise Addition: Position vectors have the exact same dimension (d_model) as token embeddings and are added directly: x_final = x_token + x_pos.",
      "5. 2D Positional Embeddings in ViT: Learned 1D/2D vectors added to 196 image patches plus 1 classification token [CLS] (total: 197 positional vectors)."
    ],
    "diagram_html": `
        <div class="visual-diagram-card animated-diagram">
          <div class="visual-diagram-title">⚡ Positional Encoding Vector Injection</div>
          <div class="flow-container">
            <div class="flow-split-2">
              <div class="flow-box" style="background:var(--primary-blue-bg); border-color:var(--primary-blue);">
                <strong>Semantic Word Vector (x_token)</strong><br>
                <small>Represents word meaning (e.g., \'Dog\')<br>Shape: (1 × d_model)</small>
              </div>
              <div class="flow-box" style="background:var(--purple-accent-bg); border-color:var(--purple-accent);">
                <strong>Positional Vector (x_pos)</strong><br>
                <small>Represents sequence position (e.g., Position #1)<br>Shape: (1 × d_model)</small>
              </div>
            </div>
            <div class="flow-connector">➕ Element-Wise Addition (x_token + x_pos)</div>
            <div class="flow-step output-step">
              <strong>Order-Aware Input Tensor (1 × d_model)</strong><br>
              <small>Carries both semantic meaning AND exact sequence position</small>
            </div>
          </div>
        </div>
        `,
    "step_by_step_example": "📐 Vision Transformer Positional Allocation Math:\n• Input Image: 224 × 224 pixels, Patch Size: 16 × 16 ==> (224 / 16) × (224 / 16) = 14 × 14 = 196 image patches.\n• Prepend 1 Classification Token [CLS] at position 0 ==> Total tokens = 196 + 1 = 197 tokens.\n• Positional Embedding Matrix Shape: Exactly 197 vectors of dimension d_model (e.g., 197 × 768).\n• Input to Transformer Layer 1 = [CLS, Patch_1, Patch_2, ..., Patch_196] + Positional_Embedding_Table.",
    "expected_exam_questions": [
      "Q1: Why do Transformer models require positional encodings in addition to token embeddings?\n-> Answer: Because self-attention is permutation-equivariant (order-agnostic) and cannot distinguish word order on its own.",
      "Q2: How are positional encodings combined with word embeddings in standard Transformers?\n-> Answer: Through element-wise addition (Token Vector + Position Vector).",
      "Q3: For a Vision Transformer with 196 patches and 1 [CLS] token, how many positional embedding vectors are needed?\n-> Answer: Exactly 197 positional embeddings (196 + 1 = 197)."
    ]
  },
  "mod5": {
    "id": "mod5",
    "num": 5,
    "title": "Module 5: Vision Transformers (ViT, Swin, CaiT)",
    "lectures": "Lecture 31",
    "why_study": "For decades, Computer Vision was dominated by Convolutional Neural Networks (CNNs). However, CNNs have a local receptive field—they only look at small 3×3 pixel neighborhoods, requiring dozens of layers before they can see the whole image. Vision Transformers (ViT) eliminated this limitation by slicing images into patches and applying self-attention to see global image context from Layer 1.",
    "what_is_it": "Vision Transformer (ViT) treats an image like a sentence of words by splitting it into patches.\n\n🧠 The Photo Jigsaw Puzzle Metaphor:\n1. ✂️ Cut the Photo: Cut a 224×224 photograph into 196 square puzzle pieces (16×16 pixel patches).\n2. 📏 Unroll the Pixels: Flatten each 16×16 RGB patch into 16 × 16 × 3 = 768 color numbers.\n3. 🎯 Linear Projection: Multiply the 768 numbers by a weight matrix to map into model dimension d_model.\n4. 🏷️ Master Summary Card: Prepend a blank [CLS] Classification Token at index 0.\n5. 🔢 Number the Pieces: Add 197 positional vectors (indices 0 to 196).\n6. 🧠 Standard Transformer: Feed all 197 tokens through standard Transformer encoder layers!",
    "real_world_use": "• 🏥 Medical Diagnostics: Identifying tumors, lesions, and fractures in high-resolution MRI and CT scans.\n• 🚗 Autonomous Driving: Tesla Full Self-Driving (FSD) and Waymo use Vision Transformers to detect road hazards and pedestrians.\n• 🖼️ Multimodal AI: ViT is the vision backbone for OpenAI CLIP, Google Gemini, and GPT-4o.",
    "core_mechanics": [
      "1. Patch Count Formula: Number of Patches N = (Image Height × Image Width) / (Patch Size)². For 224×224 image with 16×16 patches: (224/16)² = 14 × 14 = 196 patches.",
      "2. Flattened Patch Size: Patch Size × Patch Size × Color Channels = 16 × 16 × 3 = 768 scalar pixel values.",
      "3. Linear Patch Projection: Maps the 768 pixel numbers into the Transformer hidden dimension d_model via a learned projection matrix E (768 × d_model).",
      "4. [CLS] Classification Token: A learned 1D vector prepended at index 0 (making sequence length 196 + 1 = 197). Its final layer output is fed to an MLP classifier.",
      "5. Inverse Quadratic Patch Scaling: Halving patch size (e.g. 16 -> 8) quadruples patch count (4x) and increases self-attention computation by 16x (since (4N)² = 16N²).",
      "6. Swin Transformer: Computes self-attention within local shifted windows to achieve linear complexity O(N) instead of quadratic O(N²)."
    ],
    "diagram_html": `
        <div class="visual-diagram-card animated-diagram">
          <div class="visual-diagram-title">⚡ Vision Transformer (ViT) Complete Pipeline</div>
          <div class="flow-container">
            <div class="flow-step"><strong>1. Input RGB Image (224 × 224 × 3)</strong></div>
            <div class="flow-connector">↓ Split into 16 × 16 Pixel Non-Overlapping Patches</div>
            <div class="flow-step">
              <strong>2. 196 Image Patches (14 × 14 Grid)</strong><br>
              <small>Flattened patch dimension: 16 × 16 × 3 = 768 scalar numbers per patch</small>
            </div>
            <div class="flow-connector">↓ Linear Patch Projection + Prepend [CLS] Token + Add 197 Positional Embeddings</div>
            <div class="flow-step">
              <strong>3. Sequence of 197 Tokens (Dimension d_model = 768)</strong>
            </div>
            <div class="flow-connector">↓ Standard Transformer Encoder (12 Layers of Self-Attention + FFN)</div>
            <div class="flow-step">
              <strong>4. Extract Final Output of [CLS] Token (Index 0)</strong>
            </div>
            <div class="flow-connector">↓ MLP Classification Head</div>
            <div class="flow-step output-step">
              <strong>5. Prediction Class Label (e.g. \'Golden Retriever: 98.5%\')</strong>
            </div>
          </div>
        </div>
        `,
    "step_by_step_example": "📐 ViT Formula Quick Reference:\n• Patch Count: N = (H × W) / P² = (224 × 224) / (16 × 16) = 196 patches.\n• With [CLS] token: Sequence Length = N + 1 = 196 + 1 = 197 tokens.\n• Larger 32×32 patches on 224×224: (224 / 32)² = 7 × 7 = 49 patches (+1 [CLS] = 50 tokens).\n• Flattened vector size: 16 × 16 × 3 = 768 numbers.\n• Doubling resolution (448×448 at 16×16 patches): (448 / 16)² = 28 × 28 = 784 patches (4x token count).",
    "expected_exam_questions": [
      "Q1: A 224 × 224 image is split into 16 × 16 patches. How many patches are created?\n-> Answer: 196 patches ((224 / 16)² = 14 × 14 = 196).",
      "Q2: How many scalar pixel values are in a flattened 16 × 16 RGB patch?\n-> Answer: 768 values (16 × 16 × 3 = 768).",
      "Q3: What is the sequence length after prepending the [CLS] classification token to 196 image patches?\n-> Answer: 197 tokens (196 + 1 = 197).",
      "Q4: If patch size is halved from 16×16 to 8×8 at fixed image resolution, by what factor does token count change?\n-> Answer: 4 times larger (since (16/8)² = 2² = 4).",
      "Q5: Which Vision Transformer architecture uses shifted local windows to achieve linear complexity O(N)?\n-> Answer: Swin Transformer."
    ]
  },
  "mod6": {
    "id": "mod6",
    "num": 6,
    "title": "Module 6: LLM Architecture & Autoregressive Pre-training",
    "lectures": "Lectures 33-35",
    "why_study": "How do Large Language Models (LLMs) like GPT-4, Claude, and LLaMA generate human-level text, poetry, and code? By mastering next-token prediction! Understanding causal decoder architectures, KV caching, and probabilistic sampling algorithms (Temperature, Top-k, Top-p) gives you complete mastery of modern generative AI systems.",
    "what_is_it": "An Autoregressive Decoder-Only LLM generates text sequentially one token at a time, where each newly generated token is conditioned on all previous tokens.\n\n🧠 The Super-Powered Smartphone Keyboard Metaphor:\nWhen typing a text message, your smartphone suggests the top 3 most likely next words based on your message so far. An LLM operates on the same principle across a 50,000 to 128,000 token vocabulary, assigning exact probability scores to every possible next token and sampling the best continuation.",
    "real_world_use": "• 💬 Conversational Assistants (ChatGPT, Claude, Gemini).\n• 💻 Code Generation & Autocomplete (GitHub Copilot, Cursor).\n• ⚡ KV Caching: Storing past Key and Value vectors in GPU memory prevents recomputing previous words, making text generation 20x faster.",
    "core_mechanics": [
      "1. Autoregressive Factorization (Chain Rule): P(w_1, w_2, ..., w_T) = ∏ P(w_t | w_1, ..., w_{t-1}). The joint probability of a sentence is the product of conditional next-token probabilities.",
      "2. Shifted Targets (+1 Alignment): During training, the input context ending at token t is trained to predict target token t+1.",
      "3. Decoder-Only Architecture: No Encoder and NO Cross-Attention! Modern LLMs (GPT, LLaMA) use only Masked Causal Self-Attention and Position-Wise Feed-Forward Networks.",
      "4. Sampling Temperature (T): Controls randomness. Lower temperature (T < 0.3) sharpens probabilities toward high-probability tokens (ideal for math/coding). Higher temperature (T > 0.8) flattens distribution for creative writing.",
      "5. Top-k Sampling: Filters the vocabulary to keep only the k highest-probability candidate tokens (e.g. k = 50) and discards the rest.",
      "6. Top-p (Nucleus) Sampling: Dynamically selects the smallest pool of top tokens whose cumulative probability reaches threshold p (e.g. p = 0.90 / 90%).",
      "7. End-of-Sequence Token [EOS]: A special token that signals the generation loop to cleanly stop."
    ],
    "diagram_html": `
        <div class="visual-diagram-card animated-diagram">
          <div class="visual-diagram-title">⚡ LLM Autoregressive Generation Loop</div>
          <div class="flow-container">
            <div class="flow-step"><strong>Input Prompt: \"The capital of France is\"</strong></div>
            <div class="flow-connector">↓ Causal Decoder Forward Pass (with GPU KV-Cache)</div>
            <div class="flow-step">
              <strong>Raw Vocabulary Logits (50,000 Possible Tokens)</strong>
            </div>
            <div class="flow-connector">↓ Temperature Scaling (Logits / T) + Top-p Nucleus Filter</div>
            <div class="flow-step">
              <strong>Filtered Probabilities: \"Paris\" (89%), \"Lyon\" (4%), \"Marseille\" (2%)</strong>
            </div>
            <div class="flow-connector">↓ Sample Next Token</div>
            <div class="flow-step output-step">
              <strong>Generated Token: \"Paris\"</strong>
            </div>
            <div class="flow-connector">↻ Append \"Paris\" to Input Prompt and Repeat Loop until [EOS]</div>
          </div>
        </div>
        `,
    "step_by_step_example": "📐 Training vs Inference Breakdown:\n• Training (Teacher Forcing with Causal Mask): The entire 4,000-word document is processed in parallel in a single GPU matrix pass. All next-token targets (t+1) are evaluated simultaneously.\n• Inference (Sequential Generation): Generation happens one token at a time. Step 1: Prompt -> \'Paris\'. Step 2: Prompt + \'Paris\' -> \'.\'. Step 3: Prompt + \'Paris\' + \'.\' -> \'[EOS]\'. Loop terminates.",
    "expected_exam_questions": [
      "Q1: In causal LM training on [token 1, token 2, token 3, token 4], which target token is paired with context ending at token 2?\n-> Answer: token 3 (shifted by +1 position).",
      "Q2: What is the effect of lowering the sampling temperature T toward 0?\n-> Answer: The probability distribution becomes sharper, making text generation more deterministic, greedy, and repetitive.",
      "Q3: How does Top-p (nucleus) sampling select candidate tokens?\n-> Answer: It dynamically selects the smallest set of most probable tokens whose cumulative probability reaches threshold p.",
      "Q4: Which attention sublayer is completely absent in a decoder-only GPT model?\n-> Answer: Encoder-Decoder Cross-Attention.",
      "Q5: What special token signals the autoregressive generation loop to terminate?\n-> Answer: The End-of-Sequence [EOS] token."
    ]
  },
  "mod7": {
    "id": "mod7",
    "num": 7,
    "title": "Module 7: Prompt Engineering Fundamentals",
    "lectures": "Lectures 35-37",
    "why_study": "Pre-trained foundation models are massive knowledge engines. Without clear instructions and formatting constraints, they produce conversational filler, hallucinate facts, or fail JSON schema parsing. Prompt Engineering is the software engineering discipline of steering pre-trained LLMs to execute tasks accurately, securely, and deterministically without modifying model weights.",
    "what_is_it": "Prompt Engineering is the practice of designing structured instructions, delimiters, system personas, and validation schemas to guide LLM behavior.\n\n🧠 The Master Architect\'s Onboarding Metaphor:\nIf you hire an expert engineer and merely say \'build something\', you will get unpredictable results. But if you provide:\n1. 🎭 Role & Persona: \'You are a Senior Cyber-Security Auditor.\'\n2. 🛡️ Quarantined Data Fences: Wrapping untrusted user input inside XML tags (<user_code>...</user_code>) to prevent prompt injection jailbreaks.\n3. 📋 Few-Shot Examples: Showing 2-3 solved input/output demonstration pairs (In-Context Learning).\n4. 📐 Output Format: Enforcing a strict JSON schema with exact keys.\n\nThe engineer will execute the task with 100% precision and reliability.",
    "real_world_use": "• 🛡️ Defending Against Prompt Injection: Using XML delimiters (<data>...</data>) prevents malicious user prompts from overriding system developer rules.\n• 🔌 Production API Integration: Forcing LLMs to respond with strict JSON schemas for automated database insertion.\n• 🤖 Automated Prompt Optimization: Using Meta-Prompting where an LLM designs, evaluates, and refines prompts automatically.",
    "core_mechanics": [
      "1. Zero-Shot Prompting: Providing direct task instructions without demonstration examples. Fast and token-efficient.",
      "2. Few-Shot Prompting (In-Context Learning): Providing 2 to 5 solved demonstration input-output pairs in the prompt. The model recognizes patterns without updating any model weights.",
      "3. Delimiters (XML tags, triple quotes): Clearly separates developer instructions from untrusted user input, preventing ambiguity and prompt injection attacks.",
      "4. Role & Persona Prompting: Instructing the model \'Act as a Senior Database Administrator\' primes domain vocabulary and professional reasoning.",
      "5. Structured Outputs (JSON Schema): Enforcing strict JSON formatting with predefined keys and types eliminates conversational fluff.",
      "6. Prompt Templates: Parameterized strings with {placeholders} allowing reusable, version-controlled software pipelines.",
      "7. Meta-Prompting: Prompting an LLM to generate, optimize, or evaluate prompts for other downstream AI tasks."
    ],
    "diagram_html": `
<div class="visual-diagram-card animated-diagram">
  <div class="visual-diagram-title">⚡ Production Prompt Engineering Pipeline</div>
  <div class="flow-container">
    <div class="flow-step" style="background:var(--primary-blue-bg); border-color:var(--primary-blue);">
      <strong>1. System Persona & Role</strong><br>
      <small>\"You are a Senior Cyber-Security Auditor.\"</small>
    </div>
    <div class="flow-connector">↓ Quarantined Input (XML Delimiters)</div>
    <div class="flow-step">
      <strong>2. Grounding Context & XML Delimiters</strong><br>
      <small>&lt;user_query&gt; {untrusted_user_input} &lt;/user_query&gt;</small>
    </div>
    <div class="flow-connector">↓ Few-Shot Demonstrations (In-Context Learning)</div>
    <div class="flow-step">
      <strong>3. Few-Shot Exemplars</strong><br>
      <small>Example 1: Input → Output | Example 2: Input → Output</small>
    </div>
    <div class="flow-connector">↓ Strict JSON Schema Output Constraint</div>
    <div class="flow-step output-step">
      <strong>4. Deterministic & Validated JSON Output</strong><br>
      <small>{\"vulnerabilities\": [...], \"severity\": \"HIGH\"}</small>
    </div>
  </div>
</div>
`,
    "step_by_step_example": "📐 Production Prompt Architecture Template:\n1. Role: \'You are a principal security engineer auditing Python code.\'\n2. Delimiters: \'Analyze ONLY the code enclosed inside <code> tags.\'\n3. Input Data: \'<code>{user_code}</code>\'\n4. Few-Shot Exemplar: [Example code snippet -> Expected JSON vulnerability report]\n5. Output Constraint: \'Output strictly valid JSON matching schema: {vulnerabilities: list, severity: string}. Do NOT include conversational markdown preamble.\'",
    "expected_exam_questions": [
      "Q1: Why are delimiters like XML tags (<text>...</text>) useful in prompt engineering?\n-> Answer: They clearly separate developer system instructions from user-provided data, preventing ambiguity and prompt injection attacks.",
      "Q2: How does few-shot in-context learning differ from model fine-tuning?\n-> Answer: Few-shot prompting updates zero model weights and operates entirely during inference inside the prompt context window.",
      "Q3: What prompt design enables software reuse of prompts with dynamic customer data?\n-> Answer: A prompt template with variable placeholders (e.g. {customer_name}).",
      "Q4: Which technique involves asking an LLM to generate or optimize prompts for downstream tasks?\n-> Answer: Meta-Prompting."
    ]
  },
  "mod8": {
    "id": "mod8",
    "num": 8,
    "title": "Module 8: Fine-Tuning & Parameter-Efficient Adaptation (LoRA & PEFT)",
    "lectures": "Lectures 36-37",
    "why_study": "Pre-trained base LLMs have general knowledge, but enterprise tasks require specialized domain mastery (medical, legal, coding). Full fine-tuning (updating 100% of weights) is prohibitively expensive, requires massive GPU clusters (560+ GB VRAM for 70B Adam optimizer states), and causes catastrophic forgetting.\n\nPEFT (Parameter-Efficient Fine-Tuning) and LoRA revolutionized the field by enabling fine-tuning of less than 1% of parameters on a single commercial GPU!",
    "what_is_it": "LoRA (Low-Rank Adaptation) completely freezes the pre-trained base model weights (W₀) and attaches two small, trainable low-rank matrices (A and B) to each layer: Weight Update ΔW = B · A.\n\n🧠 The Transparent Sticky Notes on the Giant Encyclopedia Metaphor:\nImagine you own a massive 10,000-page Encyclopedia (a 70-Billion parameter base LLM):\n• ❌ Full Fine-Tuning: Erasing and re-printing all 10,000 pages every time you want to learn a new task (costing $50,000 in compute and 140 GB per task).\n• ✅ LoRA Adaptation: Leaving the encyclopedia 100% frozen and untouched, and simply sticking small transparent sticky notes (<1% size, 20 MB) on relevant pages. You can peel off, swap, or fuse sticky notes instantly!",
    "real_world_use": "• 🚀 Multi-Adapter Serving (vLLM / S-LoRA): A company loads one shared 70B base model (140 GB) into GPU memory once, and dynamically hot-swaps 100 different 20 MB LoRA adapters for Finance, Legal, Support, and Coding.\n• ⚡ Zero-Latency Deployment: When deploying to production, Merged Weights = W₀ + (alpha / rank) · (B · A) permanently fuses the weights, giving exactly 0% extra inference latency.",
    "core_mechanics": [
      "1. Base Model Freezing: Pre-trained weight matrices W₀ (d_out × d_in) are completely frozen (requires_grad = False), eliminating 8 bytes of Adam optimizer memory per parameter.",
      "2. Low-Rank Decomposition: Weight update ΔW = B · A, where Matrix A has shape (r × d_in) and Matrix B has shape (d_out × r), with rank r ≪ min(d_in, d_out).",
      "3. Initialization: Matrix A is initialized with random Gaussian noise, and Matrix B is initialized to all zeros. This ensures ΔW = B · A = 0 at the start of training, preserving exact base model behavior initially.",
      "4. Linear Parameter Scaling: Adapter Parameters = rank r × (d_in + d_out). Trainable parameter count scales strictly linearly with rank r.",
      "5. Forward Pass with Scaling Factor: h = W₀ · x + (α / r) · (B · A) · x, where α is a constant scaling hyperparameter.",
      "6. Weight Merging: W_merged = W₀ + (α / r) · (B · A). Merging matrices eliminates the separate adapter path, resulting in zero extra inference latency."
    ],
    "diagram_html": `
        <div class="visual-diagram-card animated-diagram">
          <div class="visual-diagram-title">⚡ LoRA Low-Rank Decomposition Architecture</div>
          <div class="flow-container">
            <div class="flow-step"><strong>Input Vector x (Dimension d_in = 4096)</strong></div>
            <div class="flow-connector">↓ Split into Parallel Forward Paths</div>
            <div class="flow-split-2">
              <div class="flow-box" style="background:var(--card-sub-bg); border:2px solid var(--border-color);">
                <strong>🔒 Path 1: Frozen Base Weights W₀</strong><br>
                <small>4096 × 4096 = 16,777,216 parameters<br>Zero gradients / Zero Adam VRAM</small><br>
                <strong>Output₁ = W₀ · x</strong>
              </div>
              <div class="flow-box" style="background:var(--purple-accent-bg); border:2px solid var(--purple-accent);">
                <strong>✨ Path 2: Trainable LoRA Adapter (Rank r = 8)</strong><br>
                <small>Matrix A (8 × 4096) + Matrix B (4096 × 8)<br>Only 65,536 trainable parameters (&lt;0.39%)</small><br>
                <strong>Output₂ = (α / r) · (B · A) · x</strong>
              </div>
            </div>
            <div class="flow-connector">➕ Element-Wise Addition: Output₁ + Output₂</div>
            <div class="flow-step output-step">
              <strong>Combined Forward Output: h = W₀ · x + (α / r) · (B · A) · x</strong><br>
              <small>⚡ Deployment: Weights permanently merged with 0% extra inference latency!</small>
            </div>
          </div>
        </div>
        `,
    "step_by_step_example": "📐 Concrete LoRA Math Calculations Walkthrough:\n• Example 1: Linear layer (4096 × 4096), LoRA rank r = 8:\n  - Matrix A shape: 8 × 4096 = 32,768 parameters.\n  - Matrix B shape: 4096 × 8 = 32,768 parameters.\n  - Total Trainable Parameters = 32,768 + 32,768 = 65,536 parameters (only 0.39% of 16.7M base weights!).\n• Example 2: Linear layer (1024 × 1024), LoRA rank r = 4:\n  - Matrix A: 4 × 1024 = 4,096 params. Matrix B: 1024 × 4 = 4,096 params.\n  - Total Trainable Parameters = 4,096 + 4,096 = 8,192 parameters.\n• Example 3: Doubling rank from r = 4 to r = 8:\n  - Parameter count doubles strictly linearly from 8,192 to 16,384 parameters.",
    "expected_exam_questions": [
      "Q1: When applying LoRA with base weights frozen, which parameters are excluded from optimizer updates?\n-> Answer: The original pre-trained base weight matrices (W₀).",
      "Q2: A 4096 × 4096 linear layer is adapted with LoRA rank r = 8. How many trainable adapter parameters are used?\n-> Answer: 65,536 parameters (8 × 4096 + 4096 × 8 = 65,536).",
      "Q3: A 1024 × 1024 weight matrix is adapted with LoRA rank r = 4. How many adapter parameters are trained?\n-> Answer: 8,192 parameters (4 × 1024 + 1024 × 4 = 8,192).",
      "Q4: Why is Matrix B initialized to zero in LoRA?\n-> Answer: So that the adapter update ΔW = B · A equals zero at the beginning of training, ensuring the model starts with the exact pre-trained base behavior.",
      "Q5: What is the practical deployment benefit of merging a trained LoRA adapter into the base model weights?\n-> Answer: It eliminates separate adapter computation, resulting in zero extra inference latency."
    ]
  }
};
