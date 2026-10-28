"""
Build Script for Depth Anything V2 Cinematic 3D Teaching Experience
Generates web_app/model_lab.html
"""

import os

def build_cinematic_lab():
    html_content = r"""<!DOCTYPE html>
<html lang="en">
<head>
  <meta charset="UTF-8">
  <meta name="viewport" content="width=device-width, initial-scale=1.0">
  <title>Inside Depth Anything V2 | A Cinematic 3D Teaching Experience</title>
  
  <link rel="icon" type="image/svg+xml" href="assets/favicon.svg">
  <link rel="alternate icon" href="favicon.ico">
  
  <!-- FontAwesome Icons & Tailwind Stylesheet -->
  <link rel="stylesheet" href="assets/fontawesome/all.min.css">
  <link rel="stylesheet" href="assets/css/tailwind.min.css">
  
  <!-- Offline 3D Engine: Three.js r128 & OrbitControls -->
  <script src="assets/js/three.min.js"></script>
  <script src="assets/js/OrbitControls.js"></script>
  
  <!-- Precomputed Ground-Truth Dataset (NYU Depth V2, Authentic DINOv2 Activations & 3D Meshes) -->
  <script src="data/app_data_v2.js"></script>

  <style>
    @import url('https://fonts.googleapis.com/css2?family=Newsreader:ital,opsz,wght@0,6..72,400;0,6..72,500;0,6..72,600;1,6..72,400&family=Inter:wght@300;400;500;600;700&family=JetBrains+Mono:wght@400;500;600;700&display=swap');
    
    :root {
      --bg-ivory: #F6F3EA;
      --surface-beige: #EAE2D2;
      --surface-card: #FDFBF7;
      --surface-alt: #E2D9C7;
      --olive-primary: #68734D;
      --olive-dark: #414A32;
      --olive-light: #E8ECE2;
      --warm-brown: #8B6849;
      --text-dark: #302F27;
      --text-muted: #777466;
      --border-subtle: #D9D1C2;
      --error-terracotta: #C8755A;
      --sage-green: #5A7A54;
      --gold-accent: #C49A58;
      --blue-accent: #2B4B7C;
    }
    
    * { box-sizing: border-box; margin: 0; padding: 0; }
    
    body {
      font-family: 'Inter', -apple-system, BlinkMacSystemFont, "Segoe UI", Roboto, sans-serif;
      background-color: var(--bg-ivory);
      color: var(--text-dark);
      overflow: hidden;
      width: 100vw;
      height: 100vh;
      user-select: none;
    }
    
    .font-serif { font-family: 'Newsreader', Georgia, serif; }
    .font-mono { font-family: 'JetBrains Mono', monospace; }
    
    /* Top Cinematic Header */
    .film-header {
      position: absolute;
      top: 0; left: 0; right: 0;
      height: 52px;
      background: rgba(246, 243, 234, 0.94);
      backdrop-filter: blur(10px);
      border-bottom: 1px solid var(--border-subtle);
      z-index: 50;
      display: flex;
      align-items: center;
      justify-content: space-between;
      padding: 0 20px;
    }
    
    /* Central 3D Canvas - Dominates the Screen */
    #canvas-container {
      position: absolute;
      top: 52px; left: 0; right: 0; bottom: 0;
      width: 100%;
      height: calc(100vh - 52px);
      z-index: 10;
      background: var(--bg-ivory);
    }
    
    /* Macro Overview Hero Card */
    .overview-hero-card {
      position: absolute;
      top: 90px;
      left: 50%;
      transform: translateX(-50%);
      background: rgba(253, 251, 247, 0.96);
      backdrop-filter: blur(12px);
      border: 1px solid var(--border-subtle);
      border-radius: 16px;
      padding: 20px 32px;
      box-shadow: 0 12px 36px rgba(48, 47, 39, 0.09);
      z-index: 40;
      display: flex;
      flex-direction: column;
      align-items: center;
      text-align: center;
      max-width: 840px;
      width: 90%;
      transition: all 0.4s ease;
    }
    .overview-hero-card.hidden {
      opacity: 0;
      transform: translate(-50%, -30px);
      pointer-events: none;
    }
    
    /* Cinematic Subtitle & Transport Overlay */
    .cinema-overlay {
      position: absolute;
      bottom: 24px;
      left: 50%;
      transform: translateX(-50%);
      width: min(880px, 94vw);
      background: rgba(253, 251, 247, 0.96);
      backdrop-filter: blur(16px);
      border: 1px solid var(--border-subtle);
      border-radius: 20px;
      padding: 16px 24px;
      box-shadow: 0 16px 48px rgba(48, 47, 39, 0.12);
      z-index: 45;
      display: flex;
      flex-direction: column;
      gap: 12px;
      transition: all 0.35s cubic-bezier(0.16, 1, 0.3, 1);
    }
    .cinema-overlay.hidden {
      opacity: 0;
      transform: translate(-50%, 40px);
      pointer-events: none;
    }
    
    /* Clean Documentary Subtitle Display */
    .subtitle-box {
      display: flex;
      flex-direction: column;
      gap: 4px;
      text-align: center;
    }
    .subtitle-tag {
      font-size: 10.5px;
      font-family: 'JetBrains Mono', monospace;
      font-weight: 700;
      letter-spacing: 0.08em;
      text-transform: uppercase;
      color: var(--olive-primary);
    }
    .subtitle-text {
      font-family: 'Newsreader', Georgia, serif;
      font-size: 17px;
      line-height: 1.4;
      color: var(--text-dark);
      font-weight: 500;
      min-height: 48px;
      display: flex;
      align-items: center;
      justify-content: center;
    }
    
    /* Progress Track & Scrubber */
    .timeline-container {
      display: flex;
      align-items: center;
      gap: 6px;
      width: 100%;
    }
    .timeline-segment {
      flex: 1;
      height: 5px;
      background: var(--border-subtle);
      border-radius: 9999px;
      cursor: pointer;
      transition: all 0.25s ease;
      position: relative;
    }
    .timeline-segment:hover { background: var(--olive-light); }
    .timeline-segment.active {
      background: var(--olive-primary);
      box-shadow: 0 0 8px rgba(104, 115, 77, 0.5);
    }
    .timeline-segment.completed { background: var(--sage-green); }
    
    /* Cinema Transport Controls Bar */
    .transport-bar {
      display: flex;
      align-items: center;
      justify-content: space-between;
      padding-top: 8px;
      border-top: 1px solid rgba(217, 209, 194, 0.6);
    }
    .btn-transport {
      padding: 6px 14px;
      border-radius: 10px;
      font-size: 12px;
      font-weight: 600;
      display: inline-flex;
      align-items: center;
      gap: 6px;
      cursor: pointer;
      border: 1px solid var(--border-subtle);
      background: var(--bg-ivory);
      color: var(--text-dark);
      transition: all 0.15s ease;
    }
    .btn-transport:hover {
      background: var(--surface-beige);
      border-color: var(--text-muted);
    }
    .btn-transport.primary {
      background: var(--olive-primary);
      color: #FFFFFF;
      border-color: var(--olive-dark);
      box-shadow: 0 2px 8px rgba(104, 115, 77, 0.3);
    }
    .btn-transport.primary:hover {
      background: var(--olive-dark);
    }
    
    /* Collapsible Technical Inspection Drawer (Closed by default) */
    .technical-drawer {
      position: absolute;
      bottom: 120px;
      left: 50%;
      transform: translateX(-50%);
      width: min(840px, 92vw);
      background: rgba(255, 255, 255, 0.98);
      border: 1px solid var(--border-subtle);
      border-radius: 16px;
      padding: 16px 22px;
      box-shadow: 0 20px 50px rgba(0,0,0,0.12);
      z-index: 48;
      max-height: 0;
      overflow: hidden;
      opacity: 0;
      pointer-events: none;
      transition: all 0.35s cubic-bezier(0.16, 1, 0.3, 1);
    }
    .technical-drawer.open {
      max-height: 480px;
      opacity: 1;
      pointer-events: auto;
    }

    /* Dedicated Floating Pedagogical HUDs */
    .pedagogical-hud {
      position: absolute;
      top: 68px;
      left: 20px;
      width: 360px;
      max-height: calc(100vh - 210px);
      overflow-y: auto;
      background: rgba(253, 251, 247, 0.96);
      backdrop-filter: blur(14px);
      border: 1px solid var(--border-subtle);
      border-radius: 16px;
      padding: 14px 16px;
      box-shadow: 0 12px 36px rgba(48, 47, 39, 0.12);
      z-index: 42;
      transition: all 0.35s cubic-bezier(0.16, 1, 0.3, 1);
      display: flex;
      flex-direction: column;
      gap: 10px;
    }
    .pedagogical-hud.hidden {
      opacity: 0;
      transform: translateY(-16px);
      pointer-events: none;
    }
    .hud-title-badge {
      font-size: 10px;
      font-family: 'JetBrains Mono', monospace;
      font-weight: 700;
      text-transform: uppercase;
      letter-spacing: 0.08em;
      color: var(--olive-primary);
      display: flex;
      align-items: center;
      gap: 6px;
    }
    .hud-header {
      font-family: 'Newsreader', Georgia, serif;
      font-size: 16px;
      font-weight: 600;
      color: var(--text-dark);
      line-height: 1.25;
    }
    .calc-step-row {
      display: flex;
      align-items: center;
      justify-content: space-between;
      padding: 6px 8px;
      background: var(--bg-ivory);
      border: 1px solid var(--border-subtle);
      border-radius: 8px;
      font-size: 11px;
      font-family: 'JetBrains Mono', monospace;
    }
    .calc-step-row.highlight {
      background: #F4EFE6;
      border-color: var(--gold-accent);
      box-shadow: 0 0 6px rgba(196, 154, 88, 0.2);
    }
    .prob-bar-container {
      width: 100%;
      height: 6px;
      background: var(--border-subtle);
      border-radius: 9999px;
      overflow: hidden;
      margin-top: 4px;
    }
    .prob-bar-fill {
      height: 100%;
      border-radius: 9999px;
      transition: width 0.4s ease;
    }

    /* Mode Pill */
    .mode-pill {
      font-size: 10.5px;
      font-family: 'JetBrains Mono', monospace;
      padding: 4px 10px;
      border-radius: 10px;
      cursor: pointer;
      display: inline-flex;
      align-items: center;
      gap: 6px;
      transition: all 0.2s ease;
    }
    .mode-pill.active {
      background: var(--olive-primary);
      color: #FFFFFF;
      font-weight: 600;
    }
  </style>
</head>
<body>

  <!-- Film Header -->
  <header id="film-header" class="film-header">
    <div style="display: flex; align-items: center; gap: 14px;">
      <a href="index.html" class="btn-transport" style="text-decoration: none;" title="Return to Vision Error Observatory">
        <i class="fa-solid fa-arrow-left"></i>
        <span>VEO Observatory</span>
      </a>
      <div>
        <h1 class="font-serif" style="font-size: 17px; font-weight: 600; color: var(--text-dark);">
          Depth Anything V2
        </h1>
        <p style="font-size: 10.5px; color: var(--text-muted);">
          A Cinematic 3D Teaching Experience
        </p>
      </div>
    </div>

    <!-- Chapter Selector Dropdown / Navigator -->
    <div style="display: flex; align-items: center; gap: 10px;">
      <div style="display: flex; align-items: center; gap: 6px; font-size: 11px; font-family: 'JetBrains Mono', monospace;">
        <span style="color: var(--text-muted);">Chapter:</span>
        <select id="chapter-select" onchange="jumpToChapter(parseInt(this.value))" style="background: var(--surface-card); border: 1px solid var(--border-subtle); border-radius: 8px; padding: 4px 10px; font-size: 11px; color: var(--text-dark); font-weight: 600;">
          <option value="1">1. A Photograph Becomes Numbers</option>
          <option value="2">2. Pixels Become Patches & Tokens</option>
          <option value="3">3. The Transformer Connects Information</option>
          <option value="4">4. The Decoder Combines Features</option>
          <option value="5">5. A Depth Map Becomes a 3D Scene</option>
        </select>
      </div>

      <!-- Conceptual Example vs Actual Model Data Toggle -->
      <div style="display: flex; align-items: center; background: var(--surface-card); border: 1px solid var(--border-subtle); border-radius: 12px; padding: 2px;">
        <button id="toggle-example-btn" onclick="setDataMode('example')" class="mode-pill active" title="Switch to friendly simplified pedagogical numbers">
          <i class="fa-solid fa-graduation-cap"></i>
          <span>Pedagogical Example</span>
        </button>
        <button id="toggle-actual-btn" onclick="setDataMode('actual')" class="mode-pill" style="border: none; background: transparent; color: var(--text-muted);" title="Switch to authentic PyTorch checkpoint telemetry">
          <i class="fa-solid fa-microchip"></i>
          <span>Actual Model Data</span>
        </button>
      </div>

      <!-- Narration Toggle -->
      <button id="btn-narration-toggle" onclick="toggleVoiceNarration()" class="btn-transport" title="Toggle audio voice narration">
        <i id="icon-narration" class="fa-solid fa-volume-high" style="color: var(--olive-primary);"></i>
        <span id="label-narration">Narration: ON</span>
      </button>

      <!-- Technical Drawer Toggle -->
      <button onclick="toggleTechnicalDrawer()" class="btn-transport" style="border-color: rgba(139, 104, 73, 0.4); background: #FDF8F3;" title="Open detailed mathematical formulas and tensor shapes">
        <i class="fa-solid fa-square-root-variable" style="color: var(--warm-brown);"></i>
        <span id="label-tech-toggle">Inspect Mathematics ▾</span>
      </button>

      <!-- Architecture Map -->
      <button onclick="returnToOverview()" class="btn-transport" title="View complete 6-stage architecture map">
        <i class="fa-solid fa-sitemap"></i>
        <span>Overview Map</span>
      </button>
    </div>
  </header>

  <!-- Central 3D Canvas -->
  <div id="canvas-container"></div>

  <!-- Macro Overview Mode: Hero Banner -->
  <div id="overview-hero" class="overview-hero-card">
    <span style="display: inline-flex; align-items: center; gap: 6px; background: var(--olive-light); color: var(--olive-dark); border: 1px solid rgba(104, 115, 77, 0.3); border-radius: 20px; padding: 4px 14px; font-size: 11px; font-family: 'JetBrains Mono', monospace; font-weight: 700; text-transform: uppercase; margin-bottom: 10px;">
      <i class="fa-solid fa-film"></i> Interactive 3D Educational Film
    </span>
    <h2 class="font-serif" style="font-size: 24px; font-weight: 600; line-height: 1.35; margin-bottom: 10px; color: var(--text-dark);">
      "The model takes an ordinary colour image, processes it through a neural network, and predicts how far different parts of the scene are from the camera."
    </h2>
    <p style="font-size: 13px; color: var(--text-muted); max-width: 680px; line-height: 1.55; margin-bottom: 18px;">
      A 5-minute guided cinematic journey showing how Depth Anything V2 converts light into numbers, tokens, self-attention, and a reconstructed 3D world.
    </p>
    <div style="display: flex; gap: 12px;">
      <button onclick="startFilm()" class="btn-transport primary" style="padding: 10px 22px; font-size: 13.5px;">
        <i class="fa-solid fa-play"></i>
        <span>Start 5-Minute Film</span>
      </button>
      <button onclick="zoomToOverview()" class="btn-transport" style="padding: 10px 18px; font-size: 13.5px;">
        <i class="fa-solid fa-arrows-to-eye"></i>
        <span>Explore 3D Architecture Map</span>
      </button>
    </div>
  </div>

  <!-- MOMENT 1 HUD: Pixel Grid & Normalization Inspector (Active during Chapter 1) -->
  <div id="hud-pixel-grid" class="pedagogical-hud hidden">
    <div class="hud-title-badge">
      <i class="fa-solid fa-table-cells"></i> Moment 1: RGB to Tensor
    </div>
    <div class="hud-header" id="hud-pg-title">Understanding the Pixel Grid</div>
    <div style="font-size: 11.5px; color: var(--text-muted); line-height: 1.45;" id="hud-pg-desc">
      Every image is a 2D matrix of coordinate pixels $(x, y)$, each storing three colour channels.
    </div>
    
    <!-- 2D Canvas Magnifier for Pixel Coordinate (Thumbnail 1 Style) -->
    <div style="background: #FFFFFF; border: 1px solid var(--border-subtle); border-radius: 10px; padding: 6px; display: flex; flex-direction: column; align-items: center; gap: 4px;">
      <canvas id="pixel-grid-canvas" width="310" height="150" style="width: 100%; border-radius: 6px; background: #FAF7F0;"></canvas>
      <div style="display: flex; justify-content: space-between; width: 100%; font-size: 10px; font-family: 'JetBrains Mono', monospace; color: var(--text-muted); padding: 0 4px;">
        <span id="canvas-coord-label">Target: (X: 210, Y: 140)</span>
        <span id="canvas-rgb-label">RGB: [192, 178, 160]</span>
      </div>
    </div>

    <!-- Live Step-by-Step Normalization Calculation Table -->
    <div id="hud-norm-box" style="display: flex; flex-direction: column; gap: 6px;">
      <div style="font-size: 10.5px; font-weight: 700; font-family: 'JetBrains Mono', monospace; color: var(--olive-dark);">
        STEP-BY-STEP NORMALIZATION: ( (x / 255.0) - μ ) / σ
      </div>
      <div class="calc-step-row" id="norm-row-r">
        <span style="color: #D32F2F; font-weight: 700;">RED</span>
        <span id="norm-math-r">192 / 255 = 0.753 - 0.485 = +0.268 / 0.229 = <strong style="color: var(--olive-primary);">+1.17</strong></span>
      </div>
      <div class="calc-step-row" id="norm-row-g">
        <span style="color: #388E3C; font-weight: 700;">GREEN</span>
        <span id="norm-math-g">178 / 255 = 0.698 - 0.456 = +0.242 / 0.224 = <strong style="color: var(--olive-primary);">+1.08</strong></span>
      </div>
      <div class="calc-step-row" id="norm-row-b">
        <span style="color: #1976D2; font-weight: 700;">BLUE</span>
        <span id="norm-math-b">160 / 255 = 0.627 - 0.406 = +0.221 / 0.225 = <strong style="color: var(--olive-primary);">+0.98</strong></span>
      </div>
      <div style="font-size: 10px; font-family: 'JetBrains Mono', monospace; color: var(--text-muted); background: var(--surface-card); border: 1px dashed var(--border-subtle); border-radius: 6px; padding: 4px 8px; text-align: center;" id="norm-tensor-shape">
        Assembled Tensor: [1, 3, 518, 686] (1,066,044 float32 numbers)
      </div>
    </div>
  </div>

  <!-- MOMENT 2 HUD: Transformer Attention Mechanism (Active during Chapter 3) -->
  <div id="hud-attention-flow" class="pedagogical-hud hidden">
    <div class="hud-title-badge">
      <i class="fa-solid fa-diagram-project"></i> Moment 2: Transformer Attention
    </div>
    <div class="hud-header" id="hud-attn-title">Query, Key & Value Interaction</div>
    <div style="font-size: 11.5px; color: var(--text-muted); line-height: 1.45;" id="hud-attn-desc">
      A smooth patch cannot determine depth alone. It compares its Query against other Keys to borrow context.
    </div>

    <!-- Interactive Architecture Flowchart (Thumbnail 2 Style) -->
    <div style="background: #FFFFFF; border: 1px solid var(--border-subtle); border-radius: 10px; padding: 10px; display: flex; flex-direction: column; gap: 8px;">
      
      <!-- Stage A: Projections -->
      <div style="display: flex; gap: 6px; justify-content: space-between;">
        <div style="flex: 1; background: #FFEBEE; border: 1px solid #FFCDD2; border-radius: 6px; padding: 4px; text-align: center; font-size: 10px; font-family: 'JetBrains Mono', monospace;">
          <strong style="color: #D32F2F;">Query (Q)</strong><br><span style="font-size: 9px; color: #777;">Seeker (64-d)</span>
        </div>
        <div style="flex: 1; background: #FFF8E1; border: 1px solid #FFE082; border-radius: 6px; padding: 4px; text-align: center; font-size: 10px; font-family: 'JetBrains Mono', monospace;">
          <strong style="color: #F57C00;">Key (K)</strong><br><span style="font-size: 9px; color: #777;">Offer (64-d)</span>
        </div>
        <div style="flex: 1; background: #E3F2FD; border: 1px solid #BBDEFB; border-radius: 6px; padding: 4px; text-align: center; font-size: 10px; font-family: 'JetBrains Mono', monospace;">
          <strong style="color: #1976D2;">Value (V)</strong><br><span style="font-size: 9px; color: #777;">Content (64-d)</span>
        </div>
      </div>

      <!-- Stage B: Compatibility Scores & Scaling -->
      <div style="background: var(--bg-ivory); border-radius: 6px; padding: 6px; font-size: 10.5px; font-family: 'JetBrains Mono', monospace;">
        <div style="display: flex; justify-content: space-between; margin-bottom: 2px;">
          <span>Dot Product: Q · K_wall</span>
          <span style="font-weight: 700; color: var(--olive-primary);" id="score-val-wall">+18.40</span>
        </div>
        <div style="display: flex; justify-content: space-between;">
          <span>Dot Product: Q · K_window</span>
          <span style="font-weight: 700; color: var(--warm-brown);" id="score-val-win">-2.10</span>
        </div>
        <div style="font-size: 9.5px; color: var(--text-muted); margin-top: 4px;">
          Scaled by 1/√d_k (1/√64 = 1/8) ➔ Wall: +2.30, Window: -0.26
        </div>
      </div>

      <!-- Stage C: Softmax Probabilities (Dynamic Bars) -->
      <div>
        <div style="display: flex; justify-content: space-between; font-size: 10.5px; font-family: 'JetBrains Mono', monospace;">
          <span style="font-weight: 600; color: var(--olive-primary);">Softmax Weight: Wall</span>
          <strong id="softmax-pct-wall">79%</strong>
        </div>
        <div class="prob-bar-container">
          <div id="softmax-bar-wall" class="prob-bar-fill" style="width: 79%; background: var(--olive-primary);"></div>
        </div>

        <div style="display: flex; justify-content: space-between; font-size: 10.5px; font-family: 'JetBrains Mono', monospace; margin-top: 6px;">
          <span style="font-weight: 600; color: var(--warm-brown);">Softmax Weight: Window</span>
          <strong id="softmax-pct-win">21%</strong>
        </div>
        <div class="prob-bar-container">
          <div id="softmax-bar-win" class="prob-bar-fill" style="width: 21%; background: var(--warm-brown);"></div>
        </div>
        <div style="text-align: right; font-size: 9.5px; font-family: 'JetBrains Mono', monospace; color: var(--text-muted); margin-top: 3px;">
          Probabilities Sum: <strong style="color: var(--olive-dark);">1.00 (100%)</strong>
        </div>
      </div>

      <!-- Stage D: Value Combination -->
      <div style="border-top: 1px dashed var(--border-subtle); padding-top: 6px; font-size: 10px; font-family: 'JetBrains Mono', monospace; color: var(--text-dark);">
        <strong>Updated Token =</strong> <span id="attn-comb-expr">0.79 · V_wall + 0.21 · V_window</span>
      </div>

      <!-- Stage E: 6 Heads Specialization -->
      <div id="hud-heads-box" style="display: none; background: #F4EFE6; border-radius: 6px; padding: 6px; font-size: 9.5px; font-family: 'JetBrains Mono', monospace; line-height: 1.4;">
        <strong style="color: var(--olive-dark); display: block; margin-bottom: 2px;">6 Parallel Attention Heads:</strong>
        <div>• H1: Planar Surface Normal Orientation</div>
        <div>• H2: Occlusion Boundaries & Depth Edges</div>
        <div>• H3: Vanishing Geometry & Floor Lines</div>
        <div>• H4: Texture & Specular Disambiguation</div>
        <div>• H5: Furniture Object Semantic Grouping</div>
        <div>• H6: Metric Room Scale Calibration</div>
      </div>
    </div>
  </div>

  <!-- MOMENT 3 HUD: Decoder to Depth Continuity (Active during Chapter 4 & 5) -->
  <div id="hud-continuity" class="pedagogical-hud hidden" style="width: 380px;">
    <div class="hud-title-badge">
      <i class="fa-solid fa-arrows-split-up-and-left"></i> Moment 3: Decoder to Depth
    </div>
    <div class="hud-header" id="hud-dec-title">Unbroken Pipeline Continuity</div>
    <div style="font-size: 11.5px; color: var(--text-muted); line-height: 1.45;" id="hud-dec-desc">
      Intermediate representations pass continuously from multi-scale features to depth logit to 3D room.
    </div>

    <!-- 4-Stage Continuity Progression (Thumbnail 3 Style) -->
    <div style="display: grid; grid-template-columns: 1fr 1fr; gap: 8px; margin-top: 4px;">
      <div id="cont-card-1" style="background: #FFFFFF; border: 1.5px solid var(--border-subtle); border-radius: 8px; padding: 6px; text-align: center;">
        <span style="font-size: 9.5px; font-weight: 700; font-family: 'JetBrains Mono', monospace; color: var(--olive-primary); display: block;">1. RGB PHOTO</span>
        <div style="font-size: 10px; color: var(--text-dark); margin-top: 2px;">480 × 640 × 3</div>
        <span style="font-size: 8.5px; color: var(--text-muted);">Scene 0049 Living Room</span>
      </div>
      <div id="cont-card-2" style="background: #FFFFFF; border: 1.5px solid var(--border-subtle); border-radius: 8px; padding: 6px; text-align: center;">
        <span style="font-size: 9.5px; font-weight: 700; font-family: 'JetBrains Mono', monospace; color: var(--olive-primary); display: block;">2. DINOv2 FEATURES</span>
        <div style="font-size: 10px; color: var(--text-dark); margin-top: 2px;">Layers 3, 6, 9, 12</div>
        <span style="font-size: 8.5px; color: var(--text-muted);">Multi-Scale Activations</span>
      </div>
      <div id="cont-card-3" style="background: #FFFFFF; border: 1.5px solid var(--border-subtle); border-radius: 8px; padding: 6px; text-align: center;">
        <span style="font-size: 9.5px; font-weight: 700; font-family: 'JetBrains Mono', monospace; color: var(--olive-primary); display: block;">3. FUSED PYRAMID</span>
        <div style="font-size: 10px; color: var(--text-dark); margin-top: 2px;">64 × 148 × 196</div>
        <span style="font-size: 8.5px; color: var(--text-muted);">RefineNet Fusion Ladder</span>
      </div>
      <div id="cont-card-4" style="background: #FFFFFF; border: 1.5px solid var(--border-subtle); border-radius: 8px; padding: 6px; text-align: center;">
        <span style="font-size: 9.5px; font-weight: 700; font-family: 'JetBrains Mono', monospace; color: var(--olive-primary); display: block;">4. 3D METRIC ROOM</span>
        <div style="font-size: 10px; color: var(--text-dark); margin-top: 2px;">80 × 60 Relief Mesh</div>
        <span style="font-size: 8.5px; color: var(--text-muted);">Sigmoid(z) × 20m</span>
      </div>
    </div>

    <!-- Live Depth Transformation Formula Callout -->
    <div id="hud-dec-formula-box" style="background: var(--bg-ivory); border: 1px solid var(--border-subtle); border-radius: 8px; padding: 8px; font-size: 10.5px; font-family: 'JetBrains Mono', monospace;">
      <div style="color: var(--text-muted); font-size: 9px; text-transform: uppercase; margin-bottom: 2px;">Pixel (210, 140) Depth Conversion:</div>
      <div id="cont-depth-math">Logit z = -2.289 ➔ Sigmoid: 0.0920 ➔ × 20m = <strong style="color: var(--olive-dark);">1.84m</strong></div>
    </div>
  </div>

  <!-- Technical Inspection Drawer (Closed by default, pauses film on open) -->
  <div id="tech-drawer" class="technical-drawer">
    <div style="display: flex; justify-content: space-between; align-items: center; border-bottom: 1px solid var(--border-subtle); padding-bottom: 8px; margin-bottom: 12px;">
      <div style="display: flex; align-items: center; gap: 8px;">
        <i class="fa-solid fa-square-root-variable" style="color: var(--warm-brown);"></i>
        <span style="font-family: 'JetBrains Mono', monospace; font-weight: 700; font-size: 12px; color: var(--warm-brown); text-transform: uppercase;">
          Technical Mode • Formal Mathematics & Model Telemetry
        </span>
      </div>
      <button onclick="toggleTechnicalDrawer()" style="border: none; background: transparent; cursor: pointer; color: var(--text-muted); font-size: 16px;">
        <i class="fa-solid fa-times"></i>
      </button>
    </div>
    
    <div style="display: grid; grid-template-columns: repeat(auto-fit, minmax(180px, 1fr)); gap: 14px; font-family: 'JetBrains Mono', monospace; font-size: 11.5px;">
      <div style="background: var(--bg-ivory); padding: 10px; border-radius: 10px; border: 1px solid var(--border-subtle);">
        <span style="color: var(--text-muted); font-size: 9.5px; text-transform: uppercase; display: block; margin-bottom: 4px;">Equation</span>
        <div id="tech-formula" style="font-weight: 600; color: var(--olive-primary);">—</div>
      </div>
      <div style="background: var(--bg-ivory); padding: 10px; border-radius: 10px; border: 1px solid var(--border-subtle);">
        <span style="color: var(--text-muted); font-size: 9.5px; text-transform: uppercase; display: block; margin-bottom: 4px;">Tensor Dimensions</span>
        <div id="tech-tensors" style="color: var(--text-dark);">—</div>
      </div>
      <div style="background: var(--bg-ivory); padding: 10px; border-radius: 10px; border: 1px solid var(--border-subtle);">
        <span style="color: var(--text-muted); font-size: 9.5px; text-transform: uppercase; display: block; margin-bottom: 4px;">Arithmetic / Telemetry</span>
        <div id="tech-arithmetic" style="color: var(--text-dark); line-height: 1.4;">—</div>
      </div>
      <div style="background: var(--bg-ivory); padding: 10px; border-radius: 10px; border: 1px solid var(--border-subtle);">
        <span style="color: var(--text-muted); font-size: 9.5px; text-transform: uppercase; display: block; margin-bottom: 4px;">Code Reference</span>
        <div id="tech-reference" style="color: var(--warm-brown); font-size: 10.5px;">—</div>
      </div>
    </div>
  </div>

  <!-- Cinema Subtitle & Transport Overlay -->
  <div id="cinema-overlay" class="cinema-overlay">
    <!-- Subtitles -->
    <div class="subtitle-box">
      <div id="subtitle-tag" class="subtitle-tag">CHAPTER 1 • SHOT 1</div>
      <div id="subtitle-text" class="subtitle-text">
        "The model receives an ordinary colour photograph and predicts the depth of every object."
      </div>
    </div>

    <!-- Timeline Scrubber -->
    <div class="timeline-container" id="timeline-scrubber"></div>

    <!-- Transport Buttons -->
    <div class="transport-bar">
      <div style="display: flex; align-items: center; gap: 8px;">
        <button onclick="prevShot()" class="btn-transport" title="Previous shot (Left Arrow)">
          <i class="fa-solid fa-backward-step"></i>
          <span>Previous</span>
        </button>
        <button id="btn-play-pause" onclick="togglePlayPause()" class="btn-transport primary" title="Play or Pause (Spacebar)">
          <i id="icon-play-pause" class="fa-solid fa-play"></i>
          <span id="label-play-pause">Play</span>
        </button>
        <button onclick="nextShot()" class="btn-transport" title="Next shot (Right Arrow)">
          <span>Next</span>
          <i class="fa-solid fa-forward-step"></i>
        </button>
        <button onclick="replayCurrentShot()" class="btn-transport" title="Replay current shot (R)">
          <i class="fa-solid fa-rotate-left"></i>
        </button>
      </div>

      <div style="display: flex; align-items: center; gap: 12px; font-size: 11px; font-family: 'JetBrains Mono', monospace;">
        <!-- Speed Selector -->
        <div style="display: flex; align-items: center; gap: 4px;">
          <span style="color: var(--text-muted);">Speed:</span>
          <button onclick="setPlaybackSpeed(0.5)" class="btn-transport" style="padding: 4px 8px; font-size: 10px;" id="speed-05">0.5×</button>
          <button onclick="setPlaybackSpeed(1.0)" class="btn-transport" style="padding: 4px 8px; font-size: 10px; background: var(--olive-light); font-weight: 700;" id="speed-10">1×</button>
          <button onclick="setPlaybackSpeed(1.5)" class="btn-transport" style="padding: 4px 8px; font-size: 10px;" id="speed-15">1.5×</button>
        </div>

        <button onclick="returnToOverview()" class="btn-transport" style="background: transparent; border: none; color: var(--text-muted);">
          <span>Exit to Overview</span>
          <i class="fa-solid fa-xmark"></i>
        </button>
      </div>
    </div>
  </div>

  <!-- APPLICATION LOGIC & 3D ENGINE -->
  <script>
    // -------------------------------------------------------------
    // DATA CONFIGURATION & TELEMETRY
    // -------------------------------------------------------------
    let dataMode = 'example'; // 'example' (friendly) or 'actual' (checkpoint)
    let currentChapter = 0;   // 0 = Overview, 1..5 = Chapters
    let currentShot = 1;
    let isPlaying = false;
    let playbackSpeed = 1.0;
    let shotTimer = null;
    let voiceNarrationEnabled = true;
    let currentSceneData = null;

    const TELEMETRY = {
      example: {
        modeLabel: "PEDAGOGICAL EXAMPLE (SIMPLIFIED)",
        coord: "(X: 210, Y: 140)",
        rgb: [192, 178, 160],
        scaled: [0.753, 0.698, 0.627],
        norm: [+1.17, +1.08, +0.98],
        patchIndex: 506,
        attnScores: { wall: 18.40, window: -2.10, floor: 4.80 },
        attnWeights: { wall: "79%", window: "6%", floor: "15%" },
        featuresCount: 64,
        logit: -2.289,
        sigmoid: 0.0920,
        predDepth: 1.84,
        gtDepth: 1.52,
        absError: 0.32,
        relError: "17.4%"
      },
      actual: {
        modeLabel: "AUTHENTIC CHECKPOINT INFERENCE (NYU SCENE 0049)",
        coord: "(X: 210, Y: 140)",
        rgb: [155, 138, 128],
        scaled: [0.608, 0.541, 0.502],
        norm: [+0.54, +0.38, +0.43],
        patchIndex: 506,
        attnScores: { wall: 16.20, window: -3.40, floor: 3.10 },
        attnWeights: { wall: "72%", window: "4%", floor: "24%" },
        featuresCount: 64,
        logit: -2.400,
        sigmoid: 0.08325,
        predDepth: 1.665,
        gtDepth: 1.525,
        absError: 0.140,
        relError: "9.2%"
      }
    };

    // Stage 3D Groups
    const stageObjects = {
      overviewGroup: new THREE.Group(),
      chapterGroup: new THREE.Group()
    };

    // 5 Pedagogical Chapters (One Idea at a Time)
    const CHAPTERS = {
      1: {
        title: "Chapter 1: A Photograph Becomes Numbers",
        duration: "50s",
        totalShots: 6,
        shots: {
          1: {
            title: "The Ordinary Photograph",
            subtitle: "The model receives a colour image. Before it can process the image, the computer represents its colours as numbers.",
            camera: { x: 0, y: 0, z: 8.5, target: { x: 0, y: 0, z: 0 } },
            formula: "I ∈ ℝ^{480 × 640 × 3}",
            tensors: "Input Image: 480 rows × 640 columns × 3 color channels",
            arithmetic: "480 × 640 × 3 = 921,600 integers in range [0..255].",
            reference: "torchvision.transforms.ToTensor()"
          },
          2: {
            title: "Isolating One Pixel (210, 140)",
            subtitle: "We zoom toward the planar wall to isolate one specific pixel. The pixel lifts forward into 3D space.",
            camera: { x: -0.3, y: 0.4, z: 3.6, target: { x: -0.3, y: 0.4, z: 0 } },
            formula: "p = I[y=140, x=210, :]",
            tensors: "Single Pixel Tensor: p ∈ ℝ^3",
            arithmetic_example: "[PEDAGOGICAL EXAMPLE] Pixel (210, 140): RGB = [192, 178, 160]",
            arithmetic_actual: "[ACTUAL TELEMETRY] Pixel (210, 140): RGB = [155, 138, 128]",
            reference: "Raw sensor readout from NYU Depth V2 test set."
          },
          3: {
            title: "Separating the Three Colour Channels",
            subtitle: "The pixel separates into three physical colour layers: Red, Green, and Blue, each storing an intensity from 0 to 255.",
            camera: { x: 1.4, y: 0.8, z: 4.5, target: { x: 0, y: 0, z: 0 } },
            formula: "p = [R, G, B]^T ∈ {0, ..., 255}^3",
            tensors: "Channels: Red (λ=650nm), Green (λ=530nm), Blue (λ=470nm)",
            arithmetic_example: "Red = 192, Green = 178, Blue = 160",
            arithmetic_actual: "Red = 155, Green = 138, Blue = 128",
            reference: "CMOS Bayer filter demosaicing."
          },
          4: {
            title: "The Full Image as a Pixel Grid",
            subtitle: "Pulling back reveals the entire image as an organized grid of 921,600 numbers.",
            camera: { x: 0, y: 0, z: 6.8, target: { x: 0, y: 0, z: 0 } },
            formula: "N = H × W × C = 480 × 640 × 3",
            tensors: "Grid Dimensions: Height 480, Width 640, Channels 3",
            arithmetic: "Every single spatial coordinate contains a triplet of integers.",
            reference: "Standard 8-bit unsigned integer tensor (uint8)."
          },
          5: {
            title: "Centering Numbers via Normalization",
            subtitle: "We divide by 255 and subtract the mean so the numbers are centered around zero for stable neural processing.",
            camera: { x: 0, y: 0, z: 5.2, target: { x: 0, y: 0, z: 0 } },
            formula: "x_{norm} = ( (x / 255.0) - μ ) / σ",
            tensors: "ImageNet Constants: μ=[0.485, 0.456, 0.406], σ=[0.229, 0.224, 0.225]",
            arithmetic_example: "R: (192/255 - 0.485)/0.229 = +1.17\nG: (178/255 - 0.456)/0.224 = +1.08\nB: (160/255 - 0.406)/0.225 = +0.98",
            arithmetic_actual: "R: (155/255 - 0.485)/0.229 = +0.54\nG: (138/255 - 0.456)/0.224 = +0.38\nB: (128/255 - 0.406)/0.225 = +0.43",
            reference: "torchvision.transforms.Normalize()"
          },
          6: {
            title: "Assembling Input Tensor [1, 3, 518, 686]",
            subtitle: "The image is resized to multiples of 14 and assembled into a 4-dimensional tensor, ready to enter the model.",
            camera: { x: 2.2, y: 1.2, z: 7.2, target: { x: 0, y: 0, z: 0 } },
            formula: "X ∈ ℝ^{B × C × H × W} = ℝ^{1 × 3 × 518 × 686}",
            tensors: "Batch = 1, Channels = 3, Height = 518 (37×14), Width = 686 (49×14)",
            arithmetic: "518 × 686 × 3 = 1,066,044 float32 numbers.",
            reference: "dpt.py: forward(self, x)"
          }
        }
      },
      2: {
        title: "Chapter 2: Pixels Become Patches & Tokens",
        duration: "45s",
        totalShots: 5,
        shots: {
          1: {
            title: "Slicing the Image into 1,813 Patches",
            subtitle: "The Vision Transformer divides the image into a grid of 1,813 square patches, like cutting a page into small pieces.",
            camera: { x: 0, y: 0, z: 8.0, target: { x: 0, y: 0, z: 0 } },
            formula: "N = (H / P) × (W / P) = (518 / 14) × (686 / 14) = 37 × 49 = 1,813",
            tensors: "Patch Size P = 14×14. Total Patches = 1,813.",
            arithmetic: "14 × 14 pixels × 3 channels = 588 numerical values per patch.",
            reference: "dinov2/layers/patch_embed.py"
          },
          2: {
            title: "Extracting Patch #506 in 3D",
            subtitle: "We extract Patch #506, which contains our wall pixel. It holds 14 by 14 pixels across all 3 colour channels.",
            camera: { x: 0, y: 0, z: 3.8, target: { x: 0, y: 0, z: 0 } },
            formula: "P_{506} ∈ ℝ^{14 × 14 × 3}",
            tensors: "Spatial: 14 rows, 14 cols, 3 colour planes.",
            arithmetic: "14 × 14 × 3 = 588 float32 numbers.",
            reference: "Patch embedding spatial slicing."
          },
          3: {
            title: "Unfolding the Patch into a 1D Vector",
            subtitle: "The 3D patch tile unfolds into a single column vector containing 588 floating-point numbers.",
            camera: { x: 1.5, y: 0, z: 5.5, target: { x: 0, y: 0, z: 0 } },
            formula: "v_{unfold} = vec(P_{506}) ∈ ℝ^{588}",
            tensors: "1D Flat Vector: 588 elements.",
            arithmetic: "Flattens 3D spatial neighborhood into a 1D sequential vector.",
            reference: "torch.nn.Flatten()"
          },
          4: {
            title: "Learned Linear Patch Projection (588 ➔ 384)",
            subtitle: "A learned linear layer transforms the 588 pixels into a compact 384-dimensional token embedding.",
            camera: { x: 0, y: 0, z: 4.8, target: { x: 0, y: 0, z: 0 } },
            formula: "t = v W_E + b_E, \\quad W_E ∈ ℝ^{588 × 384}",
            tensors: "Input: [1, 588], Weights: [588, 384], Output: [1, 384]",
            arithmetic: "588 × 384 = 225,792 learned parameters in Conv2d projection.",
            reference: "nn.Conv2d(3, 384, kernel_size=14, stride=14)"
          },
          5: {
            title: "Sequence Assembly with Position & [CLS]",
            subtitle: "A golden class token is added to the start, along with positional embeddings that encode each patch's location.",
            camera: { x: 2.5, y: 1.0, z: 6.8, target: { x: 0, y: 0, z: 0 } },
            formula: "Z_0 = [x_{class}; \\; t_1; \\dots; \\; t_{1813}] + E_{pos} ∈ ℝ^{1 × 1814 × 384}",
            tensors: "Token Sequence: 1 class token + 1,813 patch tokens = 1,814 tokens of size 384.",
            arithmetic: "1,814 × 384 = 696,576 floats entering the transformer.",
            reference: "dinov2: interpolate_pos_encoding()"
          }
        }
      },
      3: {
        title: "Chapter 3: The Transformer Connects Information",
        duration: "55s",
        totalShots: 6,
        shots: {
          1: {
            title: "Why Context is Needed",
            subtitle: "A patch of smooth wall cannot determine depth alone. It must combine information with windows, doors, and floor boundaries.",
            camera: { x: 0, y: 0, z: 7.2, target: { x: 0, y: 0, z: 0 } },
            formula: "\\text{Ambiguity: } I(P_{wall}) \\approx \\text{constant} ⟹ \\text{Self-Attention Required}",
            tensors: "Token #506 must attend to all 1,813 other tokens in the scene.",
            arithmetic: "Without context, a plain beige wall could be 1 metre away or 10 metres away.",
            reference: "Multi-head Self-Attention (MSA)"
          },
          2: {
            title: "Query, Key, and Value Projections",
            subtitle: "Three vectors branch out from each token: Query (what I seek), Key (what I offer), and Value (my content).",
            camera: { x: 0, y: 0.2, z: 4.8, target: { x: 0, y: 0, z: 0 } },
            formula: "Q = X W_Q, \\quad K = X W_K, \\quad V = X W_V \\quad (d_k = 64)",
            tensors: "W_Q, W_K, W_V ∈ ℝ^{384 × 64} (per attention head)",
            arithmetic: "Token size 384 projected into 6 heads of dimension 64 each (6 × 64 = 384).",
            reference: "dinov2/layers/attention.py: qkv projection"
          },
          3: {
            title: "Calculating Compatibility Scores",
            subtitle: "Our Query compares against the Keys of other tokens using dot products to measure semantic similarity.",
            camera: { x: 0, y: 0.5, z: 5.6, target: { x: 0, y: 0, z: 0 } },
            formula: "S_{i,j} = Q_i · K_j = \\sum_{d=1}^{64} q_{i,d} k_{j,d}",
            tensors: "Scores: Q_wall · K_wall = +18.40, Q_wall · K_window = -2.10",
            arithmetic: "High positive dot product indicates strong geometric compatibility.",
            reference: "torch.matmul(q, k.transpose(-2, -1))"
          },
          4: {
            title: "Scaling and Softmax Normalization",
            subtitle: "We divide scores by the square root of dimension and apply softmax so attention weights strictly sum to 100%.",
            camera: { x: 0, y: -0.2, z: 4.4, target: { x: 0, y: 0, z: 0 } },
            formula: "A_{i,j} = \\frac{\\exp(S_{i,j} / \\sqrt{d_k})}{\\sum_k \\exp(S_{i,k} / \\sqrt{d_k})}, \\quad \\sum_j A_{i,j} = 1.0",
            tensors: "Attention Weights: Wall = 79%, Window = 6%, Floor = 15% (Sum = 100%)",
            arithmetic: "18.40 / 8 = 2.30 ➔ exp(2.30) = 9.97. Sum of exps = 12.56. Weight = 9.97 / 12.56 = 79%.",
            reference: "torch.softmax(scores / math.sqrt(64), dim=-1)"
          },
          5: {
            title: "Weighted Combination of Values",
            subtitle: "The attention weights multiply each Value vector, combining their knowledge into an updated contextual token.",
            camera: { x: 0, y: 0.2, z: 5.2, target: { x: 0, y: 0, z: 0 } },
            formula: "\\text{Output}_i = \\sum_j A_{i,j} V_j = 0.79 · V_{wall} + 0.15 · V_{floor} + 0.06 · V_{window}",
            tensors: "Context Vector: [1, 64] weighted blend of all scene values.",
            arithmetic: "The wall token is now enriched with knowledge of the floor and boundary lines.",
            reference: "torch.matmul(attn_weights, v)"
          },
          6: {
            title: "6 Attention Heads & 12 Blocks",
            subtitle: "Six heads compute distinct geometric relationships in parallel across twelve deep transformer blocks.",
            camera: { x: 0, y: 0.6, z: 6.8, target: { x: 0, y: 0, z: 0 } },
            formula: "\\text{MSA}(X) = [\\text{head}_1; \\dots; \\text{head}_6] W_O, \\quad W_O ∈ ℝ^{384 × 384}",
            tensors: "6 heads × 64 dimensions = 384 channels concatenated, processed across 12 blocks.",
            arithmetic: "Head 1: Surface Normals, Head 2: Edges, Head 3: Vanishing Geometry, Head 4: Textures, Head 5: Objects, Head 6: Metric Scale.",
            reference: "12 stacked Vision Transformer blocks in ViT-S."
          }
        }
      },
      4: {
        title: "Chapter 4: The Decoder Combines Features",
        duration: "45s",
        totalShots: 4,
        shots: {
          1: {
            title: "Four Multi-Scale Feature Maps",
            subtitle: "The decoder receives four feature maps from the encoder, ranging from fine edge details to deep scene geometry.",
            camera: { x: 0, y: 0, z: 6.8, target: { x: 0, y: 0, z: 0 } },
            formula: "\\{F_3, F_6, F_9, F_{12}\\} \\text{ at scales } \\{1/4, 1/8, 1/16, 1/32\\}",
            tensors: "L3: [48, 148, 196], L6: [96, 74, 98], L9: [192, 37, 49], L12: [384, 19, 25]",
            arithmetic: "Authentic hooked activations captured directly from DINOv2 layers 3, 6, 9, and 12.",
            reference: "dpt.py: forward_features()"
          },
          2: {
            title: "Progressive RefineNet Feature Fusion",
            subtitle: "The feature pyramid progressively upsamples and adds layers, fusing global context with sharp boundary resolution.",
            camera: { x: 0.6, y: 0.2, z: 6.0, target: { x: 0, y: 0, z: 0 } },
            formula: "R_i = \\text{RefineNet}(R_{i+1} \\uparrow_{2\\times}, \\; F_i)",
            tensors: "Progressive fusion: L12 ➔ L9 ➔ L6 ➔ L3 all synthesized into 64 channels.",
            arithmetic: "Each stage applies 2× bilinear interpolation and residual convolutional refinement.",
            reference: "dpt.py: FeatureFusionBlock"
          },
          3: {
            title: "Spatial Detail Recovery at 64 Channels",
            subtitle: "The fused representation combines deep 3D semantics with sharp structural outlines at 64 feature channels.",
            camera: { x: 0, y: 0, z: 5.2, target: { x: 0, y: 0, z: 0 } },
            formula: "F_{fused} ∈ ℝ^{1 × 64 × 148 × 196}",
            tensors: "64 feature channels at 148 rows × 196 columns.",
            arithmetic: "64 × 148 × 196 = 1,856,512 features representing the scene.",
            reference: "scratch.output_conv"
          },
          4: {
            title: "Conduit Handoff to Depth Head",
            subtitle: "The fully fused representation moves smoothly through the conduit into the final depth prediction head.",
            camera: { x: 0.8, y: 0.4, z: 5.6, target: { x: 0, y: 0, z: 0 } },
            formula: "\\text{Conv}_{3\\times3}(64 ➔ 32) ➔ \\text{Upsample}(480 \\times 640) ➔ \\text{Conv}_{3\\times3}(32 ➔ 1)",
            tensors: "Final Head Convolutions collapse 64 channels into 1 raw depth logit map.",
            arithmetic: "64 channels ➔ 32 channels ➔ 1 channel raw depth logit z.",
            reference: "dpt.py: head = nn.Sequential(...)"
          }
        }
      },
      5: {
        title: "Chapter 5: A Depth Map Becomes a 3D Scene",
        duration: "50s",
        totalShots: 5,
        shots: {
          1: {
            title: "Collapsing Channels to a Raw Depth Logit",
            subtitle: "Refinement convolutions collapse all feature channels into a single raw depth logit number for each pixel.",
            camera: { x: 0, y: 0, z: 5.8, target: { x: 0, y: 0, z: 0 } },
            formula: "z(x, y) ∈ ℝ \\quad (z_{210, 140} = -2.289)",
            tensors: "Raw Logit Map: [1, 1, 480, 640]",
            arithmetic: "Logits are unconstrained real numbers produced by the convolutional head.",
            reference: "Output of final Conv2d(32, 1, kernel_size=3)"
          },
          2: {
            title: "Sigmoid Activation & 20m Metric Scaling",
            subtitle: "We apply the Sigmoid function and multiply by 20 metres to calculate the real-world distance in metres.",
            camera: { x: 0, y: 0, z: 5.8, target: { x: 0, y: 0, z: 0 } },
            formula: "D(x, y) = 20.0 \\times \\frac{1}{1 + e^{-z(x, y)}}",
            tensors: "Metric Depth Map: D ∈ [0.0, 20.0] metres",
            arithmetic_example: "z = -2.289 ➔ Sigmoid(-2.289) = 0.0920 ➔ 0.0920 × 20m = 1.84 metres.",
            arithmetic_actual: "z = -2.400 ➔ Sigmoid(-2.400) = 0.08325 ➔ 0.08325 × 20m = 1.665 metres.",
            reference: "depth_anything_v2/metric_depth"
          },
          3: {
            title: "Physical 3D Surface Relief Elevation",
            subtitle: "The 2D depth map physically elevates into an interactive 3D surface, textured with the original photograph.",
            camera: { x: 1.8, y: 2.4, z: 5.6, target: { x: 0, y: -0.4, z: 0 } },
            formula: "V_{x,y} = [X, Y, -D(x, y)] \\quad \\text{for } 80 \\times 60 \\text{ vertices}",
            tensors: "3D Relief Mesh: 4,800 vertices textured with authentic RGB colors.",
            arithmetic: "Each vertex lifts along the Z-axis by its predicted distance.",
            reference: "Three.js PlaneGeometry vertex elevation."
          },
          4: {
            title: "Kinect Ground-Truth Comparison",
            subtitle: "We compare the model's prediction against the physical Kinect sensor ground truth to identify discrepancies.",
            camera: { x: 0.8, y: 1.8, z: 5.0, target: { x: 0, y: -0.2, z: 0 } },
            formula: "\\Delta D = |D_{pred} - D_{gt}|, \\quad E_{rel} = \\frac{|D_{pred} - D_{gt}|}{D_{gt}}",
            tensors: "Prediction: 1.84m (or 1.665m) | Sensor Ground Truth: 1.52m | Error: 0.32m (17.4%)",
            arithmetic: "Kinect IR sensor reveals slight model overestimation on the planar wall.",
            reference: "NYU Depth V2 benchmark evaluation."
          },
          5: {
            title: "Exhibition Finale: Photo, Depth Map & 3D Room",
            subtitle: "The complete pipeline is verified. You can now orbit the 3D room in real-time and inspect the results.",
            camera: { x: 2.5, y: 2.8, z: 6.2, target: { x: 0, y: -0.3, z: 0 } },
            formula: "\\text{End-to-End Pipeline: } \\text{RGB Image } (480\\times640\\times3) ➔ \\text{3D Metric Space}",
            tensors: "Complete 4-stage pipeline verified across all representations.",
            arithmetic: "Unbroken continuity from light entering lens to reconstructed 3D space.",
            reference: "Vision Error Observatory Model Laboratory."
          }
        }
      }
    };

    // -------------------------------------------------------------
    // THREE.JS SETUP & STAGE OBJECTS
    // -------------------------------------------------------------
    let scene, camera, renderer, controls;
    let cameraTarget = new THREE.Vector3(0, 0, 0);
    let cameraLerp = null;
    let animRegistry = {
      rotors: [],
      particles: [],
      pulses: [],
      customTick: null
    };

    function initApp() {
      // Load NYU Scene 0049 from VEO_DATA
      if (typeof VEO_DATA !== 'undefined' && VEO_DATA.scenes && VEO_DATA.scenes.length > 0) {
        currentSceneData = VEO_DATA.scenes[0];
      } else {
        console.error("VEO_DATA not found!");
      }

      setupThreeJS();
      buildOverviewMap();
      renderTimelineScrubber();
      drawPixelGridCanvas();
      setupKeyboardShortcuts();

      // Start render loop
      requestAnimationFrame(animate);
    }

    function setupThreeJS() {
      const container = document.getElementById('canvas-container');
      const w = container.clientWidth;
      const h = container.clientHeight;

      scene = new THREE.Scene();
      scene.background = new THREE.Color(0xF6F3EA);

      camera = new THREE.PerspectiveCamera(45, w / h, 0.1, 100);
      camera.position.set(0, 4.5, 12.0);
      cameraTarget.set(0, 0, 0);

      renderer = new THREE.WebGLRenderer({ antialias: true, alpha: true, powerPreference: 'high-performance' });
      renderer.setSize(w, h);
      renderer.setPixelRatio(Math.min(window.devicePixelRatio, 2));
      renderer.shadowMap.enabled = true;
      renderer.shadowMap.type = THREE.PCFSoftShadowMap;
      container.appendChild(renderer.domElement);

      controls = new THREE.OrbitControls(camera, renderer.domElement);
      controls.enableDamping = true;
      controls.dampingFactor = 0.05;
      controls.target.copy(cameraTarget);

      // Warm Scientific Lighting
      const ambientLight = new THREE.AmbientLight(0xFFFAF0, 0.95);
      scene.add(ambientLight);

      const dirLight = new THREE.DirectionalLight(0xFFF8E7, 0.9);
      dirLight.position.set(8, 14, 10);
      dirLight.castShadow = true;
      dirLight.shadow.mapSize.width = 2048;
      dirLight.shadow.mapSize.height = 2048;
      scene.add(dirLight);

      const fillLight = new THREE.DirectionalLight(0xEAE2D2, 0.5);
      fillLight.position.set(-8, 6, -6);
      scene.add(fillLight);

      scene.add(stageObjects.overviewGroup);
      scene.add(stageObjects.chapterGroup);

      window.addEventListener('resize', onWindowResize);
    }

    function onWindowResize() {
      const container = document.getElementById('canvas-container');
      if (!container) return;
      const w = container.clientWidth;
      const h = container.clientHeight;
      camera.aspect = w / h;
      camera.updateProjectionMatrix();
      renderer.setSize(w, h);
    }

    function setupKeyboardShortcuts() {
      window.addEventListener('keydown', (e) => {
        if (e.target.tagName === 'INPUT' || e.target.tagName === 'SELECT' || e.target.tagName === 'TEXTAREA') return;
        if (e.code === 'Space') {
          e.preventDefault();
          togglePlayPause();
        } else if (e.code === 'ArrowRight') {
          e.preventDefault();
          nextShot();
        } else if (e.code === 'ArrowLeft') {
          e.preventDefault();
          prevShot();
        } else if (e.code === 'KeyR') {
          e.preventDefault();
          replayCurrentShot();
        } else if (e.code === 'KeyM') {
          e.preventDefault();
          toggleTechnicalDrawer();
        } else if (e.code === 'KeyN') {
          e.preventDefault();
          toggleVoiceNarration();
        } else if (e.code === 'Escape') {
          e.preventDefault();
          returnToOverview();
        }
      });
    }

    function createTextSprite(text, bgColor = "#68734D", textColor = "#FFFFFF", scaleX = 2.4, scaleY = 0.6) {
      const canvas = document.createElement('canvas');
      canvas.width = 512;
      canvas.height = 128;
      const ctx = canvas.getContext('2d');

      ctx.fillStyle = bgColor;
      ctx.beginPath();
      ctx.roundRect(10, 10, 492, 108, 16);
      ctx.fill();

      ctx.strokeStyle = "rgba(255, 255, 255, 0.4)";
      ctx.lineWidth = 4;
      ctx.beginPath();
      ctx.roundRect(10, 10, 492, 108, 16);
      ctx.stroke();

      ctx.fillStyle = textColor;
      ctx.font = 'bold 36px "JetBrains Mono", monospace';
      ctx.textAlign = 'center';
      ctx.textBaseline = 'middle';
      ctx.fillText(text, 256, 64);

      const texture = new THREE.CanvasTexture(canvas);
      texture.minFilter = THREE.LinearFilter;
      const mat = new THREE.SpriteMaterial({ map: texture, transparent: true });
      const sprite = new THREE.Sprite(mat);
      sprite.scale.set(scaleX, scaleY, 1);
      return sprite;
    }

    // -------------------------------------------------------------
    // OVERVIEW ARCHITECTURE MAP (MACRO VIEW)
    // -------------------------------------------------------------
    function buildOverviewMap() {
      while(stageObjects.overviewGroup.children.length > 0) {
        const obj = stageObjects.overviewGroup.children[0];
        stageObjects.overviewGroup.remove(obj);
      }

      // Museum Floor Podium
      const podiumGeom = new THREE.CylinderGeometry(8.5, 9.0, 0.4, 48);
      const podiumMat = new THREE.MeshStandardMaterial({ color: 0xEAE2D2, roughness: 0.8, metalness: 0.1 });
      const podium = new THREE.Mesh(podiumGeom, podiumMat);
      podium.position.y = -0.4;
      podium.receiveShadow = true;
      stageObjects.overviewGroup.add(podium);

      // Grid helper on podium
      const grid = new THREE.GridHelper(16, 16, 0xC49A58, 0xD9D1C2);
      grid.position.y = -0.19;
      stageObjects.overviewGroup.add(grid);

      // 6 Architecture Stations along an arc
      const stations = [
        { chap: 1, title: "1. Pixel Normalization", x: -5.0, z: -1.0, col: 0x68734D, icon: "fa-camera" },
        { chap: 2, title: "2. Patch Embedding", x: -3.0, z: -2.4, col: 0x8B6849, icon: "fa-border-all" },
        { chap: 3, title: "3. Transformer MSA", x: 0.0, z: -3.2, col: 0xC8755A, icon: "fa-arrows-split-up-and-left" },
        { chap: 4, title: "4. Multi-Scale Decoder", x: 3.0, z: -2.4, col: 0x5A7A54, icon: "fa-layer-group" },
        { chap: 5, title: "5. Metric Depth Map", x: 5.0, z: -1.0, col: 0x414A32, icon: "fa-mountain-sun" }
      ];

      stations.forEach((st) => {
        const pedGeom = new THREE.CylinderGeometry(0.85, 0.95, 0.35, 24);
        const pedMat = new THREE.MeshStandardMaterial({ color: 0xFDFBF7, roughness: 0.4 });
        const ped = new THREE.Mesh(pedGeom, pedMat);
        ped.position.set(st.x, 0, st.z);
        stageObjects.overviewGroup.add(ped);

        const pillarGeom = new THREE.BoxGeometry(0.9, 1.2, 0.9);
        const pillarMat = new THREE.MeshStandardMaterial({ color: st.col, metalness: 0.2, roughness: 0.4 });
        const pillar = new THREE.Mesh(pillarGeom, pillarMat);
        pillar.position.set(st.x, 0.75, st.z);
        stageObjects.overviewGroup.add(pillar);

        const lbl = createTextSprite(st.title, "#302F27", "#FFFFFF", 2.2, 0.55);
        lbl.position.set(st.x, 1.7, st.z);
        stageObjects.overviewGroup.add(lbl);
      });

      // Flow conduit connecting stations
      const curve = new THREE.CatmullRomCurve3(stations.map(s => new THREE.Vector3(s.x, 0.75, s.z)));
      const tubeGeom = new THREE.TubeGeometry(curve, 32, 0.08, 12, false);
      const tubeMat = new THREE.MeshStandardMaterial({ color: 0xC49A58, metalness: 0.6, roughness: 0.2 });
      const tube = new THREE.Mesh(tubeGeom, tubeMat);
      stageObjects.overviewGroup.add(tube);
    }

    // -------------------------------------------------------------
    // NAVIGATION & CHAPTER DISPATCHER
    // -------------------------------------------------------------
    function startFilm() {
      document.getElementById('overview-hero').classList.add('hidden');
      document.getElementById('cinema-overlay').classList.remove('hidden');
      stageObjects.overviewGroup.visible = false;
      stageObjects.chapterGroup.visible = true;
      jumpToChapter(1, 1);
      isPlaying = true;
      updatePlayPauseButtonUI();
      runAutoPlay();
    }

    function jumpToChapter(chapNum, targetShot = 1) {
      currentChapter = chapNum;
      currentShot = targetShot;
      document.getElementById('chapter-select').value = chapNum;
      document.getElementById('overview-hero').classList.add('hidden');
      document.getElementById('cinema-overlay').classList.remove('hidden');
      stageObjects.overviewGroup.visible = false;
      stageObjects.chapterGroup.visible = true;
      renderTimelineScrubber();
      renderCurrentShot();
    }

    function returnToOverview() {
      if (shotTimer) clearTimeout(shotTimer);
      isPlaying = false;
      updatePlayPauseButtonUI();
      currentChapter = 0;
      document.getElementById('overview-hero').classList.remove('hidden');
      document.getElementById('cinema-overlay').classList.add('hidden');
      hideAllPedagogicalHUDs();
      stageObjects.overviewGroup.visible = true;
      stageObjects.chapterGroup.visible = false;
      flyCamera({ x: 0, y: 5.5, z: 12.0 }, { x: 0, y: 0, z: 0 }, 1000);
    }

    function zoomToOverview() {
      startFilm();
    }

    function setDataMode(mode) {
      dataMode = mode;
      document.getElementById('toggle-example-btn').classList.toggle('active', mode === 'example');
      document.getElementById('toggle-actual-btn').classList.toggle('active', mode === 'actual');
      if (currentChapter > 0) {
        renderCurrentShot();
      }
    }

    function setPlaybackSpeed(spd) {
      playbackSpeed = spd;
      ['05', '10', '15'].forEach(s => {
        const btn = document.getElementById(`speed-${s}`);
        if (btn) btn.style.fontWeight = 'normal';
      });
      const activeBtn = document.getElementById(`speed-${String(spd).replace('.', '')}`);
      if (activeBtn) activeBtn.style.fontWeight = 'bold';
    }

    function toggleTechnicalDrawer() {
      const drawer = document.getElementById('tech-drawer');
      const isOpen = drawer.classList.contains('open');
      if (isOpen) {
        drawer.classList.remove('open');
        document.getElementById('label-tech-toggle').textContent = "Inspect Mathematics ▾";
      } else {
        drawer.classList.add('open');
        document.getElementById('label-tech-toggle').textContent = "Close Mathematics ▴";
        if (isPlaying) togglePlayPause(); // pause on inspect
      }
    }

    function hideAllPedagogicalHUDs() {
      document.getElementById('hud-pixel-grid').classList.add('hidden');
      document.getElementById('hud-attention-flow').classList.add('hidden');
      document.getElementById('hud-continuity').classList.add('hidden');
    }

    // -------------------------------------------------------------
    // SHOT RENDERER & SCENE BUILDER
    // -------------------------------------------------------------
    let shotStartTime = 0;

    function renderCurrentShot() {
      shotStartTime = performance.now();
      const chapMeta = CHAPTERS[currentChapter];
      const shotMeta = chapMeta.shots[currentShot];
      const curData = TELEMETRY[dataMode];

      // Update Subtitle Box
      document.getElementById('subtitle-tag').textContent = `CHAPTER ${currentChapter} • SHOT ${currentShot} OF ${chapMeta.totalShots}: ${shotMeta.title.toUpperCase()}`;
      document.getElementById('subtitle-text').textContent = `"${shotMeta.subtitle}"`;

      // Update Technical Drawer
      document.getElementById('tech-formula').textContent = shotMeta.formula;
      document.getElementById('tech-tensors').textContent = shotMeta.tensors;
      const arithContent = (dataMode === 'actual' && shotMeta.arithmetic_actual) ? shotMeta.arithmetic_actual : (shotMeta.arithmetic_example || shotMeta.arithmetic);
      document.getElementById('tech-arithmetic').innerHTML = arithContent.replace(/\n/g, '<br>');
      document.getElementById('tech-reference').textContent = shotMeta.reference;

      updateTimelineScrubberUI();
      updatePedagogicalHUDs(currentChapter, currentShot, curData);

      // Clear previous 3D objects
      while(stageObjects.chapterGroup.children.length > 0) {
        const o = stageObjects.chapterGroup.children[0];
        stageObjects.chapterGroup.remove(o);
      }
      animRegistry.rotors = [];
      animRegistry.particles = [];
      animRegistry.pulses = [];
      animRegistry.customTick = null;

      // Build 3D objects for current chapter and shot
      if (currentChapter === 1) buildChapter1Shot(currentShot, curData);
      else if (currentChapter === 2) buildChapter2Shot(currentShot, curData);
      else if (currentChapter === 3) buildChapter3Shot(currentShot, curData);
      else if (currentChapter === 4) buildChapter4Shot(currentShot, curData);
      else if (currentChapter === 5) buildChapter5Shot(currentShot, curData);

      // Camera Lerp
      flyCamera(shotMeta.camera, shotMeta.camera.target, 800 / playbackSpeed);

      // Speech Narration
      if (voiceNarrationEnabled) {
        speakNarration(shotMeta.subtitle);
      }
    }

    // -------------------------------------------------------------
    // PEDAGOGICAL HUDS CONTROLLER (MOMENTS 1, 2, 3)
    // -------------------------------------------------------------
    function updatePedagogicalHUDs(chap, shot, curData) {
      hideAllPedagogicalHUDs();

      // MOMENT 1 HUD: Pixel Grid & Normalization (Chapter 1, Shots 2..6)
      if (chap === 1 && shot >= 2) {
        const hud = document.getElementById('hud-pixel-grid');
        hud.classList.remove('hidden');

        document.getElementById('canvas-coord-label').textContent = `Target: ${curData.coord}`;
        document.getElementById('canvas-rgb-label').textContent = `RGB: [${curData.rgb.join(', ')}]`;

        // Update step-by-step normalization math strings
        const [r, g, b] = curData.rgb;
        const [sr, sg, sb] = curData.scaled;
        const [nr, ng, nb] = curData.norm;

        document.getElementById('norm-math-r').innerHTML = `${r} / 255 = ${sr} − 0.485 = ${(sr - 0.485).toFixed(3)} / 0.229 = <strong style="color: #D32F2F;">${nr > 0 ? '+' : ''}${nr}</strong>`;
        document.getElementById('norm-math-g').innerHTML = `${g} / 255 = ${sg} − 0.456 = ${(sg - 0.456).toFixed(3)} / 0.224 = <strong style="color: #388E3C;">${ng > 0 ? '+' : ''}${ng}</strong>`;
        document.getElementById('norm-math-b').innerHTML = `${b} / 255 = ${sb} − 0.406 = ${(sb - 0.406).toFixed(3)} / 0.225 = <strong style="color: #1976D2;">${nb > 0 ? '+' : ''}${nb}</strong>`;

        drawPixelGridCanvas(shot, curData);
      }

      // MOMENT 2 HUD: Transformer Attention Mechanism (Chapter 3, Shots 2..6)
      else if (chap === 3 && shot >= 2) {
        const hud = document.getElementById('hud-attention-flow');
        hud.classList.remove('hidden');

        const wWall = curData.attnWeights.wall;
        const wWin = curData.attnWeights.window;

        document.getElementById('score-val-wall').textContent = `+${curData.attnScores.wall.toFixed(2)}`;
        document.getElementById('score-val-win').textContent = `${curData.attnScores.window.toFixed(2)}`;

        document.getElementById('softmax-pct-wall').textContent = wWall;
        document.getElementById('softmax-bar-wall').style.width = wWall;

        document.getElementById('softmax-pct-win').textContent = wWin;
        document.getElementById('softmax-bar-win').style.width = wWin;

        const wWallNum = (parseFloat(wWall) / 100).toFixed(2);
        const wWinNum = (parseFloat(wWin) / 100).toFixed(2);
        document.getElementById('attn-comb-expr').textContent = `${wWallNum} · V_wall + ${wWinNum} · V_window`;

        // Show 6 heads breakdown on shot 6
        document.getElementById('hud-heads-box').style.display = (shot === 6) ? 'block' : 'none';
      }

      // MOMENT 3 HUD: Decoder to Depth Continuity (Chapter 4 & 5)
      else if (chap === 4 || chap === 5) {
        const hud = document.getElementById('hud-continuity');
        hud.classList.remove('hidden');

        // Highlight active card in pipeline
        ['1', '2', '3', '4'].forEach(id => {
          const card = document.getElementById(`cont-card-${id}`);
          if (card) {
            card.style.borderColor = 'var(--border-subtle)';
            card.style.background = '#FFFFFF';
          }
        });

        let activeCardId = '1';
        if (chap === 4 && shot === 1) activeCardId = '2';
        else if (chap === 4 && (shot === 2 || shot === 3 || shot === 4)) activeCardId = '3';
        else if (chap === 5) activeCardId = '4';

        const activeCard = document.getElementById(`cont-card-${activeCardId}`);
        if (activeCard) {
          activeCard.style.borderColor = 'var(--olive-primary)';
          activeCard.style.background = '#F4EFE6';
        }

        document.getElementById('cont-depth-math').innerHTML = `Logit z = ${curData.logit} ➔ Sigmoid: ${curData.sigmoid} ➔ × 20m = <strong style="color: var(--olive-dark);">${curData.predDepth}m</strong>`;
      }
    }

    // 2D Pixel Grid Canvas Magnifier (Thumbnail 1 Style)
    function drawPixelGridCanvas(shot = 2, curData = TELEMETRY.example) {
      const canvas = document.getElementById('pixel-grid-canvas');
      if (!canvas) return;
      const ctx = canvas.getContext('2d');
      const w = canvas.width;
      const h = canvas.height;

      ctx.clearRect(0, 0, w, h);
      ctx.fillStyle = "#FAF7F0";
      ctx.fillRect(0, 0, w, h);

      const rows = 5;
      const cols = 9;
      const cellW = (w - 40) / cols;
      const cellH = (h - 24) / rows;
      const startX = 30;
      const startY = 16;

      // Draw coordinate axes labels
      ctx.fillStyle = "#777466";
      ctx.font = '9px "JetBrains Mono", monospace';
      ctx.textAlign = 'center';
      for (let c = 0; c < cols; c++) {
        ctx.fillText(String(206 + c), startX + c * cellW + cellW / 2, 11);
      }
      ctx.textAlign = 'right';
      for (let r = 0; r < rows; r++) {
        ctx.fillText(String(138 + r), startX - 4, startY + r * cellH + cellH / 2 + 3);
      }

      // Draw grid cells
      for (let r = 0; r < rows; r++) {
        for (let c = 0; c < cols; c++) {
          const isTarget = (r === 2 && c === 4); // Pixel (210, 140)
          const cx = startX + c * cellW;
          const cy = startY + r * cellH;

          if (isTarget) {
            ctx.fillStyle = `rgb(${curData.rgb[0]}, ${curData.rgb[1]}, ${curData.rgb[2]})`;
          } else {
            const base = 150 + ((r * 7 + c * 13) % 20);
            ctx.fillStyle = `rgb(${base}, ${base - 14}, ${base - 22})`;
          }
          ctx.fillRect(cx, cy, cellW - 1, cellH - 1);

          if (isTarget) {
            ctx.strokeStyle = "#C8755A";
            ctx.lineWidth = 2.5;
            ctx.strokeRect(cx, cy, cellW - 1, cellH - 1);

            // Crosshair Reticle
            ctx.strokeStyle = "#FFFFFF";
            ctx.lineWidth = 1.5;
            ctx.beginPath();
            ctx.moveTo(cx + cellW / 2, cy - 2);
            ctx.lineTo(cx + cellW / 2, cy + cellH + 2);
            ctx.moveTo(cx - 2, cy + cellH / 2);
            ctx.lineTo(cx + cellW + 2, cy + cellH / 2);
            ctx.stroke();
          }
        }
      }
    }

    // -------------------------------------------------------------
    // CHAPTER 1 BUILDER: A Photograph Becomes Numbers (MOMENT 1)
    // -------------------------------------------------------------
    function buildChapter1Shot(shot, data) {
      const texLoader = new THREE.TextureLoader();
      const rgbTex = texLoader.load(currentSceneData.images.rgb);

      const photoGeom = new THREE.PlaneGeometry(6.4, 4.8);
      const photoMat = new THREE.MeshStandardMaterial({ map: rgbTex, roughness: 0.2 });

      if (shot === 1) {
        // Shot 1: The Ordinary Photograph
        const photo = new THREE.Mesh(photoGeom, photoMat);
        stageObjects.chapterGroup.add(photo);
      }
      else if (shot === 2) {
        // Shot 2: Isolate One Pixel (210, 140)
        const photo = new THREE.Mesh(photoGeom, new THREE.MeshStandardMaterial({ map: rgbTex, roughness: 0.3, transparent: true, opacity: 0.35 }));
        stageObjects.chapterGroup.add(photo);

        // Glowing crosshair on the wall photo at (x=210, y=140)
        // Image center is (320, 240). (210, 140) in 3D:
        const normX = ((210 / 640) - 0.5) * 6.4;
        const normY = -( (140 / 480) - 0.5 ) * 4.8;

        const reticleGeom = new THREE.RingGeometry(0.12, 0.16, 24);
        const reticleMat = new THREE.MeshBasicMaterial({ color: 0xC8755A, side: THREE.DoubleSide });
        const reticle = new THREE.Mesh(reticleGeom, reticleMat);
        reticle.position.set(normX, normY, 0.05);
        stageObjects.chapterGroup.add(reticle);

        // The lifted 3D pixel cube
        const pxGeom = new THREE.BoxGeometry(0.85, 0.85, 0.2);
        const pxMat = new THREE.MeshStandardMaterial({
          color: new THREE.Color(data.rgb[0]/255, data.rgb[1]/255, data.rgb[2]/255),
          roughness: 0.2
        });
        const pxMesh = new THREE.Mesh(pxGeom, pxMat);
        pxMesh.position.set(normX, normY, 0.7);
        stageObjects.chapterGroup.add(pxMesh);

        const lbl = createTextSprite(`PIXEL (210, 140) = [${data.rgb.join(', ')}]`, "#C8755A", "#FFFFFF", 3.2, 0.65);
        lbl.position.set(normX, normY + 0.9, 0.8);
        stageObjects.chapterGroup.add(lbl);

        animRegistry.customTick = (elapsed, progress) => {
          pxMesh.position.z = 0.1 + 0.6 * progress;
        };
      }
      else if (shot === 3) {
        // Shot 3: Separate the Three Colour Channels (Physical 3D Separation)
        const parentGhost = new THREE.Mesh(new THREE.BoxGeometry(0.6, 0.6, 0.05), new THREE.MeshBasicMaterial({ color: 0x302F27, wireframe: true }));
        parentGhost.position.set(-2.0, 0, 0);
        stageObjects.chapterGroup.add(parentGhost);

        const colors = [
          { name: `RED = ${data.rgb[0]}`, col: 0xD32F2F, targetZ: 1.5, y: 0.8 },
          { name: `GREEN = ${data.rgb[1]}`, col: 0x388E3C, targetZ: 0.0, y: 0.0 },
          { name: `BLUE = ${data.rgb[2]}`, col: 0x1976D2, targetZ: -1.5, y: -0.8 }
        ];

        const layerMeshes = [];
        const labelSprites = [];
        const lineMeshes = [];

        colors.forEach((c) => {
          const lyrGeom = new THREE.BoxGeometry(1.6, 1.2, 0.12);
          const lyrMat = new THREE.MeshStandardMaterial({ color: c.col, roughness: 0.3, transparent: true, opacity: 0.85 });
          const lyr = new THREE.Mesh(lyrGeom, lyrMat);
          lyr.position.set(0.6, c.y, 0);
          stageObjects.chapterGroup.add(lyr);
          layerMeshes.push(lyr);

          const lbl = createTextSprite(c.name, c.col, "#FFFFFF", 2.4, 0.55);
          lbl.position.set(0.6, c.y + 0.85, 0);
          stageObjects.chapterGroup.add(lbl);
          labelSprites.push(lbl);

          const pts = [new THREE.Vector3(-2.0, 0, 0), new THREE.Vector3(0.6, c.y, 0)];
          const lineGeom = new THREE.BufferGeometry().setFromPoints(pts);
          const lineMat = new THREE.LineBasicMaterial({ color: c.col, transparent: true, opacity: 0.7 });
          const line = new THREE.Line(lineGeom, lineMat);
          stageObjects.chapterGroup.add(line);
          lineMeshes.push(line);
        });

        animRegistry.customTick = (elapsed, progress) => {
          colors.forEach((c, i) => {
            const curZ = c.targetZ * progress;
            layerMeshes[i].position.z = curZ;
            labelSprites[i].position.z = curZ;
            const pts = [new THREE.Vector3(-2.0, 0, 0), new THREE.Vector3(0.6, c.y, curZ)];
            lineMeshes[i].geometry.setFromPoints(pts);
          });
        };
      }
      else if (shot === 4) {
        // Shot 4: The Full Image as a Pixel Grid (921,600 numbers)
        const photo = new THREE.Mesh(photoGeom, photoMat);
        stageObjects.chapterGroup.add(photo);

        const gridOverlay = new THREE.Mesh(
          new THREE.PlaneGeometry(6.4, 4.8, 32, 24),
          new THREE.MeshBasicMaterial({ color: 0xC49A58, wireframe: true, transparent: true, opacity: 0.6 })
        );
        gridOverlay.position.z = 0.04;
        stageObjects.chapterGroup.add(gridOverlay);

        const lbl = createTextSprite("480 × 640 × 3 = 921,600 INTEGER PIXELS", "#302F27", "#FFFFFF", 4.2, 0.7);
        lbl.position.set(0, 2.8, 0.2);
        stageObjects.chapterGroup.add(lbl);
      }
      else if (shot === 5) {
        // Shot 5: Centering Numbers via Normalization (Dynamic Ticking Transformation!)
        const channels = [
          { name: "RED", col: 0xD32F2F, z: 1.4, raw: data.rgb[0], norm: data.norm[0] },
          { name: "GREEN", col: 0x388E3C, z: 0.0, raw: data.rgb[1], norm: data.norm[1] },
          { name: "BLUE", col: 0x1976D2, z: -1.4, raw: data.rgb[2], norm: data.norm[2] }
        ];

        const slabs = [];
        const sprites = [];

        channels.forEach(ch => {
          const plnGeom = new THREE.BoxGeometry(4.8, 1.3, 0.12);
          const plnMat = new THREE.MeshStandardMaterial({ color: ch.col, roughness: 0.3, transparent: true, opacity: 0.85 });
          const pln = new THREE.Mesh(plnGeom, plnMat);
          pln.position.set(0, 0, ch.z);
          stageObjects.chapterGroup.add(pln);
          slabs.push(pln);

          const mathText = `${ch.name}: (${ch.raw}/255 - μ)/σ = ${ch.norm > 0 ? '+' : ''}${ch.norm}`;
          const lbl = createTextSprite(mathText, "#302F27", "#FFFFFF", 4.2, 0.65);
          lbl.position.set(0, 0.95, ch.z);
          stageObjects.chapterGroup.add(lbl);
          sprites.push(lbl);
        });

        animRegistry.customTick = (elapsed, progress) => {
          channels.forEach((ch, idx) => {
            // Slabs physically shift from positive height to centered zero
            slabs[idx].position.y = (1 - progress) * 0.4 + Math.sin(elapsed * 2 + idx) * 0.05;
          });
        };
      }
      else if (shot === 6) {
        // Shot 6: Assembling Input Tensor [1, 3, 518, 686]
        const boxGeom = new THREE.BoxGeometry(5.0, 3.8, 2.2);
        const boxMat = new THREE.MeshStandardMaterial({ color: 0x68734D, transparent: true, opacity: 0.3, roughness: 0.2 });
        const tensorBox = new THREE.Mesh(boxGeom, boxMat);
        stageObjects.chapterGroup.add(tensorBox);

        const wireframe = new THREE.LineSegments(
          new THREE.EdgesGeometry(boxGeom),
          new THREE.LineBasicMaterial({ color: 0xC49A58, linewidth: 2 })
        );
        stageObjects.chapterGroup.add(wireframe);

        const planeColors = [0xD32F2F, 0x388E3C, 0x1976D2];
        const planes = [];
        [-0.7, 0, 0.7].forEach((zPos, i) => {
          const pln = new THREE.Mesh(
            new THREE.PlaneGeometry(4.8, 3.6),
            new THREE.MeshBasicMaterial({ color: planeColors[i], transparent: true, opacity: 0.55, side: THREE.DoubleSide })
          );
          pln.position.z = zPos * 2.0; // start wide
          stageObjects.chapterGroup.add(pln);
          planes.push({ mesh: pln, targetZ: zPos });
        });

        const lbl = createTextSprite("ASSEMBLED INPUT TENSOR: [1, 3, 518, 686]", "#414A32", "#FFFFFF", 4.2, 0.7);
        lbl.position.set(0, 2.4, 0);
        stageObjects.chapterGroup.add(lbl);

        animRegistry.customTick = (elapsed, progress) => {
          // Channel planes physically slide into the volumetric tensor block
          planes.forEach(p => {
            p.mesh.position.z = p.targetZ + (1 - progress) * (p.targetZ > 0 ? 1.5 : -1.5);
          });
        };
      }
    }

    // -------------------------------------------------------------
    // CHAPTER 2 BUILDER: Pixels Become Patches & Tokens
    // -------------------------------------------------------------
    function buildChapter2Shot(shot, data) {
      const texLoader = new THREE.TextureLoader();
      const rgbTex = texLoader.load(currentSceneData.images.rgb);

      if (shot === 1) {
        // Shot 1: Slicing into 1,813 Patches
        const imgMesh = new THREE.Mesh(new THREE.PlaneGeometry(6.4, 4.8), new THREE.MeshStandardMaterial({ map: rgbTex, roughness: 0.3 }));
        stageObjects.chapterGroup.add(imgMesh);

        const gridOverlay = new THREE.Mesh(new THREE.PlaneGeometry(6.4, 4.8, 49, 37), new THREE.MeshBasicMaterial({ color: 0xFAF7F0, wireframe: true }));
        gridOverlay.position.z = 0.02;
        stageObjects.chapterGroup.add(gridOverlay);

        const lbl = createTextSprite("37 × 49 = 1,813 SQUARE PATCHES (14×14 px each)", "#414A32", "#FFFFFF", 4.2, 0.7);
        lbl.position.set(0, 2.8, 0.1);
        stageObjects.chapterGroup.add(lbl);
      }
      else if (shot === 2) {
        // Shot 2: Extracting Patch #506
        const imgMesh = new THREE.Mesh(new THREE.PlaneGeometry(6.4, 4.8), new THREE.MeshStandardMaterial({ map: rgbTex, roughness: 0.4, transparent: true, opacity: 0.3 }));
        stageObjects.chapterGroup.add(imgMesh);

        const patchBox = new THREE.Mesh(new THREE.BoxGeometry(1.6, 1.6, 0.2), new THREE.MeshStandardMaterial({ color: 0xC8755A, roughness: 0.3 }));
        patchBox.position.set(0, 0, 0.8);
        stageObjects.chapterGroup.add(patchBox);

        const lbl = createTextSprite("PATCH #506 (14×14×3 = 588 PIXELS)", "#C8755A", "#FFFFFF", 3.6, 0.65);
        lbl.position.set(0, 1.4, 0.9);
        stageObjects.chapterGroup.add(lbl);
      }
      else if (shot === 3) {
        // Shot 3: Unfolding the Patch into a 1D Vector (14 spatial rows)
        const colGeom = new THREE.BoxGeometry(0.35, 4.2, 0.15);
        const colMat = new THREE.MeshStandardMaterial({ color: 0x8B6849, roughness: 0.3 });
        const colMesh = new THREE.Mesh(colGeom, colMat);
        colMesh.position.set(0, 0, 0);
        stageObjects.chapterGroup.add(colMesh);

        for (let i = 0; i < 14; i++) {
          const notchGeom = new THREE.BoxGeometry(0.38, 0.04, 0.16);
          const notchMat = new THREE.MeshBasicMaterial({ color: 0xFDFBF7 });
          const notch = new THREE.Mesh(notchGeom, notchMat);
          notch.position.set(0, (i - 6.5) * 0.28, 0);
          stageObjects.chapterGroup.add(notch);
        }

        const lbl = createTextSprite("UNFOLDED VECTOR: [588 × 1]", "#8B6849", "#FFFFFF", 3.2, 0.65);
        lbl.position.set(0, 2.5, 0);
        stageObjects.chapterGroup.add(lbl);
      }
      else if (shot === 4) {
        // Shot 4: Learned Linear Patch Projection (588 -> 384)
        const inVec = new THREE.Mesh(new THREE.BoxGeometry(0.3, 3.8, 0.1), new THREE.MeshStandardMaterial({ color: 0x8B6849 }));
        inVec.position.set(-2.0, 0, 0);
        stageObjects.chapterGroup.add(inVec);

        const matBox = new THREE.Mesh(new THREE.BoxGeometry(1.6, 2.4, 0.6), new THREE.MeshStandardMaterial({ color: 0xC49A58, metalness: 0.4 }));
        matBox.position.set(0, 0, 0);
        stageObjects.chapterGroup.add(matBox);

        const matLbl = createTextSprite("W_E [588 × 384]", "#C49A58", "#111111", 2.2, 0.55);
        matLbl.position.set(0, 1.6, 0);
        stageObjects.chapterGroup.add(matLbl);

        const outTok = new THREE.Mesh(new THREE.BoxGeometry(0.3, 2.6, 0.1), new THREE.MeshStandardMaterial({ color: 0x68734D }));
        outTok.position.set(2.0, 0, 0);
        stageObjects.chapterGroup.add(outTok);

        const outLbl = createTextSprite("TOKEN [384]", "#68734D", "#FFFFFF", 2.2, 0.55);
        outLbl.position.set(2.0, 1.7, 0);
        stageObjects.chapterGroup.add(outLbl);
      }
      else if (shot === 5) {
        // Shot 5: Sequence Assembly with Position & [CLS]
        for (let i = 0; i < 7; i++) {
          const isCls = (i === 0);
          const tokGeom = new THREE.BoxGeometry(0.35, 1.8, 0.1);
          const tokMat = new THREE.MeshStandardMaterial({
            color: isCls ? 0xC49A58 : 0x68734D,
            metalness: isCls ? 0.7 : 0.2
          });
          const tok = new THREE.Mesh(tokGeom, tokMat);
          tok.position.set((i - 3) * 0.75, 0, 0);
          stageObjects.chapterGroup.add(tok);

          const pinGeom = new THREE.CylinderGeometry(0.04, 0.04, 0.5, 12);
          const pinMat = new THREE.MeshStandardMaterial({ color: 0xC8755A });
          const pin = new THREE.Mesh(pinGeom, pinMat);
          pin.position.set((i - 3) * 0.75, 1.15, 0);
          stageObjects.chapterGroup.add(pin);
        }

        const lbl = createTextSprite("[CLS] + 1,813 PATCH TOKENS + E_pos = [1,814 × 384]", "#414A32", "#FFFFFF", 4.2, 0.7);
        lbl.position.set(0, 2.0, 0);
        stageObjects.chapterGroup.add(lbl);
      }
    }

    // -------------------------------------------------------------
    // CHAPTER 3 BUILDER: Transformer Attention Mechanism (MOMENT 2)
    // -------------------------------------------------------------
    function buildChapter3Shot(shot, data) {
      if (shot === 1) {
        // Shot 1: Why Context is Needed (Query & Contextual Keys)
        const qTok = new THREE.Mesh(new THREE.SphereGeometry(0.3, 20, 20), new THREE.MeshStandardMaterial({ color: 0xD32F2F, roughness: 0.3 }));
        qTok.position.set(-2.2, 0, 0);
        stageObjects.chapterGroup.add(qTok);
        const qLbl = createTextSprite("QUERY: Token #506 (Wall)", "#D32F2F", "#FFFFFF", 2.6, 0.6);
        qLbl.position.set(-2.2, 0.8, 0);
        stageObjects.chapterGroup.add(qLbl);

        const kTokA = new THREE.Mesh(new THREE.SphereGeometry(0.26, 20, 20), new THREE.MeshStandardMaterial({ color: 0x68734D, roughness: 0.3 }));
        kTokA.position.set(2.0, 1.2, 0);
        stageObjects.chapterGroup.add(kTokA);
        const kLblA = createTextSprite("KEY 1: Token #508 (Wall)", "#68734D", "#FFFFFF", 2.4, 0.55);
        kLblA.position.set(2.0, 1.9, 0);
        stageObjects.chapterGroup.add(kLblA);

        const kTokB = new THREE.Mesh(new THREE.SphereGeometry(0.26, 20, 20), new THREE.MeshStandardMaterial({ color: 0xC49A58, roughness: 0.3 }));
        kTokB.position.set(2.0, 0, 0);
        stageObjects.chapterGroup.add(kTokB);
        const kLblB = createTextSprite("KEY 2: Token #720 (Floor)", "#C49A58", "#111111", 2.4, 0.55);
        kLblB.position.set(2.0, 0.65, 0);
        stageObjects.chapterGroup.add(kLblB);

        const kTokC = new THREE.Mesh(new THREE.SphereGeometry(0.26, 20, 20), new THREE.MeshStandardMaterial({ color: 0x8B6849, roughness: 0.3 }));
        kTokC.position.set(2.0, -1.2, 0);
        stageObjects.chapterGroup.add(kTokC);
        const kLblC = createTextSprite("KEY 3: Token #120 (Window)", "#8B6849", "#FFFFFF", 2.4, 0.55);
        kLblC.position.set(2.0, -1.9, 0);
        stageObjects.chapterGroup.add(kLblC);
      }
      else if (shot === 2) {
        // Shot 2: Q, K, V Projections (d_k = 64)
        const tokHub = new THREE.Mesh(new THREE.SphereGeometry(0.35, 24, 24), new THREE.MeshStandardMaterial({ color: 0x68734D }));
        tokHub.position.set(-2.4, 0, 0);
        stageObjects.chapterGroup.add(tokHub);

        const pathways = [
          { name: "QUERY (Q) [64]", col: 0xD32F2F, y: 1.2 },
          { name: "KEY (K) [64]", col: 0xF57C00, y: 0.0 },
          { name: "VALUE (V) [64]", col: 0x1976D2, y: -1.2 }
        ];

        pathways.forEach(p => {
          const cy = new THREE.Mesh(new THREE.CylinderGeometry(0.12, 0.12, 2.6, 16), new THREE.MeshStandardMaterial({ color: p.col, metalness: 0.4 }));
          cy.rotation.z = Math.PI / 2;
          cy.position.set(0.2, p.y, 0);
          stageObjects.chapterGroup.add(cy);

          const lbl = createTextSprite(p.name, p.col, "#FFFFFF", 2.4, 0.55);
          lbl.position.set(2.2, p.y, 0);
          stageObjects.chapterGroup.add(lbl);
        });
      }
      else if (shot === 3) {
        // Shot 3: Calculating Compatibility Scores (Animated Bezier Pulses!)
        const qTok = new THREE.Mesh(new THREE.SphereGeometry(0.28, 20, 20), new THREE.MeshBasicMaterial({ color: 0xD32F2F }));
        qTok.position.set(-2.5, 0, 0);
        stageObjects.chapterGroup.add(qTok);

        const keys = [
          { label: `Q · K_wall = +${data.attnScores.wall.toFixed(2)}`, col: 0x68734D, target: new THREE.Vector3(2.2, 1.2, 0), ctrl: new THREE.Vector3(0, 1.8, 0.6) },
          { label: `Q · K_floor = +${data.attnScores.floor.toFixed(2)}`, col: 0xC49A58, target: new THREE.Vector3(2.2, 0.0, 0), ctrl: new THREE.Vector3(0, 0.4, 0.6) },
          { label: `Q · K_window = ${data.attnScores.window.toFixed(2)}`, col: 0x8B6849, target: new THREE.Vector3(2.2, -1.2, 0), ctrl: new THREE.Vector3(0, -1.6, 0.6) }
        ];

        keys.forEach((k, idx) => {
          const kMesh = new THREE.Mesh(new THREE.SphereGeometry(0.24, 20, 20), new THREE.MeshBasicMaterial({ color: k.col }));
          kMesh.position.copy(k.target);
          stageObjects.chapterGroup.add(kMesh);

          const curve = new THREE.QuadraticBezierCurve3(new THREE.Vector3(-2.5, 0, 0), k.ctrl, k.target);
          const arcMesh = new THREE.Mesh(new THREE.TubeGeometry(curve, 24, 0.05, 8, false), new THREE.MeshBasicMaterial({ color: k.col, transparent: true, opacity: 0.7 }));
          stageObjects.chapterGroup.add(arcMesh);

          const lbl = createTextSprite(k.label, k.col, "#FFFFFF", 3.0, 0.6);
          lbl.position.set(k.ctrl.x, k.ctrl.y + 0.35, k.ctrl.z);
          stageObjects.chapterGroup.add(lbl);

          // Moving pulse sphere
          const pulse = new THREE.Mesh(new THREE.SphereGeometry(0.12, 16, 16), new THREE.MeshBasicMaterial({ color: 0xFFFFFF }));
          stageObjects.chapterGroup.add(pulse);
          animRegistry.pulses.push({ mesh: pulse, curve: curve, speed: 0.8 + idx * 0.2 });
        });

        animRegistry.customTick = (elapsed) => {
          animRegistry.pulses.forEach((p, i) => {
            const t = (elapsed * p.speed + i * 0.3) % 1.0;
            p.mesh.position.copy(p.curve.getPoint(t));
          });
        };
      }
      else if (shot === 4) {
        // Shot 4: Scaling & Softmax Normalization (3D Proportional Cylinders Rising)
        const wWall = parseFloat(data.attnWeights.wall) / 100;
        const wFloor = parseFloat(data.attnWeights.floor) / 100;
        const wWin = parseFloat(data.attnWeights.window) / 100;

        const bars = [
          { name: `WALL: ${data.attnWeights.wall}`, weight: wWall, col: 0x68734D, x: -1.8 },
          { name: `FLOOR: ${data.attnWeights.floor}`, weight: wFloor, col: 0xC49A58, x: 0.0 },
          { name: `WINDOW: ${data.attnWeights.window}`, weight: wWin, col: 0x8B6849, x: 1.8 }
        ];

        const barMeshes = [];
        const labelSprites = [];

        bars.forEach(b => {
          const cylGeom = new THREE.CylinderGeometry(0.3, 0.3, 1, 24);
          const cylMat = new THREE.MeshStandardMaterial({ color: b.col, metalness: 0.6, roughness: 0.3 });
          const cyl = new THREE.Mesh(cylGeom, cylMat);
          cyl.position.set(b.x, -1.5, 0);
          stageObjects.chapterGroup.add(cyl);
          barMeshes.push({ mesh: cyl, weight: b.weight });

          const lbl = createTextSprite(b.name, b.col, "#FFFFFF", 2.6, 0.6);
          lbl.position.set(b.x, -0.6, 0);
          stageObjects.chapterGroup.add(lbl);
          labelSprites.push(lbl);
        });

        const sumLbl = createTextSprite("SOFTMAX PROBABILITIES: SUM = 1.00 (100%)", "#302F27", "#FFFFFF", 4.2, 0.7);
        sumLbl.position.set(0, 2.5, 0);
        stageObjects.chapterGroup.add(sumLbl);

        animRegistry.customTick = (elapsed, progress) => {
          barMeshes.forEach((bm, i) => {
            const h = Math.max(bm.weight * 4.2 * progress, 0.08);
            bm.mesh.scale.y = h;
            bm.mesh.position.y = h / 2 - 1.5;
            labelSprites[i].position.y = h - 1.0;
          });
        };
      }
      else if (shot === 5) {
        // Shot 5: Weighted Combination of Values
        const aggNode = new THREE.Mesh(new THREE.SphereGeometry(0.42, 24, 24), new THREE.MeshStandardMaterial({ color: 0xC49A58, metalness: 0.8, roughness: 0.2 }));
        aggNode.position.set(0, 0, 0);
        stageObjects.chapterGroup.add(aggNode);

        const vWall = new THREE.Mesh(new THREE.CylinderGeometry(0.14, 0.14, 1.8, 16), new THREE.MeshStandardMaterial({ color: 0x68734D }));
        vWall.position.set(-2.6, 1.0, 0);
        stageObjects.chapterGroup.add(vWall);

        const vWin = new THREE.Mesh(new THREE.CylinderGeometry(0.06, 0.06, 1.8, 16), new THREE.MeshStandardMaterial({ color: 0x8B6849 }));
        vWin.position.set(-2.6, -1.0, 0);
        stageObjects.chapterGroup.add(vWin);

        // Flow scaled pipes
        const wallPipe = new THREE.Mesh(new THREE.CylinderGeometry(0.14, 0.14, 2.8, 16), new THREE.MeshStandardMaterial({ color: 0x68734D, transparent: true, opacity: 0.85 }));
        wallPipe.position.set(-1.3, 0.5, 0);
        wallPipe.rotation.z = -Math.PI / 8;
        stageObjects.chapterGroup.add(wallPipe);

        const winPipe = new THREE.Mesh(new THREE.CylinderGeometry(0.05, 0.05, 2.8, 16), new THREE.MeshStandardMaterial({ color: 0x8B6849, transparent: true, opacity: 0.6 }));
        winPipe.position.set(-1.3, -0.5, 0);
        winPipe.rotation.z = Math.PI / 8;
        stageObjects.chapterGroup.add(winPipe);

        const outLbl = createTextSprite(`OUTPUT = ${data.attnWeights.wall}·V_wall + ${data.attnWeights.window}·V_window`, "#C49A58", "#111111", 4.4, 0.75);
        outLbl.position.set(0, 1.8, 0);
        stageObjects.chapterGroup.add(outLbl);
      }
      else if (shot === 6) {
        // Shot 6: 6 Attention Heads (Specialized Visual Roles, Not Generic Rotors!)
        const headRoles = [
          { name: "Head 1: Surface Normal", col: 0x68734D, x: -3.0 },
          { name: "Head 2: Depth Edges", col: 0xC8755A, x: -1.8 },
          { name: "Head 3: Vanishing Lines", col: 0xC49A58, x: -0.6 },
          { name: "Head 4: Shadow/Texture", col: 0x8B6849, x: 0.6 },
          { name: "Head 5: Object Groups", col: 0x5A7A54, x: 1.8 },
          { name: "Head 6: Metric Scale", col: 0x2B4B7C, x: 3.0 }
        ];

        headRoles.forEach(hr => {
          const cy = new THREE.Mesh(new THREE.CylinderGeometry(0.2, 0.2, 1.4, 16), new THREE.MeshStandardMaterial({ color: hr.col, metalness: 0.5 }));
          cy.position.set(hr.x, 0, 0);
          stageObjects.chapterGroup.add(cy);

          const lbl = createTextSprite(hr.name, hr.col, "#FFFFFF", 2.0, 0.5);
          lbl.position.set(hr.x, 1.1, 0);
          stageObjects.chapterGroup.add(lbl);
        });

        const concatLbl = createTextSprite("6 HEADS × 64 DIMENSIONS = 384 CHANNELS (CONCATENATED & PROJECTED)", "#414A32", "#FFFFFF", 4.6, 0.75);
        concatLbl.position.set(0, 2.2, 0);
        stageObjects.chapterGroup.add(concatLbl);
      }
    }

    // -------------------------------------------------------------
    // CHAPTER 4 BUILDER: The Decoder Combines Features (MOMENT 3-A)
    // -------------------------------------------------------------
    function buildChapter4Shot(shot, data) {
      const texLoader = new THREE.TextureLoader();

      const layersMeta = [
        { key: "layer_3", label: "Layer 3 (proj=48, 148×196)", y: 1.8, col: 0x5A7A54 },
        { key: "layer_6", label: "Layer 6 (proj=96, 74×98)", y: 0.6, col: 0x68734D },
        { key: "layer_9", label: "Layer 9 (proj=192, 37×49)", y: -0.6, col: 0x8B6849 },
        { key: "layer_12", label: "Layer 12 (proj=384, 19×25)", y: -1.8, col: 0x414A32 }
      ];

      if (shot === 1) {
        // Shot 1: Four Multi-Scale Feature Maps (Using Real Hooked Activations)
        layersMeta.forEach(lm => {
          let mat;
          if (currentSceneData.feature_maps && currentSceneData.feature_maps[lm.key]) {
            const actTex = texLoader.load(currentSceneData.feature_maps[lm.key].image);
            mat = new THREE.MeshBasicMaterial({ map: actTex, side: THREE.DoubleSide });
          } else {
            mat = new THREE.MeshStandardMaterial({ color: lm.col, side: THREE.DoubleSide });
          }
          const pln = new THREE.Mesh(new THREE.PlaneGeometry(3.6, 0.95), mat);
          pln.position.set(-1.2, lm.y, 0);
          stageObjects.chapterGroup.add(pln);

          const lbl = createTextSprite(lm.label, "#414A32", "#FFFFFF", 2.6, 0.55);
          lbl.position.set(-3.8, lm.y, 0);
          stageObjects.chapterGroup.add(lbl);
        });

        const pyr = new THREE.Mesh(new THREE.ConeGeometry(1.2, 4.0, 4), new THREE.MeshStandardMaterial({ color: 0x68734D, metalness: 0.4 }));
        pyr.rotation.y = Math.PI / 4;
        pyr.position.set(2.4, 0, 0);
        stageObjects.chapterGroup.add(pyr);

        const pyrLbl = createTextSprite("RefineNet Fusion (features = 64)", "#68734D", "#FFFFFF", 2.8, 0.6);
        pyrLbl.position.set(2.4, 2.4, 0);
        stageObjects.chapterGroup.add(pyrLbl);
      }
      else if (shot === 2) {
        // Shot 2: Progressive RefineNet Feature Fusion Ladder
        layersMeta.forEach(lm => {
          let mat;
          if (currentSceneData.feature_maps && currentSceneData.feature_maps[lm.key]) {
            const actTex = texLoader.load(currentSceneData.feature_maps[lm.key].image);
            mat = new THREE.MeshBasicMaterial({ map: actTex, side: THREE.DoubleSide });
          } else {
            mat = new THREE.MeshStandardMaterial({ color: lm.col, side: THREE.DoubleSide });
          }
          const pln = new THREE.Mesh(new THREE.PlaneGeometry(2.8, 0.75), mat);
          pln.position.set(-2.0, lm.y, 0);
          stageObjects.chapterGroup.add(pln);
        });

        for (let i = 0; i < 3; i++) {
          const y1 = layersMeta[3 - i].y;
          const y2 = layersMeta[2 - i].y;
          const pts = [new THREE.Vector3(0.5, y1, 0), new THREE.Vector3(1.5, y2, 0)];
          const lineGeom = new THREE.BufferGeometry().setFromPoints(pts);
          const line = new THREE.Line(lineGeom, new THREE.LineBasicMaterial({ color: 0xC49A58, linewidth: 2 }));
          stageObjects.chapterGroup.add(line);
        }

        const fusedPln = new THREE.Mesh(new THREE.PlaneGeometry(2.4, 3.2), new THREE.MeshStandardMaterial({ color: 0x68734D, metalness: 0.5 }));
        fusedPln.position.set(2.2, 0, 0);
        stageObjects.chapterGroup.add(fusedPln);

        const fusedLbl = createTextSprite("FUSED FEATURES [64, 148, 196]", "#68734D", "#FFFFFF", 3.2, 0.65);
        fusedLbl.position.set(2.2, 2.0, 0);
        stageObjects.chapterGroup.add(fusedLbl);
      }
      else if (shot === 3) {
        // Shot 3: Spatial Detail Recovery at 64 Channels
        const fusedPln = new THREE.Mesh(new THREE.PlaneGeometry(4.2, 3.0), new THREE.MeshStandardMaterial({ color: 0x68734D, metalness: 0.4 }));
        stageObjects.chapterGroup.add(fusedPln);

        const lbl = createTextSprite("DENSE FUSED REPRESENTATION: [64 × 148 × 196]", "#414A32", "#FFFFFF", 3.8, 0.7);
        lbl.position.set(0, 2.0, 0);
        stageObjects.chapterGroup.add(lbl);
      }
      else if (shot === 4) {
        // Shot 4: Direct Conduit Handoff to Depth Prediction Head
        const fusedPln = new THREE.Mesh(new THREE.PlaneGeometry(3.2, 2.4), new THREE.MeshStandardMaterial({ color: 0x68734D }));
        fusedPln.position.set(-1.8, 0, 0);
        stageObjects.chapterGroup.add(fusedPln);

        const conduit = new THREE.Mesh(new THREE.CylinderGeometry(0.12, 0.12, 3.0, 16), new THREE.MeshStandardMaterial({ color: 0xC49A58 }));
        conduit.rotation.z = Math.PI / 2;
        conduit.position.set(0.6, 0, 0);
        stageObjects.chapterGroup.add(conduit);

        const headBox = new THREE.Mesh(new THREE.BoxGeometry(1.6, 2.0, 0.8), new THREE.MeshStandardMaterial({ color: 0xC8755A }));
        headBox.position.set(2.4, 0, 0);
        stageObjects.chapterGroup.add(headBox);

        const headLbl = createTextSprite("DEPTH PREDICTION HEAD", "#C8755A", "#FFFFFF", 2.6, 0.6);
        headLbl.position.set(2.4, 1.4, 0);
        stageObjects.chapterGroup.add(headLbl);
      }
    }

    // -------------------------------------------------------------
    // CHAPTER 5 BUILDER: A Depth Map Becomes a 3D Scene (MOMENT 3-B)
    // -------------------------------------------------------------
    function buildChapter5Shot(shot, data) {
      const texLoader = new THREE.TextureLoader();
      const rgbTex = texLoader.load(currentSceneData.images.rgb);
      const predTex = texLoader.load(currentSceneData.images.depth_pred);

      if (shot === 1) {
        // Shot 1: Raw Depth Logit z
        const depthPlane = new THREE.Mesh(new THREE.PlaneGeometry(6.4, 4.8), new THREE.MeshStandardMaterial({ map: predTex, roughness: 0.3 }));
        stageObjects.chapterGroup.add(depthPlane);

        const lbl = createTextSprite(`RAW LOGIT MAP: z(210, 140) = ${data.logit}`, "#C8755A", "#FFFFFF", 3.4, 0.65);
        lbl.position.set(0, 2.7, 0);
        stageObjects.chapterGroup.add(lbl);
      }
      else if (shot === 2) {
        // Shot 2: Sigmoid Activation and 20m Metric Scaling
        const depthPlane = new THREE.Mesh(new THREE.PlaneGeometry(6.4, 4.8), new THREE.MeshStandardMaterial({ map: predTex, roughness: 0.3 }));
        stageObjects.chapterGroup.add(depthPlane);

        const lbl = createTextSprite(`z = ${data.logit} ➔ Sigmoid: ${data.sigmoid} × 20m = ${data.predDepth}m`, "#C8755A", "#FFFFFF", 4.0, 0.7);
        lbl.position.set(0, 2.7, 0);
        stageObjects.chapterGroup.add(lbl);
      }
      else if (shot === 3 || shot === 4 || shot === 5) {
        // Shot 3, 4, 5: Physical 3D Surface Relief Elevation (Authentic 80x60 Vertices)
        if (currentSceneData.mesh_3d) {
          const m = currentSceneData.mesh_3d;
          const gw = m.grid_w;
          const gh = m.grid_h;
          const sGeom = new THREE.PlaneGeometry(6.4, 4.8, gw - 1, gh - 1);
          const pos = sGeom.attributes.position;
          const colors = new Float32Array(gw * gh * 3);

          let idx = 0;
          for (let r = 0; r < gh; r++) {
            for (let c = 0; c < gw; c++) {
              pos.setZ(idx, 0);

              const rgb = m.rgb_colors[r][c];
              colors[idx * 3] = rgb[0];
              colors[idx * 3 + 1] = rgb[1];
              colors[idx * 3 + 2] = rgb[2];
              idx++;
            }
          }
          sGeom.computeVertexNormals();
          sGeom.setAttribute('color', new THREE.BufferAttribute(colors, 3));

          const sMat = new THREE.MeshStandardMaterial({
            vertexColors: true,
            roughness: 0.3,
            metalness: 0.1,
            side: THREE.DoubleSide
          });
          const reliefMesh = new THREE.Mesh(sGeom, sMat);
          reliefMesh.rotation.x = -Math.PI / 8;
          stageObjects.chapterGroup.add(reliefMesh);

          animRegistry.customTick = (elapsed, progress) => {
            let pIdx = 0;
            for (let r = 0; r < gh; r++) {
              for (let c = 0; c < gw; c++) {
                const d = m.depth_pred[r][c];
                pos.setZ(pIdx, -(d - 1.5) * 1.5 * progress);
                pIdx++;
              }
            }
            sGeom.attributes.position.needsUpdate = true;
          };
        }

        if (shot === 4) {
          const cmpLbl = createTextSprite(
            `Predicted: ${data.predDepth}m | Ground Truth: ${data.gtDepth}m (Error: ${data.absError}m, ${data.relError})`,
            "#414A32",
            "#FFFFFF",
            4.2,
            0.7
          );
          cmpLbl.position.set(0, 2.9, 0);
          stageObjects.chapterGroup.add(cmpLbl);
        } else if (shot === 5) {
          const finalLbl = createTextSprite(
            "NYU SCENE 0049 • RECONSTRUCTED METRIC 3D SPACE",
            "#68734D",
            "#FFFFFF",
            4.0,
            0.7
          );
          finalLbl.position.set(0, 2.9, 0);
          stageObjects.chapterGroup.add(finalLbl);
        }
      }
    }

    // -------------------------------------------------------------
    // TRANSPORT & PLAYBACK CONTROLLER
    // -------------------------------------------------------------
    function nextShot() {
      const chapMeta = CHAPTERS[currentChapter];
      if (currentShot < chapMeta.totalShots) {
        currentShot++;
        renderCurrentShot();
      } else {
        advanceToNextChapter();
      }
    }

    function prevShot() {
      if (currentShot > 1) {
        currentShot--;
        renderCurrentShot();
      } else if (currentChapter > 1) {
        jumpToChapter(currentChapter - 1, CHAPTERS[currentChapter - 1].totalShots);
      }
    }

    function replayCurrentShot() {
      renderCurrentShot();
    }

    function togglePlayPause() {
      isPlaying = !isPlaying;
      updatePlayPauseButtonUI();

      if (isPlaying) {
        runAutoPlay();
      } else {
        if (shotTimer) clearTimeout(shotTimer);
      }
    }

    function updatePlayPauseButtonUI() {
      document.getElementById('icon-play-pause').className = isPlaying ? "fa-solid fa-pause" : "fa-solid fa-play";
      document.getElementById('label-play-pause').textContent = isPlaying ? "Pause" : "Play";
    }

    function runAutoPlay() {
      if (!isPlaying) return;
      if (shotTimer) clearTimeout(shotTimer);

      const shotDuration = (7500 / playbackSpeed);

      shotTimer = setTimeout(() => {
        if (!isPlaying) return;
        const chapMeta = CHAPTERS[currentChapter];
        if (currentShot < chapMeta.totalShots) {
          currentShot++;
          renderCurrentShot();
          runAutoPlay();
        } else {
          advanceToNextChapter();
        }
      }, shotDuration);
    }

    function advanceToNextChapter() {
      if (currentChapter < 5) {
        jumpToChapter(currentChapter + 1, 1);
        if (isPlaying) runAutoPlay();
      } else {
        // Complete Film!
        isPlaying = false;
        updatePlayPauseButtonUI();
        speakNarration("Congratulations! You have completed the 5-minute Depth Anything V2 teaching experience.");
      }
    }

    function renderTimelineScrubber() {
      const scrubber = document.getElementById('timeline-scrubber');
      if (!scrubber || currentChapter === 0) return;
      scrubber.innerHTML = '';

      const total = CHAPTERS[currentChapter].totalShots;
      for (let s = 1; s <= total; s++) {
        const seg = document.createElement('div');
        seg.className = 'timeline-segment';
        seg.title = `Jump to Shot ${s}`;
        seg.onclick = () => {
          currentShot = s;
          renderCurrentShot();
        };
        scrubber.appendChild(seg);
      }
      updateTimelineScrubberUI();
    }

    function updateTimelineScrubberUI() {
      const scrubber = document.getElementById('timeline-scrubber');
      if (!scrubber) return;
      const segs = scrubber.querySelectorAll('.timeline-segment');
      segs.forEach((seg, i) => {
        const shotIdx = i + 1;
        seg.className = 'timeline-segment';
        if (shotIdx === currentShot) seg.classList.add('active');
        else if (shotIdx < currentShot) seg.classList.add('completed');
      });
    }

    function speakNarration(text) {
      if (!('speechSynthesis' in window)) return;
      window.speechSynthesis.cancel();
      const clean = text.replace(/[^a-zA-Z0-9.,?! ]/g, ' ');
      const utterance = new SpeechSynthesisUtterance(clean);
      utterance.rate = 1.05 * playbackSpeed;
      utterance.pitch = 1.0;
      window.speechSynthesis.speak(utterance);
    }

    function toggleVoiceNarration() {
      voiceNarrationEnabled = !voiceNarrationEnabled;
      const icon = document.getElementById('icon-narration');
      const label = document.getElementById('label-narration');
      if (voiceNarrationEnabled) {
        icon.className = "fa-solid fa-volume-high";
        icon.style.color = "var(--olive-primary)";
        label.textContent = "Narration: ON";
        if (currentChapter > 0) {
          const chapMeta = CHAPTERS[currentChapter];
          speakNarration(chapMeta.shots[currentShot].subtitle);
        }
      } else {
        icon.className = "fa-solid fa-volume-xmark";
        icon.style.color = "var(--text-muted)";
        label.textContent = "Narration: OFF";
        if ('speechSynthesis' in window) window.speechSynthesis.cancel();
      }
    }

    function flyCamera(pos, target, duration = 800) {
      cameraLerp = {
        startPos: camera.position.clone(),
        endPos: new THREE.Vector3(pos.x, pos.y, pos.z),
        startTarget: controls.target.clone(),
        endTarget: new THREE.Vector3(target.x, target.y, target.z),
        startTime: performance.now(),
        duration: duration
      };
    }

    function updateFly() {
      if (!cameraLerp) return;
      const now = performance.now();
      const elapsed = now - cameraLerp.startTime;
      const progress = Math.min(elapsed / cameraLerp.duration, 1.0);
      const ease = progress < 0.5 ? 2 * progress * progress : -1 + (4 - 2 * progress) * progress;

      camera.position.lerpVectors(cameraLerp.startPos, cameraLerp.endPos, ease);
      controls.target.lerpVectors(cameraLerp.startTarget, cameraLerp.endTarget, ease);

      if (progress >= 1.0) cameraLerp = null;
    }

    function animate(time) {
      requestAnimationFrame(animate);

      updateFly();

      const elapsed = (time - shotStartTime) * 0.001;
      const progress = Math.min(elapsed / (4.0 / playbackSpeed), 1.0);
      const easeOut = 1 - Math.pow(1 - progress, 3);

      if (animRegistry.customTick) {
        animRegistry.customTick(elapsed, easeOut);
      }

      controls.update();
      renderer.render(scene, camera);
    }

    window.addEventListener('DOMContentLoaded', initApp);
  </script>
</body>
</html>
"""

    out_path = 'web_app/model_lab.html'
    with open(out_path, 'w', encoding='utf-8') as f:
        f.write(html_content)
    print(f"Successfully compiled refined cinematic experience at: {out_path} ({len(html_content)} bytes)")

if __name__ == '__main__':
    build_cinematic_lab()
