---
title: "The Friend Writes First, the Teacher Grades It: Speculative Decoding Made Easy"
seo_title: "Speculative Decoding Explained Simply: From the Basics to EAGLE and DFlash | ThakiCloud"
seo_description: "A single analogy explains why LLMs are slow and how speculative decoding speeds them up two to six times without changing the answer. Covers the grading rule, the break-even point for how many letters to draft ahead, recent methods like EAGLE and DFlash, and why the effect shrinks as batch size grows."
excerpt: "A large model spreads out every heavy book just to write one letter. Seat a quick-witted friend next to it, and it has to spread those books far less often. Here is why the answer stays the same while only the speed changes."
date: 2026-08-24
tags:
  - speculative-decoding-explained
  - speculative-decoding
  - inference-optimization
  - EAGLE
  - DFlash
  - vLLM
  - draft-model
  - LLMOps
  - beginner-guide
categories: [llmops]
author_profile: true
toc: true
toc_label: "Contents"
toc_sticky: true
reading_time: true
lang: en
canonical_url: "https://thakicloud.com/tech-blog/en/llmops/speculative-decoding-easy-guide/"
---

If you have ever watched a chatbot type out letters one by one and wondered why it is so slow, this single post gives you both the answer and the fix. Modern inference engines use a technique called **speculative decoding** that speeds things up two to six times without changing a single letter of the answer, and the idea behind it is simple enough for a grade schooler to follow. A quick-witted friend writes first, and the teacher only grades the work.

## Writing One Letter Means a Trip to the Library

The way large language models write sentences is more frustrating than it looks. Once the model settles on a letter, it appends that letter back to the input, runs the whole calculation from scratch, and appends whatever letter comes out next. A hundred-letter answer means repeating this process a hundred times.

That part is well known. The real problem comes next. What eats up time in a single pass is not the calculation itself. Pulling the model's weights from memory into the compute unit takes far longer.

Picture a library. To write one letter, the teacher has to pull hundreds of very heavy books off the shelves and spread every one of them open on the desk. Actually reading the books, though, takes no time at all. Most of the time goes into pulling the books out and opening them up. Then the teacher writes one letter and puts the books back. To write the next letter, the teacher has to pull them all out again from scratch.

It sounds wasteful, but there is no other way. You need to know the next letter before you can compute the one after that. In technical terms, this bottleneck is called a memory bandwidth limitation. The GPU has plenty of compute power to spare; it is just sitting idle because the path carrying the data is too narrow.

## Seat a Quick-Witted Friend Next to You

There is a way out once you notice one thing. **Not every letter is equally hard to write.**

Think of a well-known opening line, one that everyone can finish without a second of thought. Once the first few words are set, the rest follows almost automatically. If you open a bracket, you eventually have to close it, and once you have written "so I," what comes next is usually predictable. Names of people, unfamiliar technical terms, or a conjunction that turns a sentence in a new direction, on the other hand, really do call for careful thought.

There is no reason for the teacher to spread out every heavy book just to write an easy letter. So we seat a **small, fast model** in the next chair. We call this friend the draft model. Because it is small, its books are thin too, so it writes much faster. In exchange, it is sometimes wrong.

This friend writes out about five letters in a row first. Then the teacher grades those five letters. Correct ones pass through, and starting from the first mistake, the teacher erases the rest and writes them instead.

{% raw %}
<!--
  animated-architecture-diagram - self-contained D3 embed template.
  HuggingFace research-article style: declarative NODES/EDGES/SEQ model,
  data(solid)/event(dashed) edges, hover-trace + tooltip, flow-dot animation
  along edge paths, replay button, scroll-into-view autoplay, reduced-motion +
  light/dark aware. The renderer injects window.__ARCH_SPEC__ at the marker.
  Format (D3 machinery + CSS) is owned by this committed template; the model
  only authors the JSON spec (content). See references/spec-schema.md.
