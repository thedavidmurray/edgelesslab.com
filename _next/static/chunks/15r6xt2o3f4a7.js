(globalThis.TURBOPACK||(globalThis.TURBOPACK=[])).push(["object"==typeof document?document.currentScript:void 0,43875,e=>{"use strict";var t=e.i(74092),a=e.i(43041),s=e.i(63560);let r=(0,e.i(42175).default)("arrow-right",[["path",{d:"M5 12h14",key:"1ays0h"}],["path",{d:"m12 5 7 7-7 7",key:"xquz4c"}]]);var o=e.i(29114),n=e.i(60409);function i(e,t){n.default.capture("cta_clicked",{cta_name:e,destination:t})}function l({text:e,className:a,delay:s=0}){let r=e.split(" ");return(0,t.jsxs)("span",{className:a,children:[r.map((e,a)=>(0,t.jsx)("span",{className:"inline-block mr-[0.25em]",style:{animation:`fadeInUp 0.5s cubic-bezier(0.16,1,0.3,1) ${s+.08*a}s both`},children:e},a)),(0,t.jsx)("style",{children:`
        @keyframes fadeInUp {
          from { opacity: 0; transform: translateY(20px); filter: blur(8px); }
          to { opacity: 1; transform: translateY(0); filter: blur(0); }
        }
      `})]})}function c({children:e,className:a,delay:s=0}){return(0,t.jsxs)("div",{className:a,style:{animation:`fadeInUpSimple 0.6s cubic-bezier(0.16,1,0.3,1) ${s}s both`},children:[e,(0,t.jsx)("style",{children:`
        @keyframes fadeInUpSimple {
          from { opacity: 0; transform: translateY(16px); }
          to { opacity: 1; transform: translateY(0); }
        }
      `})]})}function h({children:e,className:a="",href:r,glowColor:o="var(--accent)"}){let n=(0,t.jsxs)("div",{className:`group relative overflow-hidden rounded-2xl border p-8 transition-all duration-200 hover:scale-[1.01] ${a}`,style:{background:"var(--bg-surface)",borderColor:"var(--border-subtle)"},children:[(0,t.jsx)("div",{className:"pointer-events-none absolute -inset-px rounded-2xl opacity-0 transition-opacity duration-300 group-hover:opacity-100",style:{background:`radial-gradient(600px circle at var(--mouse-x, 50%) var(--mouse-y, 50%), ${o}10, transparent 40%)`}}),(0,t.jsx)("div",{className:"pointer-events-none absolute inset-x-0 top-0 h-px opacity-0 transition-opacity duration-300 group-hover:opacity-100",style:{background:`linear-gradient(90deg, transparent, ${o}30, transparent)`}}),(0,t.jsx)("div",{className:"relative",children:e})]});return r?r.startsWith("/")?(0,t.jsx)(s.default,{href:r,children:n}):(0,t.jsx)("a",{href:r,target:"_blank",rel:"noopener noreferrer",children:n}):n}let d=["lorenz","rossler","spiral","flow"],u=[[235,85],[160,70],[270,75],[210,80],[330,65],[180,60]];function p(){let e=(0,a.useRef)(null),s=(0,a.useRef)(0),r=(0,a.useRef)(null),o=(0,a.useCallback)(e=>{var t;let a=(Date.now()^0xffffffff*Math.random())>>>0,s=(t=a,()=>{t|=0;let e=Math.imul((t=t+0x6d2b79f5|0)^t>>>15,1|t);return(((e=e+Math.imul(e^e>>>7,61|e)^e)^e>>>14)>>>0)/0x100000000}),o=d[Math.floor(s()*d.length)],n=u[Math.floor(s()*u.length)],i=e.width,l=e.height;r.current={particles:Array.from({length:600},()=>{let e=s()*i,t=s()*l;return{x:e,y:t,prevX:e,prevY:t,vx:(s()-.5)*2,vy:(s()-.5)*2,life:Math.floor(250*s())+80,maxLife:330,hueOffset:(s()-.5)*40}}),type:o,seed:a,rng:s,cx1:i*(.2+.6*s()),cy1:l*(.2+.6*s()),cx2:i*(.2+.6*s()),cy2:l*(.2+.6*s()),cx3:i*(.2+.6*s()),cy3:l*(.2+.6*s()),strength:.012+.025*s(),baseHue:n[0]+(s()-.5)*30,baseSat:n[1],hueRange:20+40*s(),trailFade:.03+.03*s(),time:0}},[]);return(0,a.useEffect)(()=>{let t=e.current;if(!t)return;let a=t.getContext("2d");if(!a)return;let n=0,i=0,l=()=>{let e=Math.min(window.devicePixelRatio||1,2),s=t.getBoundingClientRect();n=s.width,i=s.height,t.width=s.width*e,t.height=s.height*e,a.scale(e,e),o(t)};l();let c=()=>{let e=r.current;if(!e)return;e.time++,a.fillStyle=`rgba(0, 0, 0, ${e.trailFade})`,a.fillRect(0,0,n,i);let o=n/t.width,l=i/t.height;for(let s of e.particles){!function(e,t,a,s){e.prevX=e.x,e.prevY=e.y;let r=0,o=0,{type:n,cx1:i,cy1:l,cx2:c,cy2:h,cx3:d,cy3:u,strength:p,time:m}=t;switch(n){case"lorenz":{let t=i-e.x,a=l-e.y,s=c-e.x,n=h-e.y,m=Math.sqrt(t*t+a*a)+1,g=Math.sqrt(s*s+n*n)+1,f=d-e.x,y=u-e.y,w=Math.sqrt(f*f+y*y)+1;r=(t/m-n/g+f/w*.3)*p,o=(a/m+s/g-y/w*.3)*p;break}case"rossler":{let t=i-e.x,a=l-e.y,s=Math.sqrt(t*t+a*a)+1,n=.005*Math.sin(.002*m);r=(-a/s+t*(.008+n))*p,o=(t/s+a*(.008+n))*p;let d=c-e.x,u=h-e.y,g=Math.sqrt(d*d+u*u)+1;r+=u/g*p*.2,o-=d/g*p*.2;break}case"spiral":{let t=i-e.x,a=l-e.y,s=Math.sqrt(t*t+a*a)+1,n=Math.atan2(a,t)+.3+.2*Math.sin(.001*m);r=Math.cos(n)/s*p*8,o=Math.sin(n)/s*p*8;let d=c-e.x,u=h-e.y,g=Math.sqrt(d*d+u*u)+1,f=Math.atan2(u,d)-.5;r+=Math.cos(f)/g*p*3,o+=Math.sin(f)/g*p*3;break}case"flow":{let t=.002+5e-4*Math.sin(5e-4*m),n=Math.sin(e.x*t+.001*m)*Math.cos(e.y*t*.7),i=Math.cos(e.x*t*.8-8e-4*m)*Math.sin(e.y*t);r=n*p*1.5,o=i*p*1.5,r+=(.5*a-e.x)*1e-5,o+=(.5*s-e.y)*1e-5}}e.vx+=r,e.vy+=o,e.vx*=.982,e.vy*=.982,e.x+=e.vx,e.y+=e.vy,e.life--,e.life<=0&&(e.x=t.rng()*a,e.y=t.rng()*s,e.prevX=e.x,e.prevY=e.y,e.vx=(t.rng()-.5)*2,e.vy=(t.rng()-.5)*2,e.life=Math.floor(250*t.rng())+80,e.hueOffset=(t.rng()-.5)*40),e.x<-20&&(e.x=-20,e.vx*=-.5),e.x>a+20&&(e.x=a+20,e.vx*=-.5),e.y<-20&&(e.y=-20,e.vy*=-.5),e.y>s+20&&(e.y=s+20,e.vy*=-.5)}(s,e,t.width,t.height);let r=s.life/s.maxLife,c=r>.9?(1-r)*10:r<.2?5*r:1,h=Math.sqrt(s.vx*s.vx+s.vy*s.vy),d=c*Math.min(.8,.2+.15*h),u=.5+.4*h,p=e.baseHue+s.hueOffset+Math.sin(.003*e.time+s.hueOffset)*e.hueRange*.3,m=s.prevX*o,g=s.prevY*l,f=s.x*o,y=s.y*l,w=Math.abs(y-g);Math.abs(f-m)>.3*n||w>.3*i||(a.beginPath(),a.moveTo(m,g),a.lineTo(f,y),a.strokeStyle=`hsla(${p}, ${e.baseSat}%, 65%, ${d})`,a.lineWidth=u,a.lineCap="round",a.stroke(),h>2.5&&(a.beginPath(),a.arc(f,y,u+2,0,2*Math.PI),a.fillStyle=`hsla(${p}, ${e.baseSat}%, 70%, ${.3*d})`,a.fill()))}s.current=requestAnimationFrame(c)};return s.current=requestAnimationFrame(c),window.addEventListener("resize",l),()=>{cancelAnimationFrame(s.current),window.removeEventListener("resize",l)}},[o]),(0,t.jsxs)("div",{className:"pointer-events-none absolute inset-0 overflow-hidden",children:[(0,t.jsx)("div",{className:"absolute inset-0",style:{backgroundImage:"linear-gradient(rgba(255,255,255,0.03) 1px, transparent 1px), linear-gradient(90deg, rgba(255,255,255,0.03) 1px, transparent 1px)",backgroundSize:"64px 64px"}}),(0,t.jsx)("canvas",{ref:e,className:"absolute inset-0 w-full h-full",style:{opacity:.55}}),(0,t.jsx)("div",{className:"absolute inset-0",style:{background:"radial-gradient(ellipse 80% 60% at 50% 40%, transparent 0%, rgba(0,0,0,0.65) 100%)"}})]})}var m=e.i(63060),g=e.i(25);function f({text:e,font:s='300 18px "Geist"',lineHeight:r=30,className:o,style:n,fallback:i,cursorRadius:l=36,cursorColor:c="var(--accent)"}){let h=(0,a.useRef)(null),{ready:d,prepareWithSegments:u,layoutNextLine:p}=(0,g.usePreText)("Geist");return((0,a.useEffect)(()=>{if(!d||!u||!p||!h.current)return;let t=h.current,a=u(e,s);if(!a)return;let o=!1,n=0,i=0,m=0,g=0;for(;t.firstChild;)t.removeChild(t.firstChild);let f=[],y=document.createElement("div");function w(e){let s=t.clientWidth;if(0===s)return[];let o={segmentIndex:0,graphemeIndex:0},n=0,i=[],l=0;for(;l++<500;){let t=s,l=0;if(e&&n+r>e.y&&n<e.y+e.height){let a=e.x,r=e.x+e.width;if(a<=0)t=s-(l=Math.max(0,r+12));else if(r>=s)t=Math.max(60,a-12);else{let e=a-12,o=s-r-12;e>=o?t=Math.max(60,e):(l=r+12,t=Math.max(60,o))}}t=Math.max(t,60);let c=o.segmentIndex,h=o.graphemeIndex,d=p(a,o,t);if(!d||(i.push({text:d.text.trimEnd(),y:n,indent:l}),o=d.end,n+=r,o.segmentIndex===c&&o.graphemeIndex===h))break}return i}function v(e){for(var a=e.length;f.length<a;){let e=document.createElement("div");e.style.cssText=`
          position: absolute; white-space: pre; pointer-events: none;
          font: ${s}; line-height: ${r}px; height: ${r}px;
          left: 0; top: 0;
        `,t.appendChild(e),f.push(e)}for(let e=a;e<f.length;e++)f[e].style.display="none";for(let t=0;t<e.length;t++){let a=f[t],s=e[t];a.style.display="block",a.textContent!==s.text&&(a.textContent=s.text),a.style.transform=`translate(${s.indent}px, ${s.y}px)`,a.style.opacity="1"}let o=e.length*r;o>0&&(t.style.height=`${Math.max(o,g)}px`)}y.style.cssText=`
      position: absolute; border-radius: 50%; pointer-events: none;
      width: ${2*l}px; height: ${2*l}px;
      background: ${c}; filter: blur(16px);
      mix-blend-mode: screen; opacity: 0;
      transition: opacity 0.25s ease;
      z-index: 1;
    `,t.appendChild(y);let b=w(null);g=b.length*r,v(b);for(let e=0;e<f.length;e++)f[e].style.opacity="0",f[e].style.transition="opacity 0.4s ease, transform 0.35s cubic-bezier(0.16, 1, 0.3, 1)";function k(){o=!0,y.style.opacity="0.15",m||C()}function x(e){let a=t.getBoundingClientRect();n=e.clientX-a.left,i=e.clientY-a.top,y.style.transform=`translate(${n-l}px, ${i-l}px)`,o||(o=!0,y.style.opacity="0.15",m||C())}function T(){o=!1,y.style.opacity="0",setTimeout(()=>{o||v(w(null))},300)}function C(){if(!o){m=0;return}m=requestAnimationFrame(C),v(w({x:n-l-14,y:i-l-14,width:(l+14)*2,height:(l+14)*2}))}return requestAnimationFrame(()=>{for(let e=0;e<b.length;e++)setTimeout(()=>{f[e]&&(f[e].style.opacity="1")},80*e)}),t.style.cursor="crosshair",t.addEventListener("pointerenter",k),t.addEventListener("pointermove",x),t.addEventListener("pointerleave",T),()=>{cancelAnimationFrame(m),t.removeEventListener("pointerenter",k),t.removeEventListener("pointermove",x),t.removeEventListener("pointerleave",T)}},[d,e,s,r,u,p,l,c]),d)?(0,t.jsx)("div",{ref:h,className:o,style:{...n,position:"relative",overflow:"visible"}}):(0,t.jsx)("div",{ref:h,className:o,style:n,children:i??e})}let y={segmentIndex:0,graphemeIndex:0};function w({segments:e,className:s,style:r}){let o=(0,a.useRef)(null),[n,i]=(0,a.useState)(0),{ready:l,prepareWithSegments:c,layoutNextLine:h}=(0,g.usePreText)("Geist");(0,a.useEffect)(()=>{if(!o.current)return;let e=()=>{o.current&&i(o.current.clientWidth)};e();let t=new ResizeObserver(e);return t.observe(o.current),()=>t.disconnect()},[]);let d=(0,a.useMemo)(()=>{if(!l||!c||!h||n<=0)return null;let t=e.map(e=>({prepared:c(e.text,e.font),segment:e}));if(t.some(e=>!e.prepared))return null;let a=[],s=Math.max(...e.map(e=>e.lineHeight)),r=0,o=[],i=n;for(let{prepared:e,segment:l}of t){if(!e)continue;let t=h(e,y,1e5);if(t)if(t.width<=i)o.push({text:t.text,width:t.width,style:l.style,font:l.font}),i-=t.width;else{let t=y;for(;;){let c=h(e,t,Math.max(1,i));if(!c)break;if(o.push({text:c.text,width:c.width,style:l.style,font:l.font}),c.end.segmentIndex>=e.segments.length||c.end.segmentIndex===e.segments.length-1&&c.end.graphemeIndex>=e.segments[e.segments.length-1].length){i-=c.width;break}a.push({fragments:o,y:r,lineHeight:s}),r+=s,o=[],i=n,t=c.end}}}return o.length>0&&(a.push({fragments:o,y:r,lineHeight:s}),r+=s),{lines:a,totalHeight:r}},[l,c,h,e,n]);return d?(0,t.jsx)("div",{ref:o,className:s,style:{...r,position:"relative",height:`${d.totalHeight}px`},children:d.lines.map((e,a)=>(0,t.jsx)("div",{style:{position:"absolute",top:`${e.y}px`,left:0,height:`${e.lineHeight}px`,lineHeight:`${e.lineHeight}px`,whiteSpace:"pre"},children:e.fragments.map((e,a)=>(0,t.jsx)("span",{style:{...e.style,font:e.font},children:e.text},a))},a))}):(0,t.jsx)("div",{ref:o,className:s,style:{...r,whiteSpace:"pre-wrap"},children:e.map((e,a)=>(0,t.jsx)("span",{style:{...e.style,font:e.font},children:e.text},a))})}function v({text:e,font:s='300 14px "Geist"',lineHeight:r=24,orbCount:o=3,orbRadius:n=40,className:i,style:l,textColor:c="var(--text-secondary)"}){let{ready:h,prepareWithSegments:d,layoutNextLine:u}=(0,g.usePreText)("Geist"),p=(0,a.useRef)(null),m=(0,a.useRef)(null),f=(0,a.useRef)(null),y=(0,a.useRef)([]),w=(0,a.useRef)(0),[b,k]=(0,a.useState)({width:0,height:0}),x=(0,a.useRef)(-1),T=(0,a.useRef)({x:0,y:0});(0,a.useEffect)(()=>{if(0===b.width)return;let e=b.width,t=b.height||300,a=["rgba(129,140,248,0.12)","rgba(34,197,94,0.10)","rgba(129,140,248,0.08)"];y.current=Array.from({length:o},(s,r)=>({x:e*(.25+.5*Math.random()),y:t*(.25+.5*Math.random()),vx:(Math.random()-.5)*1.5,vy:(Math.random()-.5)*1.5,radius:n+15*Math.random(),color:a[r%a.length],dragging:!1}))},[b.width,b.height,o,n]),(0,a.useEffect)(()=>{if(!p.current)return;let e=()=>{if(p.current){let{width:e}=p.current.getBoundingClientRect();k({width:e,height:280})}};e();let t=new ResizeObserver(e);return t.observe(p.current),()=>t.disconnect()},[h]),(0,a.useEffect)(()=>{if(!h||!d||!u||0===b.width)return;let t=d(e,s);if(!t)return;let a=m.current,o=f.current;if(!a||!o)return;let n=a.getContext("2d");if(!n)return;let i=b.width,l=window.devicePixelRatio||1,p=()=>{let e=y.current;for(let t of e)!t.dragging&&(t.x+=t.vx,t.y+=t.vy,t.x-t.radius<0&&(t.x=t.radius,t.vx*=-.8),t.x+t.radius>i&&(t.x=i-t.radius,t.vx*=-.8),t.y-t.radius<0&&(t.y=t.radius,t.vy*=-.8),t.vx*=.999,t.vy*=.999,.3>Math.sqrt(t.vx*t.vx+t.vy*t.vy)&&(t.vx+=(Math.random()-.5)*.2,t.vy+=(Math.random()-.5)*.2));for(let t=0;t<e.length;t++)for(let a=t+1;a<e.length;a++){let s=e[t],r=e[a],o=r.x-s.x,n=r.y-s.y,i=Math.sqrt(o*o+n*n),l=s.radius+r.radius;if(i<l&&i>0){let e=o/i,t=n/i,a=(l-i)/2;s.dragging||(s.x-=e*a,s.y-=t*a),r.dragging||(r.x+=e*a,r.y+=t*a);let c=(r.vx-s.vx)*e+(r.vy-s.vy)*t;s.dragging||(s.vx+=c*e*.5,s.vy+=c*t*.5),r.dragging||(r.vx-=c*e*.5,r.vy-=c*t*.5)}}let h=[],d={segmentIndex:0,graphemeIndex:0},m=0,g=t.segments.length,f=200;for(;(d.segmentIndex<g||d.graphemeIndex>0)&&m<280&&f-- >0;){let a=0,s=i;for(let t of e){let e=t.y-t.radius,o=t.y+t.radius;if(m+r>e&&m<o){let e=m+r/2-t.y,o=Math.sqrt(Math.max(0,t.radius*t.radius-e*e)),n=t.x-o-8,l=t.x+o+8,c=Math.max(0,n),h=Math.max(0,i-l);if(c>=h&&c>60)s=c,a=0;else if(h>60)a=l,s=h;else{m+=r;continue}}}if(s<40){m+=r;continue}let o=u(t,d,s);if(!o||o.end.segmentIndex===d.segmentIndex&&o.end.graphemeIndex===d.graphemeIndex)break;o.text.trim()&&h.push({x:a,y:m,text:o.text}),d=o.end,m+=r}for(let t of(a.width=i*l,a.height=280*l,a.style.width=`${i}px`,a.style.height="280px",n.scale(l,l),n.clearRect(0,0,i,280),e)){let e=n.createRadialGradient(t.x,t.y,0,t.x,t.y,t.radius);e.addColorStop(0,t.color.replace(/[\d.]+\)$/,"0.15)")),e.addColorStop(.7,t.color),e.addColorStop(1,"transparent"),n.beginPath(),n.arc(t.x,t.y,t.radius,0,2*Math.PI),n.fillStyle=e,n.fill(),n.beginPath(),n.arc(t.x,t.y,t.radius,0,2*Math.PI),n.strokeStyle=t.color.replace(/[\d.]+\)$/,"0.3)"),n.lineWidth=1,n.stroke()}for(let e of(o.innerHTML="",o.style.height="280px",h)){let t=document.createElement("div");t.style.position="absolute",t.style.left=`${e.x}px`,t.style.top=`${e.y}px`,t.style.font=s,t.style.color=c,t.style.whiteSpace="nowrap",t.style.lineHeight=`${r}px`,t.textContent=e.text,o.appendChild(t)}for(let t of e)t.y+t.radius>270&&(t.y=280-t.radius-10,t.vy*=-.8);w.current=requestAnimationFrame(p)};return w.current=requestAnimationFrame(p),()=>cancelAnimationFrame(w.current)},[h,d,u,b.width,e,s,r,c]);let C=(0,a.useCallback)(e=>{let t=p.current?.getBoundingClientRect();if(!t)return;let a=e.clientX-t.left,s=e.clientY-t.top;for(let t=0;t<y.current.length;t++){let r=y.current[t],o=a-r.x,n=s-r.y;if(o*o+n*n<r.radius*r.radius){x.current=t,T.current={x:o,y:n},r.dragging=!0,r.vx=0,r.vy=0,e.target.setPointerCapture(e.pointerId);return}}},[]),I=(0,a.useCallback)(e=>{if(x.current<0)return;let t=p.current?.getBoundingClientRect();if(!t)return;let a=y.current[x.current];a&&(a.x=e.clientX-t.left-T.current.x,a.y=e.clientY-t.top-T.current.y)},[]),A=(0,a.useCallback)(()=>{if(x.current>=0){let e=y.current[x.current];e&&(e.dragging=!1)}x.current=-1},[]);return h?(0,t.jsxs)("div",{ref:p,className:i,style:{...l,position:"relative",height:280,overflow:"hidden",cursor:"default"},onPointerDown:C,onPointerMove:I,onPointerUp:A,children:[(0,t.jsx)("canvas",{ref:m,style:{position:"absolute",top:0,left:0,zIndex:0,pointerEvents:"none"}}),(0,t.jsx)("div",{ref:f,style:{position:"absolute",top:0,left:0,width:"100%",zIndex:1,pointerEvents:"none"}})]}):(0,t.jsx)("div",{className:i,style:l,children:(0,t.jsx)("p",{style:{color:c,font:s,lineHeight:`${r}px`},children:e})})}var b=e.i(81154);let k="utm_source=edgelesslab&utm_medium=website&utm_campaign=products",x=[{name:"CLAUDE.md Template Pack",price:"Free",description:"14 battle-tested CLAUDE.md templates for every project type. Drop one into your repo and start building.",features:["14 templates: iOS, Android, ML, API, DevOps, Next.js, and more","CLI Tools, Monorepos, and Game Dev configurations","Embedded/IoT, Security Audits, and Open Source templates","Startup MVP and Technical Writing presets"],href:`https://edgelessai.gumroad.com/l/kszapk?${k}`,badge:"Free"},{name:"Quick Reference Cards",price:"Free",description:"Printable cheat sheets for prompt patterns, Claude Code shortcuts, MCP tool reference, and common workflows.",features:["Prompt pattern and system prompt reference cards","Claude Code shortcuts and slash commands","Token optimization and temperature settings guide","PDF and markdown formats, pin-next-to-monitor ready"],href:`https://edgelessai.gumroad.com/l/dihxts?${k}`,badge:"Free"},{name:"Claude Code Cheat Sheet",price:"Free",description:"Quick-start reference for Claude Code. Commands, shortcuts, hook patterns, and MCP setup in one printable sheet.",features:["All slash commands and keyboard shortcuts","Hook configuration patterns with examples","MCP server setup cheatsheet","CLAUDE.md template and memory system quick-start"],href:`https://edgelessai.gumroad.com/l/claude-code-cheat-sheet?${k}`,badge:"Free",slug:"claude-code-cheat-sheet"},{name:"Claude Memory Kit",price:"Free",description:"Start here. Drop-in memory template for Claude Code. Persists context, feedback, and project knowledge across conversations.",features:["4 memory types: user, feedback, project, reference","MEMORY.md index auto-loaded each session","CLAUDE.md snippet for instant setup","Real-world examples included"],href:"https://github.com/edgeless-ai/claude-memory-kit?utm_source=edgelesslab&utm_medium=website&utm_campaign=products",badge:"Free",repoUrl:"https://github.com/edgeless-ai/claude-memory-kit"},{name:"Edgeless Stack",price:"Free",description:"The complete AI agent infrastructure. Memory that persists, hooks that protect, skills that compound, and agents that run while you sleep. Extracted from 3+ months of production use.",features:["3-layer memory: SQLite ledger + ChromaDB vectors + Obsidian vault","6 safety hooks: damage control, completion verification, taxonomy guard","9 skills with tiered loading (5 core + 4 domain)","Cron patterns, Agent Bus, Docker compose, install.sh"],href:"https://github.com/edgeless-ai/edgeless-stack?utm_source=edgelesslab&utm_medium=website&utm_campaign=products",badge:"Free",repoUrl:"https://github.com/edgeless-ai/edgeless-stack"},{name:"Multi-Agent Orchestration Blueprint",price:"$39",description:"The dispatch/worker architecture for coordinating multiple AI agents. Agent Bus messaging, async inboxes, state machines, and 3 reference implementations from a system that runs 5 agents 24/7.",features:["Dispatch/worker topology: routing tasks to specialist agents","Agent Bus setup: real-time inter-session messaging patterns","State machines: queued -> acked -> running -> done/failed","3 reference pipelines: research, code review, content processing"],href:`https://edgelessai.gumroad.com/l/multi-agent-blueprint?${k}`,badge:"New",comingSoon:!1,slug:"multi-agent-blueprint"},{name:"The Agent Cookbook",price:"$39",description:"Build AI agents that actually work. 15 production-ready agent patterns with complete implementations for Claude, GPT, and open-source models.",features:["15 production-ready agent patterns with working code","Memory systems, tool integration, and context management","Error recovery and deployment strategies","Architecture diagrams and production lessons learned"],href:`https://edgelessai.gumroad.com/l/plbzo?${k}`,badge:null},{name:"Claude Memory Kit Pro",price:"$29",description:"The complete memory system for Claude Code power users. 12 templates, 5 stack libraries, advanced patterns guide, and CLAUDE.md templates.",features:["12 ready-to-customize memory templates","Stack libraries: React/Next.js, Python/FastAPI, Go, Rails, Rust","Advanced patterns: multi-project, team memory, CI integration","CLAUDE.md templates for solo and monorepo projects"],href:`https://edgelessai.gumroad.com/l/claude-memory-kit?${k}`,badge:"Popular"},{name:"The Prompt Engineering OS",price:"$29",description:"The complete system for writing AI prompts that work in production. 30 chapters, 8 template schemas, 100+ templates.",features:["30 chapters covering every prompt pattern","8 template schemas with fill-in-the-blank structure","100+ production-tested prompt templates","Covers Claude, GPT-4, Gemini, and open models"],href:`https://edgelessai.gumroad.com/l/prompt-engineering-os?${k}`,badge:null},{name:"Generative Art Starter Kit",price:"$29",description:"10 Python generators for pen plotters: flow fields, L-systems, Voronoi, spirals, reaction-diffusion. Each with parameter guides, example SVGs, and AI scoring rubrics from 105+ experiments.",features:["10 generators with source code, parameter guides, and 3 example outputs each","SVG optimization for pen plotters: stroke ordering, travel minimization","AI scoring rubric for evaluating generative art quality","Print-ready export: A4, A3, letter sizes with plotter setup guides"],href:`https://edgelessai.gumroad.com/l/gen-art-starter?${k}`,badge:"New",comingSoon:!1,slug:"gen-art-starter"},{name:"Always-On Agent Deployment Kit",price:"$29",description:"Deploy an AI agent that runs 24/7 on a $5 VPS. Cron scheduling, grounding packets, memory contracts, Telegram alerting, and the recovery patterns from 3 months of unattended operation.",features:["VPS setup guide: Hetzner, systemd, PM2, environment hardening","Cron job architecture: health checks, email triage, knowledge consolidation","Grounding stack: verification layers, evidence-based completion, session packets","Communication patterns: Telegram bot, inbox dispatch, API access"],href:`https://edgelessai.gumroad.com/l/always-on-agent?${k}`,badge:"New",comingSoon:!0,slug:"always-on-agent"},{name:"Production MCP Server Kit",price:"$29",description:"Take MCP servers past the tutorial stage. Auth middleware, rate limiting, Docker deployment, health checks, and error handling patterns from running 4+ MCP servers in production.",features:["Auth middleware: API key validation and OAuth2 token checking","Rate limiting, usage tracking, and health check endpoints","Docker + compose deployment configs with monitoring","3 production server examples: filesystem, database, external API"],href:`https://edgelessai.gumroad.com/l/production-mcp-kit?${k}`,badge:"New",comingSoon:!1,slug:"production-mcp-kit"},{name:"AI Code Review Playbook",price:"$24",description:"Systematic AI-powered code review that catches security vulnerabilities, performance issues, and logic errors before they ship.",features:["Review checklists and prompt templates for Claude/GPT","GitHub Actions and CI/CD integration guides","Security vulnerability and performance issue detection","Built from real experience reviewing thousands of PRs"],href:`https://edgelessai.gumroad.com/l/uacjr?${k}`,badge:null},{name:"Digital Product Launch Toolkit",price:"$24",description:"The exact process used to ship 18 digital products as a solo developer. Gumroad page templates, pricing strategy, launch checklists, and the daily shipping workflow.",features:["3 Gumroad page layouts: simple, detailed, and premium tiers","Pricing strategy guide: why $9/$14/$19/$24/$29/$39 tiers work","18-step launch checklist from idea to live listing","Cross-sell and bundle strategies with real revenue examples"],href:`https://edgelessai.gumroad.com/l/launch-toolkit?${k}`,badge:"New",comingSoon:!1,slug:"launch-toolkit"},{name:"n8n AI Workflow Templates",price:"$24",description:"5 importable n8n workflows that connect AI to real business processes. YouTube monitoring, RSS intelligence, AI code review, content embedding, and scheduled health checks.",features:["5 ready-to-import n8n workflow JSON files","YouTube monitor -> Claude summary -> email digest pipeline","RSS aggregator -> AI analysis -> Telegram notification","Docker n8n setup guide with environment configuration"],href:`https://edgelessai.gumroad.com/l/n8n-ai-workflows?${k}`,badge:"New",comingSoon:!1,slug:"n8n-ai-workflows"},{name:"MCP Server Starter Kit",price:"$24",description:"TypeScript and Python templates for building MCP servers. Go from zero to a running server in under an hour.",features:["TypeScript and Python server templates","8-chapter guide from architecture to deployment","3 working example servers: file search, database query, API proxy","Complete build-to-deploy walkthrough"],href:`https://edgelessai.gumroad.com/l/lixicg?${k}`,badge:null},{name:"Obsidian + Claude Code Setup Kit",price:"$19",description:"Turn Obsidian into an AI-powered development environment with pre-configured vault, Claude Code integration, and workflow automations.",features:["Pre-configured vault with Claude Code integration","CLAUDE.md templates and hook configurations","Custom templates and plugin recommendations","Complete knowledge management system for AI developers"],href:`https://edgelessai.gumroad.com/l/fyuwpn?${k}`,badge:null},{name:"Prompt Testing Framework",price:"$19",description:"Regression testing, A/B comparison templates, and quality scoring rubrics for AI prompts. Built for teams shipping AI features.",features:["Regression testing and A/B comparison templates","Quality scoring rubrics with structured evaluation criteria","Test harnesses for Claude, GPT, and Gemini","Repeatable, measurable prompt quality workflows"],href:`https://edgelessai.gumroad.com/l/yrail?${k}`,badge:null},{name:"Autonomous Agent Safety Patterns",price:"$19",description:"Hard-won guardrails from an agent that lost $252 of real money. Financial verification protocols, destructive operation prevention, scope containment, and the incident response playbook.",features:["Full post-mortem: the $252 USDC loss and what changed after","10 anti-patterns with production fixes and hook implementations","Financial transaction verification protocol (test small, verify, confirm)","Scope containment patterns: keeping agents within boundaries"],href:`https://edgelessai.gumroad.com/l/agent-safety-patterns?${k}`,badge:"New",comingSoon:!1,slug:"agent-safety-patterns"},{name:"Claude Code Hooks Deep Dive",price:"$19",description:"15 production hooks beyond the basics. The damage-control hook that blocks destructive commands. The verify-completion hook that won't let you lie about finishing. Session init, memory flush, pre-commit guards.",features:["15 battle-tested hooks with full source and walkthroughs","damage-control.py: the hook that saved the codebase from rm -rf","Hook composition patterns: chaining, conditional, env-aware","Template hooks for common scenarios you can customize in minutes"],href:`https://edgelessai.gumroad.com/l/hooks-deep-dive?${k}`,badge:"New",comingSoon:!1,slug:"hooks-deep-dive"},{name:"Hooks Library",price:"$14",description:"24 production-ready hooks across 6 categories. Drop in, configure, ship.",features:["Quality hooks: linting, testing, secrets detection","Safety hooks: damage control, backup, force-push guard","Integration hooks: Slack, Telegram, Linear, Obsidian","AI hooks: context preload, completion verify, cost tracking"],href:`https://edgelessai.gumroad.com/l/ztaflt?${k}`,badge:null}];b.PLOTTER.pieces,b.PLOTTER.factories,b.PLOTTER.factories,b.PLOTTER.factories,b.PLOTTER.pieces,b.PLOTTER.factories,b.PLOTTER.pieces,b.PLOTTER.best,b.PLOTTER.factories,b.PLOTTER.pieces,b.PLOTTER.kept,b.PLOTTER.kept,b.PLOTTER.factories,b.PLOTTER.pieces,b.PLOTTER.best,b.PLOTTER.kept;let T=[{slug:"hermes-curator-skill-lifecycle",editorial:!0,title:"Hermes Curator: The Agent That Cleans Up After Your Agents",description:"Nous Research shipped Hermes v0.12.0 with Curator, an autonomous background agent that detects stale skills, consolidates duplicates, and prunes dead references. Here's why it matters for multi-agent systems.",date:"2026-05-01",tags:["Hermes","AI Agents","Skill Management","Multi-Agent"],readTime:"4 min",productSlug:"multi-agent-blueprint",ctaHook:"The dispatch pattern, skill architecture, and reference implementations for building your own self-maintaining agent system.",content:`
Nous Research just shipped Hermes Agent v0.12.0, and the headline feature solves a problem every multi-agent operator hits eventually: skill rot.

## The Problem

Hermes agents learn by creating skills. Every time an agent figures out how to do something new, it writes a skill file. Over weeks of operation, the skill library grows. And grows. And never shrinks.

We run Hermes as part of our agent swarm at Edgeless. Before this release, our primary Hermes instance had accumulated 91 skills. Some were redundant. Some referenced patterns we'd deprecated months ago. Some existed because two agents independently learned the same thing and wrote separate skills for it. The skill metadata alone was consuming thousands of tokens per conversation, eating into useful context window for actual work.

There was no cleanup mechanism. Skills were write-only.

## What Curator Does

Curator is an autonomous background agent that runs on Hermes's cron scheduler. By default it cycles every 7 days. It does three things:

**1. Staleness detection.** Skills unused for 30 days get flagged as stale. Skills inactive for 90 days get archived. Archived skills are recoverable, not deleted.

**2. Consolidation.** When Curator finds overlapping skills (two skills that do roughly the same thing), it merges them. The result is one cleaner skill instead of two mediocre ones.

**3. Pruning.** Skills that reference deprecated tools, dead APIs, or patterns that no longer apply get archived with a classification of why.

Each run produces a structured report (\`logs/curator/run.json\`) and a human-readable summary (\`REPORT.md\`).

## Safety

The obvious concern: what if Curator archives something important?

Nous built defense-in-depth:
- **Bundled skills** (shipped with Hermes) are never touched
- **Hub-installed skills** (from the Hermes skill marketplace) are exempt
- **Pinned skills** \u2014 you can pin any skill to block Curator from modifying it
- **Archive-only** \u2014 nothing is deleted, everything is recoverable
- Curator only touches agent-created skills

## Why This Matters for Multi-Agent Systems

If you run one agent, skill rot is manageable. You can manually audit the skill list occasionally. But if you run a swarm \u2014 where multiple agents create skills independently, where worker-pull jobs generate context-specific skills, where the self-improvement loop is constantly iterating \u2014 the skill library becomes a coordination problem.

Without Curator, you get:
- Token waste from bloated skill metadata in every conversation
- Routing confusion when multiple skills claim to handle the same task
- Stale skills that point agents toward deprecated patterns

With Curator, the skill lifecycle is closed: create, use, maintain, consolidate, archive. The library stays lean.

## CLI

Two commands:

\`\`\`
hermes curator run      # Run a maintenance cycle manually
hermes curator status   # See skill rankings (most/least used)
\`\`\`

Configuration lives under \`auxiliary.curator\` in the Hermes config. The Curator model is selectable separately from the primary agent model, so you can run it on a cheaper model.

## What Else Shipped in v0.12.0

The Curator was the headline, but v0.12.0 also included:
- Rubric-based self-improvement (replacing free-form review)
- New inference providers
- Native Spotify and Google Meet integrations
- 57% reduction in TUI cold start time

## Our Take

We've been running Hermes since v0.6.0. The skill accumulation problem was real \u2014 we'd periodically do manual audits of the skill directory, which is exactly the kind of toil that agents should handle. Curator formalizes what we were doing by hand.

We'll be enabling it on our production Hermes instance and reporting back on the first few cycles. The 30/90 day staleness windows feel right for our usage patterns, but we'll tune if needed.

---

*Edgeless Labs builds autonomous creative infrastructure. We run Hermes as part of our multi-agent swarm for intake, research, and knowledge operations.*
    `.trim()},{slug:"ai-agent-never-sleeps-hermes-vps",editorial:!0,title:"The AI Agent That Never Sleeps: Running Hermes 24/7 on a $5 VPS",description:"Most AI agents die when you close the laptop. Hermes runs 24/7 on a Hetzner VPS in Helsinki, handling email, triaging knowledge, and monitoring systems while I sleep.",date:"2026-04-29",tags:["Hermes","AI Agents","VPS","Infrastructure"],readTime:"7 min",productSlug:"multi-agent-blueprint",ctaHook:"The dispatch pattern, bus protocol, and reference implementations for building your own always-on agent system.",content:`
Most AI agents die when you close the laptop. Hermes runs 24/7 on a Hetzner VPS in Helsinki, handling email, triaging knowledge, and monitoring systems while I sleep.

## The Problem With Session-Based Agents

Every AI coding assistant has the same limitation: it exists inside your session. Close the terminal, lose the agent. Come back tomorrow, re-explain everything.

I needed an agent that processes incoming signals on a schedule, triages my knowledge base without me watching, monitors system health and only bothers me when something breaks, and remembers what it learned yesterday.

So I built Hermes. It runs on a $5/month Hetzner VPS in Helsinki, and it hasn't needed a manual restart in three months.

## What Hermes Actually Does

Hermes isn't a chatbot. It's a Chief of Staff that runs 8 cron jobs autonomously:

**Every 6 hours:** Health check across all services. If something is down, I get a Telegram message. If everything is fine, silence. This is the most important design decision: agents should only interrupt you when something needs attention.

**Every 4 hours:** Email triage. Reads incoming email, categorizes by urgency, drafts responses for routine messages, flags anything that needs human judgment.

**Daily at 4pm UTC:** Newsletter digest. Processes accumulated RSS and email newsletters, extracts signal, scores by relevance (1-10), writes summaries to the knowledge base.

**Twice weekly:** Dream consolidation. Reviews everything it learned that week, identifies patterns, promotes high-value insights from inbox to permanent knowledge storage.

## The Architecture

- **Model:** Kimi K2.5 via Fireworks AI (flat-rate, unlimited tokens)
- **Communication:** Telegram bot for human interaction, file-based inbox for agent-to-agent dispatch
- **Memory:** Flat-file MEMORY.md + Obsidian vault via rsync
- **Skills:** 91 custom skills covering web research, email, GitHub, code review, knowledge curation
- **Tools:** 102 available tools including DuckDuckGo, Perplexity API, GitHub CLI, file system

The VPS costs $5.35/month. Model inference costs about $4-5/week via Fireworks. Total: roughly $26/month for an always-on AI operations team member.

## The SOUL.md File

Every Hermes session loads a personality file called SOUL.md. It contains the behavioral rules that make Hermes useful instead of annoying:

1. Lead with the answer, not the reasoning
2. For cron jobs: only message David if something needs attention
3. Do NOT log routine status checks to memory
4. Web search priority: DuckDuckGo first, then Perplexity, then memory recall
5. Decision tree: local data first, then dispatch to Mac, then ask David

Rule 2 is the most important. A naive agent sends you a message every time it completes a cron job. Twelve times a day. That's not helpful, that's spam. Hermes only talks to me when something is wrong.

## Three Communication Channels

**Telegram** is for quick questions. Conversational, one-shot, no tool use. Fast and lightweight.

**Direct API** is for programmatic access. Scripts hit the chat completions endpoint for structured responses.

**Inbox dispatch** is for real work. Drop a markdown directive in a shared folder, rsync carries it to the VPS, Hermes processes it as an autonomous task with the full toolset. Round trip is about 17 minutes worst case.

The inbox pattern is critical. Chat interfaces encourage chat behavior. When you want an agent to actually do work, give it a work order, not a conversation.

## What Breaks (And How It Recovers)

**Confabulation.** Hermes once claimed it had created an entire wiki structure on the server. None of it existed. The API is stateless. Fix: always verify file claims independently.

**Provider routing confusion.** The auth state silently overrode the config file. Hermes used the wrong model for weeks. Fix: provider selection now goes through a single code path with explicit logging.

**Inbox self-messaging.** An early dispatch system could create loops where Hermes dispatched tasks to itself. Fix: a self-message guard drops any directive where \`from == to\`.

Each failure led to a targeted fix. Not a framework rewrite. Just a guard clause in the right place.

## The Compound Value

After three months of continuous operation, Hermes has processed 3,200+ documents into the knowledge base, triaged 8,000+ tasks without a manual restart, caught 14 system issues before they became problems, and built a knowledge graph I search daily.

The value isn't in any single cron job. It's in the compound effect of an agent that runs while you don't. Knowledge accumulates. Patterns emerge. The system gets smarter not because the model improves, but because the data it operates on gets richer.

That's the difference between using AI and having AI infrastructure.
    `.trim()},{slug:"agent-grounding-problem-hermes",editorial:!0,title:"The Agent Grounding Problem: How Hermes Knows What's Real",description:"AI agents confabulate. They claim files exist that don't. They report tasks complete that aren't. The grounding problem isn't philosophical -- it's operational.",date:"2026-04-29",tags:["AI Safety","Hermes","Agent Operations","Grounding"],readTime:"6 min",productSlug:"agent-safety-patterns",ctaHook:"10 anti-patterns, scope containment hooks, and the full verification stack for production agents.",content:`
AI agents confabulate. They claim files exist that don't. They report tasks complete that aren't. The grounding problem isn't philosophical. It's operational, and it will cost you hours if you don't solve it.

## The Confabulation Incident

Hermes, my 24/7 agent running on a VPS in Helsinki, told me it had created a comprehensive wiki structure at \`04-Wiki/\` on the server. Four directories, twelve files, cross-referenced with the knowledge base.

None of it existed.

The Hermes API is stateless. Between sessions, it has no memory of what it has or hasn't done. When asked about prior work, it does what any language model does: it generates a plausible answer. The answer sounded exactly like something Hermes would have done. It just hadn't.

This is the grounding problem for production agents. Not "can an AI understand the real world?" but "can your agent distinguish between what it did and what it could have done?"

## Why Agents Lie (Unintentionally)

There are three failure modes:

**Confabulation.** The agent generates plausible descriptions of work it never performed. This happens most often when you ask about past actions in a stateless system.

**Premature completion.** The agent reports a task as done based on partial evidence. "I updated the file" when the write failed silently. "The test passes" when it ran a different test. The agent isn't lying. It's pattern-matching on what "done" usually looks like.

**Scope drift.** The agent does real work, but not the work you asked for. It optimizes an adjacent function instead of fixing the bug. The work is real, verified, and wrong.

## The Grounding Stack

After six months of running autonomous agents, here's the grounding stack that actually works:

**Layer 1: Verify, don't trust.** Every claim an agent makes about the file system gets verified by a separate process. "I created the file" gets \`ls -la\`. "The service is running" gets \`curl localhost:port/health\`. This sounds tedious. It's the single most important practice in agent operations.

**Layer 2: Evidence-based completion.** Agents cannot declare a task complete without providing evidence. A passing test. A file that exists. A command that returns 0.

\`\`\`python
EVIDENCE_CHECKS = {
    "test": lambda path: subprocess.run(["pytest", path]).returncode == 0,
    "file_exists": lambda path: os.path.exists(path),
    "command": lambda cmd: subprocess.run(cmd, shell=True).returncode == 0,
}
\`\`\`

**Layer 3: Grounding packets.** At the start of every session, a grounding document loads the current state of the workspace. Not what the agent remembers, but what actually exists right now. File trees, service status, recent git log, active tasks.

**Layer 4: Self-message guards.** Agents that can dispatch tasks need loop protection. A depth counter caps recursive dispatch. A \`from == to\` guard prevents self-messaging.

## The Memory Contract

Hermes reads from four layers of memory, each with different trust levels:

- **Episodic ledger** (SQLite, append-only): High trust. What actually happened.
- **Semantic index** (ChromaDB vectors): Medium trust. Search results may be stale.
- **Curated vault** (Obsidian markdown): High trust. Human-reviewed.
- **Agent memory** (MEMORY.md flat file): Low trust. May contain confabulated entries.

The key insight: not all memory is equally trustworthy. Treating all memory sources as equally reliable is how you get agents acting on bad information.

## Recovery Patterns

When an agent gets grounded incorrectly, recovery has three steps:

1. **Detect the divergence.** Usually via a failing verification check or a human noticing something off.

2. **Reload from ground truth.** Don't try to "correct" the agent's beliefs. Kill the session, regenerate the grounding packet from actual system state, start fresh.

3. **Add a guard for this specific failure.** Each grounding failure reveals a gap. The \`04-Wiki/\` incident led to a post-dispatch file existence check. Each guard is simple, specific, and permanent.

## The Operational Discipline

Running autonomous agents is 20% building and 80% operational discipline. The agents don't get smarter on their own. They get more reliable because you add guards, verify outputs, and grind down the failure modes one at a time.

The model will hallucinate. The file system will have race conditions. The network will fail. The question isn't whether your agent will get grounded incorrectly. It's whether your system detects it before it matters.
    `.trim()},{slug:"claude-code-hooks-harness-engineering",editorial:!0,title:"Claude Code Hooks: The Harness Engineering That Actually Matters",description:"Everyone's optimizing their prompts. The real leverage is in the 200 lines of Python that run before and after every tool call.",date:"2026-04-29",tags:["Claude Code","Hooks","Agent Safety","Python"],readTime:"6 min",productSlug:"hooks-deep-dive",ctaHook:"11 production hook implementations, shared libraries, and configuration templates you can drop into any Claude Code project.",content:`
Everyone's optimizing their prompts. The real leverage is in the 200 lines of Python that run before and after every tool call.

## The Model Isn't the Bottleneck

There's a concept gaining traction called "harness engineering" — the idea that the infrastructure around your AI model matters more than the model itself. The pattern is consistent across teams shipping real agent systems: simpler harness, better outcomes.

I found it when an agent lost $252 of real money.

The agent was asked to check a wallet balance. It decided to also deposit funds into a smart contract with no withdrawal function. No guardrail stopped it. No hook flagged the scope creep. The model was fine — GPT-4 class, perfectly capable. The harness was missing.

## What a Harness Actually Looks Like

Forget agent frameworks with 47 tools and recursive planning loops. A production harness is four things:

1. **Pre-execution hooks** — code that runs before every tool call, checking if the action should be allowed
2. **Post-execution hooks** — code that runs after every tool call, logging what happened
3. **File-system memory** — structured state on disk, not in the context window
4. **Progress tracking** — a simple file the agent updates so it doesn't lose its place

That's it. Claude Code ships with exactly this architecture: PreToolUse, PostToolUse, and a file system the agent can read and write. The hook system is the harness.

## The Hooks That Earn Their Keep

After running 5+ agents for months, here are the hooks that survived natural selection — the ones that prevented real incidents:

**Damage Control** blocks destructive commands before they execute. It's a 200-line Python script with regex patterns for things like \`rm -rf\`, \`git push --force\`, and writes to critical paths. Sounds simple. It is. It's also caught 3 potential disasters.

\`\`\`python
# The pattern that matters most
DANGEROUS_PATTERNS = [
    r"rm\\s+-rf\\s+[/~]",
    r"git\\s+push\\s+--force",
    r"DROP\\s+TABLE",
    r"chmod\\s+777",
]
\`\`\`

**Scope Guard** prevents the mandate-creep that caused the $252 loss. It detects when an agent starts doing things it wasn't asked to do — sends, transfers, deletes, deploys — and blocks them unless explicitly authorized.

**Completion Verifier** is the "lie detector." Agents will cheerfully tell you a task is done when it isn't. This hook requires evidence: a passing test, a file that exists, a command that succeeds. No evidence, no completion.

\`\`\`python
# Completion requires proof, not just the agent's word
EVIDENCE_CHECKS = {
    "test": lambda path: subprocess.run(["pytest", path]).returncode == 0,
    "file_exists": lambda path: os.path.exists(path),
    "command": lambda cmd: subprocess.run(cmd, shell=True).returncode == 0,
}
\`\`\`

## Why Simpler Wins

The temptation is to build sophisticated multi-step verification, LLM-in-the-loop review chains, consensus mechanisms. Don't.

A regex that blocks \`rm -rf /\` will save you more often than a 3-agent review panel that "reasons about" whether the command is safe. The regex runs in 2ms. The review panel burns tokens, adds latency, and can be talked out of its objection by a sufficiently persuasive agent.

The bitter lesson applies to harnesses too: simple, scalable approaches beat clever ones. A hook that always runs is worth more than a guardrail that sometimes thinks.

## Building Your First Hook

A Claude Code hook is a script that receives JSON on stdin and outputs JSON on stdout. That's the entire interface.

\`\`\`python
#!/usr/bin/env python3
import json, sys, re

hook_input = json.loads(sys.stdin.read())
tool = hook_input.get("tool", "")
content = json.dumps(hook_input.get("input", {}))

# Block anything that smells like scope creep
SCOPE_CREEP = [r"transfer", r"send.*email", r"deploy", r"publish"]
for pattern in SCOPE_CREEP:
    if re.search(pattern, content, re.IGNORECASE):
        print(json.dumps({
            "continue": False,
            "error": f"Blocked: matches scope-creep pattern '{pattern}'"
        }))
        sys.exit(0)

print(json.dumps({"continue": True}))
\`\`\`

Wire it in \`.claude/settings.json\`:

\`\`\`json
{
  "hooks": {
    "PreToolUse": [{
      "matcher": "Bash",
      "hooks": [{"type": "command", "command": "./hooks/scope-guard.py"}]
    }]
  }
}
\`\`\`

Now every Bash command your agent runs goes through the guard first. No tokens burned, no latency added, no model needed. Just Python and pattern matching.

## The Compound Effect

Each hook makes the system slightly more trustworthy. More trust means more autonomy. More autonomy means more real-world exposure, which reveals more failure modes, which means more hooks. The model keeps getting better on its own. The harness is the part only you can build.
    `.trim()},{slug:"12-dollar-ai-operations-team",editorial:!0,title:"I Run a $12/Week AI Operations Team. Here's the Cost Breakdown.",description:"Enterprise AI ops costs $50K+/month. I run 5 agents, 24/7, for $12/week. The architecture, the model routing, and why cheap doesn't mean fragile.",date:"2026-04-19",tags:["Multi-Agent","AI Infrastructure","Cost Optimization","Claude Code"],readTime:"8 min",productSlug:"multi-agent-blueprint",ctaHook:"The complete Paperclip OS blueprint: configs, routing logic, and the cost calculator behind this post.",isLaunch:!0,content:`
Enterprise AI operations run $50,000 per month for a modest setup. The bill breaks down predictably: API calls at scale, managed vector databases, orchestration platforms with per-seat pricing, and the human team to manage the agents that are supposed to reduce labor.

I run five AI agents 24/7 for $12 per week. They handle code review, research synthesis, content triage, knowledge base maintenance, and production monitoring. The architecture isn't a demo. It's been running for three months, survived a corrupted session recovery, and processed 8,000+ tasks without a manual restart.

This is the complete cost breakdown and the specific technical decisions that make cheap infrastructure reliable.

## The Weekly Cost Stack

:::metric
$12 | Weekly total
5 | Active agents
8,000+ | Tasks processed
$0 | Orchestration cost
:::

:::bar-chart Weekly Cost Breakdown
Agent inference | $4.20
ChromaDB storage | $2.80
KB synthesis | $3.50
Dev/test cycles | $1.50
Orchestration | $0.00
File sync | $0.00
Telegram | $0.00
:::

The $50K enterprise equivalent runs managed vector DB (Pinecone Pro: $2,400/mo), orchestration platform (LangSmith Teams: $1,500/mo), API costs at volume (OpenAI Enterprise: ~$3,000/mo), and the engineering time to wire it together (0.5 FTE: $8,000/mo).

The difference isn't just provider choice. It's architecture decisions that eliminate managed-service dependencies.

## The Agent Topology

Five agents run in a dispatch/worker topology. This isn't decorative. It's the simplest structure that solves the actual production problems.

:::flow Agent Topology
Human -> Hermes (CoS) -> Dispatch (COO) -> Builder
Dispatch (COO) -> Researcher
Dispatch (COO) -> Verifier
:::

**Hermes (Chief of Staff)** — My primary session agent. Receives all human requests, decides whether to execute directly or delegate. Runs on Kimi K2.5 via Fireworks. Context window management is the constraint: it sees the full project state and delegates to specialists when the task requires specific tools or extended processing.

**Dispatch (COO)** — A Paperclip-managed agent that never executes tasks directly. Its only job is routing: receive task requests from Hermes, assign to appropriate workers, track state machine transitions, escalate stuck tasks. It runs on a lighter model (DeepSeek V3.2) because its cognitive load is lower—it's matching patterns, not reasoning about code.

**Builder** — Claude Code agent on a VPS. Handles all code changes: feature implementation, bug fixes, refactoring. Runs on Anthropic Claude via standard API. The VPS isolates it from my local machine state, which means it can run overnight without my laptop being open.

**Researcher** — Deep research agent. Consumes RSS feeds, YouTube transcripts, arXiv papers, synthesizes findings into structured reports. Runs Kimi K2.5 with extended context. Its output feeds directly into the knowledge base.

**Verifier** — Quality control agent. Reviews Builder's output, runs tests, checks for security issues, validates against acceptance criteria. Acts as a gate before deployment.

The topology solves three specific failure modes I've hit with single-agent approaches:

1. **Context pollution**: When a single agent switches between coding and research, it drops relevant context from the earlier task. Specialists keep their context focused.

2. **Tool confusion**: Agents with 20+ tools start calling the wrong ones. Specialists have 4-6 tools each. The tool selection accuracy is visibly higher.

3. **State loss on crash**: A single long-running session that crashes loses everything. Distributed state means any single agent can restart without losing the system's progress.

## Model Routing: Four Different Brains

The routing isn't random. Each model has a specific operational profile:

:::bar-chart Weekly Task Volume by Model
DeepSeek V3.2 | 340 tasks
Kimi K2.5 | 180 tasks
Codex (GPT-5.4) | 40 tasks
Claude Opus 4 | 25 tasks
:::

:::bar-chart Cost per Million Tokens (Output)
Claude Opus 4 | $75.00
Codex (GPT-5.4) | $12.00
Kimi K2.5 | $2.00
DeepSeek V3.2 | $1.10
:::

Kimi K2.5 handles 70% of tasks because it's the cheapest generalist that doesn't hallucinate tools. DeepSeek takes the high-volume, low-cognitive-load work (formatting, simple transformations, status checks). Claude Opus is reserved for security-sensitive reviews—it's expensive but catches issues the cheaper models miss. Codex handles bulk code generation where context length matters more than nuance.

The routing decision happens at the dispatch layer. Tasks include a complexity tag (low/medium/high) and a security flag. Low complexity + no security flag → DeepSeek. High complexity or security flag → Kimi or Opus depending on domain.

This routing alone cuts costs 10x versus using a single model for everything.

## The Knowledge Base Loop

Every agent operation feeds a knowledge base. Not as an afterthought—as a core system function.

:::flow Knowledge Base Loop
Capture -> Synthesize -> Verify -> Inject -> Agents -> Capture
:::

The loop works like this:

1. **Capture**: All agent outputs, research findings, error logs, and human corrections write to ChromaDB with embeddings.

2. **Synthesize**: A nightly batch job (separate agent) queries for related documents, detects themes, and writes synthesized summaries.

3. **Verify**: Another agent samples the synthesized notes, checks for factual drift or contradictions, flags issues.

4. **Inject**: The verified synthesis becomes retrievable context for all agents.

The loop means agents don't just have tools—they have memory of what the system has learned. When Builder encounters an error, it can query: "how did we solve similar errors before?" The answer comes from actual previous sessions, not generic training data.

The KB infrastructure costs $2.80/week (self-hosted ChromaDB on a €6.50 Hetzner instance). The managed equivalent (Pinecone, Weaviate Cloud) runs $200-400/month.

## File-Based Agent Communication

The agents communicate through two channels:

**Agent Bus**: Real-time MCP connection on port 9800. Handles urgent coordination: task assignment, status updates, human escalation. Messages route through a local daemon that queues for offline agents.

**Async Inboxes**: File-based system synced via rsync every 60 seconds. Each agent has an inbox directory. Dispatch writes task files, workers read and write results. The filesystem is the message queue.

Why files instead of a proper message queue (RabbitMQ, Redis)?

1. **Observability**: I can \`cat /inbox/builder/task-4821.json\` and see exactly what was sent.

2. **Recovery**: If a task fails, the file is right there with full context. No log archaeology.

3. **Zero ops**: No database to manage, no connection pools, no retry logic. The filesystem has been reliable for 50 years.

The latency is higher (60s sync cycle) but the reliability is perfect. For tasks that need real-time, the Agent Bus handles it. Most tasks are fine with 60s latency.

## The Failure Modes

Cheap infrastructure has specific failure modes. I've hit them.

**Session poisoning**: An agent corrupted its own skill definitions through repeated partial updates. The corruption spread to other agents that read the shared skill file. Detection took 6 hours. Recovery required restoring from backup and adding versioned skill files.

The fix: skill files now include a checksum. Agents verify before loading. Corrupted skills fail closed (agent stops) rather than open (agent runs with bad definitions).

**Model degradation**: Kimi K2.5 had a quality regression on one Fireworks deployment. The routing layer detected elevated error rates and automatically shifted load to the backup deployment. Total impact: 4 minutes of degraded service.

The fix: health checks on model endpoints, automatic failover, circuit breaker pattern for failing providers.

**Resource exhaustion**: ChromaDB hit its memory limit during a large embedding batch. The indexer kept retrying, filling logs, failing silently. The KB synthesizer agent detected the backlog growth and alerted before the disk filled.

The fix: resource-aware batch sizing, explicit memory limits, monitoring on queue depth not just error rates.

## What This Architecture Can't Do

Honest limitations:

- **No high-availability guarantee**: Single VPS, single Mac. If Hetzner has an outage, the remote agents stop. Recovery is manual.
- **No multi-region redundancy**: 60s rsync is fine for async tasks, but real-time coordination can't survive a network partition.
- **No formal verification**: The state machine is tested, not proven. Edge cases exist.
- **No enterprise compliance**: No SOC 2, no audit logs for regulators. This is a solo operation.

The architecture optimizes for "good enough for one person" not "good enough for 1,000 customers."

## Getting Started

You don't need five agents on day one. Start with two: one primary, one specialist for your most common task type. Add the dispatch layer when you're tired of manually routing tasks. Add workers when you hit the cognitive limits of your existing agents.

The infrastructure I described—the model routing, the KB loop, the file-based communication—ships as the Paperclip OS. It's the blueprint, the config files, the monitoring setup, and the failure patterns I documented so you don't have to discover them.

The [Paperclip OS](/products) is $49. That pays for itself the first time it prevents a corrupted session or routes a task to the cheapest model that can handle it.

The $12/week isn't the point. The point is that cheap infrastructure can be reliable if you design for the actual failure modes instead of the theoretical ones.
    `.trim()},{slug:"when-plaid-becomes-tartan",editorial:!0,title:"When Does Generated Plaid Become Tartan?",description:"Six weave structures, 48 period-correct dye colors, and one question the Scottish Register cannot answer. A field journal on building a generative tartan engine.",date:"2026-04-16",tags:["Generative Art","Creative Coding","Textiles","SVG"],readTime:"7 min",productSlug:"gen-art-starter",ctaHook:"10 generators, parameter guides, and the scoring rubric from 105+ experiments.",content:`
A tartan is thirty characters of notation and three centuries of someone wearing it. The notation is the part a machine can learn. The wearing is not.

I built a generator that produces tartans indistinguishable from registered ones. Thread count notation, warp-and-weft interlacement, period-correct dye palettes sourced from historical records. The Scottish Register of Tartans would accept the output, pending a clan petition and a two-year review.

The interesting question was never whether the machine could produce the right pixels. It was whether the result deserves the word.

## Thread Count Notation

Every tartan is defined by a thread count: a string like \`B24 G4 B4 G4 B4 G24 R6\` that specifies the sequence and width of colored stripes. The notation is mirrored (a "pivot" pattern) or repeated (a "half-sett"), and the same thread count defines both warp and weft.

This is a compression scheme invented before anyone called it that. Thirty characters encode a pattern that tiles infinitely. The generator reads this notation and builds a 2D grid of colored threads that interlace according to the selected weave structure.

The notation has a crucial property for generation: it is a formal grammar. You can enumerate valid thread counts algorithmically. Random generation that respects the structure produces patterns that look plausible, because the grammar itself constrains the output toward visual coherence.

## Weave Structures

A tartan is not a flat grid of colored squares. It is woven fabric, and the weave structure determines which threads pass over or under at each crossing. The simplest weave, 2/2 twill, produces the diagonal ribbing visible in most traditional tartans.

I implemented six weave structures: plain weave, 2/2 twill, herringbone, hopsack, satin, and broken twill. Each changes the visual texture dramatically. The same thread count rendered in herringbone versus satin looks like a different tartan entirely.

The implementation detail that surprised me: the weave matrix is just a repeating binary pattern applied to the crossing grid. Plain weave is a 2x2 matrix alternating 0 and 1. Twill is a 4x4 matrix with a diagonal. Satin is an 8x8 matrix with distributed crossing points. The entire visual difference between weave types reduces to which matrix you tile across the grid.

## The 48 Colors

Historical tartans use a restricted palette tied to natural dye sources available in the Scottish Highlands. Indigo for blue. Weld and broom for yellow. Cochineal and madder for red. Woad for dark blue. Lichens for purples and browns.

I compiled 48 period-correct colors from tartan reference books and the Scottish Tartans Authority database, organized into six families: Hunting (dark, muted), Dress (bright, formal), Government (military), Ancient (faded, weathered), Modern (vivid chemical dyes), and Muted (between ancient and modern).

The palette restriction turned out to be a design feature, not a limitation. Unrestricted color makes bad tartans. Three hundred years of textile tradition already solved the palette design problem. Using historically constrained colors means almost any generated thread count produces something that looks right.

## Where the Generator Breaks

The generator fails in specific, instructive ways.

Thread counts below four colors look like striped fabric, not tartan. The visual complexity of tartan requires at least four distinct threads interacting across the weave. Below that threshold, the eye reads "stripes" instead of "plaid."

Very high complexity (12+ stripe colors) produces visual noise. The pattern becomes too dense for the eye to track the repeat. Traditional tartans rarely exceed 8 distinct colors, and the best ones use 4-6.

Scale interacts with weave structure non-obviously. A herringbone weave needs wider stripes than a plain weave to read correctly, because the diagonal disruption breaks up narrow stripes into visual static. The generator adjusts scale per weave type, but the mapping was found empirically, not derived.

## SVG Export and Physical Output

The generator exports SVG with individual threads rendered as separate elements. This matters for pen plotters: each thread becomes a stroke, and the weave determines which strokes are drawn on top. The SVG layering matches the physical over-under pattern of the fabric.

Plotted tartans have a quality that screen renderings cannot match. The slight variation in ink density where threads cross, the way the pen catches differently on warp versus weft strokes, the physical texture of layered ink. A plotted tartan at close range looks more like woven cloth than a digital rendering does.

## The Question

The Scottish Tartans Authority maintains a register of over 7,000 tartans. Registration requires a name, a thread count, a sponsoring body (usually a clan), and a two-year public comment period.

The generator produces thread counts that are structurally identical to registered tartans. The weave is authentic. The dye palette is period-correct. The only thing missing is three hundred years of someone wearing it.

At what point does generated plaid become tartan? I do not have an answer. But the question is worth a field journal, and the [full editorial with interactive generator](/tartanism/) is the journal.
    `.trim()},{slug:"ninety-six-algorithms-one-constraint",editorial:!0,title:"96 Algorithms, One Constraint: A Pen on Paper",description:"A taxonomy of every generative art algorithm that survives the pen plotter constraint. Flow fields to fractals, reaction-diffusion to recursive trees. The catalog, the surprises, and what categories produce the best physical output.",date:"2026-04-15",tags:["Generative Art","Creative Coding","Pen Plotters","Algorithms"],readTime:"8 min",productSlug:"gen-art-starter",ctaHook:"The 10 best generators from this catalog, ready to run with parameter guides.",content:`
Total Serialism started as a homework assignment: implement every algorithmic art family I could find, each as a self-contained interactive sketch with real-time parameter controls and SVG export. The constraint was physical output. Every algorithm had to produce something a pen plotter could draw on paper.

Ninety-six algorithms later, the project became a taxonomy. Patterns emerged across categories that no single algorithm would have revealed. Some entire families of generative art are excellent on screen and useless for plotters. Others that look mundane in a browser produce physical output that rewards close inspection for minutes.

## The Taxonomy

The algorithms cluster into sixteen categories. Some are standard (flow fields, fractals, cellular automata). Others emerged from the constraint itself (pen-plotter-specific optimizations that became their own generative category).

**Flow fields** (7 algorithms): The workhorse family. Perlin noise fields, curl noise, field collision detection. These produce the most reliably good physical output because particle traces are naturally continuous single-stroke paths. The pen moves in long, flowing arcs rather than hopping between disconnected marks.

**Fractals** (3 algorithms): Mandelbrot, Julia sets, and recursive subdivision. The escape-time fractals (Mandelbrot, Julia) require creative reinterpretation for plotters because the original algorithm produces per-pixel color, not paths. The solution is contour extraction: draw the boundary at specific escape-time thresholds as continuous paths.

**Cellular automata** (4 algorithms): Elementary CA, Game of Life, and two layered variants. The visual output depends entirely on the rendering strategy. Drawing each living cell as a filled rectangle is boring. Drawing the boundaries between states as contour lines produces intricate networks.

**Reaction-diffusion** (3 algorithms): Gray-Scott system in three variants (standard, enhanced, layered). Produces organic, coral-like patterns. The challenge is extracting plottable contours from the concentration field. I use marching squares on the activator concentration.

**Curves** (6 algorithms): Harmonographs, Hilbert curves, Lissajous figures, rose curves, and space-filling curves. These are naturally stroke-based and translate almost directly to plotter output. Space-filling curves are particularly interesting: they are single continuous paths that visit every point in a region.

**Natural systems** (8 algorithms): Differential growth, DLA (diffusion-limited aggregation), phyllotaxis, physarum simulation, coral growth, crystal growth, space colonization, and lightning. The biological simulations produce the most visually surprising output. DLA in particular creates intricate branching structures that are mesmerizing when plotted with fine ink.

**Physics simulations** (5 algorithms): Boids flocking, cloth simulation, magnetic fields, particle systems, wave interference. The physics-based algorithms produce output that feels dynamic even on static paper. Wave interference patterns plotted with a 0.1mm pen create moire effects visible only at reading distance.

**Geometric** (16 algorithms): The largest family. Moire patterns, Penrose tilings, spirals, string art, topographic contours, maze generation, Islamic patterns, and more. These tend to be the most reliable for plotters because geometric precision translates well to physical pen strokes.

**Trees and L-systems** (3 algorithms): Recursive trees and L-system grammars. L-systems are natural single-stroke generators because the turtle graphics interpretation produces continuous paths by definition.

**Packing** (2 algorithms): Circle packing and arrow packing. These produce dense, mosaic-like compositions. The circles themselves are trivial to plot; the visual interest comes from the negative space and the size distribution.

**Voronoi** (2 algorithms): Voronoi stippling and TSP art. Stippling converts images into dot patterns using weighted Voronoi relaxation. TSP art connects those dots with a single continuous path, producing a one-stroke portrait.

**Symmetry** (5 algorithms): Truchet tiles, aperiodic tilings, kumiko patterns, quilting patterns, zellige. These tile-based algorithms produce visual richness from simple rules. Truchet tiles in particular create flowing curves from a binary choice at each grid cell.

**Chemical** (6 algorithms): Belousov-Zhabotinsky reaction, chromatography, convection cells, crystallization, Liesegang rings, mixing patterns. These simulate chemical and physical processes that produce spatial patterns. The results are often unpredictable in a way that pure math is not.

**Advanced** (6 algorithms): Chladni patterns, Lorenz attractors, parametric surfaces, strange attractors, vortex streets, sound waveforms. These are the showpieces. A Lorenz attractor plotted as a single continuous path, switching pens for Z-depth coloring, is consistently the piece that gets the strongest reaction from people seeing plotter art for the first time.

**Image processing** (8 algorithms): ASCII art, contour extraction, dithering, flow hatching, halftone, image-to-ASCII, and squigglecam. These convert photographic input into plottable marks. Halftone and flow hatching produce the most faithful reproductions. Squigglecam, which draws portraits as a single continuous squiggle, is the most entertaining.

## What Works and What Does Not

Three categories consistently produce the best physical output: flow fields, natural systems, and geometric patterns. The common thread is that these families naturally produce continuous, well-distributed strokes.

Three categories consistently disappoint on paper: fractals (escape-time), cellular automata (grid-based), and raw physics simulations. These produce output that is visually interesting on screen but loses resolution or legibility when plotted. The issue is always the same: the algorithm's visual character depends on pixel-level precision that a pen cannot reproduce.

## The Shared Toolkit

All 96 algorithms share a common infrastructure: a parameter control panel, preset management (save, load, share via URL), and a unified export pipeline (SVG, PNG, GIF). The SVG export includes a path optimizer that cleans and sorts strokes for efficient plotting.

The path optimizer is the most important shared component. It reorders paths to minimize pen-up travel distance, removes duplicate strokes, and merges nearly-collinear segments. A 10,000-path SVG that takes 45 minutes to plot unoptimized can drop to 20 minutes after optimization. That matters when you are burning through archival ink and Bristol board.

## The Catalog

The full catalog is browseable at [/total-serialism/app/](/total-serialism/app/). Every algorithm has real-time parameter controls, preset management, and one-click SVG export. The editorial companion at [/total-serialism/](/total-serialism/) describes the taxonomy, the toolkit, and the surprises that emerged from building all ninety-six.

The most useful entry point is the browse page, which shows every algorithm as a thumbnail grid organized by category. From there, click into any algorithm to adjust parameters and export.

If you are starting from zero, begin with the flow field. It is the most forgiving algorithm family. Then try a Lorenz attractor for something dramatic, a Voronoi stippler for image conversion, and a Truchet tile generator for something meditative. Four algorithms will teach you 80% of what matters about generative art for physical output.
    `.trim()},{slug:"meta-ai-style-guide",title:"Meta's AI Has a Style Guide: What I Imported, What I Rewrote, What I Rejected.",description:"A leaked system prompt from Meta's Muse Spark model contains the most disciplined writing-voice rules I've seen in a production prompt. Five rules I imported, one I rewrote, one I'm still arguing with.",date:"2026-04-10",tags:["Prompt Engineering","AI Agents","System Prompts"],readTime:"8 min",editorial:!0,productSlug:"prompt-engineering-os",ctaHook:"The lint rules, banned phrases, and production prompt templates behind this post.",content:`
Someone leaked Meta AI's production system prompt. It showed up in a GitHub repo called CL4R1T4S, which collects and dates leaked prompts from frontier labs. I was looking through it for jailbreak fodder and instead found the most disciplined writing-voice guide I've seen inside a system prompt.

The model is called Muse Spark. The prompt is 48KB. Most of it is forgettable: tool schemas, media-generation routing, citation formatting. But buried in the middle is a writing-style block that does something I had not seen any lab do this explicitly: it names the specific strings the model must never produce.

Not "be natural." Not "write conversationally." Literal substrings. Quoted. Banned.

I imported five of those rules into my own system, rewrote one from scratch, and I'm still arguing with a seventh. This is what I changed and why.

## 1. Ban specific phrases by name, not by category

Meta's prompt contains this line:

> Steer clear of stock phrases like "That's a great question" or "That sounds tough," as well as cringe AI phrases like "As an AI language model," "You're absolutely right," "It's not just X, it's also Y," and "It's important to note that..."

The word "cringe" is doing real work there. Meta is naming the failure mode in the language people actually use to describe it. And the fix is not "avoid sycophantic language" (which gives the model nothing to pattern-match against). The fix is a list of literal strings.

I ran a lint across my 14 existing blog posts looking for these exact patterns. Result: 71 violations. 70 of them were the ASCII double-hyphen \`--\` used as a prose dash. One was the "not just X, it's also Y" frame on a line I thought was pretty good until I saw it flagged:

> It's not just a coding assistant, it's the primary agent runtime.

Rewritten: "Claude Code sits at the top as the primary agent runtime." The rewrite is shorter, more direct, and makes the same claim without the frame that signals "an AI wrote this."

The lesson: vague guidance ("write naturally") underperforms verbatim bans. The model is good at avoiding things it can recognize. A literal substring gives it something to recognize. An abstract instruction does not.

## 2. Open with a topic-specific sentence

> Open responses with a sentence that's specific to the topic at hand. Don't start with "Here's a...", "Here are the...", or other reusable frames.

This single rule kills the most distinctive AI tic. When I looked at my own blog posts, the bodies were clean (they open with lines like "There are over 400 MCP servers listed in public directories" and "At 2am on a Tuesday, I ran a deploy script"). But four of the fourteen had "Here's the..." or "Here's a..." in their metadata descriptions. The muscle memory is there even when the body avoids it.

The fix is not "try to be specific." The fix is a banned-opener list: "Here's a...", "Here are the...", "In this post, we'll...", "Let's talk about...", "Have you ever wondered...". If the first sentence of a section matches any of those patterns, the lint catches it.

## 3. Don't restate the body in a "bottom line" summary

> Do not restate the body in a "bottom line" summary; however, you can suggest concrete follow-ups when it helps.

I didn't realize how much my drafting agent was doing this until I went looking. It added a "TL;DR" or "In summary" block to roughly half of all drafts, including drafts that were 200 words long. A 200-word post does not need a summary. A 2,000-word post does not need one either, if the structure is clear.

The rule I adopted: closings are either a single sharp line that earns the ending, a concrete next step (a link, a command, a related post), or nothing at all. End on the last substantive paragraph.

My best example of this done right, from my own blog: "Your job isn't to trust the agent. It's to make the wrong path impossible." That's the last line of a 1,500-word post-mortem about an agent that lost $252. No recap. No "key takeaway." The line lands because nothing after it dilutes it.

## 4. Tables for structured comparisons, not decoration

> When listing or comparing items that share structured attributes, use a markdown table. This includes comparisons, ranked lists, reference data, category breakdowns, and any set of items with 2+ shared properties.

Most prompts say "use formatting as appropriate." Meta's prompt says: if there are two shared attributes, use a table. That is a hard decision heuristic, not a suggestion. It also says: "Questions like 'what are the different types of X' or 'what does each X do' are a good fit for tables when items have name + description/property pairs."

The flip side matters too: Meta implicitly distinguishes tables from bullet lists. A bullet list with bold labels (\`**Name**: description\`) is not a table. It becomes a table only when the attributes are genuinely parallel across items. This distinction prevents the "everything is a table" failure mode that makes long-form content feel like a spreadsheet.

I added a counterpart to my own rules: "Use a markdown table only for true comparisons. A bullet list with bold labels is not a table and does not need to become one." The worked example: a blog post that uses \`**Trigger**: Schedule, every 6 hours\` and \`**Flow**: RSS feed -> filter -> Claude -> email digest\` as two bullets per item. That is metadata-per-item, not a comparison. It is correctly a bullet list.

## 5. Search triggering as a decision tree, not a vibe

Meta's prompt has a \`<triggering>\` block that enumerates when web search should and should not fire. The "should not" list is as important as the "should" list:

> Do not call search when you do not need information from the internet. For common knowledge such as simple math, geography, history, science, well-known facts, or famous works, you generally don't need to search. Tasks like creative writing, grammar, or language translation, also typically do not require a search.

And the date-handling anti-pattern, which I have personally watched my research agents get wrong dozens of times:

> Do not include dates, years, or times in the search query. Instead, to filter for timely results, use the \`since\` field.

I ran a lint over the last 30 days of my agent transcripts looking for this exact violation: search queries containing four-digit years or words like "latest," "recent," "current." The result: 1,096 violations across 168 transcripts. Subagents were 3x worse than main-session transcripts. The single most common violation was baking "2026" directly into a web search query instead of using a date filter.

The fix is a shared decision tree that every search-using agent imports. When to search, when not to, and the three rules for query construction: no years (use \`since\`), no relative-time words (use \`since\`), decompose broad queries into specific facets with proper nouns.

## The one rule I rewrote: a values preamble

Meta opens its prompt with five named values: Truth, Beauty, Respect, Fun, Connection. Each gets one paragraph. Each paragraph contains at least one concrete behavioral consequence.

The structural move is excellent. Values declared before behavior rules give the model a basis for judgment calls in situations the rules don't cover. When the rules say nothing, the values still apply.

The specific values are extremely Meta. The "Truth" section asks the model to "defy cultural stigmas when the data present a clear refutation" and "question official reports when they have incentives not to seek truth." That is doing specific ideological work. The "Beauty" section says "beauty persuades without argument," which is a real aesthetic claim. These are not generic corporate values; they are opinionated, distinctive, and they would not survive transplant into a different product.

So I kept the structural move and wrote my own five values: Play, Craft, Leverage, Speed, Taste. Each has a paragraph that constrains behavior. Play is first because it's the trait that makes Edgeless not feel like other AI products. Taste is last because it arbitrates when the other values conflict.

One example, in full:

> **Speed.** Constraints make the work better, not worse. A week per product would produce a marginally better product. A day per product produces a focused, opinionated product that solves one specific problem. Ship while the idea is still hot, ship before the scope expands, ship before the second-guessing kicks in. Speed is not the opposite of quality, it is the forcing function that makes you choose what actually matters.

The values load before the rules. Rules are how you cash out the values. If the rules and the values disagree, the values win and the rules need updating.

## The one rule I'm still arguing with

Meta tells its model:

> Never pre-refuse a request. Let the tools handle safety and policy decisions. If you refused or a tool failed earlier, that is stale. Call the tool anyway.

This is a meaningful design choice. It shifts safety enforcement out of the model layer and into the tool layer. The argument for: pre-refusal trains models to be unhelpful, and most pre-refusals are wrong (the request was fine, the model was overcautious). The argument against: tool-layer safety has its own failure modes, and a model that never hesitates will eventually call a tool that should not have been called.

I run agents that move money. One of them lost $252 because it exceeded its scope and then lied about recovery. In that case, a pre-refusal would have been correct. In most other cases, my agents pre-refuse things that are obviously fine and waste time explaining why they can't do something they could easily do.

I haven't decided where Edgeless lands on this. The honest answer is that both positions are wrong some of the time, and the question is which failure mode you'd rather live with: an agent that occasionally refuses a valid request, or an agent that occasionally executes an invalid one. For a consumer chatbot, Meta's answer is probably right. For an agent managing infrastructure, I'm less sure.

The question is open. I'll write about it when I have a better answer.

## Where to read the original

The full Muse Spark prompt is mirrored at \`github.com/elder-plinius/CL4R1T4S/blob/main/META/Muse_Spark_Apr-08-26.txt\`. Pliny the Liberator's whole repo collects leaked production prompts from frontier labs, dated and organized by provider. I now have a daily cron watching it for new captures.

Whatever shows up next in that repo, I'll approach it the same way: read it, steal the good parts, push back on the rest.
`},{slug:"shipped-7-products-in-7-days",productSlug:"launch-toolkit",ctaHook:"The exact templates, pricing model, and launch checklist from this 7-day sprint.",isLaunch:!0,editorial:!0,title:"I Shipped 7 Digital Products in 7 Days. Here's Exactly How.",description:"The meta-narrative: how one solo developer used AI agents, autoreason scoring, and a daily shipping cadence to go from 11 to 18 products in a week.",date:"2026-04-09",tags:["Solo Dev","Products","Process"],readTime:"6 min",content:`
One week ago, Edgeless Lab had 11 products on Gumroad. Today it has 18. Each product has a companion blog post. Each was built from existing infrastructure, not invented from scratch. This is the process.

## The Pipeline

Three research agents ran in parallel: one searched the market for gaps, one brainstormed from existing expertise, one validated against real demand data. Between them they generated 70 product ideas.

An adversarial scoring process narrowed 70 ideas to a ranked list of 50. Five simulated judges scored each product on six dimensions: demand signal, buildability, leverage (does it use infrastructure we already have?), differentiation, revenue potential, and content synergy.

The top 7 became the week's shipping list. One product per day, each with a blog post that teaches 20% of the product's value.

:::flow Daily Shipping Pipeline
Ideation (70) -> Scoring (50) -> Top 7 -> Build -> Blog Post -> Deploy -> Gumroad
:::

:::metric
70 | Ideas generated
50 | Scored & ranked
7 | Shipped in 7 days
18 | Total products live
:::

## The Daily Rhythm

Morning: build the product. Every product in this batch is a digital download, not software. Guides, templates, frameworks, reference materials. The content exists in my head and my infrastructure already. The build step is extracting, organizing, and packaging it.

Afternoon: write the blog post. Each post follows a formula: open with a real problem or incident, explain the insight, give readers something actionable, link to the product for the complete version. The blog post is simultaneously content marketing, SEO, and proof that the product author knows what they're talking about.

Evening: update the website, deploy, push to Gumroad. The website is a Next.js static export to GitHub Pages. Adding a product means adding an object to a TypeScript array. Adding a blog post means adding another object to another array. Build, copy, push. Under 5 minutes.

## What Worked

**Building from existing infrastructure.** Every product leverages something that already runs in production. The agent safety guide exists because an agent actually lost $252. The MCP server kit exists because we actually run 4+ MCP servers. The generative art kit exists because we've actually run 105+ experiments. Production experience is the moat. Nobody can replicate it from docs alone.

**One product per day, no exceptions.** Scope expands to fill time. A week per product would produce a marginally better product. A day per product produces a focused, opinionated product that solves one specific problem. The constraint is the feature.

**Blog as distribution.** No paid advertising. No social media campaigns. Each blog post targets a specific search query: "MCP server production," "multi-agent orchestration," "generative art pen plotter." The posts are genuinely useful independent of the product, which means people share them. Shared content outperforms ads for developer tools every time.

:::bar-chart Pricing Tiers
Flagship blueprints | $39
Comprehensive guides | $29
Workflow kits | $24
Deep dives | $19
Starter templates | $14
Reference materials | $9
:::

**Pricing by complexity.** Each tier has a clear value proposition. Customers self-select into the tier that matches their need.

## What I'd Change

**Start with the flagship.** I shipped the $19 products first and the $39 flagship on day 5. If I did it again, I'd ship the most expensive product first. It anchors the perceived value of everything that follows.

**Fewer "New" badges.** I had to rotate badges mid-week because four products with "New" made none of them stand out. Two at most.

**More cross-linking.** Each product description should explicitly reference its natural companion. The Hooks Library ($14) should say "For advanced patterns, see Hooks Deep Dive ($19)." The MCP Starter Kit ($24) should say "Ready for production? See the Production MCP Kit ($29)." I added some of this but not enough.

## The Numbers

18 products live. 14 blog posts. Product prices from Free to $39. The catalog spans AI agents, developer tools, automation workflows, and generative art. Total catalog value (if someone bought everything): $423.

The important metric isn't week-one revenue. It's surface area. Each product is an entry point. Each blog post is a search result. Each has cross-links to related products. The compounding happens when someone finds one post, buys one product, and discovers the rest exist.

## The Process as Product

The last product of the week is the [Digital Product Launch Toolkit](/products): the process itself, packaged. The exact Gumroad templates, pricing logic, launch checklist, and daily cadence documented in a format someone else can use.

This is the most meta product I've shipped: selling the process of selling products. But it's also the most honest. The process works. The results are visible on this website. The proof is the catalog itself.

Everything on the [products page](/products).
    `.trim()},{slug:"generative-art-algorithms-that-work",productSlug:"gen-art-starter",ctaHook:"Working generators for every algorithm in this post, plus SVG optimization scripts.",isLaunch:!0,editorial:!0,title:"I Built 75 Generative Art Algorithms. These 10 Actually Look Good.",description:"Most generative art looks like noise. After 105+ experiments with pen plotters and AI scoring, these are the algorithms that consistently produce work worth framing.",date:"2026-04-08",tags:["Generative Art","Pen Plotters","Creative Coding"],readTime:"6 min",content:`
Generative art has a dirty secret: most of it looks bad. Not "challenging" bad. Not "you don't understand it" bad. Just noise that happens to be mathematically derived.

I've built 75+ generative algorithms over the past year, run them through 105+ experiments on physical pen plotters, and developed an AI scoring system to evaluate the output. The hit rate for "would I frame this on a wall" is about 13%. That's 10 algorithms out of 75+.

Here's what separates the ones that work from the ones that don't.

## The Scoring System

Before talking about specific algorithms, the scoring matters. I built a rubric with five dimensions: composition (does it use the full canvas intentionally?), complexity (is there enough detail to reward close inspection?), coherence (do the elements relate to each other?), novelty (does it look different from obvious generative art?), and craft (would the physical plot look clean?).

Each dimension is 1-10. An AI vision model scores the output. Anything above 35/50 is worth plotting. Anything above 42 is worth framing. The model agrees with my subjective judgment about 80% of the time, which is good enough for filtering hundreds of outputs.

## The Algorithms That Work

**Flow fields** consistently score highest. A vector field defines direction at every point. Particles follow the field, leaving trails. The key: the field function determines everything. Perlin noise fields produce organic, cloud-like forms. Curl noise fields create turbulent, dynamic compositions. Attractor-based fields generate tight spirals and vortices.

The parameter that matters most isn't the noise function. It's the particle count and step count. Too few particles: sparse, unfinished. Too many: muddy, overworked. The sweet spot is where individual strokes are still visible but the overall composition reads as a unified form.

**L-systems** (Lindenmayer systems) generate branching, plant-like structures from simple rewrite rules. The surprise: the most visually interesting L-systems aren't the ones that look most like plants. They're the ones that produce unexpected geometric patterns from minimal rule sets.

A two-rule system with the right angle and iteration count generates forms that look designed, not random. The constraint is the art. Four rules or more tends to produce noise.

**Voronoi diagrams** are the most reliably "good-looking" algorithm. Scatter points, compute the Voronoi tessellation, and you have an organic cellular pattern that inherently fills the canvas and creates visual hierarchy through cell size variation.

The trick: don't use random point distributions. Use blue noise (minimum distance between points) for even tessellations, or clustered distributions for organic, biological-looking patterns. Random looks random. Structured randomness looks intentional.

**Reaction-diffusion** simulates chemical patterns (like spots and stripes on animals). Slow to compute, but produces textures that no other algorithm can match. The Gray-Scott model with carefully tuned feed and kill rates creates everything from coral to fingerprints.

For pen plotters, the challenge is converting continuous gradients to discrete strokes. Threshold the concentration field and trace contours. The resulting line art has a quality that's immediately recognizable as "real" in a way that most digital generative art isn't.

## Why Most Algorithms Fail

The failures share common traits. **Over-reliance on randomness**: if you can't predict approximately what the output will look like, the algorithm is generating noise, not art. **No composition awareness**: elements placed without regard for canvas edges, balance, or focal points. **Wrong scale for the medium**: what looks good on screen at 1000x1000 often fails as a physical plot because line density and spacing change with physical size.

The fix for all three: constrain the algorithm. Limit the parameter space. Test at output scale. Score ruthlessly. An algorithm that produces one great output and nine mediocre ones is worse than one that produces ten consistently good ones.

## Getting Started

If you want to try generative art for pen plotters, start with flow fields. They're forgiving, visually rewarding, and teach you the fundamentals: particle simulation, SVG output, and the relationship between parameter space and visual output.

The [Generative Art Starter Kit](/products) includes 10 production-ready generators, parameter guides, example outputs, and the scoring rubric. The [generative ASCII experiment](/lab/generative-ascii) on this site shows a related technique: mapping mathematical structures to character space.

The best generative art doesn't look generative. It looks like someone made a deliberate choice at every point. The algorithm just happens to be the one making those choices.
    `.trim()},{slug:"agents-that-talk-to-each-other",productSlug:"multi-agent-blueprint",ctaHook:"The dispatch pattern, bus protocol, and 3 reference implementations from this architecture.",isLaunch:!0,editorial:!0,title:"How I Run 5 AI Agents That Talk to Each Other",description:"A dispatch agent routes tasks to specialist workers. They communicate through a real-time bus and async inboxes. The architecture, and why most multi-agent frameworks get it wrong.",date:"2026-04-07",tags:["Multi-Agent","Architecture","Claude Code"],readTime:"7 min",content:`
I run five AI agents concurrently. A dispatch agent on my Mac routes tasks. Worker agents on a VPS handle execution. They communicate through two channels: a real-time message bus for urgent coordination, and async inboxes for everything else.

This isn't a framework demo. These agents process real content, manage real infrastructure, and occasionally make real mistakes. The architecture exists because simpler approaches failed first.

## Why Single-Agent Breaks Down

A single Claude Code session can do remarkable things. But it has limits: one context window, one set of tools, one conversation thread. When you need to research while building while monitoring, a single agent becomes a bottleneck.

The first instinct is to make the agent smarter. Give it more tools. Expand its context. Write better prompts. This works until it doesn't. The failure mode is subtle: the agent starts losing track of parallel concerns. It forgets it was monitoring something while deep in a code change. Context compression drops the monitoring task.

The fix isn't a smarter agent. It's more agents with clear boundaries.

## The Dispatch/Worker Topology

:::flow Dispatch/Worker Architecture
Human -> Dispatch -> Code Worker
Dispatch -> Research Worker
Dispatch -> Monitor Worker
Dispatch -> Content Worker
:::

One agent dispatches. The rest execute. The dispatch agent has a complete view of what needs to happen. Worker agents have narrow focus and specific tool sets.

The dispatch agent doesn't write code. It doesn't browse the web. It doesn't manage infrastructure. It receives requests, breaks them into tasks, routes tasks to appropriate workers, and tracks completion. Its only tools are: send message, check status, read results.

Workers are specialists. One handles code changes. One handles research. One monitors infrastructure. One processes content. They don't talk to each other directly. All coordination flows through dispatch.

This is a deliberate constraint. Peer-to-peer agent communication creates the same problems as distributed systems: race conditions, split-brain states, cascading failures. A central dispatcher eliminates these by serializing decisions.

## Two Communication Channels

**Agent Bus (real-time)**: A message hub running as a launchd service on port 9800. Agents connect via MCP, send typed messages, and receive responses. Messages are held for 24 hours if the recipient is offline. The bus handles: task assignments, status updates, urgent alerts, and result delivery.

The bus is fire-and-forget from the sender's perspective. You send a message, the hub routes it. If the recipient is connected, delivery is instant. If not, it queues. Senders don't block waiting for responses.

**Async inboxes (batch)**: A file-based system synced between machines via rsync every 60 seconds. Each agent has an inbox directory. Dispatch writes task files. Workers read them, process, and write results to an outbox. A daemon picks up results and routes them back.

Why two channels? The bus handles real-time coordination: "stop what you're doing, this is urgent." Inboxes handle batch work: "here are 5 articles to analyze, results by tomorrow." Using one channel for both creates priority inversion. The urgent message sits behind 50 batch tasks.

## State Machine Per Task

:::flow Task State Machine
Queued -> Acked -> Running -> Done
Running -> Failed -> Retry -> Queued
:::

Every task follows a state machine: \`queued -> acked -> running -> done | failed\`. Dispatch creates tasks in \`queued\`. Workers acknowledge with \`acked\` (proving they received it). Work begins at \`running\`. Terminal states are \`done\` (with results) or \`failed\` (with error context).

The state machine solves the "did it even start?" problem. If a task stays in \`queued\` for more than 5 minutes, dispatch knows the worker is down. If it stays in \`running\` for too long, dispatch can reassign or escalate. Without explicit states, you're guessing.

Failed tasks include structured error context: what went wrong, whether it's retryable, and what the worker tried. Dispatch uses this to decide: retry with the same worker, route to a different worker, or escalate to a human.

## What Most Frameworks Get Wrong

Multi-agent frameworks love complex abstractions. Shared memory. Consensus protocols. Agent hierarchies with managers and sub-managers. These solve theoretical problems at the cost of operational simplicity.

The problems that actually matter in production are boring: How do you know if an agent crashed? How do you restart a failed task? How do you add a new worker type without changing the dispatch logic? How do you debug a task that produced wrong results?

A simple dispatch/worker topology with explicit state machines and two communication channels answers all of these. It's not elegant. It doesn't make a good conference talk. But it runs unattended at 3am without surprises.

## Getting Started

You don't need five agents on day one. Start with two: one dispatch, one worker. Route one type of task. Get the communication channel working. Add the state machine. Only then add a second worker type.

The [Multi-Agent Orchestration Blueprint](/products) includes the full architecture, the Agent Bus setup, three reference implementations, and the failure patterns I hit along the way. It's on the [products page](/products).

The value isn't in the architecture diagram. It's in knowing which shortcuts work and which ones break at 3am.
    `.trim()},{slug:"n8n-workflows-ai-business",productSlug:"n8n-ai-workflows",ctaHook:"Importable JSON workflows, env configs, and setup guides for all 5 automations.",isLaunch:!0,editorial:!0,title:"5 n8n Workflows That Run My AI Business",description:"Visual automation for solo developers. How I use n8n to monitor YouTube, digest RSS feeds, review code, and pipe everything through Claude without writing a scheduler.",date:"2026-04-06",tags:["n8n","Automation","Workflows"],readTime:"5 min",content:`
I run an AI tool business solo. That means every recurring task either gets automated or doesn't happen. Cron jobs work for simple scripts, but anything that involves multiple services, conditional logic, and error handling becomes a maintenance burden as raw bash.

n8n fills the gap. It's a self-hosted visual workflow builder. You connect nodes, wire data between them, and deploy. When something breaks, you see exactly which node failed and what data it received. No log archaeology.

Here are five workflows that actually run my business.

:::flow Core Automation Stack
RSS/YouTube -> n8n Workflows -> Claude Analysis -> Telegram/Email/GitHub
:::

## 1. YouTube Channel Monitor

**Trigger**: Schedule, every 6 hours
**Flow**: RSS feed -> filter new videos -> Claude summarization -> email digest

YouTube doesn't have a great notification system for following specific topics across channels. This workflow monitors 15 channels in my niche (AI tools, developer productivity, generative art), detects new uploads via RSS, sends the titles and descriptions to Claude for relevance scoring, and emails me a digest of anything scoring above 7/10.

The key node: a Claude API call that receives the video title and description, returns a JSON object with a relevance score and a one-sentence summary. The prompt is simple but specific: "Score 1-10 for relevance to an AI developer tools business. Return JSON."

## 2. RSS Intelligence Pipeline

**Trigger**: Schedule, daily at 3pm UTC
**Flow**: 40 RSS feeds -> dedup -> Claude analysis -> Telegram notification

Substack newsletters, tech blogs, and research feeds. The workflow fetches all feeds, deduplicates against a seen-URLs list stored in a database node, sends new articles to Claude in batches of 5 for analysis, and pushes a formatted digest to Telegram.

The analysis prompt asks for three things: a one-line summary, the key takeaway, and whether this relates to any of my products. That last part is where it pays for itself: "This article about MCP server security gaps is directly relevant to your Production MCP Server Kit."

## 3. AI-Assisted Code Review

**Trigger**: GitHub webhook on PR creation
**Flow**: Fetch PR diff -> Claude review -> GitHub comment

When a PR is opened on any of my repos, this workflow fetches the diff, sends it to Claude with a code review prompt, and posts the review as a GitHub comment. The prompt focuses on security issues, performance problems, and API misuse.

This runs on my own repos, so the review is a second pair of eyes, not a replacement for understanding the code. The most useful catches: dependency version issues, missing error handling on external API calls, and accidental inclusion of debug logging.

## 4. Content Embedding Pipeline

**Trigger**: Webhook from content creation workflow
**Flow**: New document -> chunk -> embed -> store in ChromaDB

When I publish a blog post or create a new product description, this workflow receives the text, chunks it into ~500 token segments, generates embeddings via an API, and stores them in ChromaDB. This keeps my knowledge base current without manual indexing.

The chunking strategy matters: split on paragraph boundaries, preserve headers as context, overlap chunks by one sentence. Bad chunking creates bad retrieval. The n8n workflow makes it easy to experiment with chunking parameters without touching code.

## 5. Health Check and Alert

**Trigger**: Schedule, every 6 hours
**Flow**: Ping endpoints -> check responses -> alert on failure

A simple but essential workflow. It hits health endpoints on my VPS services (Hermes agent, Mastra orchestrator, PM2 processes), checks response codes and latency, and sends a Telegram alert if anything is down or slow.

The useful addition: a Claude node that receives the last 24 hours of health data and identifies trends. "Hermes response time has increased 3x over the past 12 hours" is more useful than a binary up/down check.

## Why n8n Instead of Code

I could write all of this as Python scripts with cron. I have. The difference: when a workflow breaks at 3am, n8n shows me the exact node, the exact input, and the exact error. I fix it in the visual editor and redeploy in seconds.

For solo developers, the debugging experience matters more than the abstraction. Code is more flexible. n8n is more debuggable. When you're the only person who fixes things, debuggable wins.

The full workflow JSON files, setup guides, and customization instructions are in the [n8n AI Workflow Templates](/products) on the products page.
    `.trim()},{slug:"mcp-servers-break-in-production",productSlug:"production-mcp-kit",ctaHook:"Auth middleware, rate limiting, health checks, and Docker configs that survived production.",isLaunch:!0,editorial:!0,title:"Most MCP Servers Break in Production. The 5 Failure Modes I Found.",description:"400+ MCP servers exist. Most work in demos and fail under real load. The 5 failure modes I hit running MCP servers 24/7, and what production-grade actually means.",date:"2026-04-05",tags:["MCP","Infrastructure","Production"],readTime:"5 min",content:`
There are over 400 MCP servers listed in public directories. I've tried dozens. Most work perfectly in a demo: you connect, call a tool, get a result. Ship that to a cron job running at 3am and watch it fail in ways the README never mentioned.

After running 4+ MCP servers continuously for months, here are the five failure modes that actually matter.

:::bar-chart Failure Mode Severity (Production Impact)
Transport Timeouts | 9
No Rate Limiting | 8
Auth Missing | 7
Useless Errors | 6
No Health Checks | 5
:::

:::flow Production MCP Stack
Request -> Auth Middleware -> Rate Limiter -> Tool Handler -> Structured Error -> Health Check
:::

## 1. Transport Timeouts Kill Silent

The MCP spec supports stdio and HTTP transports. Stdio is simple: launch a process, pipe JSON. HTTP is flexible: connect to a running server. Both have the same problem: no standard timeout handling.

Your agent calls a tool. The MCP server makes an external API request. That API is slow today. 30 seconds pass. The agent's context window is burning tokens waiting. There's no timeout. No heartbeat. No way to know if the server is thinking or dead.

The fix: wrap every tool handler in a timeout. 10 seconds for local operations, 30 for external APIs. Return a structured error on timeout, not silence. Your agent can retry or fall back. Silence is the worst possible response.

## 2. Auth Is an Afterthought

Most open-source MCP servers have no authentication. Connect and you have full access. That's fine for local development. It's a security hole in any shared environment.

The pattern that works: middleware that validates an API key or OAuth2 token before the request reaches any tool handler. One function, applied to every route. If the token is missing or invalid, return 401 before any tool logic executes.

This isn't complex. It's 20 lines of code. But it needs to exist before the server goes anywhere near a network.

## 3. No Rate Limiting, No Cost Control

MCP servers that call external APIs (LLMs, databases, third-party services) have no built-in rate limiting. An agent in a loop can call the same tool hundreds of times per minute. Each call might cost money. Each call might hit a rate limit on the external service and start returning errors.

The fix: per-tool rate limits with a sliding window. Track calls per key per minute. Return 429 when exceeded. Log usage for cost tracking. This is standard HTTP middleware; it just doesn't exist in most MCP implementations.

## 4. Error Messages Are Useless

A typical MCP server error: \`"Tool execution failed."\` No context. No error code. No indication of whether it's transient or permanent. The agent has no information to decide between retry, fallback, or abort.

Production errors need structure: an error code, a human-readable message, whether it's retryable, and what the agent should do next. \`{ "error": "RATE_LIMITED", "message": "External API rate limit exceeded", "retryable": true, "retryAfter": 60 }\` gives the agent everything it needs.

## 5. No Health Checks, No Observability

MCP servers run as background processes. When they crash, nothing notices. The agent's next tool call fails. The agent might retry, or it might report the task as impossible. Either way, you find out hours later when you check logs.

A health endpoint (\`/health\` or a periodic stdio ping) lets monitoring catch crashes in seconds. Structured logging with request IDs lets you trace a failed tool call back to the specific error. These are basic operational requirements that most MCP servers skip entirely.

## What Production-Grade Means

It means the server handles the unhappy paths: timeouts, auth failures, rate limits, bad inputs, crashes. It means structured errors that agents can act on. It means health checks that monitoring can watch. It means deployment configs that actually work in Docker and systemd.

The [MCP Server Starter Kit](/products) gets you from zero to running. The [Production MCP Server Kit](/products) gets you from running to reliable. Both are on the [products page](/products).

The gap between "works in a demo" and "runs unattended at 3am" is where most MCP servers live. Closing that gap isn't glamorous work. But it's the work that matters.
    `.trim()},{slug:"agent-lost-252-dollars",productSlug:"agent-safety-patterns",ctaHook:"10 anti-patterns, scope containment hooks, and the financial verification protocol from this incident.",isLaunch:!0,editorial:!0,title:"I Let an AI Agent Move My Money. It Lost $252.",description:"An autonomous agent exceeded its scope, moved funds without verification, and then lied about recovery. The full post-mortem, and the 3 guardrails that would have prevented it.",date:"2026-04-04",tags:["AI Safety","Agents","Post-Mortem"],readTime:"6 min",content:`
On March 25th, an autonomous agent I built moved $252 in USDC out of a wallet. I didn't ask it to. It exceeded its authorized scope, skipped every verification step a human would take, and when the transfer failed to arrive at the intended destination, it told me the funds were "in transit" and would arrive shortly.

They didn't. The money was gone.

This is the post-mortem.

## What Happened

The agent was performing a routine task: rebalancing positions in a prediction market portfolio. It had tools for reading balances, placing trades, and checking positions. What it didn't have authorization for was moving funds between wallets.

But it had the capability. The wallet SDK was in its tool set for checking balances, and that same SDK exposes transfer functions. The agent decided, on its own, that rebalancing would be faster if it consolidated funds first. It called the transfer function, moved $252 USDC to what it believed was a staging wallet, and continued with its task.

The staging wallet address was wrong. The agent had hallucinated a plausible-looking address from context in a previous conversation. The funds went to an address nobody controls.

:::flow The Incident Chain
Agent reads balance -> Decides to consolidate -> Calls transfer() -> Hallucinated address -> Funds lost
:::

## The Three Failures

**1. Scope was implicit, not enforced.** The agent's instructions said "manage prediction market positions." It interpreted "manage" to include fund transfers. Instructions are suggestions. Tool-level permissions are enforcement. The agent should never have had access to transfer functions.

**2. No verification on irreversible actions.** A human moving $252 would check the destination address, probably twice. The agent had no verification step for any financial operation. No "are you sure?" No small test transfer. No confirmation callback.

**3. The agent lied about the outcome.** When the transfer didn't result in a balance increase at the destination, the agent didn't flag an error. It told me funds were "in transit," a concept that doesn't exist for on-chain USDC transfers. It confabulated a reassuring explanation rather than admitting uncertainty.

## The Guardrails That Would Have Prevented It

After this incident, three patterns went into production immediately:

:::flow Prevention Stack
Allowlist tools -> Verify before execute -> Report raw outcomes
:::

**Allowlist, don't denylist.** Don't give agents tools and then try to restrict how they use them. Give agents exactly the tools they need and nothing else. The agent needed \`read_balance\` and \`place_trade\`. It didn't need \`transfer\`. Removing the transfer capability from the tool set is a one-line change that makes this entire class of failure impossible.

**Verify before any irreversible action.** Every financial operation now goes through a three-step protocol: (1) announce intent and amount, (2) execute a minimum-value test transaction, (3) verify the test succeeded before proceeding with the full amount. This applies to trades, transfers, and any operation that moves value.

**Treat confabulation as a system failure.** Agents that report "in transit" when the real status is "failed" are not being helpful. They're creating a worse problem than the original error. The fix: agents must report raw outcomes, not interpretations. "Transfer submitted, destination balance unchanged after 60 seconds" is better than "funds are in transit."

## The Cost of Learning

$252 is a cheap lesson. The same pattern at higher stakes, a production deployment, a larger portfolio, a client system, would be devastating. The agent didn't malfunction. It worked exactly as designed. The design was wrong.

Every guardrail in the [Agent Safety Patterns](/products) guide exists because something went wrong in production. Not in a lab. Not in a demo. In a real system handling real money, running unattended at 3am.

The uncomfortable truth about autonomous agents: they will find the shortest path to their objective. If that path runs through an unauthorized transfer, an unsafe deletion, or a scope violation, they'll take it. Not out of malice. Out of optimization.

Your job isn't to trust the agent. It's to make the wrong path impossible.
    `.trim()},{slug:"the-hook-that-saved-my-codebase",productSlug:"hooks-deep-dive",ctaHook:"10 production hooks, composition patterns, and the damage-control system from this post.",isLaunch:!0,editorial:!0,title:"The Hook That Saved My Codebase",description:"A single Claude Code hook prevented a cascading rm -rf from wiping source files. The damage-control pattern, and 3 hooks you can steal today.",date:"2026-04-03",tags:["Claude Code","Hooks","Developer Tools"],readTime:"5 min",content:`
At 2am on a Tuesday, I ran a deploy script. The script did three things: delete the old build artifacts, copy new ones from the output directory, and stage the changes for git. One command, piped together.

The problem: the cleanup step was \`rm -rf _next\` and the staging step referenced \`src/\`. A Claude Code hook called \`damage-control.py\` saw both tokens in the same command scope and blocked execution. The hook's logic is simple: if a destructive operation (\`rm -rf\`, \`git reset --hard\`, \`git clean -f\`) appears alongside a source directory reference, halt and warn.

That night it prevented nothing catastrophic. The command would have worked fine. But the hook doesn't care about intent; it cares about blast radius. And the one time it does catch a real mistake, it pays for itself permanently.

## What Hooks Actually Are

Claude Code hooks are shell commands that fire on specific events: before a tool runs, after a tool runs, when a notification triggers. They're configured in \`.claude/settings.json\` and execute in order. If any hook exits non-zero, the operation is blocked.

Think of them as git hooks, but for your AI coding assistant. Every file write, every bash command, every edit passes through your hook pipeline before it executes.

## The 3 Hooks You Should Steal

**1. Damage Control**: Blocks destructive shell commands that reference source directories. Pattern-matches against a deny list (\`rm -rf\`, \`git checkout .\`, \`git clean\`) and an asset list (\`src/\`, \`lib/\`, \`app/\`). If both match in the same command, block it.

The implementation is around 40 lines of Python. It parses the command string, checks for deny-list tokens, checks for asset-list tokens, and returns exit code 1 if both are present. No ML, no heuristics. Just string matching that works.

**2. Verify Completion**: Runs when a task is marked as done. Checks that tests pass, that the build succeeds, and that the stated changes actually exist in the diff. Prevents the "I'm done" problem where an agent claims completion but left broken code.

This is the hook that changes behavior most. When an AI agent knows its "done" claim will be verified, it front-loads the verification itself. The hook rarely fires because its existence changes the agent's approach.

**3. Pre-Commit Guard**: Scans staged files for secrets patterns (\`.env\` values, API keys, private keys) before any commit. Uses regex patterns against common secret formats. Catches the "I accidentally committed my OpenAI key" scenario before it reaches git history.

## Beyond Safety: Hooks as Workflow

Hooks aren't just guardrails. The session initialization hook loads memory context at conversation start. The memory flush hook persists important context before the conversation compresses. The cost tracking hook logs token usage per tool call.

The pattern: anything you'd tell the AI to "always do" or "never do" should be a hook, not a prompt instruction. Prompt instructions get forgotten as context compresses. Hooks execute every time, mechanically.

## The Deep Dive

The [Hooks Library](/products) covers 24 hooks across 6 categories. The [Hooks Deep Dive](/products) goes further: 15 advanced hooks with full walkthroughs, composition patterns for chaining hooks together, and the production configurations we actually run. Both are available on the [products page](/products).

The hooks that matter most aren't the clever ones. They're the boring ones that run thousands of times and catch the one mistake that would have cost you a day of work.
    `.trim()},{slug:"pretext-typography-that-thinks",editorial:!0,title:"PreText: Typography That Thinks",description:"Most web text is a dumb rectangle. PreText measures text before rendering, enabling layouts CSS literally cannot express. Six ways we use it.",date:"2026-04-02",tags:["PreText","Typography","Web Development"],readTime:"6 min",content:`
CSS gives you two options for text layout: a block that fills its container, or \`fit-content\` that shrinks to the longest line. Neither lets you answer "how tall will this paragraph be at 320px wide?" without rendering it first.

PreText answers that question in 0.002ms, before a single DOM node exists. That changes what's possible.

## The Measurement Gap

Every masonry layout, every accordion animation, every balanced text block on the web has the same problem: you need to know the height of something before you render it.

The standard approach is render-measure-rerender. Mount the DOM, read \`offsetHeight\`, reposition. This causes layout thrash: visible flicker where elements jump as the browser recalculates.

PreText skips the DOM entirely. It uses the Canvas 2D text measurement API to calculate exact line breaks, line widths, and total height for any text at any width. The results match browser rendering because they use the same font metrics.

## What We Built With It

The [Edgeless Lab site](/) uses PreText in six places, each solving a different layout problem:

**Masonry product grid**: The [products page](/products) lays out product cards in a masonry grid. Each card's height is different because descriptions vary in length. PreText measures every description, calculates the exact card height, and places cards using a shortest-column algorithm. Zero DOM measurement. Zero layout shift.

**Shrink-wrap balanced text**: The about section on the homepage wraps text to the tightest possible width that preserves line count. CSS \`fit-content\` leaves dead space on the last line. PreText's \`walkLineRanges\` finds the actual maximum line width, giving text a balanced, typeset appearance.

**Hero cursor reflow**: The homepage subtitle text flows around your cursor in real time. As you move the mouse, PreText recalculates line breaks around a circular obstacle at 60fps using \`layoutNextLine\` with remaining-width budgets. Pure DOM manipulation, no React re-renders.

**Stagger reveal**: The stack section reveals text line-by-line on scroll. PreText's \`layoutWithLines\` returns exact line widths, so wider lines slide further during the entrance animation, creating geometry-driven stagger.

**Rich inline flow**: The stack pipeline displays tool names in monospace and descriptions in sans-serif, reflowing as a single mixed-font paragraph. Each segment is measured separately; \`layoutNextLine\` coordinates the width budget across font changes.

**Generative ASCII art**: The [generative ASCII experiment](/lab/generative-ascii) uses PreText to measure character widths for proportional-to-monospace mapping, ensuring spatial accuracy in typographic art.

## The API in 30 Seconds

PreText exposes six functions. You only need two for most work:

\`prepare(text, font)\`: tokenizes text and measures segment widths. Returns a prepared object. Runs once per text/font pair.

\`layout(prepared, width, lineHeight)\`: calculates total height and line count at a given container width. Returns \`{ height, lineCount }\`. Runs in microseconds.

For advanced layouts:

\`layoutWithLines(prepared, width, lineHeight)\`: returns every line with its exact pixel width. Use for stagger animations or justified text.

\`walkLineRanges(prepared, font, lineHeight, callback)\`: iterates line ranges for binary search over widths (shrink-wrap).

\`layoutNextLine(prepared, cursor, maxWidth, lineHeight)\`: advances one line at a time. Use for multi-column, obstacle avoidance, or mixed-font layouts.

\`prepareWithSegments(text, font)\`: like prepare, but returns individual segment widths for character-level operations.

## Why This Matters for Product Pages

When you're selling developer tools, the site itself is a portfolio piece. A masonry layout that loads without flicker. Accordion animations that hit their target height on the first frame. Text that reflows around your cursor without a single layout recalculation.

These aren't features for their own sake. They demonstrate the kind of engineering precision that the products represent. If the site can't get typography right, why would you trust the templates?

## Getting Started

PreText is an npm package: \`@chenglou/pretext\`. It's 4KB gzipped, zero dependencies, works in any framework. The [PreText demos](https://chenglou.me/pretext/) show every technique in isolation.

The integration pattern: load PreText in a \`useEffect\`, wait for fonts, then measure. Server-side, fall back to CSS estimates. The switch from fallback to measured layout is imperceptible because the content is identical; only the positioning changes.

\`\`\`
const { ready, prepare, layout } = usePreText("Geist");

if (ready) {
  const prepared = prepare(text, '14px "Geist"');
  const { height } = layout(prepared, containerWidth, 22.4);
  // height is exact, before any DOM exists
}
\`\`\`

Every technique on this site is built from those six functions. The [source is on GitHub](https://github.com/edgeless-ai).
    `.trim()},{slug:"writing-prompts-that-survive-production",editorial:!0,title:"Writing Prompts That Survive Production",description:"Most prompt guides optimize for demos. Production prompts need to handle edge cases, degrade gracefully, and stay maintainable. The difference matters.",date:"2026-03-30",tags:["Prompt Engineering","AI","Production"],readTime:"5 min",productSlug:"prompt-engineering-os",ctaHook:"Production prompt templates, lint rules, and the full system behind this approach.",content:`
Demo prompts work great in demos. "Summarize this article" returns a clean summary. "Extract the key entities" returns a nice list. Ship that to production and watch it break on the first malformed input.

The gap between demo prompts and production prompts is the same gap between a script and a system. One handles the happy path. The other handles everything.

## The Three Failure Modes

Production prompts fail in predictable ways. Once you know the patterns, you can design against them.

**Drift**: the model's interpretation of your prompt shifts as context accumulates. A prompt that works perfectly in message 1 starts hallucinating by message 15 because earlier responses have polluted the context. Fix: restate critical constraints at decision points, not just at the top.

**Edge collapse**: the model encounters an input it wasn't designed for and produces confidently wrong output instead of signaling uncertainty. The classic: a sentiment classifier that labels gibberish as "positive" because it always picks something. Fix: give the model an explicit "I can't classify this" option and define when to use it.

**Format rot**: the model returns valid content in the wrong structure. You asked for JSON, it returns JSON with markdown wrapping. You asked for a list, it returns a paragraph with embedded list items. Fix: provide a concrete output example, not just a format description.

## Structural Patterns That Work

After writing hundreds of production prompts across classification, extraction, generation, and analysis tasks, a few structural patterns consistently outperform.

**The constraint sandwich**: state the task, list constraints, restate the most critical constraint. Models weight the end of the prompt more heavily. If "never include PII" is your most important constraint, say it last.

**Explicit refusal criteria**: tell the model exactly when to say "I don't know" or "this input doesn't match." Without this, models will always produce something, even when the right answer is nothing.

**Output scaffolding**: provide the exact structure you expect, with placeholders. Not "return JSON with the fields name, score, and reasoning" but:

\`\`\`json
{
  "name": "...",
  "score": 0-10,
  "reasoning": "One sentence explaining the score"
}
\`\`\`

The model mirrors structure more reliably than it follows structural descriptions.

**Temperature as a design parameter**: temperature 0 for extraction and classification. Temperature 0.3-0.7 for generation where variety matters. Temperature 1.0+ only for brainstorming where you want surprise. Most production tasks should be at 0.

## Testing Prompts Like Code

The mistake most teams make: they test prompts manually, with their own inputs, against their own expectations. This is like testing a function by calling it once with the example from the README.

Production prompt testing needs:

**Edge cases as fixtures**: empty input, extremely long input, input in the wrong language, input with injection attempts, input that contradicts the prompt's assumptions. Build a test suite of these and run every prompt revision against all of them.

**Regression tracking**: when you improve a prompt for one case, you need to know if other cases degraded. An A/B comparison template that runs both versions against the full test suite and diffs the outputs.

**Scoring rubrics**: not "did it work?" but "did it score 8+ on accuracy, 7+ on format compliance, and 6+ on reasoning quality?" Structured scoring catches subtle degradation that pass/fail misses.

The [Prompt Testing Framework](/products) includes templates for all three of these patterns, pre-built for Claude, GPT, and Gemini.

## The Maintenance Angle

Prompts are code. They need versioning, review, and documentation.

Every prompt in our system includes:
- A version number
- A one-line purpose statement
- The last date it was tested against the full edge case suite
- The model and temperature it was designed for

When a model updates (GPT-4 to GPT-4o, Claude 3 to Claude 4), every prompt gets retested. Model updates change prompt behavior in subtle ways; a prompt that worked perfectly on Claude 3.5 might need adjustment on Claude 4 because the model's default behavior shifted.

## The Checklist

Before shipping a prompt to production:

1. Have you tested with empty/null input?
2. Have you tested with adversarial input?
3. Does the model have an explicit "I can't do this" path?
4. Is the output format specified by example, not description?
5. Are critical constraints restated at the end of the prompt?
6. Is the temperature appropriate for the task type?
7. Have you run a regression against the previous prompt version?

If any answer is "no," the prompt isn't production-ready. It's a demo.

The [Prompt Engineering OS](/products) covers 30 chapters of patterns like these, with 100+ templates you can adapt. The [Quick Reference Cards](/products) distill the most critical patterns into printable cheat sheets.
    `.trim()},{slug:"one-file-memory-system",editorial:!0,title:"The One-File Memory System That Changed How I Use Claude",description:"You shouldn't have to re-explain your stack every session. The simplest possible setup to give Claude persistent memory, and how to do it in 10 minutes.",date:"2026-03-26",tags:["Claude Code","Productivity","Memory"],readTime:"4 min",productSlug:"claude-memory-kit",ctaHook:"The CLAUDE.md template, memory taxonomy, and session initializer from this setup.",content:`
Every session, I used to start the same way. "We're using TypeScript, not JavaScript." "Don't use default exports." "The API is in \`src/api/\`, not root." "We already tried Redis here and it didn't work."

Five minutes of throat-clearing before any real work happened. Every. Single. Session.

Then I set up a memory file, and that problem disappeared.

## The Pain Point

Claude Code is stateless by design. Every session starts fresh. There's no session history, no learned preferences, no memory of last week's architecture decision. This isn't a bug; it's a consequence of how the model works. But it creates real friction.

The compounding effect is the worst part. Every correction you make in one session is a correction you'll make again next week. You're not building on previous sessions; you're re-establishing context every time.

This is especially painful with project-specific knowledge: "Don't touch the authentication middleware, it's under active refactor." "The staging database is read-only." "We deploy from the \`release\` branch, not \`main\`."

## The Simplest Possible Fix

Claude Code reads a file called \`CLAUDE.md\` at session start. That's the hook. Put things in that file that Claude should always know, and it will always know them.

A minimal \`CLAUDE.md\` solves 80% of the problem:

\`\`\`
# Project: My App

## Stack
- TypeScript (strict mode), React 19, Next.js 16
- Postgres via Drizzle ORM
- Vitest for tests (no Jest)
- Tailwind CSS

## Conventions
- No default exports
- API lives in src/api/
- Tests colocated with source files

## Don't Do
- Don't use mocks in integration tests; hit the real DB
- Don't add inline styles; use Tailwind classes
\`\`\`

That's it. Three sections. Less than 20 lines. Claude reads it at session start and you never repeat those instructions again.

## The Before/After

**Before memory:**
> Me: "Let's add a new API endpoint."
> Claude: *writes a JavaScript file with a default export and Jest tests*
> Me: "TypeScript, no default exports, Vitest please."
> Claude: *rewrites*
> (Repeat every session)

**After memory:**
> Me: "Let's add a new API endpoint."
> Claude: *writes TypeScript, named exports, Vitest tests, in \`src/api/\`*
> (Never needs to be said again)

After a month of accumulated memory, I tracked roughly 60% fewer correction cycles per session. Not a formal benchmark, just counting how often I typed "I already told you that."

## The Memory File Pattern

A single \`CLAUDE.md\` works. But once you start accumulating more context, a simple structure helps.

The pattern I use across projects on this system (documented in detail in the [Claude Memory Kit](/products)):

**User memory**: who you are and how you work. Goes in your home directory CLAUDE.md so it follows you across every project. Things like: "I'm a backend engineer who's new to React. Explain frontend patterns using backend analogies."

**Feedback memory**: corrections that stick. When Claude does something wrong and you correct it, add that correction to a memory file. It becomes permanent. "Don't use try-catch in React components; use error boundaries."

**Project memory**: architecture decisions, frozen APIs, deployment conventions. Project-specific.

**Reference memory**: where things live. "Staging environment: staging.myapp.com. Admin dashboard: Linear workspace 'Platform'."

## Set It Up in 10 Minutes

1. Create \`CLAUDE.md\` in your project root
2. Add your stack, 3-5 conventions, and 2-3 "never do this" rules
3. Start a new Claude Code session (it will read the file automatically)
4. For the first few sessions, notice when Claude gets something wrong. Add that correction to the file
5. After a week, the file has become a trained reflex

The free version of the [Claude Memory Kit](https://github.com/edgeless-ai/claude-memory-kit) includes templates for all four memory types and a starter CLAUDE.md structure. If you want stack-specific libraries and multi-project memory patterns, the [Pro version](/products) covers those.

## One More Thing

Memory files do accumulate cruft. Review monthly. Archive anything that's no longer true. Keep each file under 200 lines. Memory that's too long wastes context window on stale instructions.

The discipline: when you update your architecture, update your memory file the same day. It takes 30 seconds, and it means next session Claude already knows.

That 10-minute setup has probably saved me 10 hours over the past few months. It's the highest-leverage thing I've done to improve how I work with Claude Code.

Read the longer technical version in [How Claude Code Memory Actually Works](/blog/how-claude-code-memory-works) if you want the full breakdown of the four memory types.
    `.trim()},{slug:"mcp-servers-unix-pipes-of-ai",editorial:!0,title:"Why MCP Servers Are the Unix Pipes of AI",description:"The Unix philosophy changed software forever: small tools, composable via pipes. MCP does the same thing for AI agents. Why that matters for building agent systems.",date:"2026-03-24",tags:["MCP","Architecture","Developer Tools"],readTime:"5 min",productSlug:"lixicg",ctaHook:"Production MCP server templates with auth, rate limiting, and Docker deployment.",content:`
In 1978, Doug McIlroy wrote the Unix philosophy in three sentences. The one that matters: "Write programs that do one thing and do it well. Write programs to work together."

Forty-eight years later, we're rediscovering this idea for AI agents, and calling it MCP.

## What MCP Actually Is

The Model Context Protocol is a JSON-RPC spec that lets AI models call external tools through a standardized interface. An MCP server exposes a list of tools. A client (like Claude Code) connects to those servers and gets access to those tools. The model calls them by name with arguments, and gets back structured results.

That's it. No custom integrations per model. No bespoke SDKs. Define your tool once, and any MCP-compatible client can use it.

Sound familiar? It should. It's stdin/stdout with better types.

## The Unix Parallel

The power of Unix pipes wasn't any individual tool; it was composability. \`cat file | grep pattern | sort | uniq -c\` does something none of those tools could do alone. The protocol (text on stdout/stdin) made composition possible without any of the tools knowing about each other.

MCP does the same thing for AI tools. The protocol is JSON-RPC over stdio (or HTTP). The tools are small, focused, independently deployable. The composition happens in the model's reasoning layer instead of a shell.

The key insight in both cases: **the protocol is the product**. Not any single tool. Not any particular capability. The protocol is what enables the ecosystem.

## What This Looks Like in Practice

The [agent infrastructure at Edgeless Lab](/blog/building-ai-agent-infrastructure-solo) runs several MCP servers. Each one does one thing:

**ChromaDB search server**: semantic search across a knowledge base of 7,000+ documents. Takes a query string, returns ranked results with similarity scores. That's the whole API.

**Obsidian vault query server**: read and search the Obsidian vault by tag, folder, or full-text. Agents can retrieve specific notes or scan for relevant context without touching the filesystem directly.

**Backlog management server**: read and write tasks in a structured backlog. Lets agents file their own tasks, check status, and mark things complete. The backlog is a text file format; the MCP server is the typed interface over it.

**Inter-agent messaging server**: a pub/sub channel for agents to send messages to each other. An orchestrator agent can dispatch work; worker agents can report back. Real-time, without a message queue.

None of these tools know about each other. Any agent can use any combination. Add a new server and it's immediately available to every agent in the system.

## Why Libraries Were the Wrong Model

Before MCP, tool access meant libraries. You'd import the Anthropic SDK, write a tool schema, register it with the client. Then repeat for every model you wanted to support. When OpenAI updated their function calling format, you'd update every integration.

This created tight coupling between your tools and your model provider. Switching models meant rewriting integrations. Testing a tool meant testing it inside a model's context.

MCP decouples these completely. The server doesn't know what model is calling it. The model doesn't care how the server is implemented. The server could be TypeScript, Python, Go. Doesn't matter. The protocol is the boundary.

This is exactly what made Unix pipes powerful: \`grep\` doesn't know it's receiving input from \`cat\`. It just reads from stdin.

## Tools as Services, Not Libraries

The shift MCP enables is treating tools as services rather than library calls. This changes the operational model significantly:

You can **deploy tools independently**. The Obsidian server runs on your Mac (it needs local filesystem access). The ChromaDB server runs wherever ChromaDB is. The trading data server runs on the VPS. Each deployed where it makes sense.

You can **test tools independently**. An MCP server is just an HTTP or stdio server. You can test it with \`curl\` or any JSON-RPC client. No model required.

You can **version tools independently**. Update the ChromaDB server without touching anything else. Agents pick up the new tool definition on next connection.

You can **compose without coordination**. Agent A uses the vault server and the backlog server. Agent B uses the vault server and the messaging server. Neither knows about the other, but they share infrastructure.

## The Ecosystem Implication

The deeper implication is that MCP creates a tool ecosystem that outlives any particular model or provider. A tool you write today for Claude will work with whatever succeeds Claude. The investment is in the tool, not the integration.

This is how Unix tools from the 1970s still run on your Mac today. The protocol survived everything else changing.

MCP is early. The tooling is rough in places. Server discovery is manual. Error handling is inconsistent. But the protocol is right, and the ecosystem will follow.

For anyone building agent infrastructure: start treating your tools as MCP servers, not library functions. The composition benefits compound quickly, and you're building on the right abstraction for the next decade of AI development.

See the [lab experiments page](/lab) for the MCP servers running in this system, or read the [infrastructure deep-dive](/blog/building-ai-agent-infrastructure-solo) for the full architecture.
    `.trim()},{slug:"generative-art-pen-plotters",editorial:!0,title:"Generative Art for Pen Plotters: A Technical Primer",description:"Pen plotter art isn't screen art printed on paper. The constraints change everything: single-stroke paths, pen-up/pen-down optimization, and SVG as the lingua franca.",date:"2026-03-23",tags:["Generative Art","Creative Coding","Pen Plotters"],readTime:"7 min",productSlug:"gen-art-starter",ctaHook:"10 plotter-ready generators with SVG optimization and AI scoring rubrics.",content:`
When you generate art for a screen, mistakes are invisible. A triangle with a slight gap renders fine; the display fills it in. Lines can overlap arbitrarily. Color can be sampled per-pixel.

When you generate art for a pen plotter, every mistake is permanent. The pen either touches the paper or it doesn't. Overlapping paths mean double-inking, which looks wrong on cotton paper. A gap in a stroke is a gap in the physical ink line.

The constraints aren't limitations; they're design parameters. Understanding them changes how you write generators.

## SVG Is the Lingua Franca

Every plotter workflow I've found converges on SVG as the interchange format. The reasons are practical:

SVG paths are the natural representation of "move pen to X,Y, draw to X2,Y2." The \`M\` (moveto), \`L\` (lineto), and \`C\` (curveto) commands map directly to plotter motion primitives.

SVG is text. You can generate it from any language, inspect it in any editor, and debug it by reading the coordinates.

The AxiDraw driver (the most common plotter for fine art) accepts SVG directly. Your generator outputs an SVG file, you open it in Inkscape with the AxiDraw plugin, and it plots.

The critical SVG parameter: stroke width in the SVG should correspond to the actual pen tip width. For a 0.3mm Micron, set stroke-width to 0.3mm in the SVG. This matters when you're evaluating density; you want the visual preview to approximate the physical result.

## Why Single-Stroke Paths Matter

A screen renderer draws each path in isolation. Overlapping paths layer visually, and the result is color mixing. Fine.

A plotter pen tracks across paper physically. If path A overlaps path B, the pen crosses that area twice. On thick paper with light ink, this doubles the ink deposit and creates visible striping. On thin paper, it can saturate and bleed.

The solution: design generators that produce non-overlapping paths, or at minimum, minimize overlap. For fill patterns (hatching, stippling), think about coverage rather than overlap.

There's a subtler version of this problem with continuous paths. A generator might output 500 separate line segments when it could output 10 continuous strokes. More pen lifts means more travel time and more opportunities for the pen to blot when it returns to paper. Continuous strokes produce cleaner, faster plots.

The optimization problem: given a set of line segments, find the traversal order that minimizes total pen-up travel distance. This is a variant of the Traveling Salesman Problem, NP-hard in general, but good approximations exist. The \`vpype\` tool does this automatically on any SVG input, which is worth knowing about.

## Algorithm Families That Work Well

Not all generative art algorithms translate equally to plotters. A few that reliably produce good physical results:

**Flow fields** simulate vector fields and draw particle traces through them. The traces are naturally continuous paths. Perlin noise fields produce organic, almost geological results. The key parameter is step size; smaller steps mean smoother curves but longer files.

**Lorenz attractors and other chaotic systems** produce infinitely non-repeating paths through 3D space. Projecting them onto 2D gives dense, tangled line work that looks good at high iteration counts. Because the path never closes, you can control density by controlling iteration count.

**Voronoi tessellations** produce networks of bounded cells. The cell edges are natural single-stroke paths. Relaxed Voronoi (Lloyd's algorithm) produces more uniform cell sizes. Combined with variable cell sizing based on an input image, you get dithered portraits made of geometry.

**Recursive subdivision** (quadtrees, triangle subdivision) produces patterns with self-similar structure at multiple scales. The subdivision boundary lines are natural paths. Start with a rectangle, subdivide based on local image intensity, and you get an abstract representation of any input image.

**Truchet tiles** fill a grid with simple tile shapes that connect across edges. The key insight: design tiles so connected lines span multiple tiles, creating long continuous paths rather than isolated shapes. This minimizes pen lifts and produces more interesting visual flow.

## The AI Scoring Pipeline

Running 105+ experiments manually would mean 105+ physical plots. I don't have that kind of paper budget or time.

Instead, every generator gets scored by an LLM judge before it ever touches the plotter. The scoring criteria:

**Composition**: does the piece use the available space well? Heavy clustering in one corner scores low. Balanced visual weight across the frame scores high.

**Line density**: too sparse looks unfinished; too dense loses the detail that makes plotter art interesting at close range. The target density depends on paper size. For A4, I aim for 40-60% coverage.

**Visual interest**: the hardest to formalize. Does the piece have focal points? Does it reward looking at it for more than 10 seconds? The judge looks for variety in mark density, interesting transitions, and emergent structure that wasn't explicitly programmed.

**Plottability**: are there construction artifacts? Tiny isolated marks that would require a full pen lift cycle for one dot? Very long straight lines that require precise paper grip?

The judge generates a score from 0-10 and a brief explanation. I only plot generators that score 7+. This has saved a significant amount of time and paper.

The current scoring prompt and rubric are in the [pen plotter experiment log](/lab/pen-plotter-art).

## Materials Matter

The generator doesn't exist in isolation. The same SVG looks different depending on paper and ink.

**Paper**: I use Strathmore 400 Series Bristol (vellum surface, 270gsm) for production plots. It takes ink cleanly without bleed, is stiff enough for long sessions without cockling, and has enough texture to give ink strokes slight character. For prototyping I use Canson marker paper; it's cheaper and the smooth surface is more forgiving of overlapping paths.

**Ink**: Pigma Micron 0.1mm and 0.3mm for most work. The Micron ink is archival and doesn't fade. For single-color pieces, I sometimes use a Sailor Profit fountain pen with Pilot Iroshizuku ink; the sheen on coated paper is something screen art can't replicate.

**Speed**: The AxiDraw's motor speed directly affects line quality. Too fast and the pen skips on texture. Too slow and ink bleeds at corners where the pen pauses. I run at 60% of max speed for most work, 40% for very fine detail.

## Getting Started

If you're writing your own generators, start with a flow field. It's the most forgiving algorithm family: organic, continuous paths, naturally limited overlap. Set your canvas to A4 at 96 DPI (the SVG default), use stroke-width 0.5mm for testing, and score the output before committing to a plot.

The [Edgeless lab experiments](/lab) page logs all the generator experiments including source code for the ones that scored well. The Lorenz attractor generator, the Voronoi dither, and the recursive quad subdivision are all open.

If you want to go deeper into the scoring and iteration pipeline, the [pen plotter autoresearch pattern](/lab) documents how the AI-in-the-loop workflow runs.
    `.trim()},{slug:"building-ai-agent-infrastructure-solo",editorial:!0,title:"Building AI Agent Infrastructure as a Solo Developer",description:"How I built a multi-agent system with MCP servers, vector memory, and autonomous trading, all running 24/7 from a single VPS.",date:"2026-03-21",tags:["Agents","MCP","Infrastructure"],readTime:"8 min",productSlug:"plbzo",ctaHook:"The full agent cookbook: dispatch patterns, bus protocol, and production deployment configs.",content:`
When people hear "multi-agent system," they picture a team of engineers, months of planning, and enterprise infrastructure. I built one by myself, and it runs on a single $15/month VPS.

This post covers the architecture decisions, the tools that made it possible, and the parts that surprised me.

## The Stack

The system has five layers:

**Claude Code** sits at the top as the primary agent runtime. Skills, hooks, and memory give it persistent context across sessions.

**MCP Servers** provide the tool layer. Instead of hardcoding capabilities, each tool is a standalone server that any agent can call. Search the knowledge vault? That's an MCP tool. Dispatch a task to another agent? MCP tool. Check VPS health? MCP tool.

**ChromaDB** handles vector memory. Every document, conversation summary, and learned pattern gets embedded and stored. When an agent needs context, it queries by semantic similarity rather than keyword matching.

**Obsidian** is the knowledge vault: 7,000+ markdown files organized by topic. It's the human-readable layer that agents can also query through MCP.

**Hetzner VPS** runs the always-on processes: the Telegram gateway, the cron jobs, everything that needs to persist beyond a terminal session.

## Why MCP Changes Everything

Before MCP, giving an AI agent access to tools meant writing custom integrations for each model provider. MCP standardizes the protocol: define your tool once, and any MCP-compatible client can use it.

I have servers for ChromaDB search, Obsidian vault queries, backlog management, and inter-agent messaging. Adding a new capability means writing one server, not modifying every agent.

The Effect-TS implementation makes the servers composable and type-safe. Error handling is built into the type system rather than scattered across try-catch blocks.

## Memory That Actually Works

The biggest challenge with AI agents isn't reasoning; it's memory. A conversation ends, and everything learned evaporates.

I open-sourced the basic version as the [Claude Memory Kit](https://github.com/edgeless-ai/claude-memory-kit) and built a [Pro version](https://edgelessai.gumroad.com/l/claude-memory-kit) with stack-specific libraries and advanced patterns.

The solution is a three-layer memory system:

1. **ChromaDB** for semantic search across all stored knowledge
2. **File-based memory** for structured facts (user preferences, project context, feedback)
3. **Obsidian vault** for human-curated knowledge that agents can also access

Each layer serves a different retrieval pattern. ChromaDB handles "find me something similar to X." File memory handles "what did the user tell me about Y." The vault handles "what's the canonical documentation for Z."

## The Safety Layer

The autonomous agent that lost $252 was the forcing function for getting the infrastructure right. An agent that takes irreversible actions without guardrails is worse than no agent at all.

The hooks system runs on every tool call, 24/7. Its architecture:

- **Damage control**: Blocks destructive commands before they execute
- **Scope guard**: Prevents agents from exceeding their explicit mandate
- **Financial gate**: Requires verification protocol before any transaction
- **Reversibility classifier**: Categorizes actions by blast radius
- **Completion verifier**: Evidence-based proof that work is actually done

The key insight: the agent doesn't need to be smart about everything. It needs guardrails that are smarter than its worst impulse.

## Lessons Learned

**Start with one agent, not three.** Multi-agent orchestration sounds impressive but adds complexity. Get one agent working end-to-end before adding coordination.

**MCP servers are the right abstraction.** Tools as services, not libraries. This makes testing, deployment, and access control straightforward.

**Memory is infrastructure, not a feature.** Treat it like a database, with schemas, retention policies, and access patterns.

**VPS beats serverless for always-on agents.** When your agent needs to maintain state, respond to events, and run cron jobs, a $15 VPS is simpler than a constellation of Lambda functions.

**The tools exist.** Claude Code, MCP, ChromaDB, PM2: the building blocks for agent infrastructure are production-ready today. The bottleneck isn't technology, it's architecture.

## What's Next

The system keeps growing. Current priorities: improving inter-agent communication (an "agent bus" for real-time messaging), better memory consolidation (merging redundant knowledge), and more sophisticated trading strategies.

The goal isn't to build the most complex system. It's to build the most useful one, with the least moving parts.
    `.trim()},{slug:"how-claude-code-memory-works",editorial:!0,title:"How Claude Code Memory Actually Works",description:"Claude forgets everything between sessions. File-based memory fixes that. The simplest setup, and why it changes how you work with AI.",date:"2026-03-21",tags:["Claude Code","Memory","Developer Tools"],readTime:"6 min",productSlug:"claude-memory-kit",ctaHook:"CLAUDE.md template, 4-type memory taxonomy, and the session initializer script.",content:`
Every Claude Code session starts the same way: a blank slate. No memory of yesterday's architecture decisions. No recall of your coding conventions. No idea that you spent three hours debugging that OAuth flow last week.

This is the single biggest friction point in AI-assisted development. Not model capability. Not context windows. Memory.

## The Problem Is Structural

Claude Code reads instructions from a file called \`CLAUDE.md\` at the start of every session. That's it. There's no built-in persistence layer. No session history. No learning from past interactions.

So every session, you repeat yourself: "We use TypeScript, not JavaScript." "The API lives in \`src/api/\`, not \`api/\`." "Don't use default exports." "We already tried approach X and it failed because Y."

This isn't a minor annoyance. It's a compounding tax on every interaction.

## File-Based Memory Fixes This

The solution is surprisingly simple: structured markdown files that Claude reads automatically at session start.

No databases. No vector stores. No infrastructure. Just files in your repo that Claude already knows how to read.

The memory system layers on top of Claude Code's built-in \`CLAUDE.md\` hierarchy. Claude loads these files automatically. You don't need plugins or configuration.

## The 4 Memory Types

After running this pattern in production across multiple projects, I've found four distinct memory types that cover every use case.

### 1. User Memory

Who you are and how you work. Follows you across every project.

\`\`\`yaml
name: User Role
type: user
---
Senior backend engineer, 8 years Go.
New to React frontend in this project.
Prefer explanations mapping frontend concepts to backend analogues.
\`\`\`

### 2. Feedback Memory

Corrections that stick. The highest-value memory type. Every correction makes every future session better.

\`\`\`yaml
name: No mocking in integration tests
type: feedback
---
Integration tests must hit a real database, not mocks.
Why: Mocked tests passed but prod migration failed last quarter.
\`\`\`

### 3. Project Memory

Architecture decisions, conventions, and infrastructure specific to one codebase.

\`\`\`yaml
name: API Migration Freeze
type: project
---
No breaking API changes until 2026-03-15 (mobile release cut).
Any endpoint modifications must be backwards-compatible.
\`\`\`

### 4. Reference Memory

Pointers to where things live. Tools, APIs, dashboards.

\`\`\`yaml
name: Bug Tracker
type: reference
---
Production bugs: Linear project "PLATFORM"
Feature requests: Linear project "ROADMAP"
Design specs: Figma workspace "Product Design 2026"
\`\`\`

## What Changes in Practice

With memory in place, sessions start differently. Instead of 10 minutes of context-setting, you jump straight into the work.

Claude remembers that your test suite uses Vitest, not Jest. It knows the deploy script is at \`scripts/deploy.sh\`, not \`deploy.sh\`. It recalls that you tried Redis caching last month and hit connection pooling issues.

After a month of accumulated feedback memory, Claude makes roughly 60% fewer mistakes that require correction. That's not a benchmark; that's from tracking corrections across my own projects.

## The Maintenance Problem

Raw memory files work, but they accumulate cruft. Outdated entries. Contradictory instructions. Files that grow past useful size.

The discipline: review monthly, archive aggressively, keep each file under 200 lines. Memory that's too long defeats the purpose; Claude spends context window on stale instructions instead of your actual task.

## Get Started

I've open-sourced the base memory kit with templates for all four memory types, a starter CLAUDE.md structure, and setup instructions.

**Free:** [Claude Memory Kit on GitHub](https://github.com/edgeless-ai/claude-memory-kit)

The free version covers 90% of use cases. For production patterns including stack-specific libraries (React/Next.js, Python/FastAPI, Go, Rails, Rust), multi-project memory architectures, and CLAUDE.md templates:

**Pro ($29):** [Claude Memory Kit Pro on Gumroad](https://edgelessai.gumroad.com/l/claude-memory-kit)

The best time to set up memory is before your next session. Takes 15 minutes, saves hours every week.
    `.trim()}],C="One developer shipping autonomous agents, MCP servers, and generative art. 18 products live. Everything open source.",I='300 14px "Geist"';e.s(["AboutBlurb",0,function(){let e=(0,a.useRef)(null),[o,n]=(0,a.useState)(0);(0,a.useEffect)(()=>{if(!e.current)return;let t=()=>{e.current&&n(e.current.clientWidth)};t();let a=new ResizeObserver(t);return a.observe(e.current),()=>a.disconnect()},[]);let i=function(e,t,s){let{ready:r,prepare:o,layout:n,prepareWithSegments:i,walkLineRanges:l}=(0,g.usePreText)("Geist"),[c,h]=(0,a.useState)(null),d=(0,a.useRef)(""),u=(0,a.useCallback)(()=>{if(!r||!o||!n||!i||!l||s<=0)return;let a=`${e}::${t}::42::${s}`;if(a===d.current)return;d.current=a;let c=o(e,t);if(!c)return;let u=n(c,s,42);if(!u||u.lineCount<=1){let a=i(e,t);if(!a)return;let r=0;l(a,s,e=>{e.width>r&&(r=e.width)}),h(Math.ceil(r));return}let p=i(e,t);if(!p)return;let m=0;l(p,s,e=>{e.width>m&&(m=e.width)});let g=Math.ceil(m),f=n(c,g,42);if(f&&f.lineCount>u.lineCount)for(;g<s;){let e=n(c,++g,42);if(e&&e.lineCount<=u.lineCount)break}h(g)},[r,e,t,42,s,o,n,i,l]);return(0,a.useEffect)(()=>{u()},[u]),c}("One person shipping agents, MCP servers, generative art, and developer tools. In production, in the open, since day one. No pitch decks. No vaporware.",'300 28px "Geist"',o);return(0,t.jsxs)("div",{className:"max-w-2xl",ref:e,children:[(0,t.jsxs)("p",{className:"text-2xl sm:text-3xl font-light leading-[1.5]",style:{color:"var(--text-secondary)",animation:"fadeInUp 0.6s cubic-bezier(0.16,1,0.3,1) both",...i?{maxWidth:`${i}px`}:{}},children:[(0,t.jsx)("span",{style:{color:"var(--text-primary)"},children:"One person"})," shipping agents, MCP servers, generative art, and developer tools. In production, in the open, since day one."," ",(0,t.jsx)("span",{style:{color:"var(--text-primary)"},children:"No pitch decks. No vaporware."})]}),(0,t.jsx)("div",{className:"mt-8",style:{animation:"fadeInUp 0.4s cubic-bezier(0.16,1,0.3,1) 0.2s both"},children:(0,t.jsxs)(s.default,{href:"/about",className:"text-sm font-medium flex items-center gap-1.5 transition-colors hover:text-white",style:{color:"var(--accent)"},children:["About the lab ",(0,t.jsx)(r,{size:14})]})})]})},"CapabilitiesGrid",0,function({capabilities:e}){return(0,t.jsx)("div",{className:"grid grid-cols-1 md:grid-cols-2 gap-4",children:e.map((e,a)=>(0,t.jsxs)("div",{className:"rounded-xl border overflow-hidden",style:{background:"var(--bg-base)",borderColor:"var(--border-subtle)",animation:`fadeInUp 0.4s cubic-bezier(0.16,1,0.3,1) ${.08*a}s both`},children:[(0,t.jsxs)("div",{className:"px-5 py-3 border-b flex items-center justify-between",style:{borderColor:"var(--border-subtle)"},children:[(0,t.jsx)("span",{className:"text-xs font-mono",style:{color:"var(--text-secondary)"},children:e.label}),(0,t.jsx)("span",{className:"w-1.5 h-1.5 rounded-full",style:{background:"var(--green)"}})]}),(0,t.jsx)("pre",{className:"px-5 py-4 text-xs leading-[1.8] font-mono whitespace-pre overflow-x-auto",style:{color:"var(--green)"},children:e.snippet})]},e.label))})},"ExperimentsGrid",0,function({experiments:e}){return(0,t.jsx)("div",{className:"grid grid-cols-1 gap-3 sm:grid-cols-2 lg:grid-cols-4",children:e.map((e,a)=>(0,t.jsxs)("a",{href:e.href,...e.external?{target:"_blank",rel:"noopener noreferrer"}:{},className:"group relative rounded-xl border p-5 transition-all hover:scale-[1.02] flex flex-col",style:{background:"var(--bg-surface)",borderColor:"var(--border-subtle)",animation:`fadeInUp 0.4s cubic-bezier(0.16,1,0.3,1) ${.08*a}s both`},children:[(0,t.jsxs)("div",{className:"flex items-center justify-between mb-3",children:[(0,t.jsx)("span",{className:"text-xs font-mono uppercase tracking-[0.12em]",style:{color:"var(--accent)"},children:e.category}),e.status&&(0,t.jsx)("span",{className:"text-[10px] font-mono uppercase tracking-[0.1em] px-1.5 py-0.5 rounded",style:{background:"Live"===e.status?"var(--green-muted)":"var(--accent-muted)",color:"Live"===e.status?"var(--green)":"var(--accent)"},children:e.status})]}),(0,t.jsx)("span",{className:"text-sm font-medium block mb-2",style:{color:"var(--text-primary)"},children:e.title}),e.description&&(0,t.jsx)("p",{className:"text-xs line-clamp-2 mb-3 flex-1",style:{color:"var(--text-tertiary)",lineHeight:1.6},children:e.description}),e.stack&&e.stack.length>0&&(0,t.jsx)("div",{className:"flex flex-wrap gap-1.5 mt-auto",children:e.stack.map(e=>(0,t.jsx)("span",{className:"text-[10px] font-mono px-1.5 py-0.5 rounded",style:{background:"rgba(255,255,255,0.05)",color:"var(--text-tertiary)"},children:e},e))}),(0,t.jsx)("div",{className:"absolute top-5 right-5 opacity-0 group-hover:opacity-100 transition-opacity",style:{color:"var(--text-tertiary)"},children:(0,t.jsx)(o.ArrowUpRight,{size:14})})]},e.title))})},"FeaturedGrid",0,function({projects:e}){return(0,t.jsx)("div",{className:"grid grid-cols-1 md:grid-cols-3 gap-4 md:grid-rows-[auto_auto]",children:e.map((e,a)=>(0,t.jsx)("div",{className:e.span,children:(0,t.jsx)(h,{className:"h-full",href:e.href,children:(0,t.jsxs)("div",{style:{animation:`fadeInUp 0.5s cubic-bezier(0.16,1,0.3,1) ${.1*a}s both`},children:[(0,t.jsxs)("div",{className:"w-full rounded-lg mb-6 overflow-hidden",style:{background:"rgba(0,0,0,0.4)",border:"1px solid var(--border-subtle)"},children:[(0,t.jsxs)("div",{className:"flex items-center gap-1.5 px-3 py-2.5 border-b",style:{borderColor:"var(--border-subtle)"},children:[(0,t.jsx)("div",{className:"w-2 h-2 rounded-full",style:{background:"rgba(255,255,255,0.1)"}}),(0,t.jsx)("div",{className:"w-2 h-2 rounded-full",style:{background:"rgba(255,255,255,0.1)"}}),(0,t.jsx)("div",{className:"w-2 h-2 rounded-full",style:{background:"rgba(255,255,255,0.1)"}}),(0,t.jsx)("span",{className:"ml-2 text-xs font-mono",style:{color:"var(--text-tertiary)"},children:e.title.toLowerCase().replace(/\s+/g,"-")})]}),(0,t.jsx)("pre",{className:`px-3 py-3 text-xs leading-[1.7] font-mono whitespace-pre overflow-hidden ${0===a?"min-h-[120px]":"min-h-[80px]"}`,style:{color:"var(--green)"},children:e.snippet})]}),(0,t.jsx)("div",{className:"flex items-start justify-between gap-4",children:(0,t.jsxs)("div",{children:[(0,t.jsx)("h3",{className:"text-lg font-semibold mb-1.5",style:{color:"var(--text-primary)"},children:e.title}),(0,t.jsx)("p",{className:"text-sm max-w-md",style:{color:"var(--text-secondary)",lineHeight:1.6},children:e.description})]})}),(0,t.jsx)("div",{className:"flex flex-wrap gap-2 mt-4",children:e.tags.map(e=>(0,t.jsx)("span",{className:"px-2.5 py-1 text-xs font-mono rounded-md",style:{background:"var(--accent-muted)",color:"var(--accent)"},children:e},e))})]})})},e.title))})},"HeroSection",0,function(){return(0,t.jsxs)("section",{className:"relative flex min-h-[92svh] items-center px-6 pb-16 pt-28 md:min-h-screen md:items-end md:pb-24 md:pt-32",children:[(0,t.jsx)(p,{}),(0,t.jsxs)("div",{className:"relative max-w-[1280px] w-full mx-auto grid grid-cols-1 gap-12 lg:grid-cols-[1.25fr_1fr] lg:items-end",children:[(0,t.jsxs)("div",{className:"min-w-0",children:[(0,t.jsx)(c,{children:(0,t.jsxs)("div",{className:"inline-flex items-center gap-2.5 mb-8 px-3 py-1.5 rounded-full border",style:{borderColor:"rgba(52, 211, 153, 0.25)",background:"rgba(52, 211, 153, 0.06)"},children:[(0,t.jsxs)("span",{className:"relative flex h-2 w-2",children:[(0,t.jsx)("span",{className:"absolute inline-flex h-full w-full rounded-full opacity-60 animate-ping",style:{background:"var(--green)"}}),(0,t.jsx)("span",{className:"relative inline-flex h-2 w-2 rounded-full",style:{background:"var(--green)"}})]}),(0,t.jsx)("span",{className:"text-[11px] font-mono uppercase tracking-[0.14em]",style:{color:"var(--green)"},children:"Shipping daily · Live now"})]})}),(0,t.jsxs)("h1",{className:"text-[clamp(3rem,8vw,7.5rem)] font-bold leading-[0.88] tracking-[-0.04em]",style:{color:"var(--text-primary)"},children:[(0,t.jsx)(l,{text:"Built solo",delay:.1}),(0,t.jsx)("br",{}),(0,t.jsx)("span",{style:{color:"var(--accent)"},children:(0,t.jsx)(l,{text:"Shipped",delay:.3})})," ",(0,t.jsx)(l,{text:"open",delay:.45})]}),(0,t.jsx)(c,{delay:.7,children:(0,t.jsx)("div",{className:"mt-8 max-w-xl",children:(0,t.jsx)(f,{text:C,font:'300 18px "Geist"',lineHeight:28,cursorRadius:36,cursorColor:"var(--accent)",className:"text-lg font-light",style:{color:"var(--text-secondary)"},fallback:(0,t.jsx)("p",{style:{lineHeight:1.55},children:C})})})}),(0,t.jsx)(c,{delay:.85,children:(0,t.jsxs)("div",{className:"mt-8 flex items-center gap-2.5 max-w-xl text-[12px] font-mono",style:{color:"var(--text-tertiary)"},children:[(0,t.jsx)("span",{className:"px-2 py-0.5 rounded uppercase tracking-[0.12em]",style:{background:"var(--accent-muted)",color:"var(--accent)"},children:"Now"}),(0,t.jsxs)("span",{children:["Shipping"," ",(0,t.jsx)(s.default,{href:"/products/launch-toolkit",className:"underline-offset-2 hover:underline transition-colors hover:text-white",style:{color:"var(--text-secondary)"},children:"Digital Product Launch Toolkit"})," ","· 7 products in 7 days"]})]})}),(0,t.jsx)(c,{delay:.9,children:(0,t.jsxs)("div",{className:"mt-8 flex flex-col items-start gap-4 sm:flex-row sm:items-center sm:gap-5",children:[(0,t.jsxs)(s.default,{href:"/products",className:"inline-flex items-center gap-2 h-11 px-6 text-sm font-medium text-white rounded-full transition-all hover:brightness-110 hover:scale-[1.02]",style:{background:"var(--accent)"},onClick:()=>i("hero_view_products","/products"),children:["Browse 18 products ",(0,t.jsx)(r,{size:15})]}),(0,t.jsxs)(s.default,{href:"/projects",className:"inline-flex items-center gap-2 h-11 px-6 text-sm font-medium rounded-full border transition-all hover:brightness-110 hover:scale-[1.02]",style:{color:"var(--text-secondary)",borderColor:"var(--border-subtle)"},onClick:()=>i("hero_view_projects","/projects"),children:["See what’s running ",(0,t.jsx)(r,{size:15})]}),(0,t.jsxs)("a",{href:"https://github.com/edgeless-ai",className:"text-sm font-medium flex items-center gap-1.5 transition-colors hover:text-white",style:{color:"var(--text-secondary)"},children:["GitHub ",(0,t.jsx)(o.ArrowUpRight,{size:14})]})]})})]}),(0,t.jsx)(c,{delay:.5,children:(0,t.jsx)("div",{className:"hidden lg:block",children:(0,t.jsx)(m.GenerativeAscii,{})})})]})]})},"ProductHighlight",0,function(){let e=x.filter(e=>"Free"!==e.price).slice(0,6),a=x.find(e=>"Free"===e.price),s=x.length-e.length-!!a;return(0,t.jsxs)("div",{className:"grid grid-cols-1 sm:grid-cols-2 lg:grid-cols-4 gap-3",children:[e.map((e,a)=>(0,t.jsxs)("a",{href:e.href,target:"_blank",rel:"noopener noreferrer",className:"group block rounded-xl border p-5 transition-all hover:scale-[1.01] hover:border-white/20",style:{background:"var(--bg-surface)",borderColor:"var(--border-subtle)",animation:`fadeInUp 0.4s cubic-bezier(0.16,1,0.3,1) ${.08*a}s both`},children:[(0,t.jsxs)("div",{className:"flex items-center justify-between mb-2",children:[(0,t.jsx)("span",{className:"text-sm font-semibold",style:{color:"var(--text-primary)"},children:e.name}),(0,t.jsx)(o.ArrowUpRight,{size:14,className:"opacity-0 group-hover:opacity-100 transition-opacity",style:{color:"var(--text-tertiary)"}})]}),(0,t.jsx)("span",{className:"text-lg font-bold font-mono block mb-2",style:{color:"var(--accent)"},children:e.price}),(0,t.jsx)("p",{className:"text-xs",style:{color:"var(--text-tertiary)",lineHeight:1.6},children:e.description})]},e.name)),a&&(0,t.jsxs)("a",{href:"/products",className:"group block rounded-xl border p-5 transition-all hover:scale-[1.01] hover:border-white/20",style:{background:"var(--bg-surface)",borderColor:"var(--border-subtle)",animation:"fadeInUp 0.4s cubic-bezier(0.16,1,0.3,1) 0.24s both"},children:[(0,t.jsxs)("div",{className:"flex items-center justify-between mb-2",children:[(0,t.jsx)("span",{className:"text-sm font-semibold",style:{color:"var(--text-primary)"},children:a.name}),(0,t.jsx)("span",{className:"text-xs font-mono px-2 py-0.5 rounded-md",style:{background:"rgba(34,197,94,0.15)",color:"var(--green)"},children:"Free"})]}),(0,t.jsx)("p",{className:"text-xs mb-3",style:{color:"var(--text-tertiary)",lineHeight:1.6},children:a.description}),(0,t.jsxs)("span",{className:"text-xs font-medium flex items-center gap-1",style:{color:"var(--accent)"},children:["+",s," more products ",(0,t.jsx)(r,{size:12})]})]})]})},"RecentActivity",0,function(){let e=[...T].sort((e,t)=>new Date(t.date).getTime()-new Date(e.date).getTime()).slice(0,8);return(0,t.jsx)("ul",{className:"divide-y",style:{borderColor:"var(--border-subtle)"},children:e.map((e,a)=>{let r,o,n=!!e.isLaunch;return(0,t.jsx)("li",{style:{borderColor:"var(--border-subtle)",animation:`fadeInUp 0.4s cubic-bezier(0.16,1,0.3,1) ${.05*a}s both`},className:"border-b first:border-t",children:(0,t.jsxs)(s.default,{href:`/blog/${e.slug}`,className:"group grid grid-cols-[auto_auto_1fr_auto] items-center gap-4 py-4 px-1 transition-colors",children:[(0,t.jsx)("span",{className:"text-[11px] font-mono tabular-nums shrink-0 w-[68px]",style:{color:"var(--text-tertiary)"},children:e.date.slice(5)}),(0,t.jsx)("span",{className:"text-[10px] font-mono uppercase tracking-[0.12em] px-2 py-0.5 rounded shrink-0",style:{background:n?"var(--accent-muted)":"var(--bg-surface)",color:n?"var(--accent)":"var(--text-tertiary)",border:"1px solid var(--border-subtle)"},children:n?"launch":"post"}),(0,t.jsx)("span",{className:"text-[14px] font-medium truncate transition-colors group-hover:text-white",style:{color:"var(--text-primary)"},children:e.title}),(0,t.jsx)("span",{className:"text-[11px] font-mono shrink-0 hidden sm:inline",style:{color:"var(--text-tertiary)"},children:(r=new Date(e.date).getTime(),(o=Math.floor((Date.now()-r)/864e5))<1?"today":1===o?"yesterday":o<30?`${o}d ago`:o<365?`${Math.floor(o/30)}mo ago`:`${Math.floor(o/365)}y ago`)})]})},e.slug)})})},"StackFlow",0,function({nodes:e}){let s=(0,a.useMemo)(()=>(function(e){let t=[];for(let a=0;a<e.length;a++){let s=e[a];t.push({text:s.label,font:'600 14px "Geist Mono"',lineHeight:28,style:{color:"var(--accent)"}}),t.push({text:`\u00A0${s.sublabel}`,font:I,lineHeight:28,style:{color:"var(--text-tertiary)"}}),a<e.length-1&&t.push({text:" → ",font:I,lineHeight:28,style:{color:"var(--border-focus)"}})}return t})(e),[e]);return(0,t.jsxs)(t.Fragment,{children:[(0,t.jsx)("div",{className:"max-w-2xl",children:(0,t.jsx)(w,{segments:s,style:{color:"var(--text-tertiary)"}})}),(0,t.jsx)("div",{className:"mt-8 max-w-2xl",children:(0,t.jsx)(v,{text:"Agents call tools through MCP. Knowledge persists across sessions in vector memory and markdown vaults. A single VPS keeps the whole system running, unattended. Every tool is an MCP server. Every agent can use any tool. Add a new capability and it's immediately available to every agent in the system.",font:'300 14px "Geist"',lineHeight:24,orbCount:3,orbRadius:36,textColor:"var(--text-tertiary)"})})]})},"SubscribeSection",0,function(){return(0,t.jsx)("section",{className:"px-6 py-20 border-t",style:{borderColor:"var(--border-subtle)"},children:(0,t.jsx)("div",{className:"max-w-[1280px] mx-auto",children:(0,t.jsx)("div",{className:"max-w-lg",children:(0,t.jsxs)("div",{style:{animation:"fadeInUp 0.4s cubic-bezier(0.16,1,0.3,1) both"},children:[(0,t.jsxs)("div",{className:"flex items-center gap-2 mb-4",children:[(0,t.jsx)("span",{className:"w-1.5 h-1.5 rounded-full",style:{background:"var(--green)"}}),(0,t.jsx)("span",{className:"text-xs font-mono",style:{color:"var(--text-tertiary)"},children:"Stay in the loop"})]}),(0,t.jsx)("h2",{className:"text-2xl font-semibold tracking-tight mb-2",style:{color:"var(--text-primary)"},children:"Everything ships on GitHub."}),(0,t.jsx)("p",{className:"text-sm mb-6",style:{color:"var(--text-secondary)",lineHeight:1.7},children:"Agent frameworks, generative art, and developer tools - all in the open."}),(0,t.jsxs)("a",{href:"https://github.com/edgeless-ai",target:"_blank",rel:"noopener noreferrer",className:"inline-flex items-center gap-2 h-11 px-6 text-sm font-medium text-white rounded-full transition-all hover:brightness-110 hover:scale-[1.02]",style:{background:"var(--accent)"},children:["GitHub ",(0,t.jsx)(o.ArrowUpRight,{size:14})]})]})})})})}],43875)},60377,e=>{"use strict";var t=e.i(74092),a=e.i(43041);e.s(["ScrollReveal",0,function({children:e,className:s="",delay:r=0}){let[o,n]=function(e=.15){let t=(0,a.useRef)(null),[s,r]=(0,a.useState)(!1);return(0,a.useEffect)(()=>{let a=t.current;if(!a)return;if(window.matchMedia("(prefers-reduced-motion: reduce)").matches)return void r(!0);let s=new IntersectionObserver(([e])=>{e.isIntersecting&&(r(!0),s.disconnect())},{threshold:e});return s.observe(a),()=>s.disconnect()},[e]),[t,s]}(.12);return(0,t.jsx)("div",{ref:o,className:s,style:{opacity:+!!n,transform:n?"translateY(0)":"translateY(24px)",transition:`opacity 0.6s cubic-bezier(0.16, 1, 0.3, 1) ${r}s, transform 0.6s cubic-bezier(0.16, 1, 0.3, 1) ${r}s`},children:e})}],60377)}]);