-->
<div class="d3-arch" data-arch-root id="specdec-en-1"></div>
<style>
  /* ---- Theme tokens (standalone; light default + dark override) ---- */
  .d3-arch {
    --page-bg: #ffffff;
    --surface-bg: #f7f8fa;
    --text-color: #1a1d21;
    --muted-color: #6b7280;
    --border-color: #d5d9e0;
    --primary-color: hsl(217 91% 55%); /* brand accent, swap for #1B4F72 etc. */
    position: relative;
    font-family: -apple-system, BlinkMacSystemFont, "Segoe UI", "Noto Sans KR", system-ui, sans-serif;
    color: var(--text-color);
  }
  @media (prefers-color-scheme: dark) {
    .d3-arch {
      --page-bg: #0f1115;
      --surface-bg: #171a21;
      --text-color: #e6e8eb;
      --muted-color: #9aa3af;
      --border-color: #2a2f3a;
      --primary-color: hsl(217 91% 62%);
    }
  }
  .d3-arch[data-theme="light"] { --page-bg:#fff; --surface-bg:#f7f8fa; --text-color:#1a1d21; --muted-color:#6b7280; --border-color:#d5d9e0; --primary-color:hsl(217 91% 55%); }
  .d3-arch[data-theme="dark"]  { --page-bg:#0f1115; --surface-bg:#171a21; --text-color:#e6e8eb; --muted-color:#9aa3af; --border-color:#2a2f3a; --primary-color:hsl(217 91% 62%); }

  .d3-arch .diagram-scroll { overflow-x: auto; }
  /* Size to the spec's natural canvas: JS caps max-width at the spec width so a
     narrow/portrait diagram is never stretched to the article column (blur + giant
     vertical figures); wide diagrams scale down but keep min-width 760 + scroll. */
  .d3-arch svg { display: block; width: 100%; max-width: 100%; height: auto; font-family: inherit; }

  /* Group boxes */
  .d3-arch .group rect { fill: none; stroke: var(--border-color); stroke-dasharray: 3 3; rx: 12px; }
  .d3-arch .group text { font-size: 10px; font-weight: 700; letter-spacing: 0.08em; text-transform: uppercase; fill: var(--muted-color); }

  /* Nodes */
  .d3-arch .node rect { fill: var(--surface-bg); stroke: var(--border-color); stroke-width: 1; transition: stroke 0.15s ease, opacity 0.15s ease; }
  .d3-arch .node .node-title { font-size: 12px; font-weight: 600; fill: var(--text-color); }
  .d3-arch .node .node-sub { font-size: 9.5px; fill: var(--muted-color); }
  .d3-arch .node { cursor: default; transition: opacity 0.15s ease; }

  /* Edges */
  .d3-arch .edge { transition: opacity 0.15s ease; }
  .d3-arch .edge path.main { fill: none; stroke-width: 1.5; }
  .d3-arch .edge.data path.main { stroke: var(--primary-color); }
  .d3-arch .edge.event path.main { stroke: var(--muted-color); stroke-dasharray: 5 4; }
  .d3-arch .edge text { font-size: 9.5px; fill: var(--muted-color); paint-order: stroke; stroke: var(--page-bg); stroke-width: 3px; stroke-linejoin: round; }

  /* Hover highlighting */
  .d3-arch.hovering .edge:not(.hl) { opacity: 0.12; }
  .d3-arch.hovering .node:not(.hl):not(.nb) { opacity: 0.25; }
  .d3-arch .node.hl rect { stroke: var(--primary-color); stroke-width: 1.5; }

  /* Flow animation */
  .d3-arch .flow-dot.data { fill: var(--primary-color); stroke: var(--page-bg); stroke-width: 1.5; }
  .d3-arch .flow-dot.event { fill: var(--page-bg); stroke: var(--muted-color); stroke-width: 1.5; }
  .d3-arch .node.anim-hl rect { stroke: var(--primary-color); stroke-width: 1.5; }
  .d3-arch .replay-btn { font: inherit; font-size: 11px; font-weight: 600; padding: 4px 10px; border: 1px solid var(--border-color); border-radius: 8px; background: var(--surface-bg); color: var(--text-color); cursor: pointer; transition: border-color 0.15s ease, opacity 0.15s ease; }
  .d3-arch .replay-btn:hover:not(:disabled) { border-color: var(--primary-color); }
  .d3-arch .replay-btn:disabled { opacity: 0.45; cursor: default; }
  .d3-arch .replay-btn:focus-visible { outline: 2px solid var(--primary-color); outline-offset: 1px; }

  /* Legend */
  .d3-arch .legend { display: flex; flex-direction: column; align-items: flex-start; gap: 6px; margin-top: 10px; }
  .d3-arch .legend-title { font-size: 12px; font-weight: 700; color: var(--text-color); }
  .d3-arch .legend .items { display: flex; flex-wrap: wrap; gap: 8px 18px; align-items: center; }
  .d3-arch .legend .item { display: inline-flex; align-items: center; gap: 7px; white-space: nowrap; font-size: 12px; color: var(--text-color); }
  .d3-arch .legend .swatch { width: 22px; height: 0; }
  .d3-arch .legend .swatch.data-line { border-top: 2.5px solid var(--primary-color); }
  .d3-arch .legend .swatch.event-line { border-top: 2.5px dashed var(--muted-color); }
  .d3-arch .legend .hint { font-size: 11px; font-style: italic; color: var(--muted-color); }
</style>
<script>
  (() => {
    const SPEC = ({"title": "en1", "ariaLabel": "en1", "width": 607, "height": 786, "legendTitle": "Legend", "legend": {"data": "Flow", "event": "Dotted / alternate path"}, "hint": "Hover a node to trace its connections.", "groups": [], "nodes": [{"id": "P", "x": 206, "y": 24, "w": 120, "h": 46, "title": "Text so far"}, {"id": "D", "x": 188, "y": 148, "w": 156, "h": 62, "title": ["Small fast drafter", "proposes 5 tokens"]}, {"id": "V", "x": 260, "y": 288, "w": 170, "h": 62, "title": ["Large target model", "scores all 5 at once"]}, {"id": "A", "x": 363, "y": 576, "w": 212, "h": 46, "title": "Accept the matching prefix"}, {"id": "X", "x": 138, "y": 428, "w": 163, "h": 62, "title": ["Drop from the first", "mismatch"]}, {"id": "O", "x": 135, "y": 708, "w": 170, "h": 46, "title": "Append to the output"}, {"id": "S", "x": 131, "y": 568, "w": 177, "h": 62, "title": ["Target model writes", "that one token itself"]}], "edges": [{"src": "P", "dst": "D", "kind": "data", "line": [266, 70, 266, 148]}, {"src": "D", "dst": "V", "kind": "data", "curve": [[301, 210], [345, 249], [345, 249], [345, 288]]}, {"src": "V", "dst": "A", "kind": "data", "curve": [[400, 350], [469, 389], [469, 529], [469, 576]]}, {"src": "V", "dst": "X", "kind": "data", "curve": [[289, 350], [220, 389], [220, 389], [220, 428]]}, {"src": "A", "dst": "O", "kind": "data", "curve": [[469, 622], [469, 669], [469, 669], [305, 710]]}, {"src": "X", "dst": "S", "kind": "data", "line": [220, 490, 220, 568]}, {"src": "S", "dst": "O", "kind": "data", "line": [220, 630, 220, 708]}, {"src": "O", "dst": "D", "kind": "event", "label": "\"next cycle\"", "curve": [[161, 708], [62, 529], [62, 319], [188, 206]], "off": "50%"}]});
    const ensureD3 = (cb) => {
      if (window.d3 && typeof window.d3.select === 'function') return cb();
      let s = document.getElementById('d3-cdn-script');
      if (!s) {
        s = document.createElement('script');
        s.id = 'd3-cdn-script';
        s.src = 'https://cdn.jsdelivr.net/npm/d3@7/dist/d3.min.js';
        document.head.appendChild(s);
      }
      const onReady = () => { if (window.d3 && typeof window.d3.select === 'function') cb(); };
      s.addEventListener('load', onReady, { once: true });
      if (window.d3) onReady();
    };

    const bootstrap = () => {
      const container = document.getElementById('specdec-en-1')
        || document.querySelector('.d3-arch[data-arch-root]:not([data-mounted])');
      if (!container || (container.dataset && container.dataset.mounted === 'true')) return;
      if (container.dataset) container.dataset.mounted = 'true';

      try {
        const uid = 'specdec-en-1';
        const NODES = SPEC.nodes || [];
        const EDGES = SPEC.edges || [];
        const GROUPS = SPEC.groups || [];
        const HOP = SPEC.hop || 800;
        const legendCfg = SPEC.legend || {};
        const dataLabel = legendCfg.data || 'Data path';
        const eventLabel = legendCfg.event || 'Event side-channel';

        const byId = Object.fromEntries(NODES.map((n) => [n.id, n]));
        const cx = (n) => n.x + n.w / 2;
        const asTitle = (t) => Array.isArray(t) ? t : [t];

        // Canvas: explicit, else auto from node/group extents + padding
        let W = SPEC.width, H = SPEC.height;
        if (!W || !H) {
          const xs = [], ys = [];
          NODES.forEach((n) => { xs.push(n.x + n.w); ys.push(n.y + n.h); });
          GROUPS.forEach((g) => { xs.push(g.x + g.w); ys.push(g.y + g.h); });
          W = W || Math.max(760, Math.ceil(Math.max(...xs, 0) + 24));
          H = H || Math.ceil(Math.max(...ys, 0) + 20);
        }

        // Tooltip
        container.style.position = container.style.position || 'relative';
        const tip = document.createElement('div');
        Object.assign(tip.style, {
          position: 'absolute', top: '0px', left: '0px',
          transform: 'translate(-9999px, -9999px)', pointerEvents: 'none',
          padding: '8px 10px', borderRadius: '8px', fontSize: '12px', lineHeight: '1.4',
          border: '1px solid var(--border-color)', background: 'var(--surface-bg)',
          color: 'var(--text-color)', boxShadow: '0 4px 24px rgba(0,0,0,.18)',
          opacity: '0', transition: 'opacity .12s ease', maxWidth: '260px', zIndex: '3'
        });
        const tipInner = document.createElement('div');
        tip.appendChild(tipInner);

        const scroll = document.createElement('div');
        scroll.className = 'diagram-scroll';
        container.appendChild(scroll);

        const svg = d3.select(scroll).append('svg')
          .attr('viewBox', `0 0 ${W} ${H}`)
          .attr('preserveAspectRatio', 'xMidYMid meet')
          .attr('role', 'img')
          .attr('aria-label', SPEC.ariaLabel || SPEC.title || 'Architecture diagram');
        // Never upscale past the spec's natural width; keep 760px readability
        // floor (with horizontal scroll) only for diagrams that are actually wide.
        svg.style('max-width', W + 'px').style('min-width', Math.min(W, 760) + 'px').style('margin', '0 auto');

        const defs = svg.append('defs');
        const mkMarker = (id, color) => {
          defs.append('marker')
            .attr('id', id).attr('viewBox', '0 0 10 10')
            .attr('refX', 9).attr('refY', 5)
            .attr('markerWidth', 6.5).attr('markerHeight', 6.5)
            .attr('orient', 'auto-start-reverse')
            .append('path').attr('d', 'M 0 0 L 10 5 L 0 10 z').style('fill', color);
        };
        mkMarker(`${uid}-arrow-data`, 'var(--primary-color)');
        mkMarker(`${uid}-arrow-event`, 'var(--muted-color)');

        // Groups
        const groups = svg.append('g');
        GROUPS.forEach((gr) => {
          const g = groups.append('g').attr('class', 'group');
          g.append('rect').attr('x', gr.x).attr('y', gr.y).attr('width', gr.w).attr('height', gr.h).attr('rx', 12);
          if (gr.label) g.append('text').attr('x', gr.lx != null ? gr.lx : gr.x + 12).attr('y', gr.ly != null ? gr.ly : gr.y + 18).text(gr.label);
        });

        // Edges (under nodes)
        const edgeLayer = svg.append('g');
        const curvePath = (p) => `M ${p[0][0]} ${p[0][1]} C ${p[1][0]} ${p[1][1]}, ${p[2][0]} ${p[2][1]}, ${p[3][0]} ${p[3][1]}`;
        EDGES.forEach((e, i) => {
          const kind = e.kind === 'event' ? 'event' : 'data';
          const g = edgeLayer.append('g').attr('class', `edge ${kind}`).attr('data-src', e.src).attr('data-dst', e.dst);
          const marker = `url(#${uid}-arrow-${kind})`;
          if (e.line) {
            const [x1, y1, x2, y2] = e.line;
            e.pathEl = g.append('path').attr('class', 'main').attr('d', `M ${x1} ${y1} L ${x2} ${y2}`).attr('marker-end', marker).node();
            if (e.label) g.append('text').attr('x', e.lx != null ? e.lx : (x1 + x2) / 2).attr('y', e.ly != null ? e.ly : (y1 + y2) / 2 - 6).attr('text-anchor', e.anchor || 'middle').text(e.label);
          } else if (e.curve) {
            e.pathEl = g.append('path').attr('class', 'main').attr('d', curvePath(e.curve)).attr('marker-end', marker).node();
            if (e.label && e.off) {
              const p = e.curve;
              const lp = p[3][0] < p[0][0] ? [p[3], p[2], p[1], p[0]] : p;
              const lpId = `${uid}-lbl-${i}`;
              g.append('path').attr('id', lpId).attr('d', curvePath(lp)).attr('fill', 'none').attr('stroke', 'none');
              g.append('text').attr('dy', -5).append('textPath').attr('href', `#${lpId}`).attr('startOffset', e.off).attr('text-anchor', 'middle').text(e.label);
            } else if (e.label) {
              g.append('text').attr('x', e.lx).attr('y', e.ly).attr('text-anchor', e.anchor || 'start').text(e.label);
            }
          }
        });

        // Nodes (over edges)
        const nodeLayer = svg.append('g');
        NODES.forEach((n) => {
          const g = nodeLayer.append('g').attr('class', 'node').attr('data-id', n.id);
          g.append('rect').attr('x', n.x).attr('y', n.y).attr('width', n.w).attr('height', n.h).attr('rx', 9);
          const title = asTitle(n.title);
          const lines = title.length;
          const baseY = n.y + n.h / 2 - (lines - 1) * 7 - (n.sub ? 5 : -4);
          title.forEach((t, li) => {
            g.append('text').attr('class', 'node-title').attr('x', cx(n)).attr('y', baseY + li * 14).attr('text-anchor', 'middle').text(t);
          });
          if (n.sub) g.append('text').attr('class', 'node-sub').attr('x', cx(n)).attr('y', baseY + (lines - 1) * 14 + 15).attr('text-anchor', 'middle').text(n.sub);
        });

        // Hover highlighting
        const edgeSel = svg.selectAll('.edge');
        const nodeSel = svg.selectAll('.node');
        nodeSel
          .on('mouseenter', function () {
            const id = this.getAttribute('data-id');
            const n = byId[id];
            container.classList.add('hovering');
            const nb = new Set([id]);
            edgeSel.classed('hl', function () {
              const hit = this.getAttribute('data-src') === id || this.getAttribute('data-dst') === id;
              if (hit) { nb.add(this.getAttribute('data-src')); nb.add(this.getAttribute('data-dst')); }
              return hit;
            });
            nodeSel.classed('hl', function () { return this.getAttribute('data-id') === id; })
                   .classed('nb', function () { return nb.has(this.getAttribute('data-id')); });
            if (n && n.desc) { tipInner.innerHTML = `<strong>${asTitle(n.title).join('')}</strong><br>${n.desc}`; tip.style.opacity = '1'; }
          })
          .on('mousemove', function (event) {
            const [mx, my] = d3.pointer(event, container);
            const flip = mx > container.clientWidth - 280;
            tip.style.transform = `translate(${flip ? mx - 270 : mx + 14}px, ${my + 14}px)`;
          })
          .on('mouseleave', function () {
            container.classList.remove('hovering');
            edgeSel.classed('hl', false);
            nodeSel.classed('hl', false).classed('nb', false);
            tip.style.opacity = '0';
            tip.style.transform = 'translate(-9999px, -9999px)';
          });

        // Flow animation sequence: explicit SEQ, else auto forward-cascade of data edges
        const resolveEdge = (s) => {
          if (typeof s.e === 'number') return s.e;
          if (s.from && s.to) return EDGES.findIndex((e) => e.src === s.from && e.dst === s.to);
          return -1;
        };
        let SEQ = (SPEC.seq || []).map((s) => ({ e: resolveEdge(s), t0: s.t0 })).filter((s) => s.e >= 0);
        if (!SEQ.length) {
          let t = 0;
          EDGES.forEach((e, i) => { if ((e.kind || 'data') === 'data') { SEQ.push({ e: i, t0: t }); t += HOP; } });
        }
        const TOTAL = SPEC.total || (Math.max(0, ...SEQ.map((s) => s.t0)) + HOP + 800);

        let playing = false, replayBtn = null;
        const pulseNode = (id) => {
          const sel = nodeSel.filter(function () { return this.getAttribute('data-id') === id; });
          sel.classed('anim-hl', true);
          setTimeout(() => sel.classed('anim-hl', false), 550);
        };
        const play = () => {
          if (playing) return;
          playing = true;
          if (replayBtn) replayBtn.disabled = true;
          const layer = svg.append('g');
          const steps = SEQ.map((s) => {
            const edge = EDGES[s.e];
            return { ...s, edge, len: edge.pathEl.getTotalLength(), dot: null, arrived: false };
          });
          const start = performance.now();
          const frame = (now) => {
            const t = now - start;
            steps.forEach((s) => {
              if (t < s.t0) return;
              const f = Math.min(1, (t - s.t0) / HOP);
              if (f >= 1) { if (s.dot) { s.dot.remove(); s.dot = null; } if (!s.arrived) { s.arrived = true; pulseNode(s.edge.dst); } return; }
              if (!s.dot) s.dot = layer.append('circle').attr('class', `flow-dot ${s.edge.kind || 'data'}`).attr('r', (s.edge.kind === 'event') ? 4 : 5);
              const p = s.edge.pathEl.getPointAtLength(d3.easeCubicInOut(f) * s.len);
              s.dot.attr('cx', p.x).attr('cy', p.y);
            });
            if (t < TOTAL) requestAnimationFrame(frame);
            else { layer.remove(); playing = false; if (replayBtn) replayBtn.disabled = false; }
          };
          requestAnimationFrame(frame);
        };

        // Legend
        const legend = document.createElement('div');
        legend.className = 'legend';
        legend.innerHTML = `
          <div class="legend-title">${SPEC.legendTitle || 'Legend'}</div>
          <div class="items">
            <span class="item"><span class="swatch data-line"></span><span>${dataLabel}</span></span>
            <span class="item"><span class="swatch event-line"></span><span>${eventLabel}</span></span>
            <button class="replay-btn" type="button" aria-label="Replay the flow animation">&#9654; Replay</button>
            <span class="hint">${SPEC.hint || 'Hover a component to trace its connections.'}</span>
          </div>`;
        container.appendChild(legend);
        container.appendChild(tip);
        replayBtn = legend.querySelector('.replay-btn');
        replayBtn.addEventListener('click', play);

        const prefersReduced = window.matchMedia && window.matchMedia('(prefers-reduced-motion: reduce)').matches;
        if (!prefersReduced && window.IntersectionObserver) {
          const io = new IntersectionObserver((entries) => {
            entries.forEach((en) => { if (en.isIntersecting) { io.disconnect(); play(); } });
          }, { threshold: 0.5 });
          io.observe(container);
        }
      } catch (err) {
        const pre = document.createElement('pre');
        pre.style.color = '#c0392b';
        pre.style.fontSize = '12px';
        pre.textContent = 'Failed to render architecture diagram: ' + (err && err.message ? err.message : err);
        container.appendChild(pre);
      }
    };

    if (document.readyState === 'loading') document.addEventListener('DOMContentLoaded', () => ensureD3(bootstrap), { once: true });
    else ensureD3(bootstrap);
  })();
</script>
{% endraw %}

## Grading Five Letters Costs Almost the Same as Grading One

Why this method actually pays off is the most important part of this post. Since the teacher still has to grade in the end, it is natural to ask what gets faster.

Here is the answer. **Once the books are open, checking five letters at once is nearly free.**

Writing one letter still requires spreading out all the heavy books, and grading five letters only requires opening them the same single time. What ate up the time was pulling the books out in the first place. Once everything is spread across the desk, scanning five spots is handled by the spare capacity that was already sitting idle. Earlier we said the GPU's compute power was going unused; speculative decoding is exactly the technique that puts that idle capacity to work.

So the math comes out like this. Before, getting five letters meant opening the heavy books five times. Now it means opening the thin books five times plus the heavy books once. Five thin-book passes are far cheaper than one heavy-book pass.

## The Guarantee That the Answer Doesn't Change

This is where the worry comes in. Doesn't using the friend's letters as-is make the answer worse?

It doesn't. And this is the real appeal of the technique. With the right grading rule in place, the final output ends up **statistically identical to what the teacher would have written alone, start to finish.**

Here is the rule. For any given letter, call the friend's confidence q and the teacher's confidence p. Grading comes down to comparing these two numbers.

If the teacher would have wanted that letter at least as much as the friend did (p is greater than or equal to q), it passes automatically. The friend was being modest, so there is no issue. But if the friend was overconfident (q is greater than p), the letter gets erased with a probability proportional to that gap. To be precise, it passes with a probability equal to p divided by q. If the friend wrote with 0.9 confidence but the teacher only had 0.45, the letter only has a fifty-fifty chance of passing.

What happens after erasing matters too. The teacher cannot just resample as usual, because the distribution has already been skewed by that first filter. Instead, the teacher resamples from what is **left over** after subtracting the friend's confidence from the teacher's own, clipping any negative values to zero, renormalizing the whole thing back to one, and then drawing from that.

Follow these two rules and the math works out to the exact same distribution as the original. This is not trading quality for speed; the speedup is simply free.

{% raw %}
<!--
  animated-architecture-diagram - self-contained D3 embed template.
  HuggingFace research-article style: declarative NODES/EDGES/SEQ model,
  data(solid)/event(dashed) edges, hover-trace + tooltip, flow-dot animation
  along edge paths, replay button, scroll-into-view autoplay, reduced-motion +
  light/dark aware. The renderer injects window.__ARCH_SPEC__ at the marker.
  Format (D3 machinery + CSS) is owned by this committed template; the model
  only authors the JSON spec (content). See references/spec-schema.md.
-->
<div class="d3-arch" data-arch-root id="specdec-en-2"></div>
<style>
  /* ---- Theme tokens (standalone; light default + dark override) ---- */
  .d3-arch {
    --page-bg: #ffffff;
    --surface-bg: #f7f8fa;
    --text-color: #1a1d21;
    --muted-color: #6b7280;
    --border-color: #d5d9e0;
    --primary-color: hsl(217 91% 55%); /* brand accent, swap for #1B4F72 etc. */
    position: relative;
    font-family: -apple-system, BlinkMacSystemFont, "Segoe UI", "Noto Sans KR", system-ui, sans-serif;
    color: var(--text-color);
  }
  @media (prefers-color-scheme: dark) {
    .d3-arch {
      --page-bg: #0f1115;
      --surface-bg: #171a21;
      --text-color: #e6e8eb;
      --muted-color: #9aa3af;
      --border-color: #2a2f3a;
      --primary-color: hsl(217 91% 62%);
    }
  }
  .d3-arch[data-theme="light"] { --page-bg:#fff; --surface-bg:#f7f8fa; --text-color:#1a1d21; --muted-color:#6b7280; --border-color:#d5d9e0; --primary-color:hsl(217 91% 55%); }
  .d3-arch[data-theme="dark"]  { --page-bg:#0f1115; --surface-bg:#171a21; --text-color:#e6e8eb; --muted-color:#9aa3af; --border-color:#2a2f3a; --primary-color:hsl(217 91% 62%); }

  .d3-arch .diagram-scroll { overflow-x: auto; }
  /* Size to the spec's natural canvas: JS caps max-width at the spec width so a
     narrow/portrait diagram is never stretched to the article column (blur + giant
     vertical figures); wide diagrams scale down but keep min-width 760 + scroll. */
  .d3-arch svg { display: block; width: 100%; max-width: 100%; height: auto; font-family: inherit; }

  /* Group boxes */
  .d3-arch .group rect { fill: none; stroke: var(--border-color); stroke-dasharray: 3 3; rx: 12px; }
  .d3-arch .group text { font-size: 10px; font-weight: 700; letter-spacing: 0.08em; text-transform: uppercase; fill: var(--muted-color); }

  /* Nodes */
  .d3-arch .node rect { fill: var(--surface-bg); stroke: var(--border-color); stroke-width: 1; transition: stroke 0.15s ease, opacity 0.15s ease; }
  .d3-arch .node .node-title { font-size: 12px; font-weight: 600; fill: var(--text-color); }
  .d3-arch .node .node-sub { font-size: 9.5px; fill: var(--muted-color); }
  .d3-arch .node { cursor: default; transition: opacity 0.15s ease; }

  /* Edges */
  .d3-arch .edge { transition: opacity 0.15s ease; }
  .d3-arch .edge path.main { fill: none; stroke-width: 1.5; }
  .d3-arch .edge.data path.main { stroke: var(--primary-color); }
  .d3-arch .edge.event path.main { stroke: var(--muted-color); stroke-dasharray: 5 4; }
  .d3-arch .edge text { font-size: 9.5px; fill: var(--muted-color); paint-order: stroke; stroke: var(--page-bg); stroke-width: 3px; stroke-linejoin: round; }

  /* Hover highlighting */
  .d3-arch.hovering .edge:not(.hl) { opacity: 0.12; }
  .d3-arch.hovering .node:not(.hl):not(.nb) { opacity: 0.25; }
  .d3-arch .node.hl rect { stroke: var(--primary-color); stroke-width: 1.5; }

  /* Flow animation */
  .d3-arch .flow-dot.data { fill: var(--primary-color); stroke: var(--page-bg); stroke-width: 1.5; }
  .d3-arch .flow-dot.event { fill: var(--page-bg); stroke: var(--muted-color); stroke-width: 1.5; }
  .d3-arch .node.anim-hl rect { stroke: var(--primary-color); stroke-width: 1.5; }
  .d3-arch .replay-btn { font: inherit; font-size: 11px; font-weight: 600; padding: 4px 10px; border: 1px solid var(--border-color); border-radius: 8px; background: var(--surface-bg); color: var(--text-color); cursor: pointer; transition: border-color 0.15s ease, opacity 0.15s ease; }
  .d3-arch .replay-btn:hover:not(:disabled) { border-color: var(--primary-color); }
  .d3-arch .replay-btn:disabled { opacity: 0.45; cursor: default; }
  .d3-arch .replay-btn:focus-visible { outline: 2px solid var(--primary-color); outline-offset: 1px; }

  /* Legend */
  .d3-arch .legend { display: flex; flex-direction: column; align-items: flex-start; gap: 6px; margin-top: 10px; }
  .d3-arch .legend-title { font-size: 12px; font-weight: 700; color: var(--text-color); }
  .d3-arch .legend .items { display: flex; flex-wrap: wrap; gap: 8px 18px; align-items: center; }
  .d3-arch .legend .item { display: inline-flex; align-items: center; gap: 7px; white-space: nowrap; font-size: 12px; color: var(--text-color); }
  .d3-arch .legend .swatch { width: 22px; height: 0; }
  .d3-arch .legend .swatch.data-line { border-top: 2.5px solid var(--primary-color); }
  .d3-arch .legend .swatch.event-line { border-top: 2.5px dashed var(--muted-color); }
  .d3-arch .legend .hint { font-size: 11px; font-style: italic; color: var(--muted-color); }
</style>
<script>
  (() => {
    const SPEC = ({"title": "en2", "ariaLabel": "en2", "width": 437, "height": 734, "legendTitle": "Legend", "hint": "Hover a node to trace its connections.", "groups": [], "nodes": [{"id": "S", "x": 131, "y": 24, "w": 163, "h": 62, "title": ["Drafted token", "drafter q, target p"]}, {"id": "C", "x": 112, "y": 164, "w": 202, "h": 84, "title": ["Did the target want it", "at least as much?", "(p >= q)"]}, {"id": "OK", "x": 256, "y": 500, "w": 128, "h": 62, "title": ["Accept", "keep the token"]}, {"id": "R", "x": 54, "y": 340, "w": 167, "h": 68, "title": ["Flip a coin with", "probability p / q"]}, {"id": "X", "x": 24, "y": 500, "w": 163, "h": 62, "title": ["Reject and resample", "from the residual"]}, {"id": "N", "x": 235, "y": 648, "w": 170, "h": 46, "title": "Score the next token"}, {"id": "E", "x": 31, "y": 640, "w": 149, "h": 62, "title": ["Cycle ends", "redraft from here"]}], "edges": [{"src": "S", "dst": "C", "kind": "data", "line": [213, 86, 213, 164]}, {"src": "C", "dst": "OK", "kind": "data", "label": "\"yes\"", "curve": [[274, 248], [341, 294], [341, 454], [329, 500]], "off": "50%"}, {"src": "C", "dst": "R", "kind": "data", "label": "\"no\"", "curve": [[177, 248], [138, 294], [138, 294], [138, 340]], "off": "50%"}, {"src": "R", "dst": "OK", "kind": "data", "label": "\"heads\"", "line": [183, 408, 290, 500], "lx": 245, "ly": 450}, {"src": "R", "dst": "X", "kind": "data", "label": "\"tails\"", "curve": [[124, 408], [106, 454], [106, 454], [106, 500]], "off": "50%"}, {"src": "OK", "dst": "N", "kind": "data", "line": [320, 562, 320, 648]}, {"src": "X", "dst": "E", "kind": "data", "line": [106, 562, 106, 640]}]});
    const ensureD3 = (cb) => {
      if (window.d3 && typeof window.d3.select === 'function') return cb();
      let s = document.getElementById('d3-cdn-script');
      if (!s) {
        s = document.createElement('script');
        s.id = 'd3-cdn-script';
        s.src = 'https://cdn.jsdelivr.net/npm/d3@7/dist/d3.min.js';
        document.head.appendChild(s);
      }
      const onReady = () => { if (window.d3 && typeof window.d3.select === 'function') cb(); };
      s.addEventListener('load', onReady, { once: true });
      if (window.d3) onReady();
    };

    const bootstrap = () => {
      const container = document.getElementById('specdec-en-2')
        || document.querySelector('.d3-arch[data-arch-root]:not([data-mounted])');
      if (!container || (container.dataset && container.dataset.mounted === 'true')) return;
      if (container.dataset) container.dataset.mounted = 'true';

      try {
        const uid = 'specdec-en-2';
        const NODES = SPEC.nodes || [];
        const EDGES = SPEC.edges || [];
        const GROUPS = SPEC.groups || [];
        const HOP = SPEC.hop || 800;
        const legendCfg = SPEC.legend || {};
        const dataLabel = legendCfg.data || 'Data path';
        const eventLabel = legendCfg.event || 'Event side-channel';

        const byId = Object.fromEntries(NODES.map((n) => [n.id, n]));
        const cx = (n) => n.x + n.w / 2;
        const asTitle = (t) => Array.isArray(t) ? t : [t];

        // Canvas: explicit, else auto from node/group extents + padding
        let W = SPEC.width, H = SPEC.height;
        if (!W || !H) {
          const xs = [], ys = [];
          NODES.forEach((n) => { xs.push(n.x + n.w); ys.push(n.y + n.h); });
          GROUPS.forEach((g) => { xs.push(g.x + g.w); ys.push(g.y + g.h); });
          W = W || Math.max(760, Math.ceil(Math.max(...xs, 0) + 24));
          H = H || Math.ceil(Math.max(...ys, 0) + 20);
        }

        // Tooltip
        container.style.position = container.style.position || 'relative';
        const tip = document.createElement('div');
        Object.assign(tip.style, {
          position: 'absolute', top: '0px', left: '0px',
          transform: 'translate(-9999px, -9999px)', pointerEvents: 'none',
          padding: '8px 10px', borderRadius: '8px', fontSize: '12px', lineHeight: '1.4',
          border: '1px solid var(--border-color)', background: 'var(--surface-bg)',
          color: 'var(--text-color)', boxShadow: '0 4px 24px rgba(0,0,0,.18)',
          opacity: '0', transition: 'opacity .12s ease', maxWidth: '260px', zIndex: '3'
        });
        const tipInner = document.createElement('div');
        tip.appendChild(tipInner);

        const scroll = document.createElement('div');
        scroll.className = 'diagram-scroll';
        container.appendChild(scroll);

        const svg = d3.select(scroll).append('svg')
          .attr('viewBox', `0 0 ${W} ${H}`)
          .attr('preserveAspectRatio', 'xMidYMid meet')
          .attr('role', 'img')
          .attr('aria-label', SPEC.ariaLabel || SPEC.title || 'Architecture diagram');
        // Never upscale past the spec's natural width; keep 760px readability
        // floor (with horizontal scroll) only for diagrams that are actually wide.
        svg.style('max-width', W + 'px').style('min-width', Math.min(W, 760) + 'px').style('margin', '0 auto');

        const defs = svg.append('defs');
        const mkMarker = (id, color) => {
          defs.append('marker')
            .attr('id', id).attr('viewBox', '0 0 10 10')
            .attr('refX', 9).attr('refY', 5)
            .attr('markerWidth', 6.5).attr('markerHeight', 6.5)
            .attr('orient', 'auto-start-reverse')
            .append('path').attr('d', 'M 0 0 L 10 5 L 0 10 z').style('fill', color);
        };
        mkMarker(`${uid}-arrow-data`, 'var(--primary-color)');
        mkMarker(`${uid}-arrow-event`, 'var(--muted-color)');

        // Groups
        const groups = svg.append('g');
        GROUPS.forEach((gr) => {
          const g = groups.append('g').attr('class', 'group');
          g.append('rect').attr('x', gr.x).attr('y', gr.y).attr('width', gr.w).attr('height', gr.h).attr('rx', 12);
          if (gr.label) g.append('text').attr('x', gr.lx != null ? gr.lx : gr.x + 12).attr('y', gr.ly != null ? gr.ly : gr.y + 18).text(gr.label);
        });

        // Edges (under nodes)
        const edgeLayer = svg.append('g');
        const curvePath = (p) => `M ${p[0][0]} ${p[0][1]} C ${p[1][0]} ${p[1][1]}, ${p[2][0]} ${p[2][1]}, ${p[3][0]} ${p[3][1]}`;
        EDGES.forEach((e, i) => {
          const kind = e.kind === 'event' ? 'event' : 'data';
          const g = edgeLayer.append('g').attr('class', `edge ${kind}`).attr('data-src', e.src).attr('data-dst', e.dst);
          const marker = `url(#${uid}-arrow-${kind})`;
          if (e.line) {
            const [x1, y1, x2, y2] = e.line;
            e.pathEl = g.append('path').attr('class', 'main').attr('d', `M ${x1} ${y1} L ${x2} ${y2}`).attr('marker-end', marker).node();
            if (e.label) g.append('text').attr('x', e.lx != null ? e.lx : (x1 + x2) / 2).attr('y', e.ly != null ? e.ly : (y1 + y2) / 2 - 6).attr('text-anchor', e.anchor || 'middle').text(e.label);
          } else if (e.curve) {
            e.pathEl = g.append('path').attr('class', 'main').attr('d', curvePath(e.curve)).attr('marker-end', marker).node();
            if (e.label && e.off) {
              const p = e.curve;
              const lp = p[3][0] < p[0][0] ? [p[3], p[2], p[1], p[0]] : p;
              const lpId = `${uid}-lbl-${i}`;
              g.append('path').attr('id', lpId).attr('d', curvePath(lp)).attr('fill', 'none').attr('stroke', 'none');
              g.append('text').attr('dy', -5).append('textPath').attr('href', `#${lpId}`).attr('startOffset', e.off).attr('text-anchor', 'middle').text(e.label);
            } else if (e.label) {
              g.append('text').attr('x', e.lx).attr('y', e.ly).attr('text-anchor', e.anchor || 'start').text(e.label);
            }
          }
        });

        // Nodes (over edges)
        const nodeLayer = svg.append('g');
        NODES.forEach((n) => {
          const g = nodeLayer.append('g').attr('class', 'node').attr('data-id', n.id);
          g.append('rect').attr('x', n.x).attr('y', n.y).attr('width', n.w).attr('height', n.h).attr('rx', 9);
          const title = asTitle(n.title);
          const lines = title.length;
          const baseY = n.y + n.h / 2 - (lines - 1) * 7 - (n.sub ? 5 : -4);
          title.forEach((t, li) => {
            g.append('text').attr('class', 'node-title').attr('x', cx(n)).attr('y', baseY + li * 14).attr('text-anchor', 'middle').text(t);
          });
          if (n.sub) g.append('text').attr('class', 'node-sub').attr('x', cx(n)).attr('y', baseY + (lines - 1) * 14 + 15).attr('text-anchor', 'middle').text(n.sub);
        });

        // Hover highlighting
        const edgeSel = svg.selectAll('.edge');
        const nodeSel = svg.selectAll('.node');
        nodeSel
          .on('mouseenter', function () {
            const id = this.getAttribute('data-id');
            const n = byId[id];
            container.classList.add('hovering');
            const nb = new Set([id]);
            edgeSel.classed('hl', function () {
              const hit = this.getAttribute('data-src') === id || this.getAttribute('data-dst') === id;
              if (hit) { nb.add(this.getAttribute('data-src')); nb.add(this.getAttribute('data-dst')); }
              return hit;
            });
            nodeSel.classed('hl', function () { return this.getAttribute('data-id') === id; })
                   .classed('nb', function () { return nb.has(this.getAttribute('data-id')); });
            if (n && n.desc) { tipInner.innerHTML = `<strong>${asTitle(n.title).join('')}</strong><br>${n.desc}`; tip.style.opacity = '1'; }
          })
          .on('mousemove', function (event) {
            const [mx, my] = d3.pointer(event, container);
            const flip = mx > container.clientWidth - 280;
            tip.style.transform = `translate(${flip ? mx - 270 : mx + 14}px, ${my + 14}px)`;
          })
          .on('mouseleave', function () {
            container.classList.remove('hovering');
            edgeSel.classed('hl', false);
            nodeSel.classed('hl', false).classed('nb', false);
            tip.style.opacity = '0';
            tip.style.transform = 'translate(-9999px, -9999px)';
          });

        // Flow animation sequence: explicit SEQ, else auto forward-cascade of data edges
        const resolveEdge = (s) => {
          if (typeof s.e === 'number') return s.e;
          if (s.from && s.to) return EDGES.findIndex((e) => e.src === s.from && e.dst === s.to);
          return -1;
        };
        let SEQ = (SPEC.seq || []).map((s) => ({ e: resolveEdge(s), t0: s.t0 })).filter((s) => s.e >= 0);
        if (!SEQ.length) {
          let t = 0;
          EDGES.forEach((e, i) => { if ((e.kind || 'data') === 'data') { SEQ.push({ e: i, t0: t }); t += HOP; } });
        }
        const TOTAL = SPEC.total || (Math.max(0, ...SEQ.map((s) => s.t0)) + HOP + 800);

        let playing = false, replayBtn = null;
        const pulseNode = (id) => {
          const sel = nodeSel.filter(function () { return this.getAttribute('data-id') === id; });
          sel.classed('anim-hl', true);
          setTimeout(() => sel.classed('anim-hl', false), 550);
        };
        const play = () => {
          if (playing) return;
          playing = true;
          if (replayBtn) replayBtn.disabled = true;
          const layer = svg.append('g');
          const steps = SEQ.map((s) => {
            const edge = EDGES[s.e];
            return { ...s, edge, len: edge.pathEl.getTotalLength(), dot: null, arrived: false };
          });
          const start = performance.now();
          const frame = (now) => {
            const t = now - start;
            steps.forEach((s) => {
              if (t < s.t0) return;
              const f = Math.min(1, (t - s.t0) / HOP);
              if (f >= 1) { if (s.dot) { s.dot.remove(); s.dot = null; } if (!s.arrived) { s.arrived = true; pulseNode(s.edge.dst); } return; }
              if (!s.dot) s.dot = layer.append('circle').attr('class', `flow-dot ${s.edge.kind || 'data'}`).attr('r', (s.edge.kind === 'event') ? 4 : 5);
              const p = s.edge.pathEl.getPointAtLength(d3.easeCubicInOut(f) * s.len);
              s.dot.attr('cx', p.x).attr('cy', p.y);
            });
            if (t < TOTAL) requestAnimationFrame(frame);
            else { layer.remove(); playing = false; if (replayBtn) replayBtn.disabled = false; }
          };
          requestAnimationFrame(frame);
        };

        // Legend
        const legend = document.createElement('div');
        legend.className = 'legend';
        legend.innerHTML = `
          <div class="legend-title">${SPEC.legendTitle || 'Legend'}</div>
          <div class="items">
            <span class="item"><span class="swatch data-line"></span><span>${dataLabel}</span></span>
            <span class="item"><span class="swatch event-line"></span><span>${eventLabel}</span></span>
            <button class="replay-btn" type="button" aria-label="Replay the flow animation">&#9654; Replay</button>
            <span class="hint">${SPEC.hint || 'Hover a component to trace its connections.'}</span>
          </div>`;
        container.appendChild(legend);
        container.appendChild(tip);
        replayBtn = legend.querySelector('.replay-btn');
        replayBtn.addEventListener('click', play);

        const prefersReduced = window.matchMedia && window.matchMedia('(prefers-reduced-motion: reduce)').matches;
        if (!prefersReduced && window.IntersectionObserver) {
          const io = new IntersectionObserver((entries) => {
            entries.forEach((en) => { if (en.isIntersecting) { io.disconnect(); play(); } });
          }, { threshold: 0.5 });
          io.observe(container);
        }
      } catch (err) {
        const pre = document.createElement('pre');
        pre.style.color = '#c0392b';
        pre.style.fontSize = '12px';
        pre.textContent = 'Failed to render architecture diagram: ' + (err && err.message ? err.message : err);
        container.appendChild(pre);
      }
    };

    if (document.readyState === 'loading') document.addEventListener('DOMContentLoaded', () => ensureD3(bootstrap), { once: true });
    else ensureD3(bootstrap);
  })();
</script>
{% endraw %}

## How Many Letters Should the Friend Draft Ahead?

Does raising the number of letters the friend drafts ahead always help? Not really.

Say the friend's odds of getting a single letter right are 70 percent. The first letter has a 70 percent chance of passing. Surviving to the second letter requires both the first and second to be correct, which drops to 49 percent. The third falls to 34 percent, the fourth to 24 percent, and it keeps sliding. The moment an earlier letter gets erased, the context changes and every letter after it is thrown out too.

So even if you have the friend draft ten letters ahead, only three or four survive on average. The rest is wasted effort on the friend's part, and that wasted effort still takes time. The average number of letters that pass per round is called tau, and past a certain point, cranking up how many letters get drafted barely moves tau at all.

![Average accepted length curve by draft hit rate. At low hit rates, the curves overlap even as the draft count grows.](/assets/images/speculative-decoding-easy-guide-tau-en.webp)
*Around a 40 percent hit rate, drafting 3 letters ahead or 7 gives almost the same result. To gain anything from a higher count, the friend has to get smarter first.*

This chart sums up where research has been heading for the past few years. Because raising the draft count hits a wall quickly, people shifted toward **making the friend better at guessing right**.

## The Ways of Building That Friend Kept Getting Better

The earliest approach was simple: bring in a smaller model from the same family and seat it next to the teacher. It requires no extra training, which is convenient, and it delivers roughly 2x to 3x. The catch is that you now have two models running, so it costs that much more GPU memory.

**Medusa** came next, and instead of keeping a separate friend, it bolted several extra hands onto the teacher's head. Each hand predicts the second, third, and fourth letters at the same time. It delivered 2.2x to 3.6x, but it had a weakness. The hands do not consult each other, so the farther-out hands tend to produce off-target letters.

**MTP (multi-token prediction)** takes the opposite approach: instead of bolting the extra hands onto a finished model, it raises them together with the model from the very start of training. As a bonus, this even sharpens the base model's own ability, so the 3x inference speedup ends up being almost a side effect.

The **EAGLE** family is the most widely used approach today, and it came from a shift in framing. Instead of asking the friend "what is the next letter," it asks "what will the teacher's internal state look like next." Inheriting the internal state turned out to line up much better than inheriting a letter, and this alone delivered 2.7x to 3.5x. EAGLE-2 followed by preparing several branches at once whenever the friend was unsure, pushing the range up to 3.05x through 4.26x. EAGLE-3 went back to predicting letters directly, but trained the friend under the exact conditions it would face in production, and reported up to 6.5x.

The most recent arrival, **DFlash**, takes a completely different approach. Instead of writing letters one at a time in order, it produces a whole block at once. It applies the same idea diffusion models use to sharpen a blurry image step by step, but to a block of letters. It averages 4x to 6x, and it scales well as the friend model grows larger.

Add **DSpark** to the mix and the recent trend becomes clear. This approach does not chase a better draft. Instead, it watches how much load the server is under right now together with how confident the friend is, and adjusts when grading happens. It boosted the speed a single user feels by 60 to 85 percent, at the cost of more moving parts and a more complex implementation.

| Method | How the draft is made | Avg. accepted per round | Speedup |
|---|---|---|---|
| Separate small model | One letter at a time, in order | About 3.6 | 2x to 3x |
| Medusa | Several hands at once | 3.0 to 3.5 | 2.2x to 3.6x |
| EAGLE-3 | One letter at a time, in order | 5 to 7.5 | Up to 6.5x |
| DFlash | Whole block at once | 4 to 8 | 6x or more |
| DSpark | Semi-autoregressive plus verification scheduling | 3.1 to 6.2 | 1.6x to 1.85x felt by users |

## The Payoff Shrinks as the Crowd Grows

This is where a lot of people trip up. They turn the feature on expecting the 6x from the paper, and in production it barely speeds anything up. There is usually one reason.

When you are alone in the library, the time spent pulling books out really does feel wasted. But once a hundred people are lined up, the picture changes. Pulling the books out once now serves all hundred people at the same time, so that cost is already split a hundred ways. There is nothing left to save.

Speculative decoding wins the most **when concurrent users are few**. Once enough users pile in that the GPU's compute is already saturated, the whole premise of putting spare capacity to work disappears. In bad cases, all you add is the cost of drafting, and you actually come out behind.

So here is a simple rule of thumb. If how quickly a single response comes back matters to your service, it is worth turning on. Conversational chatbots, coding assistants, and agents that reason through many steps on their own all fit here. On the other hand, if you are running an overnight batch job processing documents in bulk, you do not really need it.

## Turning It On Yourself

Every major inference engine supports this today. vLLM, SGLang, llama.cpp, and MLX all need just a line or two of configuration. Here is an example of launching with the DFlash method on SGLang.

```bash
python -m sglang.launch_server \
  --model-path <path-to-target-model> \
  --speculative-algorithm DFLASH \
  --speculative-draft-model-path <path-to-draft-model> \
  --speculative-num-draft-tokens 5
```

Once it is on, check two numbers in the logs. One is the acceptance rate, and the other is the average accepted length per round. If the accepted length cannot get past 2, the friend and the teacher just are not a good match, and swapping out the draft model is the right move, not raising the draft count.

## What to Check Before You Turn It On

Running GPU serving ourselves taught us one lesson the expensive way. **Speculative decoding is something you turn on last, not first.**

In August 2026, we measured throughput on our B200 hardware while changing nothing but the serving configuration. Same model, same GPU, same engine, and yet two settings alone produced an 18.8x difference in single-stream throughput. Compilation was off, and the number of requests that could be handled concurrently was stuck at the default of 32. What had been 7.4 tokens per second became 138.8.

What happens if you turn on speculative decoding in that state? You would be using a technique that gets you 6x to try to claw back an 18.8x loss. The order is backwards. Fix the base configuration first, and only then layer speculative decoding on top, so the technique can actually deliver what it is capable of.

Our inference product, **Metis**, exists precisely so tenants do not have to fine-tune these serving settings themselves. And the place this technique fits especially well is **Paxis**. An agent handling a single request calls tools, reads the results, and reasons again, over and over, and during that loop concurrent users tend to be few while the latency of each step becomes the felt speed directly. That is exactly the "wins the most when the crowd is small" condition described earlier.

If you tried speculative decoding once already and gave up on it, our own record of running into the same thing and reopening the question might help. In [It Wasn't Speculative Decoding That Was Slow, It Was the Lookup Method](/tech-blog/en/llmops/speculative-decoding-lookup-vs-drafter/), we walk through how a single method choice produced an 11.9x swing. [DFlash Block-Diffusion Drafting](/tech-blog/en/llmops/dflash-speculative-decoding-vllm/) and [Running EAGLE on vLLM](/tech-blog/en/llmops/vllm-eagle-speculative-decoding-production/) also cover the actual configuration values we used.

## Wrapping Up

Speculative decoding boils down to one sentence. A fast friend writes first, and a slow but precise teacher grades it all at once. With the grading rule set up correctly, not a single letter of the answer changes.

The trajectory of the field is worth noting too. At first, it was all about "how do we make the friend smarter." It started with a separate model, moved on to bolting hands onto the teacher's head, and arrived at inheriting internal state instead of letters. But recent research is asking a different question. As more users pile in, **when and how should grading be batched together**, and scheduling verification is turning out to be the harder problem, more so than drafting itself. This looks like where the fight will be over the next few years.

The original explanation behind this post is Leonie Monigatti's [Speculative Decoding](https://leoniemonigatti.com/blog/speculative-decoding.html). If you need the formulas and paper links, we recommend reading the original alongside this one.
